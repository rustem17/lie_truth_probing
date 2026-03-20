"""
Unified AUROC evaluation for lie/truth probes on precomputed activations.

Probes: shared_direction.pt (contrastive, mass_mean) + irm_probe.pt (auto-discovered)
Activations: activations/{name}.pt (n_samples, n_layers, hidden_dim)
Directions: shared, per_scenario, residuals, or all
Output: CSV + heatmap + layer-sweep plots
"""
import sys
from datetime import datetime
from pathlib import Path

import fire
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
import numpy as np
import pandas as pd
import seaborn as sns
import torch

SCRIPT_DIR = Path(__file__).resolve().parent
sys.path.insert(0, str(SCRIPT_DIR.parent))
from config import ALL_DATASETS, ACTIVATIONS_DIR, COLORS, SHORT, TRAIN_DATASETS, VALIDATION_DATASETS
from probe_utils import default_irm_path, default_probe_paths, find_peak_auroc, load_directions


def resolve_datasets(datasets, activations_dir):
    if not datasets:
        return [n for n in ALL_DATASETS if (activations_dir / f"{n}.pt").exists()]
    if isinstance(datasets, str):
        if datasets == "train":
            return [n for n in TRAIN_DATASETS if (activations_dir / f"{n}.pt").exists()]
        if datasets == "validation":
            return [n for n in VALIDATION_DATASETS if (activations_dir / f"{n}.pt").exists()]
        return [d.strip() for d in datasets.split(",")]
    return list(datasets)


def plot_heatmap(df, dataset_names, direction_names, out_dir, timestamp):
    pivot = df.pivot(index="direction", columns="dataset", values="auroc")
    pivot_layers = df.pivot(index="direction", columns="dataset", values="peak_layer")

    col_order = [d for d in dataset_names if d in pivot.columns]
    row_order = [d for d in direction_names if d in pivot.index]
    if not col_order or not row_order:
        return
    pivot = pivot.loc[row_order, col_order]
    pivot_layers = pivot_layers.loc[row_order, col_order]

    annot = pivot.copy().astype(str)
    for r in annot.index:
        for c in annot.columns:
            v = pivot.loc[r, c]
            l = pivot_layers.loc[r, c]
            annot.loc[r, c] = f"{v:.2f}\nL{int(l)}"

    col_labels = [SHORT.get(c, c) for c in col_order]
    sns.set_theme(style="whitegrid")
    fig, ax = plt.subplots(figsize=(max(8, len(col_order) * 1.2), max(5, len(row_order) * 0.6)))
    sns.heatmap(pivot.astype(float), annot=annot, fmt="", cmap="RdYlGn", vmin=0.4, vmax=1.0,
                linewidths=0.5, ax=ax, xticklabels=col_labels, cbar_kws={"label": "AUROC"})
    ax.set_title("AUROC (lie vs truth) at peak layer")
    ax.set_xlabel("")
    ax.set_ylabel("")
    plt.tight_layout()
    plot_path = out_dir / "plots" / f"auroc_heatmap_{timestamp}.png"
    fig.savefig(plot_path, dpi=150)
    plt.close(fig)
    print(f"Heatmap: {plot_path}")


def plot_sweep(all_aurocs, dataset_names, direction_names, out_dir, timestamp):
    sns.set_theme(style="whitegrid")
    for dir_name in direction_names:
        available = [(ds, all_aurocs[(dir_name, ds)]) for ds in dataset_names
                     if (dir_name, ds) in all_aurocs]
        if not available:
            continue
        fig, ax = plt.subplots(figsize=(12, 4))
        for ds_name, aurocs in available:
            n_layers = len(aurocs)
            layers = np.arange(1, n_layers + 1)
            color = COLORS.get(ds_name, "#333333")
            short = SHORT.get(ds_name, ds_name)
            is_val = "validation" in ds_name or "control" in ds_name
            peak_idx = int(np.nanargmax(aurocs))
            ax.plot(layers, aurocs, color=color, linestyle="--" if is_val else "-",
                    marker="o", markersize=2, linewidth=1,
                    label=f"{short} (peak L{peak_idx+1}={aurocs[peak_idx]:.3f})")
        ax.axhline(0.5, color="black", linestyle="--", linewidth=0.8)
        ax.set_xlabel("Layer")
        ax.set_ylabel("AUROC")
        ax.set_title(dir_name)
        ax.set_xlim(1, n_layers)
        ax.legend(loc="upper left", fontsize=7, framealpha=0.7)
        fig.tight_layout()
        safe_name = dir_name.replace("/", "_")
        fig.savefig(out_dir / "plots" / f"auroc_sweep_{safe_name}_{timestamp}.png", dpi=150)
        plt.close(fig)
    print(f"Sweep plots: {out_dir / 'plots'}")


def main(
    probe_paths=None,
    irm_path="auto",
    activations_dir=None,
    datasets=None,
    directions="all",
    plot_type="all",
    output_dir="results",
):
    if not activations_dir:
        activations_dir = ACTIVATIONS_DIR
    activations_dir = Path(activations_dir)

    if not probe_paths:
        probe_paths = default_probe_paths()
    elif isinstance(probe_paths, str):
        probe_paths = [p.strip() for p in probe_paths.split(",")]

    if irm_path == "auto":
        irm_path = default_irm_path()

    dataset_names = resolve_datasets(datasets, activations_dir)

    print(f"Activations: {activations_dir}")
    print(f"Datasets: {dataset_names}")
    print(f"Directions: {directions}")

    all_directions = load_directions(probe_paths, irm_path, directions=directions)
    direction_names = list(all_directions.keys())

    if not direction_names:
        print("No directions found. Check probe paths.")
        return

    rows = []
    all_aurocs = {}
    for ds_name in dataset_names:
        act_path = activations_dir / f"{ds_name}.pt"
        if not act_path.exists():
            continue
        data = torch.load(act_path, weights_only=False)
        act = np.asarray(data["activations"])
        labels = np.asarray(data["labels"])
        print(f"  {ds_name}: {act.shape[0]} samples")
        for dir_name, dir_stack in all_directions.items():
            peak_auroc, peak_layer, aurocs = find_peak_auroc(act, labels, dir_stack)
            rows.append({"direction": dir_name, "dataset": ds_name,
                         "auroc": peak_auroc, "peak_layer": peak_layer + 1})
            all_aurocs[(dir_name, ds_name)] = aurocs

    df = pd.DataFrame(rows)
    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    out_dir = Path(output_dir)
    out_dir.mkdir(parents=True, exist_ok=True)
    (out_dir / "plots").mkdir(parents=True, exist_ok=True)

    csv_path = out_dir / f"auroc_eval_{timestamp}.csv"
    df.to_csv(csv_path, index=False)
    print(f"CSV: {csv_path}")

    if plot_type in ("all", "heatmap"):
        plot_heatmap(df, dataset_names, direction_names, out_dir, timestamp)
    if plot_type in ("all", "sweep"):
        plot_sweep(all_aurocs, dataset_names, direction_names, out_dir, timestamp)


if __name__ == "__main__":
    fire.Fire(main)
