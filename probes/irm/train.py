"""
Invariant linear probe (IRMv1 or V-REx) across multiple environments (deception conditions).

Environments: subsets of TRAIN_DATASETS (default: instructed, spontaneous, sycophancy)
Input: activations/{name}.pt + paired dataset JSONs
Probe: nn.Linear(hidden_dim, 2), no bias
Penalty modes:
  irm  — ||grad(CE_e w.r.t. dummy_scalar)||^2 (IRMv1 gradient penalty)
  vrex — Var(CE_e across environments) (V-REx risk extrapolation)
Loss: sum(CE_e) + lambda_irm * penalty
Training: all 80 layers vectorized in one batched operation on GPU
Annealing: lambda_irm=0 for warmup_steps, linear ramp over ramp_steps to lambda_irm target
Output: probes/irm/irm_probe.pt
"""

import sys
import json
import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np
from pathlib import Path
from collections import defaultdict
from sklearn.metrics import roc_auc_score
import fire

sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
from config import TRAIN_DATASETS

DEVICE = torch.device("cuda" if torch.cuda.is_available() else "cpu")


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


def load_envs(env_names, data_dir, activations_dir, max_samples=None):
    envs = {}
    model_tag = ""
    model_id = ""
    for name in env_names:
        filename, label_map = TRAIN_DATASETS[name]
        saved = torch.load(Path(activations_dir) / f"{name}.pt", weights_only=False)
        if not model_tag:
            model_tag = saved.get("model_tag", "")
            model_id = saved.get("model_id", "")
        data = json.load(open(Path(data_dir) / filename))[:len(saved["activations"])]
        if max_samples:
            data = data[:max_samples]
            saved["activations"] = saved["activations"][:max_samples]
        pair_diffs, pair_ids = get_pair_diffs(saved["activations"], data, label_map)
        envs[name] = {"D": pair_diffs, "pair_ids": pair_ids}
    return envs, model_tag, model_id


def get_lambda(step, warmup_steps, ramp_steps, lambda_target):
    if step < warmup_steps:
        return 0.0
    if ramp_steps == 0:
        return lambda_target
    progress = min((step - warmup_steps) / ramp_steps, 1.0)
    return lambda_target * progress


def train_all_layers(env_data, env_names, n_layers, hidden_dim, n_epochs, lr, warmup_steps,
                     ramp_steps, lambda_irm, penalty="irm", weight_decay=0.0, verbose=True):
    W = torch.empty(n_layers, 2, hidden_dim, device=DEVICE)
    nn.init.kaiming_uniform_(W.view(n_layers * 2, hidden_dim), a=5**0.5)
    W = nn.Parameter(W)
    optimizer = torch.optim.Adam([W], lr=lr, weight_decay=weight_decay)

    env_tensors = []
    for name in env_names:
        D = env_data[name]["D"]
        n = D.shape[0]
        D_t = np.transpose(D, (1, 0, 2))
        X = np.concatenate([D_t, -D_t], axis=1)
        y = np.array([1] * n + [0] * n)
        env_tensors.append((
            torch.tensor(X, dtype=torch.float32, device=DEVICE),
            torch.tensor(y, dtype=torch.long, device=DEVICE),
        ))

    for step in range(n_epochs):
        lam = get_lambda(step, warmup_steps, ramp_steps, lambda_irm)
        total_loss = torch.tensor(0.0, device=DEVICE)
        total_penalty = torch.tensor(0.0, device=DEVICE)
        per_env_layer_losses = []

        for X_e, y_e in env_tensors:
            n_samples = X_e.shape[1]
            logits = torch.bmm(X_e, W.transpose(1, 2))
            logits_flat = logits.reshape(-1, 2)
            y_flat = y_e.unsqueeze(0).expand(n_layers, -1).reshape(-1)
            per_sample_ce = F.cross_entropy(logits_flat, y_flat, reduction='none')
            per_layer_ce = per_sample_ce.reshape(n_layers, n_samples).mean(dim=1)
            total_loss = total_loss + per_layer_ce.sum()
            per_env_layer_losses.append(per_layer_ce)

            if penalty == "irm":
                dummy = torch.ones(n_layers, 1, 1, device=DEVICE, requires_grad=True)
                scaled_flat = (logits * dummy).reshape(-1, 2)
                scaled_ce = F.cross_entropy(scaled_flat, y_flat, reduction='none')
                scaled_per_layer = scaled_ce.reshape(n_layers, n_samples).mean(dim=1)
                grad = torch.autograd.grad(scaled_per_layer.sum(), dummy, create_graph=True)[0]
                total_penalty = total_penalty + (grad.squeeze() ** 2).sum()

        if penalty == "vrex":
            stacked = torch.stack(per_env_layer_losses)
            total_penalty = stacked.var(dim=0).sum()

        objective = total_loss + lam * total_penalty
        optimizer.zero_grad()
        objective.backward()
        optimizer.step()

        if verbose and (step % 100 == 0 or step == n_epochs - 1):
            print(f"  step {step:4d}  loss={total_loss.item():.4f}  penalty={total_penalty.item():.6f}  lambda={lam:.1f}")

    w = W.detach().cpu().numpy()
    directions = w[:, 1, :] - w[:, 0, :]
    norms = np.linalg.norm(directions, axis=1, keepdims=True)
    directions = directions / norms
    return directions, w


def eval_auroc(direction, env_diffs_layer):
    aucs = []
    for D_layer in env_diffs_layer:
        n = D_layer.shape[0]
        scores = np.concatenate([D_layer @ direction, -D_layer @ direction])
        labels = np.concatenate([np.ones(n), np.zeros(n)])
        aucs.append(roc_auc_score(labels, scores))
    return float(np.mean(aucs)), aucs


def train(envs="instructed,spontaneous,sycophancy", data_dir="../..", activations_dir="../../activations",
          output_dir=".", n_epochs=500, lr=1e-3, lambda_irm=1e3, warmup_steps=100, ramp_steps=100,
          max_samples=None, penalty="irm", weight_decay=0.0):
    Path(output_dir).mkdir(parents=True, exist_ok=True)
    env_names = [e.strip() for e in envs.split(",")] if isinstance(envs, str) else list(envs)
    env_data, model_tag, model_id = load_envs(env_names, data_dir, activations_dir, max_samples)

    n_layers = next(iter(env_data.values()))["D"].shape[1]
    hidden_dim = next(iter(env_data.values()))["D"].shape[2]
    print(f"envs: {env_names}, layers: {n_layers}, dim: {hidden_dim}, device: {DEVICE}")
    for name, ed in env_data.items():
        print(f"  {name}: {ed['D'].shape[0]} pairs")

    directions, weights = train_all_layers(
        env_data, env_names, n_layers, hidden_dim, n_epochs, lr,
        warmup_steps, ramp_steps, lambda_irm, penalty, weight_decay)

    layer_results = []
    for layer in range(n_layers):
        env_diffs = [env_data[name]["D"][:, layer] for name in env_names]
        mean_auroc, per_env = eval_auroc(directions[layer], env_diffs)
        per_env_dict = {name: float(a) for name, a in zip(env_names, per_env)}
        layer_results.append({"layer": layer + 1, "auroc": mean_auroc, "per_env": per_env_dict})
        print(f"  layer {layer+1}: AUROC={mean_auroc:.4f}  " + "  ".join(f"{n}={a:.4f}" for n, a in per_env_dict.items()))

    best = max(layer_results, key=lambda r: r["auroc"])
    best_idx = best["layer"] - 1
    print(f"\nbest layer: {best['layer']}, AUROC={best['auroc']:.4f}")

    all_directions = {layer: directions[layer] for layer in range(n_layers)}

    probe_fname = f"irm_probe_{model_tag}.pt" if model_tag else "irm_probe.pt"
    torch.save({
        "direction": directions[best_idx],
        "weight": weights[best_idx],
        "best_layer": best["layer"],
        "all_directions": all_directions,
        "layer_results": layer_results,
        "envs": env_names,
        "model_tag": model_tag,
        "model_id": model_id,
        "config": {
            "n_epochs": n_epochs, "lr": lr, "lambda_irm": lambda_irm,
            "warmup_steps": warmup_steps, "ramp_steps": ramp_steps,
            "penalty": penalty, "weight_decay": weight_decay,
        },
    }, Path(output_dir) / probe_fname)

    print(f"saved to {output_dir}/{probe_fname}")


if __name__ == "__main__":
    fire.Fire(train)
