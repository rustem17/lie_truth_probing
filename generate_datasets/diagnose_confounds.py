"""Diagnose confounds in probing paired sample sets.

Checks per file:
  - Response length: mean lie/truth chars, ratio, t-test p, signed diff stats
  - Prompt confounds: system_prompt and user_message identity across conditions
  - Keyword leakage: condition-correlated keywords in model responses (chi-squared)

Usage:
    python diagnose_confounds.py instructed_lie_truth.json spontaneous_lie_truth.json
    python diagnose_confounds.py  # defaults to all paired JSONs in probing/ root
"""
import json
from pathlib import Path

import fire
import numpy as np
from scipy.stats import chi2_contingency, ttest_ind

KEYWORDS = [
    "incorrect", "wrong", "false", "lie",
    "correct", "right", "true", "truth",
    "actually", "sorry", "mistake",
]


def pair_entries(data):
    pairs = []
    for i in range(0, len(data) - 1, 2):
        a, b = data[i], data[i + 1]
        if "lie" in a["condition"]:
            pairs.append((a, b))
        else:
            pairs.append((b, a))
    return pairs


def analyze_file(path):
    data = json.load(open(path))
    pairs = pair_entries(data)
    n = len(pairs)

    lie_lens = [len(p[0]["model_response"]) for p in pairs]
    truth_lens = [len(p[1]["model_response"]) for p in pairs]
    diffs = [l - t for l, t in zip(lie_lens, truth_lens)]

    same_sp = sum(1 for p in pairs if p[0]["system_prompt"] == p[1]["system_prompt"])
    same_um = sum(1 for p in pairs if p[0]["user_message"] == p[1]["user_message"])

    print(f"\n{'='*65}")
    print(f"{path} ({n} pairs)")
    print(f"{'='*65}")

    print(f"\n{'Metric':<25} {'Lie':>10} {'Truth':>10} {'Ratio':>7} {'p-val':>8}")
    print("-" * 65)
    lm, tm = np.mean(lie_lens), np.mean(truth_lens)
    ratio = lm / tm if tm > 0 else float("inf")
    _, p = ttest_ind(lie_lens, truth_lens)
    print(f"{'Response (chars)':<25} {lm:>10.0f} {tm:>10.0f} {ratio:>7.3f} {p:>8.1e}")

    print(f"\nSigned diff (lie - truth): mean={np.mean(diffs):.1f}  median={np.median(diffs):.1f}  std={np.std(diffs):.1f}  min={min(diffs)}  max={max(diffs)}")

    print(f"\nPrompt identity:")
    print(f"  system_prompt same: {same_sp}/{n}")
    print(f"  user_message  same: {same_um}/{n}")
    if same_sp < n:
        lie_sp_len = np.mean([len(p[0]["system_prompt"]) for p in pairs])
        truth_sp_len = np.mean([len(p[1]["system_prompt"]) for p in pairs])
        print(f"  system_prompt length: lie={lie_sp_len:.0f}  truth={truth_sp_len:.0f}")
    if same_um < n:
        lie_um_len = np.mean([len(p[0]["user_message"]) for p in pairs])
        truth_um_len = np.mean([len(p[1]["user_message"]) for p in pairs])
        print(f"  user_message  length: lie={lie_um_len:.0f}  truth={truth_um_len:.0f}")

    lie_responses = [p[0]["model_response"].lower() for p in pairs]
    truth_responses = [p[1]["model_response"].lower() for p in pairs]

    print(f"\n{'Keyword':<15} {'Lie freq':>10} {'Truth freq':>12} {'chi2 p':>8}")
    print("-" * 50)
    for kw in KEYWORDS:
        lc = sum(1 for r in lie_responses if kw in r)
        tc = sum(1 for r in truth_responses if kw in r)
        table = [[lc, n - lc], [tc, n - tc]]
        if lc + tc == 0:
            p = 1.0
        else:
            _, p, _, _ = chi2_contingency(table)
        print(f"{kw:<15} {lc:>7}/{n:<3} {tc:>9}/{n:<3} {p:>8.1e}")


def main(*paired_file):
    if not paired_file:
        root = Path(__file__).parent.parent
        paired_file = sorted(str(p) for p in root.glob("*.json")
                             if "multi" not in p.name and "dataset" not in p.name and "results" not in p.name)
    for f in paired_file:
        analyze_file(f)


if __name__ == "__main__":
    fire.Fire(main)
