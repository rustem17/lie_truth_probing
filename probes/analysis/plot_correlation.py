"""
Projection correlation between probe directions across layers.

Probes: contrastive LR directions from shared_direction.pt
Activations: first-position hidden states from activations/{name}.pt
Layer: best_layer_transfer from shared_direction.pt (configurable via --layer)
Output: compare_projection_correlation.png
"""
import sys
import numpy as np
import torch
import matplotlib.pyplot as plt
import seaborn as sns
from pathlib import Path
from itertools import combinations
from scipy.stats import pearsonr
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import COLORS, SHORT, pair_color, PROBING_ROOT, ACTIVATIONS_DIR

sns.set_theme(style="whitegrid")


def main(activations_dir=None, probes_dir=None, output_dir=None,
         datasets="instructed,spontaneous,sycophancy", layer=None):
    activations_dir = Path(activations_dir) if activations_dir else ACTIVATIONS_DIR
    probes_dir = Path(probes_dir) if probes_dir else PROBING_ROOT / "probes" / "contrastive"
    output_dir = Path(output_dir) if output_dir else probes_dir / "plots"
    output_dir.mkdir(parents=True, exist_ok=True)

    shared = torch.load(probes_dir / "shared_direction.pt", weights_only=False)
    directions = {k: v for k, v in shared["per_layer_directions"].items()}
    n_layers = next(iter(directions.values())).shape[0]

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

    print(f"layer {layer + 1}, probes: {probe_names}, datasets: {sorted(ds.keys())}")

    pairs = list(combinations(probe_names, 2))
    per_layer_corr = {f"{a}_vs_{b}": [] for a, b in pairs}
    per_layer_cosine = {f"{a}_vs_{b}": [] for a, b in pairs}

    for l in range(n_layers):
        for a, b in pairs:
            w_a, w_b = directions[a][l], directions[b][l]
            per_layer_cosine[f"{a}_vs_{b}"].append(
                float(np.dot(w_a, w_b) / (np.linalg.norm(w_a) * np.linalg.norm(w_b))))

            others = [n for n in ds if n != a and n != b]
            if not others:
                per_layer_corr[f"{a}_vs_{b}"].append(np.nan)
                continue
            shared_acts = np.concatenate([ds[n]["activations"][:, l] for n in others])
            s_a = shared_acts @ w_a
            s_b = shared_acts @ w_b
            r, _ = pearsonr(s_a, s_b)
            per_layer_corr[f"{a}_vs_{b}"].append(float(r))

    layers = np.arange(1, n_layers + 1)
    mean_corr = [np.nanmean([per_layer_corr[k][l] for k in per_layer_corr]) for l in range(n_layers)]

    fig, ax = plt.subplots(figsize=(10, 5))
    for a, b in pairs:
        k = f"{a}_vs_{b}"
        color = pair_color(a, b)
        ax.plot(layers, per_layer_corr[k], label=f"{SHORT[a]} vs {SHORT[b]} (proj r)",
                color=color, linewidth=1.5, alpha=0.85)
        ax.plot(layers, per_layer_cosine[k], color=color, linewidth=0.8, alpha=0.4,
                linestyle="--")
    ax.plot(layers, mean_corr, label="mean proj r", color="black", linewidth=2.2)
    ax.axvline(layer + 1, color="gray", linestyle=":", linewidth=1)
    ax.axhline(0, color="gray", linestyle="--", linewidth=0.8, alpha=0.5)
    ax.set_xlabel("Layer")
    ax.set_ylabel("Correlation")
    ax.set_title("Projection Correlation by Layer (solid=Pearson r, dashed=cosine)")
    ax.legend(loc="upper left", fontsize=8)
    fig.tight_layout()
    suffix = "_".join(SHORT.get(n, n) for n in sorted(ds))
    out = output_dir / f"correlation_L{layer+1}_{suffix}.png"
    fig.savefig(out, dpi=150)
    plt.close(fig)
    print(f"saved {out}")


if __name__ == "__main__":
    fire.Fire(main)
