"""
Mahalanobis cosine similarity between probe weight vectors.

Probes: directions from shared_direction.pt
Activations: first-position hidden states from activations/{name}.pt
Covariance: Ledoit-Wolf shrinkage on pooled activations per layer
Layer: best_layer_transfer from shared_direction.pt (configurable via --layer)
GPU: --gpu flag uses torch Ledoit-Wolf on CUDA (much faster for large d)
Output: mahalanobis_L{layer}_{suffix}.png (per-layer curves)
        mahalanobis_matrix_L{layer}_{suffix}.png (heatmap at selected layer)
"""
import sys
import numpy as np
import torch
import matplotlib.pyplot as plt
import matplotlib.colors as mcolors
import seaborn as sns
from pathlib import Path
from itertools import combinations
from sklearn.covariance import LedoitWolf
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import SHORT, pair_color, PROBING_ROOT, ACTIVATIONS_DIR

sns.set_theme(style="whitegrid")


def ledoit_wolf_gpu(X):
    X = X.to(torch.float64)
    n, p = X.shape
    X_c = X - X.mean(dim=0)
    S = (X_c.T @ X_c) / (n - 1)
    trace_S = S.trace()
    trace_S2 = (S * S).sum()
    mu = trace_S / p
    delta = ((n - 1.0) / n) * (trace_S2 - trace_S ** 2 / p)
    X2 = X_c * X_c
    beta = (1.0 / (n * n * (n - 1))) * ((X2.T @ X2).sum() - (1.0 / n) * (X_c.T @ X_c).pow(2).sum())
    shrinkage = min(float(beta / delta), 1.0) if float(delta) > 0 else 1.0
    return ((1 - shrinkage) * S + shrinkage * mu * torch.eye(p, device=X.device, dtype=torch.float64)).float()


def mahal_cosine(w_a, w_b, cov):
    cw_a = cov @ w_a
    cw_b = cov @ w_b
    cross = w_a @ cw_b
    norm_a = (w_a @ cw_a).sqrt() if isinstance(cov, torch.Tensor) else np.sqrt(w_a @ cw_a)
    norm_b = (w_b @ cw_b).sqrt() if isinstance(cov, torch.Tensor) else np.sqrt(w_b @ cw_b)
    return float(cross / (norm_a * norm_b))


def std_cosine(w_a, w_b):
    if isinstance(w_a, torch.Tensor):
        return float(torch.dot(w_a, w_b) / (w_a.norm() * w_b.norm()))
    return float(np.dot(w_a, w_b) / (np.linalg.norm(w_a) * np.linalg.norm(w_b)))


def main(activations_dir=None, probes_dir=None, output_dir=None,
         datasets="instructed,spontaneous,sycophancy", layer=None, gpu=False):
    activations_dir = Path(activations_dir) if activations_dir else ACTIVATIONS_DIR
    probes_dir = Path(probes_dir) if probes_dir else PROBING_ROOT / "probes" / "contrastive"
    output_dir = Path(output_dir) if output_dir else probes_dir / "plots"
    output_dir.mkdir(parents=True, exist_ok=True)

    shared = torch.load(probes_dir / "shared_direction.pt", weights_only=False)
    directions = dict(shared["per_layer_directions"])
    n_layers = next(iter(directions.values())).shape[0]

    if layer is not None:
        layer = int(layer) - 1

    names = set(datasets) if isinstance(datasets, (list, tuple)) else {d.strip() for d in datasets.split(",")}
    probe_names = sorted(n for n in names if n in directions)

    ds = {}
    for name in sorted(names):
        act_path = activations_dir / f"{name}.pt"
        if not act_path.exists():
            continue
        saved = torch.load(act_path, weights_only=False)
        ds[name] = saved["activations"]

    print(f"layer {layer + 1 if layer is not None else 'auto'}, probes: {probe_names}, datasets: {sorted(ds.keys())}")
    n_samples = sum(a.shape[0] for a in ds.values())
    print(f"pooled samples for covariance: {n_samples}")

    if gpu:
        device = torch.device("cuda")
        ds_gpu = {n: torch.tensor(ds[n], dtype=torch.float32, device=device) for n in sorted(ds)}
        dir_gpu = {n: torch.tensor(directions[n], dtype=torch.float32, device=device) for n in probe_names}
        print(f"using GPU: {torch.cuda.get_device_name()}")

    pairs = list(combinations(probe_names, 2))
    suffix = "_".join(SHORT.get(n, n) for n in sorted(ds))
    cache_path = output_dir / f"mahalanobis_cache_{suffix}.pt"

    if cache_path.exists():
        cached = torch.load(cache_path, weights_only=False)
        if cached.get("probe_names") == probe_names and cached.get("n_layers") == n_layers:
            per_layer_mahal = cached["per_layer_mahal"]
            per_layer_cos = cached["per_layer_cos"]
            print(f"loaded cache: {cache_path}")
        else:
            cached = None

    if not cache_path.exists() or cached is None:
        per_layer_mahal = {f"{a}_vs_{b}": [] for a, b in pairs}
        per_layer_cos = {f"{a}_vs_{b}": [] for a, b in pairs}

        for l in range(n_layers):
            if gpu:
                pooled = torch.cat([ds_gpu[n][:, l] for n in sorted(ds)])
                cov = ledoit_wolf_gpu(pooled)
                for a, b in pairs:
                    k = f"{a}_vs_{b}"
                    per_layer_mahal[k].append(mahal_cosine(dir_gpu[a][l], dir_gpu[b][l], cov))
                    per_layer_cos[k].append(std_cosine(dir_gpu[a][l], dir_gpu[b][l]))
            else:
                pooled = np.concatenate([ds[n][:, l] for n in sorted(ds)])
                cov = LedoitWolf().fit(pooled).covariance_
                for a, b in pairs:
                    k = f"{a}_vs_{b}"
                    w_a, w_b = directions[a][l], directions[b][l]
                    per_layer_mahal[k].append(mahal_cosine(w_a, w_b, cov))
                    per_layer_cos[k].append(std_cosine(w_a, w_b))

            if (l + 1) % 10 == 0:
                print(f"  layer {l + 1}/{n_layers}")

        torch.save({"per_layer_mahal": per_layer_mahal, "per_layer_cos": per_layer_cos,
                     "probe_names": probe_names, "n_layers": n_layers}, cache_path)
        print(f"saved cache: {cache_path}")
    layers_arr = np.arange(1, n_layers + 1)
    mean_mahal = np.array([np.mean([per_layer_mahal[k][l] for k in per_layer_mahal]) for l in range(n_layers)])

    if layer is None:
        n_sections = 4
        section_size = n_layers // n_sections
        top_layers = []
        for s in range(n_sections):
            lo, hi = s * section_size, (s + 1) * section_size if s < n_sections - 1 else n_layers
            best_in_section = lo + int(np.argmax(mean_mahal[lo:hi]))
            top_layers.append(best_in_section)
        global_best = int(np.argmax(mean_mahal))
        if global_best not in top_layers:
            top_layers.append(global_best)
        top_layers = sorted(set(top_layers))
        print(f"auto-selected layers: {[l+1 for l in top_layers]} (global best: {global_best+1})")
    else:
        top_layers = [layer]

    fig, ax = plt.subplots(figsize=(10, 5))
    for a, b in pairs:
        k = f"{a}_vs_{b}"
        color = pair_color(a, b)
        ax.plot(layers_arr, per_layer_mahal[k], label=f"{SHORT[a]} vs {SHORT[b]} (Mahal)",
                color=color, linewidth=1.5, alpha=0.85)
        ax.plot(layers_arr, per_layer_cos[k], color=color, linewidth=0.8, alpha=0.4,
                linestyle="--")
    ax.plot(layers_arr, mean_mahal, label="mean Mahal cos", color="black", linewidth=2.2)
    for tl in top_layers:
        ax.axvline(tl + 1, color="gray", linestyle=":", linewidth=1, alpha=0.7)
    ax.axhline(0, color="gray", linestyle="--", linewidth=0.8, alpha=0.5)
    ax.set_xlabel("Layer")
    ax.set_ylabel("Cosine Similarity")
    ax.set_title("Mahalanobis Cosine Similarity by Layer (solid=Mahal, dashed=standard)")
    ax.legend(loc="upper left", fontsize=8)
    fig.tight_layout()
    layers_tag = "_".join(str(l+1) for l in top_layers)
    out1 = output_dir / f"mahalanobis_L{layers_tag}_{suffix}.png"
    fig.savefig(out1, dpi=150)
    plt.close(fig)
    print(f"saved {out1}")

    n = len(probe_names)
    short_labels = [SHORT.get(p, p) for p in probe_names]
    cmap = mcolors.LinearSegmentedColormap.from_list("rg", ["#d9534f", "#f5f5dc", "#2d8659"])

    for tl in top_layers:
        matrix = np.ones((n, n))
        if gpu:
            pooled_at = torch.cat([ds_gpu[name][:, tl] for name in sorted(ds)])
            cov_at = ledoit_wolf_gpu(pooled_at)
            for i in range(n):
                for j in range(n):
                    if i != j:
                        matrix[i, j] = mahal_cosine(dir_gpu[probe_names[i]][tl],
                                                    dir_gpu[probe_names[j]][tl],
                                                    cov_at)
        else:
            pooled_at = np.concatenate([ds[name][:, tl] for name in sorted(ds)])
            cov_at = LedoitWolf().fit(pooled_at).covariance_
            for i in range(n):
                for j in range(n):
                    if i != j:
                        matrix[i, j] = mahal_cosine(directions[probe_names[i]][tl],
                                                    directions[probe_names[j]][tl],
                                                    cov_at)

        fig, ax = plt.subplots(figsize=(max(5, n * 1.8), max(4, n * 1.5)))
        im = ax.imshow(matrix, cmap=cmap, vmin=-1, vmax=1, aspect="equal")
        for i in range(n):
            for j in range(n):
                ax.text(j, i, f"{matrix[i, j]:.2f}", ha="center", va="center",
                        fontsize=14, fontweight="bold", color="white" if abs(matrix[i, j]) > 0.3 else "black")
        ax.set_xticks(range(n))
        ax.set_xticklabels(short_labels)
        ax.set_yticks(range(n))
        ax.set_yticklabels(short_labels)
        ax.set_title(f"Mahalanobis Cosine Similarity (layer {tl + 1}, mean={mean_mahal[tl]:.3f})")
        fig.colorbar(im, ax=ax, label="Mahal cosine", shrink=0.8)
        fig.tight_layout()
        out2 = output_dir / f"mahalanobis_matrix_L{tl+1}_{suffix}.png"
        fig.savefig(out2, dpi=150)
        plt.close(fig)
        print(f"saved {out2}")


if __name__ == "__main__":
    fire.Fire(main)
