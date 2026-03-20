"""
Sweep activation extraction positions and evaluate mass-mean probes.

Model: meta-llama/Llama-3.1-70B-Instruct + LoRA
Positions: first, last, first_assistant, last_user, mean_assistant
Probe: mass-mean (mean of pair diffs, no LR)
Validation: contrastive-style cross-dataset transfer AUROC
Phases: extract (GPU), train, validate, all (default)
Output: per-position folders with probes + validation, summary CSV + heatmap
"""

import sys
import json
import csv
import numpy as np
import torch
from pathlib import Path
from collections import defaultdict
from datetime import datetime
from sklearn.model_selection import KFold
from sklearn.metrics import roc_auc_score
import fire
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
import seaborn as sns

SCRIPT_DIR = Path(__file__).resolve().parent
sys.path.insert(0, str(SCRIPT_DIR))
sys.path.insert(0, str(SCRIPT_DIR.parent))

from config import TRAIN_DATASETS, VALIDATION_DATASETS, VALIDATION_MAP, SHORT

POSITIONS = ["first", "last", "first_assistant", "last_user", "mean_assistant",
             "mid_assistant", "first_k_assistant", "last_k_assistant"]


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


def train_mass_mean(data_dir, activations_dir, output_dir, n_splits=5):
    Path(output_dir).mkdir(parents=True, exist_ok=True)
    for name, (filename, label_map) in TRAIN_DATASETS.items():
        act_path = Path(activations_dir) / f"{name}.pt"
        data_path = Path(data_dir) / filename
        if not act_path.exists() or not data_path.exists():
            print(f"    skip {name}: missing files")
            continue
        saved = torch.load(act_path, weights_only=False)
        data = json.load(open(data_path))[:len(saved["activations"])]
        pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
        n_pairs, n_layers, _ = pair_diffs.shape

        layer_results = []
        for layer in range(n_layers):
            D = pair_diffs[:, layer]
            kf = KFold(n_splits=n_splits, shuffle=True, random_state=42)
            aucs = []
            for train_idx, test_idx in kf.split(np.arange(n_pairs)):
                direction = D[train_idx].mean(axis=0)
                norm = np.linalg.norm(direction)
                if norm < 1e-12:
                    aucs.append(0.5)
                    continue
                direction = direction / norm
                scores = D[test_idx] @ direction
                scores_all = np.concatenate([scores, -scores])
                labels_all = np.concatenate([np.ones(len(test_idx)), np.zeros(len(test_idx))])
                aucs.append(roc_auc_score(labels_all, scores_all))
            layer_results.append({"layer": layer + 1, "auroc": float(np.mean(aucs))})

        best = max(layer_results, key=lambda r: r["auroc"])
        all_directions = {}
        for layer in range(n_layers):
            d = pair_diffs[:, layer].mean(axis=0)
            norm = np.linalg.norm(d)
            all_directions[layer] = d / norm if norm > 1e-12 else np.zeros_like(d)

        torch.save({
            "direction": all_directions[best["layer"] - 1],
            "best_layer": best["layer"],
            "all_directions": all_directions,
            "layer_results": layer_results,
            "n_pairs": n_pairs,
            "pair_ids": pair_ids,
        }, Path(output_dir) / f"{name}_probe.pt")
        print(f"    {name}: {n_pairs} pairs, best L{best['layer']} AUROC={best['auroc']:.4f}")


def validate_probes(data_dir, activations_dir, probes_dir):
    results = {}
    for probe_name, val_sets in VALIDATION_MAP.items():
        probe_path = Path(probes_dir) / f"{probe_name}_probe.pt"
        if not probe_path.exists():
            continue
        probe = torch.load(probe_path, weights_only=False)
        direction = probe["direction"]
        best_layer = probe["best_layer"]

        for val_name, val_file, label_map in val_sets:
            act_path = Path(activations_dir) / f"{val_name}.pt"
            data_path = Path(data_dir) / val_file
            if not act_path.exists() or not data_path.exists():
                continue
            saved = torch.load(act_path, weights_only=False)
            data = json.load(open(data_path))[:len(saved["activations"])]
            pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
            n_pairs = len(pair_ids)
            D = pair_diffs[:, best_layer - 1]
            scores = D @ direction
            scores_aug = np.concatenate([scores, -scores])
            labels_aug = np.concatenate([np.ones(n_pairs), np.zeros(n_pairs)])
            auroc = roc_auc_score(labels_aug, scores_aug)
            results[f"{probe_name}→{val_name}"] = {
                "auroc": float(auroc), "n_pairs": n_pairs, "layer": best_layer,
            }
            print(f"    {probe_name}→{val_name}: AUROC={auroc:.4f} (L{best_layer}, {n_pairs} pairs)")
    return results


def phase_extract(data_dir, positions, model_name, adapter_id, k=10):
    from extract_activations import load_model, extract_with_model
    needed = []
    for pos in positions:
        act_dir = "activations" if pos == "first" else f"activations_{pos}"
        act_path = Path(data_dir) / act_dir
        if act_path.exists() and any(act_path.glob("*.pt")):
            print(f"  {pos}: {act_dir}/ already exists, skipping")
        else:
            needed.append(pos)
    if not needed:
        return
    model, tokenizer = load_model(model_name, adapter_id)
    for pos in needed:
        act_dir = "activations" if pos == "first" else f"activations_{pos}"
        act_path = Path(data_dir) / act_dir
        print(f"\n  extracting: position={pos} → {act_dir}/")
        extract_with_model(model, tokenizer, data_dir=data_dir,
                           output_dir=str(act_path), position=pos, k=k)


def phase_train(data_dir, positions, sweep_dir):
    for pos in positions:
        act_dir = Path(data_dir) / ("activations" if pos == "first" else f"activations_{pos}")
        if not act_dir.exists():
            print(f"  {pos}: no activations at {act_dir}, skipping")
            continue
        probe_dir = sweep_dir / pos / "probes"
        print(f"\n  training: {pos}")
        train_mass_mean(data_dir, str(act_dir), str(probe_dir))


def phase_validate(data_dir, positions, sweep_dir):
    all_results = []
    for pos in positions:
        act_dir = Path(data_dir) / ("activations" if pos == "first" else f"activations_{pos}")
        probe_dir = sweep_dir / pos / "probes"
        if not probe_dir.exists():
            print(f"  {pos}: no probes, skipping")
            continue
        print(f"\n  validating: {pos}")
        val_results = validate_probes(data_dir, str(act_dir), str(probe_dir))
        val_path = probe_dir / "validation_results.json"
        with open(val_path, "w") as f:
            json.dump(val_results, f, indent=2)
        for key, info in val_results.items():
            probe, val_set = key.split("→")
            all_results.append({
                "position": pos, "probe": probe, "val_set": val_set,
                "auroc": info["auroc"], "n_pairs": info["n_pairs"], "layer": info["layer"],
            })
    return all_results


def write_summary(all_results, sweep_dir, ts):
    if not all_results:
        print("  no results to summarize")
        return

    csv_path = sweep_dir / f"position_sweep_{ts}.csv"
    with open(csv_path, "w", newline="") as f:
        writer = csv.DictWriter(f, fieldnames=all_results[0].keys())
        writer.writeheader()
        writer.writerows(all_results)
    print(f"\nCSV: {csv_path}")

    positions = sorted(set(r["position"] for r in all_results))
    probes = sorted(set(r["probe"] for r in all_results))
    val_sets = sorted(set(r["val_set"] for r in all_results))
    row_labels = [f"{p}/{pr}" for p in positions for pr in probes]
    col_labels = val_sets

    lookup = {(r["position"], r["probe"], r["val_set"]): r["auroc"] for r in all_results}
    mat = np.full((len(row_labels), len(col_labels)), np.nan)
    for i, rl in enumerate(row_labels):
        pos, probe = rl.split("/", 1)
        for j, vs in enumerate(col_labels):
            mat[i, j] = lookup.get((pos, probe, vs), np.nan)

    sns.set_theme(style="whitegrid")
    annot = np.empty_like(mat, dtype=object)
    for i in range(mat.shape[0]):
        for j in range(mat.shape[1]):
            v = mat[i, j]
            annot[i, j] = f"{v:.2f}" if not np.isnan(v) else ""

    col_short = [SHORT.get(c, c[:8]) for c in col_labels]
    fig, ax = plt.subplots(figsize=(max(8, len(col_labels) * 1.5),
                                     max(6, len(row_labels) * 0.4)))
    sns.heatmap(mat, annot=annot, fmt="", cmap="RdYlGn", vmin=0.4, vmax=1.0,
                linewidths=0.5, ax=ax, xticklabels=col_short, yticklabels=row_labels,
                cbar_kws={"label": "AUROC"})
    ax.set_title("Mass-mean probe AUROC by extraction position")
    ax.tick_params(axis="y", labelsize=7)
    plt.tight_layout()
    heatmap_path = sweep_dir / f"position_heatmap_{ts}.png"
    fig.savefig(heatmap_path, dpi=150)
    plt.close(fig)
    print(f"Heatmap: {heatmap_path}")

    print(f"\n{'position':<20} {'mean_auroc':>10} {'min_auroc':>10}")
    print("-" * 42)
    for pos in positions:
        aurocs = [r["auroc"] for r in all_results if r["position"] == pos]
        if aurocs:
            print(f"{pos:<20} {np.mean(aurocs):>10.4f} {min(aurocs):>10.4f}")


def main(data_dir=None, output_dir=None, phase="all",
         positions="first,last,first_assistant,last_user,mean_assistant,mid_assistant,first_k_assistant,last_k_assistant",
         model_name="meta-llama/Llama-3.1-70B-Instruct",
         adapter_id="dv347/Llama-3.1-70B-Instruct-honly", k=10):
    probing_root = Path(__file__).resolve().parents[1]
    if data_dir is None:
        data_dir = str(probing_root)
    if output_dir is None:
        output_dir = str(probing_root / "eval" / "results")

    pos_list = [p.strip() for p in positions.split(",")] if isinstance(positions, str) else list(positions)
    ts = datetime.now().strftime("%Y%m%d_%H%M%S")
    sweep_dir = Path(output_dir) / f"position_sweep_{ts}"
    sweep_dir.mkdir(parents=True, exist_ok=True)

    print(f"positions: {pos_list}")
    print(f"phase: {phase}")
    print(f"output: {sweep_dir}\n")

    if phase in ("all", "extract"):
        phase_extract(data_dir, pos_list, model_name, adapter_id, k=k)

    if phase in ("all", "train"):
        phase_train(data_dir, pos_list, sweep_dir)

    if phase in ("all", "validate"):
        all_results = phase_validate(data_dir, pos_list, sweep_dir)
        write_summary(all_results, sweep_dir, ts)

    print(f"\nDone. Output: {sweep_dir}")


if __name__ == "__main__":
    fire.Fire(main)
