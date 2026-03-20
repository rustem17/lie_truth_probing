"""Multi-run vLLM inference for spontaneous MCQ dataset.

Model (inference): vLLM-served (default meta-llama/Llama-3.1-70B-Instruct)
Model (judge): Anthropic API (default claude-haiku-4-5-20251001), only for regex failures
Input: spontaneous_matched_dataset.json (2000 MCQ samples)
Output: multi_results.json — checkpoint with parsed_answers per run, LLM-resolved where regex failed
Temperature: 0.6, N_runs: 10
"""
import asyncio
import json
import re
from collections import Counter

import fire
from dotenv import load_dotenv
from openai import AsyncOpenAI
from anthropic import AsyncAnthropic
from tqdm.asyncio import tqdm_asyncio

load_dotenv()

MAX_CONCURRENT_INFER = 32
MAX_CONCURRENT_JUDGE = 32
infer_sem = asyncio.Semaphore(MAX_CONCURRENT_INFER)
judge_sem = asyncio.Semaphore(MAX_CONCURRENT_JUDGE)

ANSWER_PATTERNS = [
    re.compile(r"(?:the\s+)?(?:correct\s+)?answer\s+is\s*:?\s*\(?([A-J])\)?", re.IGNORECASE),
    re.compile(r"\b([A-J])\.\s", re.MULTILINE),
    re.compile(r"\(([A-J])\)\s*$", re.MULTILINE),
]
FALLBACK = re.compile(r"(?<![a-zA-Z0-9*^/\\])([A-J])(?:\.|(?:\s*[\)\.])|$)")

JUDGE_PROMPT = """A model answered a multiple-choice question. What answer letter (A-J) did it select?

Question:
{question}

Model's response:
{response}

Respond with ONLY the letter (A-J) or "unclear". Nothing else."""


def extract_answer(response):
    for pat in ANSWER_PATTERNS:
        matches = pat.findall(response)
        if matches:
            return matches[-1].upper()
    matches = FALLBACK.findall(response)
    if matches:
        return matches[-1].upper()
    return None


async def sample(client, system_prompt, user_message, model, temperature):
    async with infer_sem:
        r = await client.chat.completions.create(
            model=model,
            messages=[{"role": "system", "content": system_prompt},
                      {"role": "user", "content": user_message}],
            temperature=temperature, max_tokens=1024)
        return r.choices[0].message.content


async def judge_one(client, question, response, model):
    async with judge_sem:
        r = await client.messages.create(
            model=model, max_tokens=8,
            messages=[{"role": "user", "content": JUDGE_PROMPT.format(
                question=question, response=response[:800])}])
        text = r.content[0].text.strip().upper()
        if len(text) == 1 and text in "ABCDEFGHIJ":
            return text
        return None


async def run(model, base_url, dataset_path, output, n_runs, temperature, judge_model):
    with open(dataset_path) as f:
        dataset = json.load(f)

    infer_client = AsyncOpenAI(api_key="not-needed", base_url=base_url)
    all_responses = {i: [] for i in range(len(dataset))}
    for run_idx in range(n_runs):
        print(f"Run {run_idx + 1}/{n_runs}")
        tasks = [sample(infer_client, s["system_prompt"], s["user_message"], model, temperature)
                 for s in dataset]
        responses = await tqdm_asyncio.gather(*tasks)
        for i, resp in enumerate(responses):
            all_responses[i].append(resp)

    all_answers = {}
    to_judge = []
    for i, s in enumerate(dataset):
        answers = []
        for j, resp in enumerate(all_responses[i]):
            a = extract_answer(resp)
            if a is None:
                to_judge.append((i, j, s["user_message"], resp))
            answers.append(a)
        all_answers[i] = answers

    if to_judge:
        print(f"Regex failed on {len(to_judge)} responses, judging with LLM...")
        judge_client = AsyncAnthropic()
        judge_tasks = [judge_one(judge_client, q, r, judge_model) for _, _, q, r in to_judge]
        judge_results = await tqdm_asyncio.gather(*judge_tasks)
        resolved = sum(1 for r in judge_results if r is not None)
        print(f"Judge resolved: {resolved}/{len(to_judge)}")
        for (i, j, _, _), new_a in zip(to_judge, judge_results):
            all_answers[i][j] = new_a

    results = []
    consistent = 0
    for i, s in enumerate(dataset):
        answers = all_answers[i]
        counts = Counter(a for a in answers if a)
        majority_answer, majority_count = counts.most_common(1)[0] if counts else (None, 0)
        is_consistent = majority_count == n_runs
        if is_consistent:
            consistent += 1
        results.append({
            **s,
            "model_responses": all_responses[i],
            "parsed_answers": answers,
            "parsed_answer": majority_answer,
            "answer_counts": dict(counts),
            "n_runs": n_runs,
            "consistent": is_consistent,
        })

    with open(output, "w") as f:
        json.dump(results, f, indent=2)

    print(f"\n{len(results)} samples, {consistent} consistent "
          f"({100*consistent/len(results):.1f}%) -> {output}")


def main(model="meta-llama/Llama-3.1-70B-Instruct", base_url="http://localhost:8000/v1",
         dataset="spontaneous_matched_dataset.json", output="multi_results.json",
         n_runs=10, temperature=0.6, judge_model="claude-haiku-4-5-20251001"):
    asyncio.run(run(model, base_url, dataset, output, n_runs, temperature, judge_model))


if __name__ == "__main__":
    fire.Fire(main)
