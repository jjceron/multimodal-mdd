"""Plot training curves, confusion matrices, and ROC from JSON results."""

import os
import sys
import glob as globmod
import json
import argparse
import numpy as np
import matplotlib

matplotlib.use("Agg" if not os.environ.get("DISPLAY") and os.name != "nt" else "TkAgg")
import matplotlib.pyplot as plt

RESULTS_ROOT = "outputs/results"
FIGURES_ROOT = "outputs/figures"

METRIC_KEYS = {
    "bacc": "val_bacc",
    "acc": "val_acc",
    "f1": "val_f1",
    "sens": "val_sens",
    "spec": "val_spec",
}


def _available_types():
    if not os.path.isdir(RESULTS_ROOT):
        return []
    return sorted(
        [
            d
            for d in os.listdir(RESULTS_ROOT)
            if os.path.isdir(os.path.join(RESULTS_ROOT, d))
        ]
    )


def _load_curves(benchmark, model, channels, suffix="ch"):
    path = os.path.join(
        RESULTS_ROOT, benchmark, f"{model}_{channels}{suffix}_curves.json"
    )
    with open(path) as f:
        return json.load(f)


def _load_results(benchmark, model, channels, suffix="ch"):
    path = os.path.join(RESULTS_ROOT, benchmark, f"{model}_{channels}{suffix}.json")
    with open(path) as f:
        return json.load(f)


def _merge_folds(curves, results):
    """Merge curves history into results folds. Returns list of fold dicts."""
    if results is None:
        return curves["folds"] if curves else []
    merged = []
    for rf in results["folds"]:
        fn = rf.get("fold")
        cf = None
        if curves:
            cf = next((c for c in curves.get("folds", []) if c.get("fold") == fn), None)
        entry = dict(rf)
        if cf:
            entry["history"] = cf["history"]
        merged.append(entry)
    return merged


def _plot_loss_metric(fig, axes, history, fold_num, metric_label, show_legend=False):
    epochs = np.arange(1, len(history["train_loss"]) + 1)
    ax_l, ax_r = axes

    ax_l.plot(
        epochs,
        history["train_loss"],
        color="blue",
        linestyle="-",
        label="Train Loss",
        linewidth=1.5,
    )
    val_loss = history.get("val_loss", [])
    if val_loss:
        ax_l.plot(
            epochs,
            val_loss,
            color="orange",
            linestyle="--",
            label="Val Loss",
            linewidth=1.5,
        )
    ax_l.set_xlabel("Epoch", fontsize=9)
    ax_l.set_ylabel("Loss", fontsize=9)
    ax_l.set_title(f"Fold {fold_num} — Loss", fontsize=10)
    ax_l.grid(True, alpha=0.3)

    if metric_label == "roc":
        ax_r.axis("off")
    else:
        mk = METRIC_KEYS[metric_label]
        train_acc = history.get("train_acc", [])
        if train_acc:
            ax_r.plot(
                epochs,
                train_acc,
                color="blue",
                linestyle="-",
                label="Train Acc",
                linewidth=1.5,
            )
        val_metric = history.get(mk, [])
        if val_metric:
            ax_r.plot(
                epochs,
                val_metric,
                color="orange",
                linestyle="--",
                label=f"Val {metric_label.upper()}",
                linewidth=1.5,
            )
        ax_r.set_xlabel("Epoch", fontsize=9)
        ax_r.set_ylabel(metric_label.upper(), fontsize=9)
        ax_r.set_title(f"Fold {fold_num} — {metric_label.upper()}", fontsize=10)
        ax_r.grid(True, alpha=0.3)

    if show_legend:
        ax_l.legend(fontsize=7, loc="upper right")
        if metric_label != "roc":
            ax_r.legend(fontsize=7, loc="lower right")


def _find_fold(folds_data, fold_num):
    """Find fold by number, with fallback to first entry for crossmodal_nested."""
    fe = next((f for f in folds_data if f.get("fold") == fold_num), None)
    if fe is None and len(folds_data) == 1:
        fe = folds_data[0]
    return fe


def _plot_cm_pair(fig, axes, fold_entry, fold_num, show_title=True):
    has_window = "test_cm_window" in fold_entry or "test_cm_subject" in fold_entry
    if not has_window:
        cm = np.array(fold_entry["test_cm"])
        ax = axes if not isinstance(axes, np.ndarray) else axes[0]
        im = ax.imshow(cm, cmap="Blues", vmin=0, vmax=cm.max() if cm.max() > 0 else 1)
        ax.set_xticks([0, 1])
        ax.set_yticks([0, 1])
        ax.set_xticklabels(["HC", "MDD"])
        ax.set_yticklabels(["HC", "MDD"])
        title = f"Fold {fold_num} — Subjects" if show_title else "Subjects"
        ax.set_title(title, fontsize=10)
        for i in range(2):
            for j in range(2):
                ax.text(
                    j,
                    i,
                    str(cm[i, j]),
                    ha="center",
                    va="center",
                    fontsize=12,
                    fontweight="bold",
                    color="white" if cm[i, j] > cm.max() * 0.5 else "black",
                )
        fig.colorbar(im, ax=ax, fraction=0.046, pad=0.04)
        if isinstance(axes, np.ndarray):
            axes[1].remove()
        return
    ax_l, ax_r = axes
    cm_w = np.array(fold_entry["test_cm_window"])
    cm_s = np.array(fold_entry["test_cm_subject"])
    for ax, cm, label in [(ax_l, cm_w, "Windows"), (ax_r, cm_s, "Subjects")]:
        im = ax.imshow(cm, cmap="Blues", vmin=0, vmax=cm.max() if cm.max() > 0 else 1)
        ax.set_xticks([0, 1])
        ax.set_yticks([0, 1])
        ax.set_xticklabels(["HC", "MDD"])
        ax.set_yticklabels(["HC", "MDD"])
        title = f"Fold {fold_num} — {label}" if show_title else label
        ax.set_title(title, fontsize=10)
        for i in range(2):
            for j in range(2):
                ax.text(
                    j,
                    i,
                    str(cm[i, j]),
                    ha="center",
                    va="center",
                    fontsize=12,
                    fontweight="bold",
                    color="white" if cm[i, j] > cm.max() * 0.5 else "black",
                )
        fig.colorbar(im, ax=ax, fraction=0.046, pad=0.04)


def _plot_roc_pair(fig, axes, fold_entry, fold_num, show_legend=False):
    ax_l, ax_r = axes

    history = fold_entry.get("history", {})
    if history:
        epochs = np.arange(1, len(history["train_loss"]) + 1)
        ax_l.plot(
            epochs,
            history["train_loss"],
            color="blue",
            linestyle="-",
            label="Train Loss",
            linewidth=1.5,
        )
        ax_l.plot(
            epochs,
            history["val_loss"],
            color="orange",
            linestyle="--",
            label="Val Loss",
            linewidth=1.5,
        )
        ax_l.set_xlabel("Epoch", fontsize=9)
        ax_l.set_ylabel("Loss", fontsize=9)
        ax_l.set_title(f"Fold {fold_num} — Loss", fontsize=10)
        ax_l.grid(True, alpha=0.3)
        if show_legend:
            ax_l.legend(fontsize=7, loc="upper right")
    else:
        ax_l.text(
            0.5,
            0.5,
            "No training curves",
            ha="center",
            va="center",
            transform=ax_l.transAxes,
        )

    roc = fold_entry.get("test_roc", {})
    if roc and "y_true" in roc:
        y_true = np.array(roc["y_true"], dtype=np.float64)
        y_prob = np.array(roc["y_prob"], dtype=np.float64)
        thresholds = np.sort(np.unique(y_prob))[::-1]
        tpr, fpr = [0.0], [0.0]
        for t in thresholds:
            yp = (y_prob >= t).astype(np.float64)
            tp = (yp * y_true).sum()
            fp = (yp * (1 - y_true)).sum()
            fn = ((1 - yp) * y_true).sum()
            tn = ((1 - yp) * (1 - y_true)).sum()
            tpr.append(tp / (tp + fn) if (tp + fn) > 0 else 0.0)
            fpr.append(fp / (fp + tn) if (fp + tn) > 0 else 0.0)
        tpr.append(1.0)
        fpr.append(1.0)
        auc = fold_entry.get("test_roc_auc", 0)
        ax_r.plot(fpr, tpr, color="orange", linewidth=1.5, label=f"ROC (AUC={auc:.3f})")
        ax_r.plot(
            [0, 1], [0, 1], color="blue", linestyle="--", linewidth=1.0, label="Chance"
        )
        ax_r.legend(fontsize=7, loc="lower right")
        ax_r.set_title(f"Fold {fold_num} — ROC", fontsize=10)
    else:
        ax_r.text(
            0.5, 0.5, "No ROC data", ha="center", va="center", transform=ax_r.transAxes
        )
        ax_r.set_title(f"Fold {fold_num} — ROC", fontsize=10)


def _average_histories(histories):
    """Average training histories across runs, truncating to min epoch count.

    Returns a dict with mean values under normal keys + std under key+'_std'.
    """
    numeric_keys = [
        "train_loss",
        "val_loss",
        "train_acc",
        "val_acc",
        "val_bacc",
        "val_f1",
        "val_sens",
        "val_spec",
        "val_subj_bacc",
        "val_subj_sens",
        "val_subj_spec",
        "entropy",
        "lr",
    ]
    active_keys = [
        k for k in numeric_keys if all(k in h and len(h[k]) > 0 for h in histories)
    ]
    result = {}
    for key in active_keys:
        lengths = [len(h[key]) for h in histories]
        min_len = min(lengths)
        arr = np.array([h[key][:min_len] for h in histories], dtype=np.float64)
        result[key] = arr.mean(axis=0).tolist()
        result[key + "_std"] = arr.std(axis=0).tolist()
    return result


def _resolve_model(results_root, bench_type, model_arg):
    """Resolve model name: use --model if given, else auto-detect if exactly one subfolder."""
    if model_arg:
        return model_arg
    models_dir = os.path.join(results_root, bench_type)
    if not os.path.isdir(models_dir):
        return None
    candidates = sorted(
        [
            d
            for d in os.listdir(models_dir)
            if os.path.isdir(os.path.join(models_dir, d))
        ]
    )
    if len(candidates) == 0:
        return None
    if len(candidates) == 1:
        print(f"  Auto-detected model: {candidates[0]}")
        return candidates[0]
    print(f"ERROR: multiple models found in {models_dir}/. Use --model to specify one:")
    for c in candidates:
        print(f"  {c}")
    sys.exit(1)


def _detect_type_and_load(args):
    """Detect structure (nested vs classical) and load data. Returns (folds_data, hist_key, out_dir)."""
    if args.type == "crossmodal_nested" or (args.type is None and args.tag):
        return _load_crossmodal_nested(args)
    if args.type is None:
        print("ERROR: --type or --tag required")
        sys.exit(1)
    nested_path = os.path.join(RESULTS_ROOT, args.type, args.model, "results.json")
    if os.path.exists(nested_path):
        # Nested structure: <type>/<model>/results.json
        results = json.load(open(nested_path))
        out_dir = os.path.join(FIGURES_ROOT, args.type, args.model)
        os.makedirs(out_dir, exist_ok=True)
        subtype = args.subtype or "fusion"
        hist_key = {
            "eeg": "eeg_history",
            "aud": "aud_history",
            "fusion": "fusion_history",
        }[subtype]
        folds_data = results["folds"]
        for fe in folds_data:
            if hist_key not in fe or not fe[hist_key]:
                print(
                    f"  Fold {fe.get('fold', '?')}: no {hist_key} saved (re-run with updated script)"
                )
        return folds_data, hist_key, out_dir, results
    # Classical structure: <type>/<modality>/<model>_<channels>ch.json
    suffix = "mel" if args.modality == "audio" else "ch"
    benchmark = f"{args.type}/{args.modality}"
    curves_path = os.path.join(
        RESULTS_ROOT, benchmark, f"{args.model}_{args.channels}{suffix}_curves.json"
    )
    results_path = os.path.join(
        RESULTS_ROOT, benchmark, f"{args.model}_{args.channels}{suffix}.json"
    )
    curves = json.load(open(curves_path)) if os.path.exists(curves_path) else None
    results = json.load(open(results_path)) if os.path.exists(results_path) else None
    if curves is None and results is None:
        print(f"ERROR: no files found for {args.model}_{args.channels}{suffix}")
        sys.exit(1)
    folds_data = _merge_folds(curves, results)
    out_dir = os.path.join(
        FIGURES_ROOT, benchmark, f"{args.model}_{args.channels}{suffix}"
    )
    os.makedirs(out_dir, exist_ok=True)
    return folds_data, "history", out_dir, results


def _find_experiment_dir(tag, seed, base_dirs):
    """Search for experiment dir matching tag+seed across base_dirs.
    Returns (experiment_dir, results_json) or raises SystemExit."""
    for base in base_dirs:
        pattern = os.path.join(
            base, f"mhcmattn_sngkf_seed{seed}_*tag{tag}"
        )
        dirs = sorted(globmod.glob(pattern))
        if not dirs:
            pattern = os.path.join(
                base, "**", f"mhcmattn_sngkf_seed{seed}_*tag{tag}"
            )
            dirs = sorted(globmod.glob(pattern, recursive=True))
        if dirs:
            exp_dir = dirs[-1]
            results = json.load(open(os.path.join(exp_dir, "results.json")))
            return exp_dir, results
    print(f"ERROR: no experiment dir for tag={tag}, seed={seed}")
    sys.exit(1)


def _load_crossmodal_nested(args):
    if args.type is not None:
        bases = [os.path.join(RESULTS_ROOT, args.type)]
    else:
        bases = [os.path.join(RESULTS_ROOT, d) for d in _available_types()]

    exp_dir, results = _find_experiment_dir(args.tag, args.seed, bases)

    subtype = args.subtype or "fusion"
    hist_key = {
        "eeg": "eeg_backbone_history",
        "aud": "aud_backbone_history",
        "fusion": "fusion_history",
    }[subtype]

    avg_inner = args.avg_inner or args.inner_fold is None

    folds_data = []
    for fd in results["folds"]:
        ofi = fd["fold"]
        if args.fold is not None and ofi != args.fold:
            continue
        inner_folds = fd.get("inner_folds", [])

        if avg_inner:
            histories = []
            for inf in inner_folds:
                hist = inf.get(hist_key, {})
                if hist and len(hist.get("train_loss", [])) > 0:
                    histories.append(hist)
            if histories:
                avg_hist = _average_histories(histories)
                folds_data.append(
                    {
                        "fold": f"{ofi} (avg {len(histories)} inner)",
                        hist_key: avg_hist,
                        "test_metrics": fd.get("test_metrics", {}),
                        "test_cm": fd.get("test_cm", []),
                        "test_roc": fd.get("test_roc", {}),
                        "test_bacc": fd.get("test_bacc"),
                        "test_auc": fd.get("test_auc"),
                    }
                )
        else:
            for inf in inner_folds:
                ifi = inf["inner_fold"]
                if args.inner_fold is not None and ifi != args.inner_fold:
                    continue
                hist = inf.get(hist_key, {})
                folds_data.append(
                    {
                        "fold": f"{ofi}.{ifi}",
                        hist_key: hist,
                        "test_metrics": fd.get("test_metrics", {}),
                        "test_cm": fd.get("test_cm", []),
                        "test_roc": fd.get("test_roc", {}),
                        "test_bacc": fd.get("test_bacc"),
                        "test_auc": fd.get("test_auc"),
                    }
                )

    out_dir = os.path.join(FIGURES_ROOT, "crossmodal_nested", args.tag)
    os.makedirs(out_dir, exist_ok=True)
    return folds_data, hist_key, out_dir, results


def main():
    avail_types = _available_types()
    if not avail_types:
        print(f"ERROR: no type directories found under {RESULTS_ROOT}/")
        sys.exit(1)

    parser = argparse.ArgumentParser(description="Plot training diagnostics")
    parser.add_argument(
        "--type",
        type=str,
        default=None,
        help=f"Experiment type (optional; auto-detected from --tag/--seed if omitted). Available: {avail_types}",
    )
    parser.add_argument(
        "--model",
        type=str,
        default=None,
        help="Model subfolder/key. Auto-detected if exactly one exists.",
    )
    parser.add_argument(
        "--channels",
        type=int,
        default=64,
        help="Feature count (channels for EEG, mels for audio)",
    )
    parser.add_argument(
        "--modality",
        type=str,
        default="eeg",
        choices=["eeg", "audio"],
        help="Data modality (eeg=64ch, audio=64mel)",
    )
    parser.add_argument("--fold", type=int, default=None, help="Fold number (1-based)")
    parser.add_argument(
        "--inner-fold",
        dest="inner_fold",
        type=int,
        default=None,
        help="Inner fold number (crossmodal_nested only). Default: averages all inner folds per outer fold.",
    )
    parser.add_argument(
        "--avg-inner",
        action="store_true",
        help="Average all inner folds for each outer fold (shows mean±std band)",
    )
    parser.add_argument("--all", action="store_true", help="Show all folds in a grid")
    parser.add_argument(
        "--metric",
        type=str,
        default=None,
        choices=["bacc", "acc", "f1", "sens", "spec", "roc"],
        help="Metric to plot alongside loss",
    )
    parser.add_argument("--cm", action="store_true", help="Show confusion matrices")
    parser.add_argument(
        "--cm-overall",
        action="store_true",
        help="Show overall confusion matrix (aggregated across folds)",
    )
    parser.add_argument(
        "--save_png", action="store_true", help="Save PNG instead of displaying"
    )
    parser.add_argument(
        "--subtype",
        type=str,
        default=None,
        choices=["eeg", "aud", "fusion"],
        help="History to plot: eeg, aud, fusion (nested structure only)",
    )
    parser.add_argument(
        "--tag", type=str, default=None, help="Experiment tag (crossmodal_nested only)"
    )
    parser.add_argument(
        "--seed", type=int, default=42, help="Experiment seed (crossmodal_nested only)"
    )
    args = parser.parse_args()
    if args.type is not None and args.type != "crossmodal_nested":
        args.model = _resolve_model(RESULTS_ROOT, args.type, args.model)

    folds_data, hist_key, out_dir, results = _detect_type_and_load(args)

    # ── Confusion matrix ───────────────────────────────────────────────
    if args.cm:
        if results is None:
            print("ERROR: no results JSON with confusion matrix data")
            sys.exit(1)

        show_all = args.all or args.fold is None
        has_window_data = any("test_cm_window" in f for f in folds_data)
        n_cols = 2 if has_window_data else 1

        if show_all:
            k = len(folds_data)
            fig, axes = plt.subplots(
                k,
                n_cols,
                figsize=(7 if has_window_data else 3.5, 3.2 * k),
                constrained_layout=True,
            )
            if k == 1:
                axes = np.array([axes])
            for i, fe in enumerate(folds_data):
                _plot_cm_pair(fig, axes[i], fe, fe.get("fold", i + 1), show_title=k > 1)
            name = "all_folds_cm"
        else:
            fe = _find_fold(folds_data, args.fold)
            if fe is None:
                print(f"ERROR: fold {args.fold} not found")
                sys.exit(1)
            fig, axes = plt.subplots(
                1, n_cols, figsize=(7 if has_window_data else 3.5, 3.2)
            )
            _plot_cm_pair(fig, axes, fe, args.fold)
            name = f"fold{args.fold}_cm"

        if args.save_png:
            fname = os.path.join(out_dir, f"{name}.png")
            fig.savefig(fname, dpi=150, bbox_inches="tight")
            print(f"Saved: {fname}")
        else:
            plt.show()
        return

    # ── Overall confusion matrix ────────────────────────────────────────
    if args.cm_overall:
        if results is None:
            print("ERROR: no results JSON with confusion matrix data")
            sys.exit(1)

        folds_data = results["folds"]
        has_window_data = any("test_cm_window" in f for f in folds_data)
        if has_window_data:
            cm_w = np.sum([np.array(f["test_cm_window"]) for f in folds_data], axis=0)
            cm_s = np.sum([np.array(f["test_cm_subject"]) for f in folds_data], axis=0)
            fig, axes = plt.subplots(1, 2, figsize=(7, 3.2), constrained_layout=True)
            fe = {"test_cm_window": cm_w, "test_cm_subject": cm_s}
            _plot_cm_pair(fig, axes, fe, 0, show_title=False)
            axes[0].set_title("Overall — Windows", fontsize=10)
            axes[1].set_title("Overall — Subjects", fontsize=10)
        else:
            cm = np.sum([np.array(f["test_cm"]) for f in folds_data], axis=0)
            fig, ax = plt.subplots(1, 1, figsize=(3.5, 3.2), constrained_layout=True)
            fe = {"test_cm": cm.tolist()}
            _plot_cm_pair(fig, ax, fe, 0, show_title=False)
        if args.save_png:
            fname = os.path.join(out_dir, "overall_cm.png")
            fig.savefig(fname, dpi=150, bbox_inches="tight")
            print(f"Saved: {fname}")
        else:
            plt.show()
        return

    # ── ROC curves ─────────────────────────────────────────────────────
    if args.metric == "roc":
        if results is None:
            print("ERROR: no results JSON with ROC data")
            sys.exit(1)

        show_all = args.all or args.fold is None

        if show_all:
            k = len(folds_data)
            fig, axes = plt.subplots(
                k, 2, figsize=(10, 3.2 * k), constrained_layout=True
            )
            if k == 1:
                axes = np.array([axes])
            for i, fe in enumerate(folds_data):
                _plot_roc_pair(
                    fig, axes[i], fe, fe.get("fold", i + 1), show_legend=i == 0
                )
            name = "all_folds_roc"
        else:
            fe = _find_fold(folds_data, args.fold)
            if fe is None:
                print(f"ERROR: fold {args.fold} not found")
                sys.exit(1)
            fig, axes = plt.subplots(1, 2, figsize=(10, 4))
            _plot_roc_pair(fig, axes, fe, args.fold, show_legend=True)
            name = f"fold{args.fold}_roc"

        if args.save_png:
            fname = os.path.join(out_dir, f"{name}.png")
            fig.savefig(fname, dpi=150, bbox_inches="tight")
            print(f"Saved: {fname}")
        else:
            plt.show()
        return

    # ── Training curves (bacc, acc, f1, sens, spec) ────────────────────
    if args.metric:
        show_all = args.all or args.fold is None

        if show_all:
            k = len(folds_data)
            fig, axes = plt.subplots(k, 2, figsize=(10, 3 * k), constrained_layout=True)
            if k == 1:
                axes = np.array([axes])
            for i, fe in enumerate(folds_data):
                hist = fe.get(hist_key)
                if hist is None or len(hist.get("train_loss", [])) == 0:
                    ax_l, ax_r = axes[i]
                    ax_l.text(
                        0.5,
                        0.5,
                        "No curves",
                        ha="center",
                        va="center",
                        transform=ax_l.transAxes,
                    )
                    ax_r.text(
                        0.5,
                        0.5,
                        "No curves",
                        ha="center",
                        va="center",
                        transform=ax_r.transAxes,
                    )
                    continue
                _plot_loss_metric(
                    fig,
                    axes[i],
                    hist,
                    fe.get("fold", i + 1),
                    args.metric,
                    show_legend=i == 0,
                )
            name = f"all_folds_{args.metric}"
        else:
            fe = _find_fold(folds_data, args.fold)
            if fe is None:
                print(f"ERROR: fold {args.fold} not found")
                sys.exit(1)
            hist = fe.get(hist_key)
            if hist is None or len(hist.get("train_loss", [])) == 0:
                print(f"ERROR: fold {args.fold} has no training curves")
                sys.exit(1)
            fig, axes = plt.subplots(1, 2, figsize=(10, 4))
            _plot_loss_metric(fig, axes, hist, args.fold, args.metric, show_legend=True)
            name = f"fold{args.fold}_{args.metric}"

        if args.save_png:
            fname = os.path.join(out_dir, f"{name}.png")
            fig.savefig(fname, dpi=150, bbox_inches="tight")
            print(f"Saved: {fname}")
        else:
            plt.show()
        return

    # ── Default: loss + bacc for all folds ─────────────────────────────
    folds_data = folds_data  # already loaded above
    show_all = args.all or args.fold is None

    if show_all:
        k = len(folds_data)
        fig, axes = plt.subplots(k, 2, figsize=(10, 3 * k), constrained_layout=True)
        if k == 1:
            axes = np.array([axes])
        for i, fe in enumerate(folds_data):
            hist = fe.get(hist_key)
            if hist is None or len(hist.get("train_loss", [])) == 0:
                ax_l, ax_r = axes[i]
                ax_l.text(
                    0.5,
                    0.5,
                    "No curves",
                    ha="center",
                    va="center",
                    transform=ax_l.transAxes,
                )
                ax_r.text(
                    0.5,
                    0.5,
                    "No curves",
                    ha="center",
                    va="center",
                    transform=ax_r.transAxes,
                )
                continue
            _plot_loss_metric(
                fig, axes[i], hist, fe.get("fold", i + 1), "bacc", show_legend=i == 0
            )
        name = "all_folds_bacc"
    else:
        fe = _find_fold(folds_data, args.fold)
        if fe is None:
            print(f"ERROR: fold {args.fold} not found")
            sys.exit(1)
        hist = fe.get(hist_key)
        if hist is None or len(hist.get("train_loss", [])) == 0:
            print(f"ERROR: fold {args.fold} has no training curves")
            sys.exit(1)
        fig, axes = plt.subplots(1, 2, figsize=(10, 4))
        _plot_loss_metric(fig, axes, hist, args.fold, "bacc", show_legend=True)
        name = f"fold{args.fold}_bacc"

    if args.save_png:
        fname = os.path.join(out_dir, f"{name}.png")
        fig.savefig(fname, dpi=150, bbox_inches="tight")
        print(f"Saved: {fname}")
    else:
        plt.show()


if __name__ == "__main__":
    main()
