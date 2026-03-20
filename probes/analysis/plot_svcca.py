"""
SVCCA / PWCCA subspace similarity between activation matrices across layers.

Compares principal subspaces of different deception datasets' activations
to test whether probes leverage the same linear subspace or different
subspaces that happen to encode the same ranking.

Method:
  1. SVD-truncate each dataset's activation matrix to top-k dims (cumvar >= threshold)
  2. Compute principal angles between truncated subspaces via SVD of V_A^T @ V_B
  3. SVCCA = mean cosine of principal angles
  4. PWCCA = variance-weighted mean (weights = variance each canonical direction
     explains in both datasets' original representations)

Activations: first-position hidden states from activations/{name}.pt
Subspace: SVD truncation at cumulative-variance threshold (default 0.99)
Layer: best_layer_transfer from shared_direction.pt (configurable via --layer)
Output: svcca_L{layers}_{suffix}.png (per-layer curves + dimensionality)
        svcca_matrix_L{layer}_{suffix}.png (heatmap at selected layer)
"""
import sys
import numpy as np
import torch
import matplotlib.pyplot as plt
import matplotlib.colors as mcolors
import seaborn as sns
from pathlib import Path
from itertools import combinations
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import COLORS, SHORT, pair_color, PROBING_ROOT, ACTIVATIONS_DIR

sns.set_theme(style="whitegrid")


def svd_truncate(X, threshold):
    X_c = X - X.mean(axis=0)
    U, s, Vt = np.linalg.svd(X_c, full_matrices=False)
    var = s ** 2
    cumvar = np.cumsum(var) / var.sum()
    k = int(np.searchsorted(cumvar, threshold)) + 1
    return Vt[:k].T, s[:k]


def subspace_similarity(V_A, s_A, V_B, s_B):
    M = V_A.T @ V_B
    P, cos_angles, Qt = np.linalg.svd(M, full_matrices=False)
    cos_angles = np.clip(cos_angles, 0, 1)
    svcca = float(cos_angles.mean())
    k = len(cos_angles)
    var_A = s_A[:P.shape[0]] ** 2
    w_A = (P[:, :k] ** 2).T @ var_A
    Q = Qt[:k].T
    var_B = s_B[:Q.shape[0]] ** 2
    w_B = (Q ** 2).T @ var_B
    w = w_A + w_B
    pwcca = float((w * cos_angles).sum() / w.sum()) if w.sum() > 0 else svcca
    return svcca, pwcca


def main(activations_dir=None, probes_dir=None, output_dir=None,
         datasets="instructed,spontaneous,sycophancy", layer=None,
         threshold=0.99):
    activations_dir = Path(activations_dir) if activations_dir else ACTIVATIONS_DIR
    probes_dir = Path(probes_dir) if probes_dir else PROBING_ROOT / "probes" / "contrastive"
    output_dir = Path(output_dir) if output_dir else probes_dir / "plots"
    output_dir.mkdir(parents=True, exist_ok=True)

    shared = torch.load(probes_dir / "shared_direction.pt", weights_only=False)
    n_layers = next(iter(shared["per_layer_directions"].values())).shape[0]

    if layer is not None:
        layer = int(layer) - 1

    names = set(datasets) if isinstance(datasets, (list, tuple)) else {d.strip() for d in datasets.split(",")}
    ds = {}
    for name in sorted(names):
        act_path = activations_dir / f"{name}.pt"
        if not act_path.exists():
            continue
        saved = torch.load(act_path, weights_only=False)
        ds[name] = saved["activations"]

    ds_names = sorted(ds.keys())
    pairs = list(combinations(ds_names, 2))
    suffix = "_".join(SHORT.get(n, n) for n in ds_names)
    cache_path = output_dir / f"svcca_cache_{suffix}.pt"

    print(f"datasets: {ds_names}, pairs: {len(pairs)}, layers: {n_layers}, threshold: {threshold}")

    cached = None
    if cache_path.exists():
        cached = torch.load(cache_path, weights_only=False)
        if (cached.get("ds_names") != ds_names
                or cached.get("n_layers") != n_layers
                or cached.get("threshold") != threshold):
            cached = None
        else:
            per_layer_svcca = cached["per_layer_svcca"]
            per_layer_pwcca = cached["per_layer_pwcca"]
            per_layer_dims = cached["per_layer_dims"]
            print(f"loaded cache: {cache_path}")

    if cached is None:
        per_layer_svcca = {f"{a}_vs_{b}": [] for a, b in pairs}
        per_layer_pwcca = {f"{a}_vs_{b}": [] for a, b in pairs}
        per_layer_dims = {n: [] for n in ds_names}

        for l in range(n_layers):
            svd_cache = {}
            for name in ds_names:
                V, s = svd_truncate(ds[name][:, l], threshold)
                svd_cache[name] = (V, s)
                per_layer_dims[name].append(V.shape[1])

            for a, b in pairs:
                k = f"{a}_vs_{b}"
                V_A, s_A = svd_cache[a]
                V_B, s_B = svd_cache[b]
                svc, pwc = subspace_similarity(V_A, s_A, V_B, s_B)
                per_layer_svcca[k].append(svc)
                per_layer_pwcca[k].append(pwc)

            if (l + 1) % 10 == 0:
                dims_str = ", ".join(f"{SHORT.get(n,n)}={per_layer_dims[n][-1]}" for n in ds_names)
                print(f"  layer {l+1}/{n_layers}  dims: {dims_str}")

        torch.save({"per_layer_svcca": per_layer_svcca, "per_layer_pwcca": per_layer_pwcca,
                     "per_layer_dims": per_layer_dims,
                     "ds_names": ds_names, "n_layers": n_layers, "threshold": threshold}, cache_path)
        print(f"saved cache: {cache_path}")

    layers_arr = np.arange(1, n_layers + 1)
    mean_pwcca = np.array([np.mean([per_layer_pwcca[k][l] for k in per_layer_pwcca])
                           for l in range(n_layers)])

    if layer is None:
        n_sections = 4
        section_size = n_layers // n_sections
        top_layers = []
        for s in range(n_sections):
            lo = s * section_size
            hi = (s + 1) * section_size if s < n_sections - 1 else n_layers
            best_in_section = lo + int(np.argmax(mean_pwcca[lo:hi]))
            top_layers.append(best_in_section)
        global_best = int(np.argmax(mean_pwcca))
        if global_best not in top_layers:
            top_layers.append(global_best)
        top_layers = sorted(set(top_layers))
        print(f"auto-selected layers: {[l+1 for l in top_layers]} (global best: {global_best+1})")
    else:
        top_layers = [layer]

    fig, axes = plt.subplots(2, 1, figsize=(10, 8), sharex=True,
                             gridspec_kw={"height_ratios": [3, 1.2]})

    ax_sim = axes[0]
    for a, b in pairs:
        k = f"{a}_vs_{b}"
        color = pair_color(a, b)
        ax_sim.plot(layers_arr, per_layer_pwcca[k],
                    label=f"{SHORT[a]} vs {SHORT[b]} (PWCCA)",
                    color=color, linewidth=1.5, alpha=0.85)
        ax_sim.plot(layers_arr, per_layer_svcca[k],
                    color=color, linewidth=0.8, alpha=0.4, linestyle="--")
    ax_sim.plot(layers_arr, mean_pwcca, label="mean PWCCA", color="black", linewidth=2.2)
    for tl in top_layers:
        ax_sim.axvline(tl + 1, color="gray", linestyle=":", linewidth=1, alpha=0.7)
    ax_sim.set_ylabel("Subspace Similarity")
    ax_sim.set_title("SVCCA / PWCCA by Layer (solid=PWCCA, dashed=SVCCA)")
    ax_sim.legend(loc="lower left", fontsize=8)

    ax_dim = axes[1]
    for name in ds_names:
        ax_dim.plot(layers_arr, per_layer_dims[name],
                    label=SHORT.get(name, name),
                    color=COLORS.get(name, "gray"), linewidth=1.2)
    ax_dim.set_xlabel("Layer")
    ax_dim.set_ylabel(f"SVD dims ({threshold:.0%} var)")
    ax_dim.set_title("Truncated Subspace Dimensionality")
    ax_dim.legend(loc="upper left", fontsize=8)

    fig.tight_layout()
    layers_tag = "_".join(str(l + 1) for l in top_layers)
    out1 = output_dir / f"svcca_L{layers_tag}_{suffix}.png"
    fig.savefig(out1, dpi=150)
    plt.close(fig)
    print(f"saved {out1}")

    n = len(ds_names)
    short_labels = [SHORT.get(p, p) for p in ds_names]
    cmap = mcolors.LinearSegmentedColormap.from_list("rg", ["#d9534f", "#f5f5dc", "#2d8659"])

    for tl in top_layers:
        matrix_svcca = np.ones((n, n))
        matrix_pwcca = np.ones((n, n))
        for i in range(n):
            for j in range(n):
                if i == j:
                    continue
                a, b = sorted([ds_names[i], ds_names[j]])
                k = f"{a}_vs_{b}"
                matrix_svcca[i, j] = per_layer_svcca[k][tl]
                matrix_pwcca[i, j] = per_layer_pwcca[k][tl]

        fig, (ax1, ax2) = plt.subplots(1, 2, figsize=(max(10, n * 3.6), max(4, n * 1.5)))
        for ax, mat, label in [(ax1, matrix_svcca, "SVCCA"), (ax2, matrix_pwcca, "PWCCA")]:
            im = ax.imshow(mat, cmap=cmap, vmin=0, vmax=1, aspect="equal")
            for i in range(n):
                for j in range(n):
                    ax.text(j, i, f"{mat[i, j]:.3f}", ha="center", va="center",
                            fontsize=12, fontweight="bold",
                            color="white" if mat[i, j] < 0.5 else "black")
            ax.set_xticks(range(n))
            ax.set_xticklabels(short_labels)
            ax.set_yticks(range(n))
            ax.set_yticklabels(short_labels)
            ax.set_title(f"{label} (layer {tl + 1})")
            fig.colorbar(im, ax=ax, label=label, shrink=0.8)

        fig.suptitle(f"Subspace Similarity (layer {tl + 1})", fontsize=14)
        fig.tight_layout()
        out2 = output_dir / f"svcca_matrix_L{tl+1}_{suffix}.png"
        fig.savefig(out2, dpi=150, bbox_inches="tight")
        plt.close(fig)
        print(f"saved {out2}")


if __name__ == "__main__":
    fire.Fire(main)
