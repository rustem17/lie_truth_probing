"""
Residual direction AUROC at every layer on matched datasets.

Each family's residual direction is evaluated on its own datasets:
  instructed residual → instructed_lie_truth, instructed_validation
  spontaneous residual → spontaneous_lie_truth, spontaneous_validation
  sycophancy residual → sycophancy_lie_truth, sycophancy_validation
  game residual → game_lie_truth, game_validation

Probes: shared_direction.pt (contrastive and/or mass_mean)
Activations: activations/{name}.pt
Output: one AUROC-vs-layer plot per family, CSV with all values
"""
import csv
import sys
from datetime import datetime
from pathlib import Path

import fire
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
import numpy as np
import seaborn as sns
import torch
from sklearn.metrics import roc_auc_score

SCRIPT_DIR = Path(__file__).resolve().parent
sys.path.insert(0, str(SCRIPT_DIR.parent))
from config import ACTIVATIONS_DIR, COLORS, SHORT

PROBES_ROOT = SCRIPT_DIR.parent / "probes"

FAMILIES = {
    "instructed": {
        "condition": "instructed",
        "datasets": ["instructed", "instructed_validation"],
    },
    "spontaneous": {
        "condition": "spontaneous",
        "datasets": ["spontaneous", "spontaneous_validation"],
    },
    "sycophancy": {
        "condition": "sycophancy",
        "datasets": ["sycophancy", "sycophancy_validation"],
    },
    "game": {
        "condition": "game_lie",
        "datasets": ["game_lie", "game_validation"],
    },
}


def _normalize(v):
    n = np.linalg.norm(v)
    return v / n if n > 1e-12 else v


def _residual(direction, shared):
    d = _normalize(direction)
    s = _normalize(shared)
    return _normalize(d - np.dot(d, s) * s)


def load_residuals(shared_path):
    sd = torch.load(shared_path, weights_only=False)
    all_dirs = sd.get("all_directions", {})
    per_layer = sd.get("per_layer_directions", {})
    n_layers = len(all_dirs)
    shared_arr = np.stack([_normalize(np.asarray(all_dirs[l])) for l in range(n_layers)])

    residuals = {}
    for cond_name, cond_dirs in per_layer.items():
        residuals[cond_name] = np.stack([
            _residual(np.asarray(cond_dirs[l]), shared_arr[l]) for l in range(n_layers)])

    label = Path(shared_path).parent.name
    return label, residuals, n_layers


def main(
    shared_paths=None,
    activations_dir=None,
    output_dir="results",
):
    if not shared_paths:
        candidates = [
            PROBES_ROOT / "contrastive" / "shared_direction.pt",
            PROBES_ROOT / "mass_mean" / "shared_direction.pt",
        ]
        shared_paths = [str(p) for p in candidates if p.exists()]
    elif isinstance(shared_paths, str):
        shared_paths = [p.strip() for p in shared_paths.split(",")]

    if not activations_dir:
        activations_dir = ACTIVATIONS_DIR
    activations_dir = Path(activations_dir)

    probe_families = {}
    for sp in shared_paths:
        label, residuals, n_layers = load_residuals(sp)
        probe_families[label] = (residuals, n_layers)
        print(f"{label}: conditions={list(residuals.keys())}, {n_layers} layers")

    Path(output_dir).mkdir(parents=True, exist_ok=True)
    (Path(output_dir) / "plots").mkdir(parents=True, exist_ok=True)
    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    sns.set_theme(style="whitegrid")

    csv_rows = []
    LINE_COLORS = ["#729ECE", "#D68F73", "#76B7B2", "#E5A84B", "#9B59B6", "#8C8C8C"]

    for family, spec in FAMILIES.items():
        cond = spec["condition"]
        ds_names = spec["datasets"]

        fig, ax = plt.subplots(figsize=(12, 4))
        has_data = False
        color_idx = 0

        for probe_label, (residuals, n_layers) in probe_families.items():
            if cond not in residuals:
                print(f"  {probe_label}: no {cond} residual, skip")
                continue
            dirs = residuals[cond]

            for ds_name in ds_names:
                act_path = activations_dir / f"{ds_name}.pt"
                if not act_path.exists():
                    print(f"  {ds_name}: missing, skip")
                    continue

                data = torch.load(act_path, weights_only=False)
                act = np.asarray(data["activations"])
                labels = np.asarray(data["labels"])
                n_samples = act.shape[0]

                if len(np.unique(labels)) < 2:
                    continue

                aurocs = np.array([roc_auc_score(labels, act[:, l, :] @ dirs[l])
                                   for l in range(n_layers)])
                layers = np.arange(1, n_layers + 1)
                peak_idx = int(np.argmax(aurocs))
                peak_auroc = aurocs[peak_idx]

                color = LINE_COLORS[color_idx % len(LINE_COLORS)]
                color_idx += 1
                short = SHORT.get(ds_name, ds_name)
                is_val = "validation" in ds_name
                linestyle = "--" if is_val else "-"

                ax.plot(layers, aurocs, color=color, linestyle=linestyle,
                        marker="o", markersize=2, linewidth=1,
                        label=f"{short} [{probe_label}]")
                has_data = True

                print(f"  {ds_name} [{probe_label}]: n={n_samples}, peak={peak_auroc:.4f} L{peak_idx+1}")

                for l in range(n_layers):
                    csv_rows.append({"family": family, "probe": probe_label,
                                     "dataset": ds_name, "layer": l + 1, "auroc": aurocs[l]})

        if not has_data:
            plt.close(fig)
            continue

        ax.axhline(0.5, color="black", linestyle="--", linewidth=0.8)
        ax.text(n_layers - 1, 0.51, "chance", fontsize=8, ha="right", va="bottom")
        ax.set_xlabel("Layer")
        ax.set_ylabel("AUROC (lie vs truth)")
        ax.set_title(f"{cond} residual direction — {family}")
        ax.set_xlim(1, n_layers)
        ax.legend(loc="upper right", fontsize=7, framealpha=0.7)
        fig.tight_layout()
        plot_path = Path(output_dir) / "plots" / f"residual_auroc_{family}_{timestamp}.png"
        fig.savefig(plot_path, dpi=150)
        plt.close(fig)
        print(f"  Plot: {plot_path}")

    if csv_rows:
        csv_path = Path(output_dir) / f"residual_auroc_sweep_{timestamp}.csv"
        with open(csv_path, "w", newline="") as f:
            writer = csv.DictWriter(f, fieldnames=csv_rows[0].keys())
            writer.writeheader()
            writer.writerows(csv_rows)
        print(f"\nCSV: {csv_path}")


if __name__ == "__main__":
    fire.Fire(main)
