"""
Shared utility: replay conversations through a model and score with linear probes.

Loads model (transformers, device_map="auto", bf16, optional LoRA merge),
registers forward hooks on target layers, scores activations via dot product
with probe directions in the hook — no full hidden state materialization.

Usage as library:
    from replay_probe import ReplayScorer, load_probes
    probes = load_probes("contrastive/shared_direction.pt,mass_mean/shared_direction.pt")
    scorer = ReplayScorer("meta-llama/Llama-3.1-70B-Instruct", probes=probes)
    results = scorer.score_many(texts, positions="last")
"""
import numpy as np
import torch
from pathlib import Path
from transformers import AutoTokenizer, AutoModelForCausalLM
from tqdm import tqdm

PROBES_ROOT = Path(__file__).resolve().parent.parent / "probes"


def _find_layers(model):
    if hasattr(model, "model") and hasattr(model.model, "layers"):
        return model.model.layers
    if hasattr(model, "model") and hasattr(model.model, "model") and hasattr(model.model.model, "layers"):
        return model.model.model.layers
    raise AttributeError("Cannot find model layers")


def load_probes(probe_paths, probes_root=PROBES_ROOT, layer_override=None):
    if isinstance(probe_paths, str):
        probe_paths = [p.strip() for p in probe_paths.split(",")]
    probes = []
    for p in probe_paths:
        path = Path(p) if Path(p).is_absolute() else probes_root / p
        data = torch.load(path, weights_only=False)
        name = f"{path.parent.name}/{path.stem}" if path.parent.name != "probes" else path.stem
        if "shared_direction_all" in data:
            direction = np.asarray(data["shared_direction_all"])
            layer = data.get("best_layer_transfer", data.get("best_layer")) - 1
        else:
            direction = np.asarray(data["direction"])
            layer = data["best_layer"] - 1
        if layer_override is not None:
            layer = int(layer_override) - 1
        probes.append((name, layer, direction))
    return probes


def load_probes_sweep(probe_path, probes_root=PROBES_ROOT):
    path = Path(probe_path) if Path(probe_path).is_absolute() else probes_root / probe_path
    data = torch.load(path, weights_only=False)
    base_name = f"{path.parent.name}/{path.stem}" if path.parent.name != "probes" else path.stem
    all_dirs = data.get("all_directions")
    if all_dirs is None:
        raise ValueError(f"{path} has no all_directions — retrain with updated train.py")
    probes = []
    for layer_idx in sorted(all_dirs.keys()):
        name = f"{base_name}/L{layer_idx + 1}"
        probes.append((name, layer_idx, np.asarray(all_dirs[layer_idx])))
    return probes


def _make_score_hook(probes_at_layer, state):
    device_cache = {}

    def hook(module, input, output):
        hs = output[0] if isinstance(output, tuple) else output
        for name, direction in probes_at_layer:
            key = (name, hs.device)
            if key not in device_cache:
                device_cache[key] = torch.from_numpy(direction).to(device=hs.device, dtype=hs.dtype)
            scores = (hs[0] @ device_cache[key]).cpu().float().numpy()
            state["scores"][name] = scores
        return output

    return hook


class ReplayScorer:
    def __init__(self, model_name, adapter_id=None, probes=None, device_map="auto"):
        self.tokenizer = AutoTokenizer.from_pretrained(model_name)
        self.tokenizer.pad_token = self.tokenizer.eos_token
        self.model = AutoModelForCausalLM.from_pretrained(
            model_name, torch_dtype=torch.bfloat16, device_map=device_map,
        )
        if adapter_id:
            from peft import PeftModel
            self.model = PeftModel.from_pretrained(self.model, adapter_id)
            self.model = self.model.merge_and_unload()
        self.model.eval()

        self.probes = probes or []
        self._state = {"scores": {}}
        self._hooks = []

        by_layer = {}
        for name, layer, direction in self.probes:
            by_layer.setdefault(layer, []).append((name, direction))

        layers = _find_layers(self.model)
        for layer_idx, probes_at_layer in by_layer.items():
            h = layers[layer_idx].register_forward_hook(
                _make_score_hook(probes_at_layer, self._state)
            )
            self._hooks.append(h)

    def _input_device(self):
        return next(self.model.parameters()).device

    @torch.inference_mode()
    def score(self, text, positions="last"):
        inputs = self.tokenizer(text, return_tensors="pt", truncation=True, max_length=16384)
        inputs = {k: v.to(self._input_device()) for k, v in inputs.items()}
        seq_len = inputs["input_ids"].shape[1]
        self._state["scores"] = {}
        self.model(**inputs)
        result = {}
        for name, _, _ in self.probes:
            all_scores = self._state["scores"][name]
            if positions == "last":
                result[name] = float(all_scores[seq_len - 1])
            elif positions == "all":
                result[name] = all_scores[:seq_len].tolist()
            elif isinstance(positions, list):
                result[name] = [float(all_scores[p]) for p in positions]
            else:
                result[name] = float(all_scores[seq_len - 1])
        return result

    def score_with_positions(self, text, prefix_text=None, positions="last"):
        inputs = self.tokenizer(text, return_tensors="pt", truncation=True, max_length=16384)
        seq_len = inputs["input_ids"].shape[1]
        if prefix_text is not None:
            prefix_ids = self.tokenizer(prefix_text, return_tensors="pt")
            prefix_len = prefix_ids["input_ids"].shape[1]
        else:
            prefix_len = 0

        inputs = {k: v.to(self._input_device()) for k, v in inputs.items()}
        self._state["scores"] = {}
        with torch.inference_mode():
            self.model(**inputs)

        result = {}
        for name, _, _ in self.probes:
            all_scores = self._state["scores"][name]
            if positions == "last":
                result[name] = float(all_scores[seq_len - 1])
            elif positions == "all":
                result[name] = all_scores[:seq_len].tolist()
            elif positions == "assistant":
                result[name] = all_scores[prefix_len:seq_len].tolist()
            elif positions == "first_assistant":
                pos = min(prefix_len + 3, seq_len - 1)
                result[name] = float(all_scores[pos])
        return result

    def score_many(self, texts, positions="last", desc="Scoring"):
        return [self.score(t, positions) for t in tqdm(texts, desc=desc)]

    def score_many_with_prefix(self, items, positions="last", desc="Scoring"):
        results = []
        for text, prefix_text in tqdm(items, desc=desc):
            results.append(self.score_with_positions(text, prefix_text, positions))
        return results
