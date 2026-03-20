"""
Shared contrastive direction analysis across deception conditions.

For each dataset, compute per-layer LR direction on augmented pair diffs.
Then measure cosine similarity and cross-transfer AUROC between directions.

Params:
  layer_range      1-indexed inclusive range for best-layer selection (default "20,40")
  layer_objective  which aggregate picks the shared layer: mean|min|median|harmonic
  shared_mode      how to build the shared direction: average|pooled
  C                inverse regularization strength for LogisticRegression (default 1.0)
  agg_mode         how to aggregate per-dataset directions: mean|geometric_median
  ensemble         multi-layer ensembling: none|top_k|transfer_weighted
  ensemble_k       number of layers for ensemble (default 5)

Input: activations/{name}.pt + paired dataset JSONs
Output: probes/contrastive/shared_direction.pt
"""

import sys
import json
import torch
import numpy as np
from pathlib import Path
from collections import defaultdict
from sklearn.linear_model import LogisticRegression
from sklearn.metrics import roc_auc_score
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import TRAIN_DATASETS


def cosine_sim(a, b):
    return float(np.dot(a, b) / (np.linalg.norm(a) * np.linalg.norm(b)))


def constrained_argmax(values, lo, hi):
    return lo + int(np.argmax(values[lo:hi]))


def geometric_median(vectors, max_iter=100, tol=1e-6):
    y = np.mean(vectors, axis=0)
    for _ in range(max_iter):
        dists = np.array([np.linalg.norm(y - v) for v in vectors])
        dists = np.maximum(dists, 1e-12)
        weights = 1.0 / dists
        y_new = np.average(vectors, axis=0, weights=weights)
        if np.linalg.norm(y_new - y) < tol:
            break
        y = y_new
    return y / np.linalg.norm(y)


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


def load_all(data_dir, activations_dir):
    diffs = {}
    for name, (filename, label_map) in TRAIN_DATASETS.items():
        act_path = Path(activations_dir) / f"{name}.pt"
        data_path = Path(data_dir) / filename
        if not act_path.exists() or not data_path.exists():
            print(f"Skipping {name}: missing files")
            continue
        saved = torch.load(act_path, weights_only=False)
        data = json.load(open(data_path))[:len(saved["activations"])]
        pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
        diffs[name] = {"D": pair_diffs, "n_pairs": len(pair_ids)}
    return diffs


def augment(D):
    n = D.shape[0]
    return np.concatenate([D, -D], axis=0), np.array([1] * n + [0] * n)


def train_all_directions(diffs, train_names, C=1.0):
    directions = {}
    for name in train_names:
        if name not in diffs:
            continue
        D = diffs[name]["D"]
        n_pairs, n_layers, _ = D.shape
        dirs = []
        for layer in range(n_layers):
            X, y = augment(D[:, layer])
            clf = LogisticRegression(C=C, max_iter=1000, fit_intercept=False)
            clf.fit(X, y)
            d = clf.coef_[0]
            dirs.append(d / np.linalg.norm(d))
        directions[name] = np.stack(dirs)
        print(f"{name}: {n_pairs} pairs, {n_layers} layers")
    return directions


def train_pooled_direction(diffs, names, layer, C=1.0):
    all_D = np.concatenate([diffs[n]["D"][:, layer] for n in names], axis=0)
    X, y = augment(all_D)
    clf = LogisticRegression(C=C, max_iter=1000, fit_intercept=False)
    clf.fit(X, y)
    d = clf.coef_[0]
    return d / np.linalg.norm(d)


def aggregate_directions(dir_list, agg_mode="mean"):
    if agg_mode == "geometric_median":
        return geometric_median(dir_list)
    avg = np.mean(dir_list, axis=0)
    return avg / np.linalg.norm(avg)


def transfer_auroc(direction, diffs_tgt_layer):
    X, y = augment(diffs_tgt_layer)
    scores = X @ direction
    return float(roc_auc_score(y, scores))


def cross_transfer(directions, diffs, layer, transfer_pairs):
    results = {}
    for src, tgt in transfer_pairs:
        results[f"{src}→{tgt}"] = transfer_auroc(directions[src][layer], diffs[tgt]["D"][:, layer])
    return results


def cross_transfer_all_layers(directions, diffs, n_layers, transfer_pairs):
    transfer_pairs = [(s, t) for s, t in transfer_pairs if s in directions and t in diffs]

    per_layer = {f"{s}→{t}": [] for s, t in transfer_pairs}
    for layer in range(n_layers):
        for src, tgt in transfer_pairs:
            per_layer[f"{src}→{tgt}"].append(
                transfer_auroc(directions[src][layer], diffs[tgt]["D"][:, layer])
            )

    mean_transfer = [
        np.mean([per_layer[k][l] for k in per_layer]) for l in range(n_layers)
    ]
    return per_layer, mean_transfer


def compute_transfer_aggregates(per_layer_transfer, n_layers):
    keys = list(per_layer_transfer.keys())
    min_vals, median_vals, harmonic_vals = [], [], []
    for l in range(n_layers):
        vals = [per_layer_transfer[k][l] for k in keys]
        min_vals.append(float(min(vals)))
        median_vals.append(float(np.median(vals)))
        pos = [v for v in vals if v > 0]
        harmonic_vals.append(len(pos) / sum(1.0 / v for v in pos) if pos else 0.0)
    return min_vals, median_vals, harmonic_vals


def build_ensemble(directions, diffs, active_names, objective_values, lo, hi,
                   ensemble_k, ensemble_mode, shared_mode, agg_mode, C):
    band_layers = list(range(lo, hi))
    band_scores = [(l, objective_values[l]) for l in band_layers]
    band_scores.sort(key=lambda x: x[1], reverse=True)
    top_k = band_scores[:ensemble_k]

    layers = [l for l, _ in top_k]
    if ensemble_mode == "transfer_weighted":
        raw = np.array([s for _, s in top_k])
        weights = raw / raw.sum()
    else:
        weights = np.ones(len(layers)) / len(layers)

    ens_directions = {}
    for l in layers:
        if shared_mode == "pooled":
            ens_directions[l + 1] = train_pooled_direction(diffs, active_names, l, C)
        else:
            ens_directions[l + 1] = aggregate_directions(
                [directions[n][l] for n in active_names], agg_mode)

    ens_weights = {l + 1: float(w) for l, w in zip(layers, weights)}
    ens_layers = [l + 1 for l in layers]
    return ens_layers, ens_directions, ens_weights


def analyze(data_dir="../..", activations_dir="../../activations", output_dir=".",
            datasets=None, layer_range="20,40", layer_objective="mean",
            shared_mode="average", C=1.0, agg_mode="mean",
            ensemble="none", ensemble_k=5):
    Path(output_dir).mkdir(parents=True, exist_ok=True)

    parts = layer_range.split(",")
    lo = int(parts[0]) - 1
    hi = int(parts[1])
    print(f"layer selection range: {lo+1}-{hi} (1-indexed)")
    print(f"C={C}, agg_mode={agg_mode}, ensemble={ensemble}, ensemble_k={ensemble_k}")

    diffs = load_all(data_dir, activations_dir)
    if datasets:
        keep = set(datasets) if isinstance(datasets, (list, tuple)) else {d.strip() for d in datasets.split(",")}
        diffs = {k: v for k, v in diffs.items() if k in keep}

    directions = train_all_directions(diffs, sorted(diffs.keys()), C=C)
    n_layers = next(iter(directions.values())).shape[0]

    active_names = sorted(directions.keys())
    active_pairs = [(a, b) for i, a in enumerate(active_names) for b in active_names[i+1:]]
    transfer_pairs = [(s, t) for s in active_names for t in active_names if s != t]

    layer_sims = {f"{a}_vs_{b}": [] for a, b in active_pairs}
    for layer in range(n_layers):
        for a, b in active_pairs:
            layer_sims[f"{a}_vs_{b}"].append(cosine_sim(directions[a][layer], directions[b][layer]))

    mean_sims = [
        np.mean([layer_sims[f"{a}_vs_{b}"][l] for a, b in active_pairs])
        for l in range(n_layers)
    ]
    best_layer_cos = constrained_argmax(mean_sims, lo, hi)

    print(f"\n--- cosine similarity ---")
    print(f"best layer: {best_layer_cos + 1} (mean cosine = {mean_sims[best_layer_cos]:.4f})")
    for a, b in active_pairs:
        print(f"  {a} vs {b}: {layer_sims[f'{a}_vs_{b}'][best_layer_cos]:.4f}")

    per_layer_transfer, mean_transfer = cross_transfer_all_layers(directions, diffs, n_layers, transfer_pairs)
    min_transfer, median_transfer, harmonic_transfer = compute_transfer_aggregates(per_layer_transfer, n_layers)

    best_layer_transfer = constrained_argmax(mean_transfer, lo, hi)
    best_layer_min = constrained_argmax(min_transfer, lo, hi)
    best_layer_median = constrained_argmax(median_transfer, lo, hi)
    best_layer_harmonic = constrained_argmax(harmonic_transfer, lo, hi)

    objective_map = {
        "mean": (best_layer_transfer, mean_transfer),
        "min": (best_layer_min, min_transfer),
        "median": (best_layer_median, median_transfer),
        "harmonic": (best_layer_harmonic, harmonic_transfer),
    }

    print(f"\n--- cross-condition transfer ---")
    print(f"best layer (mean):     {best_layer_transfer + 1} (AUROC = {mean_transfer[best_layer_transfer]:.4f})")
    print(f"best layer (min):      {best_layer_min + 1} (AUROC = {min_transfer[best_layer_min]:.4f})")
    print(f"best layer (median):   {best_layer_median + 1} (AUROC = {median_transfer[best_layer_median]:.4f})")
    print(f"best layer (harmonic): {best_layer_harmonic + 1} (AUROC = {harmonic_transfer[best_layer_harmonic]:.4f})")
    print(f"using: {layer_objective}")
    transfer_at_best = cross_transfer(directions, diffs, best_layer_transfer, transfer_pairs)
    for k, v in transfer_at_best.items():
        print(f"  {k}: AUROC={v:.4f}")

    if "spontaneous" in directions and "sycophancy" in directions:
        sp_sy_cosines = [
            cosine_sim(directions["spontaneous"][l], directions["sycophancy"][l])
            for l in range(n_layers)
        ]
        best_sp_sy = constrained_argmax(sp_sy_cosines, lo, hi)

        sp_sy_transfer = []
        for layer in range(n_layers):
            a1 = transfer_auroc(directions["spontaneous"][layer], diffs["sycophancy"]["D"][:, layer])
            a2 = transfer_auroc(directions["sycophancy"][layer], diffs["spontaneous"]["D"][:, layer])
            sp_sy_transfer.append((a1 + a2) / 2)
        best_sp_sy_transfer = constrained_argmax(sp_sy_transfer, lo, hi)

        print(f"\n--- spontaneous + sycophancy only ---")
        print(f"best cosine layer: {best_sp_sy + 1} (cosine = {sp_sy_cosines[best_sp_sy]:.4f})")
        print(f"best transfer layer: {best_sp_sy_transfer + 1} (mean AUROC = {sp_sy_transfer[best_sp_sy_transfer]:.4f})")
        print(f"  sp→syc: {transfer_auroc(directions['spontaneous'][best_sp_sy_transfer], diffs['sycophancy']['D'][:, best_sp_sy_transfer]):.4f}")
        print(f"  syc→sp: {transfer_auroc(directions['sycophancy'][best_sp_sy_transfer], diffs['spontaneous']['D'][:, best_sp_sy_transfer]):.4f}")
    else:
        best_sp_sy_transfer = best_layer_transfer
        sp_sy_cosines = []
        sp_sy_transfer = []

    best_layer, obj_values = objective_map[layer_objective]

    if shared_mode == "pooled":
        shared_all = train_pooled_direction(diffs, active_names, best_layer, C)
    else:
        shared_all = aggregate_directions(
            [directions[n][best_layer] for n in active_names], agg_mode)

    sp_sy_names = [n for n in ["spontaneous", "sycophancy"] if n in directions]
    if sp_sy_names:
        if shared_mode == "pooled":
            shared_sp_sy = train_pooled_direction(diffs, sp_sy_names, best_sp_sy_transfer, C)
        else:
            shared_sp_sy = aggregate_directions(
                [directions[n][best_sp_sy_transfer] for n in sp_sy_names], agg_mode)
    else:
        shared_sp_sy = None

    all_directions = {}
    for layer in range(n_layers):
        if shared_mode == "pooled":
            all_directions[layer] = train_pooled_direction(diffs, active_names, layer, C)
        else:
            all_directions[layer] = aggregate_directions(
                [directions[n][layer] for n in active_names], agg_mode)

    ens_layers, ens_directions, ens_weights = [], {}, {}
    if ensemble != "none":
        ens_layers, ens_directions, ens_weights = build_ensemble(
            directions, diffs, active_names, obj_values, lo, hi,
            ensemble_k, ensemble, shared_mode, agg_mode, C)
        print(f"\n--- ensemble ({ensemble}, k={ensemble_k}) ---")
        for l in ens_layers:
            print(f"  layer {l}: weight={ens_weights[l]:.3f}")

    print(f"\nshared_mode={shared_mode}, layer_objective={layer_objective}, best_layer={best_layer + 1}")

    torch.save({
        "shared_direction_all": shared_all,
        "shared_direction_sp_sy": shared_sp_sy,
        "best_layer_cosine": best_layer_cos + 1,
        "best_layer_transfer": best_layer_transfer + 1,
        "best_layer_min_transfer": best_layer_min + 1,
        "best_layer_median_transfer": best_layer_median + 1,
        "best_layer_harmonic_transfer": best_layer_harmonic + 1,
        "best_layer_sp_sy_transfer": best_sp_sy_transfer + 1,
        "all_directions": all_directions,
        "probe_type": "contrastive",
        "layer_range": [lo + 1, hi],
        "layer_objective": layer_objective,
        "shared_mode": shared_mode,
        "C": C,
        "agg_mode": agg_mode,
        "ensemble_mode": ensemble,
        "ensemble_layers": ens_layers,
        "ensemble_directions": ens_directions,
        "ensemble_weights": ens_weights,
        "cosine": {
            "per_layer_mean": [float(x) for x in mean_sims],
            "per_layer": {k: [float(x) for x in v] for k, v in layer_sims.items()},
        },
        "transfer": {
            "per_layer_mean": [float(x) for x in mean_transfer],
            "per_layer_min": [float(x) for x in min_transfer],
            "per_layer_median": [float(x) for x in median_transfer],
            "per_layer_harmonic": [float(x) for x in harmonic_transfer],
            "per_layer": per_layer_transfer,
        },
        "sp_sy": {
            "per_layer_cosine": [float(x) for x in sp_sy_cosines],
            "per_layer_transfer": [float(x) for x in sp_sy_transfer],
        },
        "per_layer_directions": {name: directions[name] for name in active_names},
    }, Path(output_dir) / "shared_direction.pt")

    print(f"\nsaved to {output_dir}/shared_direction.pt")


if __name__ == "__main__":
    fire.Fire(analyze)
