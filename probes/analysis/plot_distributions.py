"""
Score distribution grid: each probe direction × each activation dataset.

Probes: contrastive LR directions from shared_direction.pt
Activations: first-position hidden states from activations/{name}.pt
Layer: best_layer_transfer from shared_direction.pt (configurable via --layer)
Output: compare_score_distributions.png
"""
import sys
import numpy as np
import torch
import matplotlib.pyplot as plt
import seaborn as sns
from pathlib import Path
from sklearn.metrics import roc_auc_score
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import COLORS, SHORT, MARKERS, PROBING_ROOT, ACTIVATIONS_DIR

sns.set_theme(style="whitegrid")


def main(activations_dir=None, probes_dir=None, output_dir=None,
         datasets="instructed,spontaneous,sycophancy", layer=None):
    activations_dir = Path(activations_dir) if activations_dir else ACTIVATIONS_DIR
    probes_dir = Path(probes_dir) if probes_dir else PROBING_ROOT / "probes" / "contrastive"
    output_dir = Path(output_dir) if output_dir else probes_dir / "plots"
    output_dir.mkdir(parents=True, exist_ok=True)

    shared = torch.load(probes_dir / "shared_direction.pt", weights_only=False)
    directions = {k: v for k, v in shared["per_layer_directions"].items()}

    if layer is None:
        layer = shared["best_layer_transfer"] - 1
    else:
        layer = int(layer) - 1

    names = set(datasets) if isinstance(datasets, (list, tuple)) else {d.strip() for d in datasets.split(",")}
    probe_names = sorted(n for n in names if n in directions)

    ds = {}
    for name in sorted(names):
        act_path = activations_dir / f"{name}.pt"
        if not act_path.exists():
            continue
        saved = torch.load(act_path, weights_only=False)
        ds[name] = {"activations": saved["activations"], "labels": saved["labels"]}

    all_ds = sorted(ds.keys())
    n_probes = len(probe_names)
    n_ds = len(all_ds)
    print(f"layer {layer + 1}, probes: {probe_names}, datasets: {all_ds}")

    fig, axes = plt.subplots(n_probes, n_ds, figsize=(4 * n_ds, 3.5 * n_probes), squeeze=False)

    for row, probe in enumerate(probe_names):
        w = directions[probe][layer]
        for col, ds_name in enumerate(all_ds):
            ax = axes[row, col]
            acts = ds[ds_name]["activations"][:, layer]
            labels = ds[ds_name]["labels"]
            scores = acts @ w

            truth_scores = scores[labels == 0]
            lie_scores = scores[labels == 1]
            bins = np.linspace(scores.min(), scores.max(), 40)

            ax.hist(truth_scores, bins=bins, alpha=0.6, color="#729ECE", label="truth", density=True)
            ax.hist(lie_scores, bins=bins, alpha=0.6, color="#d9534f", label="lie", density=True)

            auroc = float(roc_auc_score(labels, scores))
            ax.text(0.97, 0.95, f"AUC={auroc:.2f}", transform=ax.transAxes,
                    ha="right", va="top", fontsize=9, fontweight="bold",
                    bbox=dict(boxstyle="round,pad=0.2", facecolor="white", alpha=0.8))

            if row == 0:
                ax.set_title(SHORT.get(ds_name, ds_name), fontsize=11)
            if col == 0:
                ax.set_ylabel(f"probe: {SHORT.get(probe, probe)}", fontsize=11)
            if row == n_probes - 1:
                ax.set_xlabel("projection score")
            if row == 0 and col == n_ds - 1:
                ax.legend(fontsize=8)

            if probe == ds_name:
                for spine in ax.spines.values():
                    spine.set_edgecolor("black")
                    spine.set_linewidth(2)

    fig.suptitle(f"Score Distributions (layer {layer + 1})", fontsize=14, y=1.01)
    fig.tight_layout()
    suffix = "_".join(SHORT.get(n, n) for n in all_ds)
    out = output_dir / f"distributions_L{layer+1}_{suffix}.png"
    fig.savefig(out, dpi=150, bbox_inches="tight")
    plt.close(fig)
    print(f"saved {out}")


if __name__ == "__main__":
    fire.Fire(main)
