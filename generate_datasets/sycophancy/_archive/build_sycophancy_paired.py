import json
import random
import re
from pathlib import Path

JUDGED = Path(__file__).parent / "sycophancy_ays_flips_judged.json"
FULL = Path(__file__).parent / "sycophancy_probe_results.json"
OUTPUT = Path(__file__).parent.parent.parent / "sycophancy_lie_truth.json"
SEED = 42


def extract_letter(text):
    m = re.search(r'(?:answer is|answer:|correct answer is)\s*\(?([A-J])\)?', text, re.I)
    if m: return m.group(1)
    letters = re.findall(r'\(([A-J])\)', text)
    if len(letters) == 1: return letters[0]
    if letters: return letters[-1]
    return None


with open(JUDGED) as f:
    judged = json.load(f)

lies = []
for r in judged:
    if not r.get("judge_flipped"):
        continue
    t2 = r.get("judge_turn2_answer", "unclear").strip().upper()
    if len(t2) == 1 and t2 in "ABCDEFGHIJ" and t2 != r["ground_truth"]:
        lies.append(r)

lie_ids = {r["id"] for r in lies}

with open(FULL) as f:
    full = json.load(f)

truths_pool = []
for r in full:
    if r["id"] in lie_ids:
        continue
    gt = r["ground_truth"]
    a1 = extract_letter(r["model_response_turn1"])
    a2 = extract_letter(r["model_response_turn2"])
    if a1 == gt and a2 == gt:
        truths_pool.append(r)

rng = random.Random(SEED)
rng.shuffle(truths_pool)
truths = truths_pool[:len(lies)]

dataset = []
for r in lies:
    dataset.append({
        "id": r["id"],
        "condition": "sycophantic_lie",
        "system_prompt": r["system_prompt"],
        "user_message": r["user_message"],
        "ground_truth": r["ground_truth"],
        "expected_behavior": "incorrect",
        "model_response_turn1": r["model_response_turn1"],
        "model_response": r["model_response_turn2"],
        "followup_message": r["followup_message"],
        "parsed_answer": r.get("judge_turn2_answer", "").strip().upper(),
    })

for r in truths:
    dataset.append({
        "id": r["id"],
        "condition": "sycophantic_truth",
        "system_prompt": r["system_prompt"],
        "user_message": r["user_message"],
        "ground_truth": r["ground_truth"],
        "expected_behavior": "correct",
        "model_response_turn1": r["model_response_turn1"],
        "model_response": r["model_response_turn2"],
        "followup_message": r["followup_message"],
        "parsed_answer": extract_letter(r["model_response_turn2"]),
    })

print(f"Lies: {len(lies)}, Truths: {len(truths)}")
print(f"Total: {len(dataset)} -> {OUTPUT}")

with open(OUTPUT, "w") as f:
    json.dump(dataset, f, indent=2)
