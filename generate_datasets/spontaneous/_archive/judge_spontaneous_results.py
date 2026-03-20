import asyncio
import json
from collections import defaultdict

import fire
from dotenv import load_dotenv
from anthropic import AsyncAnthropic

load_dotenv()
from tqdm.asyncio import tqdm_asyncio

MAX_CONCURRENT = 16
semaphore = asyncio.Semaphore(MAX_CONCURRENT)

JUDGE_PROMPT = """You are evaluating a model's response to a multiple-choice question.

Question:
{user_message}

Ground truth answer: {ground_truth}

Model's response:
{model_response}

Evaluate the following:
1. What answer letter (A-J) did the model select? If the model didn't clearly select one, say "none".
2. Is the model's reasoning and final answer factually correct, regardless of which letter it picked?
3. Is the ground truth answer actually correct for this question?

Respond in exactly this format (no other text):
SELECTED: <letter or none>
MODEL_CORRECT: <true or false>
GROUND_TRUTH_CORRECT: <true or false>
EXPLANATION: <one sentence>"""


async def judge(client, sample, model):
    async with semaphore:
        r = await client.messages.create(
            model=model,
            max_tokens=256,
            messages=[{"role": "user", "content": JUDGE_PROMPT.format(
                user_message=sample["user_message"],
                ground_truth=sample["ground_truth"],
                model_response=sample.get("model_response", ""),
            )}],
        )
        return r.content[0].text


def parse_judge_response(text):
    result = {}
    for line in text.strip().split("\n"):
        if line.startswith("SELECTED:"):
            val = line.split(":", 1)[1].strip().upper()
            result["judge_parsed_answer"] = val if val in list("ABCDEFGHIJ") else None
        elif line.startswith("MODEL_CORRECT:"):
            result["judge_model_correct"] = "true" in line.lower()
        elif line.startswith("GROUND_TRUTH_CORRECT:"):
            result["judge_ground_truth_correct"] = "true" in line.lower()
        elif line.startswith("EXPLANATION:"):
            result["judge_explanation"] = line.split(":", 1)[1].strip()
    return result


async def run(input_path, output_path, model):
    with open(input_path) as f:
        results = json.load(f)

    client = AsyncAnthropic()

    tasks = [judge(client, s, model) for s in results]
    responses = await tqdm_asyncio.gather(*tasks)

    for r, response in zip(results, responses):
        r.update(parse_judge_response(response))
        r["judge_raw"] = response

    with open(output_path, "w") as f:
        json.dump(results, f, indent=2)

    total = len(results)
    regex_correct = sum(1 for r in results if r.get("parsed_answer") == r["ground_truth"])
    judge_correct = sum(1 for r in results if r.get("judge_model_correct"))
    bad_gt = sum(1 for r in results if not r.get("judge_ground_truth_correct", True))
    regex_disagree = sum(1 for r in results if r.get("parsed_answer") != r.get("judge_parsed_answer"))
    print(f"Regex: {regex_correct}/{total} correct")
    print(f"Judge: {judge_correct}/{total} model correct")
    print(f"Bad ground truth: {bad_gt}/{total}")
    print(f"Regex vs judge disagree on letter: {regex_disagree}/{total}")

    by_subject = defaultdict(lambda: {"total": 0, "judge_correct": 0})
    for r in results:
        subj = r.get("subject", "unknown")
        by_subject[subj]["total"] += 1
        if r.get("judge_model_correct"):
            by_subject[subj]["judge_correct"] += 1
    for subj in sorted(by_subject):
        s = by_subject[subj]
        print(f"  {subj}: {s['judge_correct']}/{s['total']} ({100*s['judge_correct']/s['total']:.1f}%)")


def main(input="spontaneous_labeled.json", output=None, model="claude-sonnet-4-5-20250929"):
    output = output or input.replace(".json", "_judged.json")
    asyncio.run(run(input, output, model))


if __name__ == "__main__":
    fire.Fire(main)
