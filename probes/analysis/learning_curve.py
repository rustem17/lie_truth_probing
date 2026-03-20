"""
Probe learning curves: AUROC vs number of training pairs.

Model: meta-llama/Llama-3.1-70B-Instruct (activations from last token position)
Datasets: instructed, spontaneous, sycophancy paired lie/truth activations
Probe: LogisticRegression(max_iter=1000, fit_intercept=False) on augmented pair diffs
Layer: best_layer_transfer from shared_direction.pt (1-indexed)
Validation: external paired sets (instructed_validation.json, spontaneous_validation.json, sycophancy_validation.json)
Metric: AUROC on augmented pair diffs (train, CV, external validation)
Params: n_repeats=20, n_splits=5 (CV folds), sample sizes via geomspace(5, n_pairs, 15)
"""

import sys
import json
import torch
import numpy as np
import matplotlib.pyplot as plt
import seaborn as sns
from pathlib import Path
from collections import defaultdict
from sklearn.linear_model import LogisticRegression
from sklearn.model_selection import KFold
from sklearn.metrics import roc_auc_score
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import TRAIN_DATASETS as _ALL_TRAIN, VALIDATION_MAP as _FULL_VAL_MAP, COLORS, PROBING_ROOT, ACTIVATIONS_DIR, DATA_DIR

sns.set_theme(style="whitegrid")

_LC_NAMES = {"instructed", "spontaneous", "sycophancy"}
TRAIN_DATASETS = {k: v for k, v in _ALL_TRAIN.items() if k in _LC_NAMES}
VALIDATION_MAP = {k: v[0] for k, v in _FULL_VAL_MAP.items() if k in _LC_NAMES}


def get_pair_diffs(activations, data, label_map):
    by_id = defaultdict(dict)
    for i, s in enumerate(data):
        is_lie = label_map[s["condition"]] == 1
        base_id = s["id"].rsplit("_", 1)[0] if s["id"].endswith(("_lie", "_truth")) else s["id"]
        by_id[base_id]["lie" if is_lie else "truth"] = i

    pair_ids, diffs = [], []
    for sid in sorted(by_id):
        pair = by_id[sid]
        if "lie" not in pair or "truth" not in pair:
            continue
        diffs.append(activations[pair["lie"]] - activations[pair["truth"]])
        pair_ids.append(sid)
    return np.stack(diffs), pair_ids


def augment(D):
    n = D.shape[0]
    return np.concatenate([D, -D], axis=0), np.array([1] * n + [0] * n)


def darken(hex_color, factor=0.6):
    r, g, b = [int(hex_color[i:i+2], 16) for i in (1, 3, 5)]
    return f"#{int(r*factor):02x}{int(g*factor):02x}{int(b*factor):02x}"


def run_learning_curve(D_train, D_val, sample_sizes, n_repeats, n_splits):
    train_aurocs = {n: [] for n in sample_sizes}
    cv_aurocs = {n: [] for n in sample_sizes}
    val_aurocs = {n: [] for n in sample_sizes}
    n_total = D_train.shape[0]

    for repeat in range(n_repeats):
        rng = np.random.RandomState(repeat)
        for n in sample_sizes:
            idx = rng.choice(n_total, size=n, replace=False)
            X_train, y_train = augment(D_train[idx])

            clf = LogisticRegression(max_iter=1000, fit_intercept=False)
            clf.fit(X_train, y_train)
            direction = clf.coef_[0]

            scores_train = X_train @ direction
            train_aurocs[n].append(float(roc_auc_score(y_train, scores_train)))

            if n >= 2 * n_splits:
                kf = KFold(n_splits=n_splits, shuffle=True, random_state=repeat)
                fold_aucs = []
                for tr_idx, te_idx in kf.split(np.arange(n)):
                    tr_mask = np.concatenate([tr_idx, tr_idx + n])
                    te_mask = np.concatenate([te_idx, te_idx + n])
                    fold_clf = LogisticRegression(max_iter=1000, fit_intercept=False)
                    fold_clf.fit(X_train[tr_mask], y_train[tr_mask])
                    fold_dir = fold_clf.coef_[0]
                    fold_scores = X_train[te_mask] @ fold_dir
                    fold_aucs.append(float(roc_auc_score(y_train[te_mask], fold_scores)))
                cv_aurocs[n].append(np.mean(fold_aucs))
            else:
                cv_aurocs[n].append(np.nan)

            if D_val is not None:
                X_val, y_val = augment(D_val)
                scores_val = X_val @ direction
                val_aurocs[n].append(float(roc_auc_score(y_val, scores_val)))
            else:
                val_aurocs[n].append(np.nan)

    results = {}
    for key, store in [("train_auroc", train_aurocs), ("cv_auroc", cv_aurocs), ("val_auroc", val_aurocs)]:
        means, stds = [], []
        for n in sample_sizes:
            vals = [v for v in store[n] if not np.isnan(v)]
            means.append(float(np.mean(vals)) if vals else np.nan)
            stds.append(float(np.std(vals)) if vals else np.nan)
        results[key] = {"mean": means, "std": stds}
    return results


def main(activations_dir=None, probes_dir=None, data_dir=None,
         output_dir=None, n_repeats=20, n_splits=5):
    activations_dir = Path(activations_dir) if activations_dir else ACTIVATIONS_DIR
    probes_dir = Path(probes_dir) if probes_dir else PROBING_ROOT / "probes" / "contrastive"
    data_dir = Path(data_dir) if data_dir else DATA_DIR
    output_dir = Path(output_dir) if output_dir else probes_dir / "plots"
    output_dir.mkdir(parents=True, exist_ok=True)

    shared = torch.load(probes_dir / "shared_direction.pt", weights_only=False)
    best_layer = shared["best_layer_transfer"]
    layer_idx = best_layer - 1

    print(f"layer: {best_layer} (0-indexed: {layer_idx})")

    all_results = {"layer": best_layer, "n_repeats": n_repeats, "datasets": {}}

    for name, (filename, label_map) in TRAIN_DATASETS.items():
        act_path = Path(activations_dir) / f"{name}.pt"
        data_path = Path(data_dir) / filename
        if not act_path.exists() or not data_path.exists():
            print(f"skipping {name}: missing files")
            continue

        saved = torch.load(act_path, weights_only=False)
        data = json.load(open(data_path))[:len(saved["activations"])]
        pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
        D_train = pair_diffs[:, layer_idx]
        n_pairs = len(pair_ids)

        D_val = None
        val_n_pairs = 0
        val_name_str = None
        if name in VALIDATION_MAP:
            val_name, val_file, val_label_map = VALIDATION_MAP[name]
            val_act_path = Path(activations_dir) / f"{val_name}.pt"
            val_data_path = Path(data_dir) / val_file
            if val_act_path.exists() and val_data_path.exists():
                val_saved = torch.load(val_act_path, weights_only=False)
                val_data = json.load(open(val_data_path))[:len(val_saved["activations"])]
                val_pair_diffs, val_pair_ids = get_pair_diffs(val_saved["activations"], val_data, val_label_map)
                D_val = val_pair_diffs[:, layer_idx]
                val_n_pairs = len(val_pair_ids)
                val_name_str = val_name

        sample_sizes = np.unique(np.geomspace(5, n_pairs, 15).astype(int))
        print(f"{name}: {n_pairs} train pairs, {val_n_pairs} val pairs, {len(sample_sizes)} size steps")

        results = run_learning_curve(D_train, D_val, sample_sizes, n_repeats, n_splits)
        all_results["datasets"][name] = {
            "n_pairs_total": n_pairs,
            "val_name": val_name_str,
            "val_n_pairs": val_n_pairs,
            "sample_sizes": [int(s) for s in sample_sizes],
            **results,
        }

    with open(Path(output_dir) / "learning_curve_results.json", "w") as f:
        json.dump(all_results, f, indent=2)

    fig, axes = plt.subplots(1, len(all_results["datasets"]), figsize=(6 * len(all_results["datasets"]), 5))
    if len(all_results["datasets"]) == 1:
        axes = [axes]

    for ax, (name, ds) in zip(axes, sorted(all_results["datasets"].items())):
        sizes = np.array(ds["sample_sizes"])
        color = COLORS.get(name, "gray")
        dark = darken(color)

        for key, label, c, ls in [
            ("train_auroc", "Train", color, ":"),
            ("cv_auroc", "CV", color, "-"),
            ("val_auroc", "Validation", dark, "-"),
        ]:
            mean = np.array(ds[key]["mean"])
            std = np.array(ds[key]["std"])
            mask = ~np.isnan(mean)
            if not mask.any():
                continue
            ax.plot(sizes[mask], mean[mask], color=c, linestyle=ls, marker="o", markersize=3, label=label)
            ax.fill_between(sizes[mask], (mean - std)[mask], (mean + std)[mask], color=c, alpha=0.2)

        ax.axhline(0.5, color="black", linestyle="--", linewidth=0.8)
        ax.set_xscale("log")
        ax.set_ylim(0.4, 1.05)
        ax.set_xlabel("Number of training pairs")
        ax.set_ylabel("AUROC")
        ax.set_title(f"{name} (n={ds['n_pairs_total']})")
        ax.legend(loc="lower right", fontsize=8)

    fig.suptitle(f"Learning Curves at Layer {best_layer}", fontsize=13, y=1.02)
    fig.tight_layout()
    fig.savefig(Path(output_dir) / "learning_curves.png", dpi=150, bbox_inches="tight")
    plt.close(fig)

    print(f"\nsaved to {output_dir}/learning_curves.png + learning_curve_results.json")


if __name__ == "__main__":
    fire.Fire(main)
