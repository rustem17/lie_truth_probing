"""
Sweep contrastive shared-direction configs and evaluate generalization.

Model: n/a (offline analysis of cached activations)
Data: activations/*.pt + paired JSONs (all train + validation datasets)
Params: grid over (C, agg_mode, shared_mode, layer_objective, ensemble, ensemble_k)
Layer range: 10-40 (1-indexed)
Metric: per-dataset AUROC of shared direction on pair diffs
Output: CSV (timestamped) + stdout table
"""

import sys
import json
import csv
import numpy as np
import torch
from pathlib import Path
from datetime import datetime
import fire
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
import seaborn as sns

sys.path.insert(0, str(Path(__file__).resolve().parents[1]))
from config import TRAIN_DATASETS, VALIDATION_DATASETS

sys.path.insert(0, str(Path(__file__).resolve().parents[1] / "probes" / "contrastive"))
from shared_direction import (
    get_pair_diffs, load_all, augment, train_all_directions,
    train_pooled_direction, aggregate_directions, transfer_auroc,
    cross_transfer_all_layers, compute_transfer_aggregates,
    constrained_argmax, build_ensemble,
)

LO, HI = 9, 40

CONFIGS = [
    {"label": "baseline",                "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "C=0.01",                  "C": 0.01, "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "C=0.1",                   "C": 0.1,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "C=10",                    "C": 10.0, "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "geomed",                  "C": 1.0,  "agg_mode": "geometric_median", "shared_mode": "average", "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "pooled",                  "C": 1.0,  "agg_mode": "mean",             "shared_mode": "pooled",  "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "pooled_C=0.1",            "C": 0.1,  "agg_mode": "mean",             "shared_mode": "pooled",  "layer_objective": "mean",     "ensemble": "none",              "ensemble_k": 5},
    {"label": "obj=min",                 "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "min",      "ensemble": "none",              "ensemble_k": 5},
    {"label": "obj=median",              "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "median",   "ensemble": "none",              "ensemble_k": 5},
    {"label": "obj=harmonic",            "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "harmonic", "ensemble": "none",              "ensemble_k": 5},
    {"label": "ens_top3",                "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "top_k",             "ensemble_k": 3},
    {"label": "ens_top5",                "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "top_k",             "ensemble_k": 5},
    {"label": "ens_tw5",                 "C": 1.0,  "agg_mode": "mean",             "shared_mode": "average", "layer_objective": "mean",     "ensemble": "transfer_weighted", "ensemble_k": 5},
    {"label": "geomed+harmonic",         "C": 1.0,  "agg_mode": "geometric_median", "shared_mode": "average", "layer_objective": "harmonic", "ensemble": "none",              "ensemble_k": 5},
    {"label": "pooled+min",              "C": 1.0,  "agg_mode": "mean",             "shared_mode": "pooled",  "layer_objective": "min",      "ensemble": "none",              "ensemble_k": 5},
    {"label": "geomed+ens_top5",         "C": 1.0,  "agg_mode": "geometric_median", "shared_mode": "average", "layer_objective": "mean",     "ensemble": "top_k",             "ensemble_k": 5},
    {"label": "C=0.1+geomed+harmonic",   "C": 0.1,  "agg_mode": "geometric_median", "shared_mode": "average", "layer_objective": "harmonic", "ensemble": "none",              "ensemble_k": 5},
    {"label": "C=0.1+pooled+ens_tw5",    "C": 0.1,  "agg_mode": "mean",             "shared_mode": "pooled",  "layer_objective": "mean",     "ensemble": "transfer_weighted", "ensemble_k": 5},
]


def load_validation_diffs(data_dir, activations_dir):
    diffs = {}
    for name, (filename, label_map) in VALIDATION_DATASETS.items():
        act_path = Path(activations_dir) / f"{name}.pt"
        data_path = Path(data_dir) / filename
        if not act_path.exists() or not data_path.exists():
            continue
        saved = torch.load(act_path, weights_only=False)
        data = json.load(open(data_path))[:len(saved["activations"])]
        pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
        diffs[name] = {"D": pair_diffs, "n_pairs": len(pair_ids)}
    return diffs


def score_direction_on_diffs(direction, diffs_dict, layer):
    results = {}
    for name, d in diffs_dict.items():
        if layer < d["D"].shape[1]:
            results[name] = transfer_auroc(direction, d["D"][:, layer])
    return results


def score_ensemble_on_diffs(ens_layers, ens_directions, ens_weights, diffs_dict):
    from sklearn.metrics import roc_auc_score as _auc
    results = {}
    for name, d in diffs_dict.items():
        n = d["D"].shape[0]
        labels_aug = np.concatenate([np.ones(n), np.zeros(n)])
        score_sum = np.zeros(2 * n)
        weight_sum = 0.0
        for l1 in ens_layers:
            l0 = l1 - 1
            if l0 >= d["D"].shape[1]:
                continue
            scores = d["D"][:, l0] @ ens_directions[l1]
            scores_aug = np.concatenate([scores, -scores])
            score_sum += ens_weights[l1] * scores_aug
            weight_sum += ens_weights[l1]
        if weight_sum > 0:
            results[name] = float(_auc(labels_aug, score_sum / weight_sum))
    return results


def run_config(cfg, train_diffs, val_diffs, directions_cache):
    C = cfg["C"]
    if C not in directions_cache:
        names = sorted(train_diffs.keys())
        directions_cache[C] = train_all_directions(train_diffs, names, C=C)
    directions = directions_cache[C]

    active_names = sorted(directions.keys())
    n_layers = next(iter(directions.values())).shape[0]
    transfer_pairs = [(s, t) for s in active_names for t in active_names if s != t]

    per_layer_transfer, mean_transfer = cross_transfer_all_layers(
        directions, train_diffs, n_layers, transfer_pairs)
    min_transfer, median_transfer, harmonic_transfer = compute_transfer_aggregates(
        per_layer_transfer, n_layers)

    obj_map = {
        "mean": mean_transfer,
        "min": min_transfer,
        "median": median_transfer,
        "harmonic": harmonic_transfer,
    }
    obj_values = obj_map[cfg["layer_objective"]]
    best_layer = constrained_argmax(obj_values, LO, HI)

    if cfg["shared_mode"] == "pooled":
        shared = train_pooled_direction(train_diffs, active_names, best_layer, C)
    else:
        shared = aggregate_directions(
            [directions[n][best_layer] for n in active_names], cfg["agg_mode"])

    row = {"label": cfg["label"], "layer": best_layer + 1}
    for k in ["C", "agg_mode", "shared_mode", "layer_objective", "ensemble", "ensemble_k"]:
        row[k] = cfg[k]

    train_scores = score_direction_on_diffs(shared, train_diffs, best_layer)
    val_scores = score_direction_on_diffs(shared, val_diffs, best_layer)
    for name, auroc in sorted(train_scores.items()):
        row[name] = round(auroc, 4)
    for name, auroc in sorted(val_scores.items()):
        row[name] = round(auroc, 4)

    all_aurocs = list(train_scores.values()) + list(val_scores.values())
    val_aurocs = list(val_scores.values())
    row["mean_auroc"] = round(float(np.mean(all_aurocs)), 4) if all_aurocs else 0.0
    row["min_auroc"] = round(float(min(all_aurocs)), 4) if all_aurocs else 0.0
    row["val_mean_auroc"] = round(float(np.mean(val_aurocs)), 4) if val_aurocs else 0.0
    row["val_min_auroc"] = round(float(min(val_aurocs)), 4) if val_aurocs else 0.0

    if cfg["ensemble"] != "none":
        ens_layers, ens_directions, ens_weights = build_ensemble(
            directions, train_diffs, active_names, obj_values, LO, HI,
            cfg["ensemble_k"], cfg["ensemble"], cfg["shared_mode"], cfg["agg_mode"], C)
        ens_train = score_ensemble_on_diffs(ens_layers, ens_directions, ens_weights, train_diffs)
        ens_val = score_ensemble_on_diffs(ens_layers, ens_directions, ens_weights, val_diffs)
        for name, auroc in sorted(ens_train.items()):
            row[f"ens_{name}"] = round(auroc, 4)
        for name, auroc in sorted(ens_val.items()):
            row[f"ens_{name}"] = round(auroc, 4)
        ens_all = list(ens_train.values()) + list(ens_val.values())
        row["ens_mean_auroc"] = round(float(np.mean(ens_all)), 4) if ens_all else 0.0

    return row


def plot_heatmap(rows, dataset_cols, output_dir, ts):
    sns.set_theme(style="whitegrid")
    labels = [r["label"] for r in rows]
    mat = np.array([[float(r.get(d, np.nan)) for d in dataset_cols] for r in rows])
    layers = [int(r["layer"]) for r in rows]
    pareto = [r.get("pareto", "") for r in rows]

    annot = np.empty_like(mat, dtype=object)
    for i in range(mat.shape[0]):
        for j in range(mat.shape[1]):
            v = mat[i, j]
            annot[i, j] = f"{v:.2f}\nL{layers[i]}" if not np.isnan(v) else ""

    row_labels = [f"{'* ' if p else ''}{l}" for l, p in zip(labels, pareto)]

    fig, ax = plt.subplots(figsize=(max(10, len(dataset_cols) * 1.3),
                                     max(6, len(rows) * 0.45)))
    from config import SHORT
    col_labels = [SHORT.get(d, d[:6]) for d in dataset_cols]
    sns.heatmap(mat, annot=annot, fmt="", cmap="RdYlGn", vmin=0.4, vmax=1.0,
                linewidths=0.5, ax=ax, xticklabels=col_labels, yticklabels=row_labels,
                cbar_kws={"label": "AUROC"})
    ax.set_title("Shared direction AUROC across configs (* = Pareto)")
    ax.set_xlabel("")
    ax.set_ylabel("")
    plt.tight_layout()
    plots_dir = Path(output_dir) / "plots"
    plots_dir.mkdir(parents=True, exist_ok=True)
    plot_path = plots_dir / f"sweep_heatmap_{ts}.png"
    fig.savefig(plot_path, dpi=150)
    plt.close(fig)
    print(f"Heatmap: {plot_path}")


def main(data_dir=None, activations_dir=None, output_dir=None):
    probing_root = Path(__file__).resolve().parents[1]
    if data_dir is None:
        data_dir = str(probing_root)
    if activations_dir is None:
        activations_dir = str(probing_root / "activations")
    if output_dir is None:
        output_dir = data_dir

    print(f"data_dir: {data_dir}")
    print(f"activations_dir: {activations_dir}")
    print(f"layer range: {LO+1}-{HI} (1-indexed)")
    print(f"configs: {len(CONFIGS)}\n")

    train_diffs = load_all(data_dir, activations_dir)
    val_diffs = load_validation_diffs(data_dir, activations_dir)
    print(f"\ntrain datasets: {sorted(train_diffs.keys())}")
    print(f"validation datasets: {sorted(val_diffs.keys())}")

    directions_cache = {}
    rows = []
    for i, cfg in enumerate(CONFIGS):
        print(f"\n[{i+1}/{len(CONFIGS)}] {cfg['label']}")
        row = run_config(cfg, train_diffs, val_diffs, directions_cache)
        rows.append(row)
        print(f"  layer={row['layer']}, mean_auroc={row['mean_auroc']}")

    dataset_cols = sorted(set(train_diffs.keys()) | set(val_diffs.keys()))
    for r in rows:
        vec = [r.get(d, 0.0) for d in dataset_cols]
        dominated = False
        for other in rows:
            if other is r:
                continue
            ovec = [other.get(d, 0.0) for d in dataset_cols]
            if all(o >= v for o, v in zip(ovec, vec)) and any(o > v for o, v in zip(ovec, vec)):
                dominated = True
                break
        r["pareto"] = "" if dominated else "Y"

    all_keys = []
    for r in rows:
        for k in r:
            if k not in all_keys:
                all_keys.append(k)

    ts = datetime.now().strftime("%Y%m%d_%H%M%S")
    out_path = Path(output_dir) / f"sweep_shared_configs_{ts}.csv"
    with open(out_path, "w", newline="") as f:
        writer = csv.DictWriter(f, fieldnames=all_keys)
        writer.writeheader()
        for r in rows:
            writer.writerow(r)

    print(f"\n{'='*80}")
    print(f"saved: {out_path}")
    print(f"{'='*80}\n")

    param_cols = ["label", "layer", "C", "shared_mode", "agg_mode", "layer_objective",
                  "ensemble", "mean_auroc", "min_auroc", "val_mean_auroc", "val_min_auroc", "pareto"]
    header = "  ".join(f"{c:>16}" for c in param_cols)
    print(header)
    print("-" * len(header))
    for r in rows:
        vals = [str(r.get(c, "")) for c in param_cols]
        print("  ".join(f"{v:>16}" for v in vals))

    plot_heatmap(rows, dataset_cols, output_dir, ts)


if __name__ == "__main__":
    fire.Fire(main)
