---
title: "Best-of-N Sampling"
slug: "best-of-n-sampling"
description: "Generating N candidate solutions and selecting the best using a reward model, majority vote, or verifier — a simple but powerful test-time compute scaling strategy with strong empirical results."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Best-of-N (BoN) sampling is the simplest and most widely deployed test-time compute scaling strategy: generate N candidate solutions for a problem and select the best one using a reward model, majority vote, or verifier. Unlike beam search (which prunes the search space during generation) or MCTS (which builds a reasoning tree), BoN generates all N candidates independently and selects post-hoc. This decoupling of generation and selection makes BoN trivially parallelisable — all N candidates can be generated simultaneously on N GPUs or via batched API calls — and robust to correlation between candidates (since each is sampled independently). Despite its simplicity, BoN achieves remarkably strong empirical results: on MATH, BoN with N=64 and a good ORM achieves 72% accuracy for a 7B-parameter model that achieves only 32% with greedy decoding. The accuracy-compute curve follows an approximate power law in N, making it straightforward to estimate the N required to hit a target accuracy given a cost budget."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"The BoN pipeline has three components: a generator LLM that produces diverse candidate solutions, a selection mechanism that scores and ranks candidates, and (optionally) a verifier that provides ground-truth correctness labels for evaluation. The generator must produce sufficiently diverse candidates to cover the space of possible correct solutions — diversity is primarily controlled by temperature (higher T = more diverse but lower average quality). The selection mechanism can be an ORM (scalar score per solution), a majority vote over extracted final answers, a weighted majority vote (ORM-weighted per candidate), or a learned verifier. BoN accuracy monotonically improves with N for any selection mechanism that is better than random, with the improvement rate depending on selection quality. The oracle pass@N rate — the probability that at least one of N solutions is correct — sets an upper bound on BoN accuracy; a perfect selector would achieve this bound. Practical selectors typically capture 70-85% of the oracle bound."},{"type":"heading","level":2,"content":"Generation Diversity via Temperature"},{"type":"text","content":"Temperature controls the trade-off between diversity and quality in the generated solution pool. At T=0 (greedy), all N solutions are identical — diversity is zero and BoN collapses to a single-sample evaluation. As T increases, solutions become more varied: the model explores different problem-solving approaches, uses different intermediate steps, and arrives at different final answers (including both correct and incorrect ones). The optimal temperature for BoN is problem-dependent: for near-deterministic problems where the model usually knows the answer (low-difficulty), T=0.6-0.8 preserves quality while adding diversity. For hard problems where the model rarely gets greedy answers correct, T=0.8-1.2 is better because diversity is more important than per-sample quality. A common heuristic is to use T=1.0 for BoN generation across all problems, since it provides strong diversity without excessive degradation in solution quality. Some implementations use temperature annealing: start at T=1.0 for the first N/2 samples and T=0.7 for the second half, combining high-diversity and high-quality samples."},{"type":"code","language":"python","content":"import asyncio\nimport time\nfrom typing import List, Tuple, Optional\nfrom dataclasses import dataclass, field\nfrom openai import AsyncOpenAI\n\naclient = AsyncOpenAI()\n\n@dataclass\nclass BonSample:\n    solution: str\n    orm_score: float = 0.0\n    is_correct: Optional[bool] = None\n\nasync def generate_candidate(problem: str, model: str,\n                               temperature: float) -\u003e str:\n    resp = await aclient.chat.completions.create(\n        model=model, temperature=temperature,\n        messages=[{\"role\": \"user\",\n                   \"content\": f\"Solve step by step: {problem}\"}]\n    )\n    return resp.choices[0].message.content\n\nasync def best_of_n(problem: str, n: int = 64,\n                     temperature: float = 1.0,\n                     model: str = \"gpt-4o-mini\") -\u003e List[BonSample]:\n    # Generate n candidates in parallel; return unsorted list.\n    t0 = time.perf_counter()\n    solutions = await asyncio.gather(\n        *[generate_candidate(problem, model, temperature) for _ in range(n)]\n    )\n    elapsed = time.perf_counter() - t0\n    samples = [BonSample(solution=s) for s in solutions]\n    print(f\"Generated {n} candidates in {elapsed:.2f}s ({elapsed/n*1000:.0f}ms each)\")\n    return samples"},{"type":"heading","level":2,"content":"Selection Strategies"},{"type":"text","content":"Three main selection strategies are used in practice, each with different accuracy-cost trade-offs. ORM selection scores each candidate with a trained reward model and returns the candidate with the highest score; this requires a pre-trained ORM but achieves the best accuracy. Majority vote (self-consistency) extracts the final answer from each candidate, computes the plurality answer, and returns any candidate that produced that answer; this requires no additional model but is limited to problems with discrete final answers (numbers, multiple choice). Weighted majority vote combines both: each candidate\u0027s vote is weighted by its ORM score, so candidates that are both popular (many agree) and high-scoring (ORM confident) receive extra weight. Weighted majority vote consistently outperforms both unweighted majority vote and plain ORM selection on mathematical benchmarks, particularly at small N (4-8) where the ORM signal and the diversity signal are both noisy. The performance gap narrows at large N (64+) where both methods approach the oracle pass@N bound."},{"type":"heading","level":2,"content":"Majority Vote (Self-Consistency)"},{"type":"text","content":"Majority vote, introduced as Self-Consistency by Wang et al. (2022), is the simplest ORM-free selection strategy for BoN. Each of the N candidates is decoded independently (typically at temperature 0.5-1.0), the final answer is extracted (via regex or model-based extraction), and the plurality answer is returned. Self-consistency is remarkably effective: on GSM8K, majority vote with N=40 samples of Chain-of-Thought reasoning achieves 74% accuracy versus 56% for a single CoT sample, a 18-point improvement with zero additional model training. The key intuition is that correct reasoning paths tend to converge on the same final answer while incorrect paths make diverse errors. Majority vote amplifies this signal by counting votes. Its main limitation is that it requires a discrete final answer to be extractable — open-ended generation tasks, code generation, and essay writing cannot use naive majority vote without additional structure. For code, majority vote can be applied over test-passing outcomes rather than string equality."},{"type":"code","language":"python","content":"import re\nfrom collections import Counter\nfrom typing import List, Optional, Tuple\n\ndef extract_final_answer(text: str) -\u003e Optional[str]:\n    # Try common patterns: boxed answer, \"= X\" at end, last number.\n    boxed = re.search(r\"\\\\boxed\\{([^}]+)\\}\", text)\n    if boxed:\n        return boxed.group(1).strip()\n    eq_end = re.search(r\"=\\s*([\\d./-]+)\\s*$\", text.strip())\n    if eq_end:\n        return eq_end.group(1).strip()\n    nums = re.findall(r\"[-+]?\\d*\\.?\\d+\", text.replace(\",\", \"\"))\n    return nums[-1] if nums else None\n\ndef majority_vote(solutions: List[str],\n                  orm_scores: Optional[List[float]] = None) -\u003e Tuple[str, str]:\n    # Extract answers, compute plurality; break ties using ORM score.\n    answers = [extract_final_answer(s) or \"\" for s in solutions]\n    counts  = Counter(a for a in answers if a)\n    if not counts:\n        return solutions[0], \"fallback\"\n    plurality_answer = counts.most_common(1)[0][0]\n    candidates = [(s, sc) for s, a, sc in\n                  zip(solutions, answers, orm_scores or [0.0]*len(solutions))\n                  if a == plurality_answer]\n    if orm_scores:\n        best = max(candidates, key=lambda x: x[1])\n    else:\n        best = candidates[0]\n    vote_pct = counts[plurality_answer] / len(answers) * 100\n    print(f\"Plurality answer: {plurality_answer} ({vote_pct:.1f}% of {len(answers)} votes)\")\n    return best[0], plurality_answer"},{"type":"heading","level":2,"content":"Reward Model Selection"},{"type":"text","content":"ORM-based selection scores each of the N candidates with a reward model and returns the highest-scoring candidate. This approach requires a pre-trained ORM but captures information that majority vote misses: a uniquely correct solution that no other candidate agrees with will be selected by the ORM if it scores high, but ignored by majority vote. ORM selection is strictly better than majority vote when the ORM is well-calibrated (AUROC \u003e 0.80) and N is large enough that diversity is not the limiting factor. The ORM scoring step adds latency proportional to N (each candidate must be scored), but this is often acceptable since the generation step (which also runs N times) dominates latency. When using a large ORM (e.g., a 13B-parameter reward model to score a 7B generator), the ORM scoring step can take as long as generation — a 13B ORM scoring 64 candidates may take 128 seconds on a single A100. Quantising the ORM to 4-bit or using a smaller ORM (3B-7B) can reduce this to 20-40 seconds with minimal accuracy loss."},{"type":"table","headers":["N samples","Temperature","Selection","MATH accuracy","Cost (1k queries)","Notes"],"rows":[["N=1","0.0 (greedy)","—","32%","$0.40","Baseline: single greedy sample"],["N=4","0.8","Majority vote","46%","$1.60","Simple vote; no ORM needed"],["N=16","1.0","ORM selection","61%","$6.40","Strong ORM required; good accuracy"],["N=64","1.0","ORM selection","72%","$25.60","Near-saturating for 7B model"],["N=256","1.0","ORM selection","77%","$102.40","Diminishing returns; expensive"],["Oracle N=64","1.0","Perfect verifier","84%","—","Upper bound: any-of-64 correct"]]},{"type":"heading","level":2,"content":"Weighted Majority Vote"},{"type":"text","content":"Weighted majority vote (WMV) combines ORM scores and plurality voting into a single selection criterion. For each unique extracted answer a, WMV computes a weight W(a) = sum of exp(ORM_score_i) for all candidates i whose extracted answer equals a. The answer with the highest total weight is selected, and any candidate with that answer is returned (typically the highest-ORM-scoring one). WMV outperforms both unweighted majority vote and plain ORM selection at small N (4-16) because it exploits two complementary signals: the ORM signal (which candidate is individually most plausible) and the agreement signal (which answer is most robustly reached by different reasoning paths). At N=4, WMV typically outperforms plain ORM selection by 2-4 percentage points on MATH. At N=64, the difference narrows to 0.5-1.5 points. WMV adds negligible latency beyond ORM scoring and is straightforward to implement; it should be the default selection strategy for any BoN system that already has an ORM."},{"type":"code","language":"python","content":"import math\nfrom collections import defaultdict\nfrom typing import List, Tuple, Optional\n\ndef weighted_majority_vote(solutions: List[str],\n                            orm_scores: List[float]) -\u003e Tuple[str, str, float]:\n    # WMV: weight each answer by sum of exp(ORM score) of agreeing candidates.\n    answers = [extract_final_answer(s) or \"\" for s in solutions]\n    weight_map: dict = defaultdict(float)\n    score_map:  dict = defaultdict(list)\n    for s, a, sc in zip(solutions, answers, orm_scores):\n        if a:\n            weight_map[a] += math.exp(sc)        # exponential weighting\n            score_map[a].append((sc, s))\n    if not weight_map:\n        return solutions[0], \"\", orm_scores[0]\n    best_ans  = max(weight_map, key=lambda a: weight_map[a])\n    best_sol  = max(score_map[best_ans], key=lambda x: x[0])[1]\n    total_w   = sum(weight_map.values())\n    conf      = weight_map[best_ans] / total_w\n    print(f\"WMV winner: {best_ans}  confidence: {conf:.3f}\")\n    return best_sol, best_ans, conf\n\ndef compare_selection_methods(solutions: List[str],\n                               orm_scores: List[float]) -\u003e None:\n    # Compare ORM-only, majority vote, and WMV on the same candidate pool.\n    orm_best  = solutions[max(range(len(solutions)), key=lambda i: orm_scores[i])]\n    mv_sol, mv_ans = majority_vote(solutions, None)\n    wm_sol, wm_ans, wm_conf = weighted_majority_vote(solutions, orm_scores)\n    print(f\"ORM best answer : {extract_final_answer(orm_best)}\")\n    print(f\"Majority vote   : {mv_ans}\")\n    print(f\"Weighted MV     : {wm_ans} (conf={wm_conf:.3f})\")"},{"type":"callout","variant":"tip","title":"Accuracy-Cost Sweet Spot","content":"Best-of-4 with a lightweight ORM typically achieves 80-90% of the gain of best-of-64 at 1/16 the cost — always benchmark the accuracy-cost curve before committing to a large N. For most production use cases, N=8 to N=16 with ORM selection provides an excellent accuracy-cost trade-off: 6-12 percentage points of MATH accuracy improvement over greedy at 8-16x the inference cost. Reserve N=64+ for offline batch evaluation or high-value queries where latency is not a constraint."},{"type":"heading","level":2,"content":"Scaling Laws for Best-of-N"},{"type":"text","content":"The BoN accuracy-compute relationship follows an approximate power law: accuracy(N) ≈ oracle_pass_rate - (oracle_pass_rate - pass@1) * N^{-alpha}, where alpha depends on the selector quality and the problem difficulty distribution. For a well-calibrated ORM on MATH, alpha ≈ 0.3-0.5, meaning accuracy scales roughly as the square root of the number of samples — doubling N from 16 to 32 gives roughly the same accuracy gain as the jump from 8 to 16. This sub-linear scaling means that the marginal value of additional samples decreases rapidly. A useful rule of thumb: 80% of the gap between pass@1 and oracle pass@N is captured by N ≈ (oracle_pass_rate / (1-pass@1))^{1/alpha}. For a model with 32% pass@1 and 84% oracle pass@64, reaching 90% of the oracle requires N ≈ 32. Fitting the power law on a small validation set (N=1,2,4,8,16,32) and extrapolating to larger N is an effective way to estimate the N needed to hit a target accuracy without running the full benchmark."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import curve_fit\nfrom typing import List, Tuple\n\ndef power_law_fit(n_values: List[int],\n                  accuracies: List[float]) -\u003e Tuple[float, float, float]:\n    # Fit accuracy(N) = oracle - (oracle - base) * N^(-alpha)\n    # Returns (oracle_rate, base_rate, alpha)\n    n_arr = np.array(n_values, dtype=float)\n    a_arr = np.array(accuracies, dtype=float)\n    def model(n, oracle, base, alpha):\n        return oracle - (oracle - base) * n**(-alpha)\n    p0 = (0.84, a_arr[0], 0.4)\n    popt, _ = curve_fit(model, n_arr, a_arr, p0=p0, maxfev=5000)\n    oracle, base, alpha = popt\n    print(f\"Fitted power law: oracle={oracle:.3f}  base={base:.3f}  alpha={alpha:.3f}\")\n    return oracle, base, alpha\n\ndef optimal_n(target_acc: float, cost_per_sample: float,\n               oracle: float, base: float, alpha: float) -\u003e int:\n    # Find smallest N achieving target_acc and estimate cost.\n    n = 1\n    while True:\n        acc = oracle - (oracle - base) * (n ** (-alpha))\n        if acc \u003e= target_acc or n \u003e 1024:\n            break\n        n *= 2\n    cost = n * cost_per_sample\n    print(f\"N={n} achieves acc={oracle-(oracle-base)*n**(-alpha):.3f} cost=${cost:.4f}\")\n    return n\n\n# Empirical MATH accuracy for Llama-2-7B + ORM across N values\nn_values   = [1, 2, 4, 8, 16, 32, 64, 128]\naccuracies = [0.32, 0.41, 0.51, 0.59, 0.65, 0.70, 0.72, 0.74]\noracle, base, alpha = power_law_fit(n_values, accuracies)\noptimal_n(target_acc=0.70, cost_per_sample=0.0004, oracle=oracle,\n          base=base, alpha=alpha)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Best-of-N sampling is the most practical entry point for test-time compute scaling due to its simplicity, parallelisability, and strong empirical results. The three selection strategies — ORM selection, majority vote, and weighted majority vote — cover a broad range of deployment scenarios, from zero-additional-model (majority vote) to full ORM (WMV). The accuracy-compute curve follows a power law with diminishing returns; always benchmark N=1,4,16,64 and fit the curve before deciding on a production N. For most applications, N=8-16 with ORM selection captures the bulk of the accuracy gain at a manageable cost. Weighted majority vote is the recommended default when an ORM is available, since it exploits both the individual quality signal and the solution agreement signal at no additional latency cost. Beyond N=64, MCTS and other structured search methods begin to outperform flat BoN at equivalent token budgets by using the compute more efficiently through adaptive exploration."},{"type":"list","ordered":false,"items":["Generate N candidates in parallel at temperature 1.0; score with ORM; return the highest-scoring solution","Majority vote (self-consistency) needs no ORM: return the plurality final answer across N samples","Weighted majority vote: W(a) = sum of exp(ORM_score) for candidates agreeing on answer a — best of both","Accuracy scales as a power law in N with alpha=0.3-0.5; fit on N=1,4,16,64 to estimate cost-accuracy curve","Best-of-4 with ORM captures 80-90% of best-of-64 gain at 1/16 the cost — benchmark before scaling N","Oracle pass@N is the upper bound; practical selectors achieve 70-85% of oracle with a good ORM","Beyond N=64, consider MCTS or beam search which use compute more efficiently via adaptive search"]}]"
---
# Best-of-N Sampling

Best-of-N (BoN) sampling is the simplest and most widely deployed test-time compute scaling strategy: generate N candidate solutions for a problem and select the best one using a reward model, majority vote, or verifier. Unlike beam search (which prunes the search space during generation) or MCTS (which builds a reasoning tree), BoN generates all N candidates independently and selects post-hoc. This decoupling of generation and selection makes BoN trivially parallelisable — all N candidates can be generated simultaneously on N GPUs or via batched API calls — and robust to correlation between candidates (since each is sampled independently). Despite its simplicity, BoN achieves remarkably strong empirical results: on MATH, BoN with N=64 and a good ORM achieves 72% accuracy for a 7B-parameter model that achieves only 32% with greedy decoding. The accuracy-compute curve follows an approximate power law in N, making it straightforward to estimate the N required to hit a target accuracy given a cost budget.

## Overview

The BoN pipeline has three components: a generator LLM that produces diverse candidate solutions, a selection mechanism that scores and ranks candidates, and (optionally) a verifier that provides ground-truth correctness labels for evaluation. The generator must produce sufficiently diverse candidates to cover the space of possible correct solutions — diversity is primarily controlled by temperature (higher T = more diverse but lower average quality). The selection mechanism can be an ORM (scalar score per solution), a majority vote over extracted final answers, a weighted majority vote (ORM-weighted per candidate), or a learned verifier. BoN accuracy monotonically improves with N for any selection mechanism that is better than random, with the improvement rate depending on selection quality. The oracle pass@N rate — the probability that at least one of N solutions is correct — sets an upper bound on BoN accuracy; a perfect selector would achieve this bound. Practical selectors typically capture 70-85% of the oracle bound.

## Generation Diversity via Temperature

Temperature controls the trade-off between diversity and quality in the generated solution pool. At T=0 (greedy), all N solutions are identical — diversity is zero and BoN collapses to a single-sample evaluation. As T increases, solutions become more varied: the model explores different problem-solving approaches, uses different intermediate steps, and arrives at different final answers (including both correct and incorrect ones). The optimal temperature for BoN is problem-dependent: for near-deterministic problems where the model usually knows the answer (low-difficulty), T=0.6-0.8 preserves quality while adding diversity. For hard problems where the model rarely gets greedy answers correct, T=0.8-1.2 is better because diversity is more important than per-sample quality. A common heuristic is to use T=1.0 for BoN generation across all problems, since it provides strong diversity without excessive degradation in solution quality. Some implementations use temperature annealing: start at T=1.0 for the first N/2 samples and T=0.7 for the second half, combining high-diversity and high-quality samples.

```python
import asyncio
import time
from typing import List, Tuple, Optional
from dataclasses import dataclass, field
from openai import AsyncOpenAI

aclient = AsyncOpenAI()

@dataclass
class BonSample:
    solution: str
    orm_score: float = 0.0
    is_correct: Optional[bool] = None

async def generate_candidate(problem: str, model: str,
                               temperature: float) -> str:
    resp = await aclient.chat.completions.create(
        model=model, temperature=temperature,
        messages=[{"role": "user",
                   "content": f"Solve step by step: {problem}"}]
    )
    return resp.choices[0].message.content

async def best_of_n(problem: str, n: int = 64,
                     temperature: float = 1.0,
                     model: str = "gpt-4o-mini") -> List[BonSample]:
    # Generate n candidates in parallel; return unsorted list.
    t0 = time.perf_counter()
    solutions = await asyncio.gather(
        *[generate_candidate(problem, model, temperature) for _ in range(n)]
    )
    elapsed = time.perf_counter() - t0
    samples = [BonSample(solution=s) for s in solutions]
    print(f"Generated {n} candidates in {elapsed:.2f}s ({elapsed/n*1000:.0f}ms each)")
    return samples
```

## Selection Strategies

Three main selection strategies are used in practice, each with different accuracy-cost trade-offs. ORM selection scores each candidate with a trained reward model and returns the candidate with the highest score; this requires a pre-trained ORM but achieves the best accuracy. Majority vote (self-consistency) extracts the final answer from each candidate, computes the plurality answer, and returns any candidate that produced that answer; this requires no additional model but is limited to problems with discrete final answers (numbers, multiple choice). Weighted majority vote combines both: each candidate's vote is weighted by its ORM score, so candidates that are both popular (many agree) and high-scoring (ORM confident) receive extra weight. Weighted majority vote consistently outperforms both unweighted majority vote and plain ORM selection on mathematical benchmarks, particularly at small N (4-8) where the ORM signal and the diversity signal are both noisy. The performance gap narrows at large N (64+) where both methods approach the oracle pass@N bound.

## Majority Vote (Self-Consistency)

Majority vote, introduced as Self-Consistency by Wang et al. (2022), is the simplest ORM-free selection strategy for BoN. Each of the N candidates is decoded independently (typically at temperature 0.5-1.0), the final answer is extracted (via regex or model-based extraction), and the plurality answer is returned. Self-consistency is remarkably effective: on GSM8K, majority vote with N=40 samples of Chain-of-Thought reasoning achieves 74% accuracy versus 56% for a single CoT sample, a 18-point improvement with zero additional model training. The key intuition is that correct reasoning paths tend to converge on the same final answer while incorrect paths make diverse errors. Majority vote amplifies this signal by counting votes. Its main limitation is that it requires a discrete final answer to be extractable — open-ended generation tasks, code generation, and essay writing cannot use naive majority vote without additional structure. For code, majority vote can be applied over test-passing outcomes rather than string equality.

```python
import re
from collections import Counter
from typing import List, Optional, Tuple

def extract_final_answer(text: str) -> Optional[str]:
    # Try common patterns: boxed answer, "= X" at end, last number.
    boxed = re.search(r"\\boxed\{([^}]+)\}", text)
    if boxed:
        return boxed.group(1).strip()
    eq_end = re.search(r"=\s*([\d./-]+)\s*$", text.strip())
    if eq_end:
        return eq_end.group(1).strip()
    nums = re.findall(r"[-+]?\d*\.?\d+", text.replace(",", ""))
    return nums[-1] if nums else None

def majority_vote(solutions: List[str],
                  orm_scores: Optional[List[float]] = None) -> Tuple[str, str]:
    # Extract answers, compute plurality; break ties using ORM score.
    answers = [extract_final_answer(s) or "" for s in solutions]
    counts  = Counter(a for a in answers if a)
    if not counts:
        return solutions[0], "fallback"
    plurality_answer = counts.most_common(1)[0][0]
    candidates = [(s, sc) for s, a, sc in
                  zip(solutions, answers, orm_scores or [0.0]*len(solutions))
                  if a == plurality_answer]
    if orm_scores:
        best = max(candidates, key=lambda x: x[1])
    else:
        best = candidates[0]
    vote_pct = counts[plurality_answer] / len(answers) * 100
    print(f"Plurality answer: {plurality_answer} ({vote_pct:.1f}% of {len(answers)} votes)")
    return best[0], plurality_answer
```

## Reward Model Selection

ORM-based selection scores each of the N candidates with a reward model and returns the highest-scoring candidate. This approach requires a pre-trained ORM but captures information that majority vote misses: a uniquely correct solution that no other candidate agrees with will be selected by the ORM if it scores high, but ignored by majority vote. ORM selection is strictly better than majority vote when the ORM is well-calibrated (AUROC > 0.80) and N is large enough that diversity is not the limiting factor. The ORM scoring step adds latency proportional to N (each candidate must be scored), but this is often acceptable since the generation step (which also runs N times) dominates latency. When using a large ORM (e.g., a 13B-parameter reward model to score a 7B generator), the ORM scoring step can take as long as generation — a 13B ORM scoring 64 candidates may take 128 seconds on a single A100. Quantising the ORM to 4-bit or using a smaller ORM (3B-7B) can reduce this to 20-40 seconds with minimal accuracy loss.

| N samples | Temperature | Selection | MATH accuracy | Cost (1k queries) | Notes |
| --- | --- | --- | --- | --- | --- |
| N=1 | 0.0 (greedy) | — | 32% | $0.40 | Baseline: single greedy sample |
| N=4 | 0.8 | Majority vote | 46% | $1.60 | Simple vote; no ORM needed |
| N=16 | 1.0 | ORM selection | 61% | $6.40 | Strong ORM required; good accuracy |
| N=64 | 1.0 | ORM selection | 72% | $25.60 | Near-saturating for 7B model |
| N=256 | 1.0 | ORM selection | 77% | $102.40 | Diminishing returns; expensive |
| Oracle N=64 | 1.0 | Perfect verifier | 84% | — | Upper bound: any-of-64 correct |

## Weighted Majority Vote

Weighted majority vote (WMV) combines ORM scores and plurality voting into a single selection criterion. For each unique extracted answer a, WMV computes a weight W(a) = sum of exp(ORM_score_i) for all candidates i whose extracted answer equals a. The answer with the highest total weight is selected, and any candidate with that answer is returned (typically the highest-ORM-scoring one). WMV outperforms both unweighted majority vote and plain ORM selection at small N (4-16) because it exploits two complementary signals: the ORM signal (which candidate is individually most plausible) and the agreement signal (which answer is most robustly reached by different reasoning paths). At N=4, WMV typically outperforms plain ORM selection by 2-4 percentage points on MATH. At N=64, the difference narrows to 0.5-1.5 points. WMV adds negligible latency beyond ORM scoring and is straightforward to implement; it should be the default selection strategy for any BoN system that already has an ORM.

```python
import math
from collections import defaultdict
from typing import List, Tuple, Optional

def weighted_majority_vote(solutions: List[str],
                            orm_scores: List[float]) -> Tuple[str, str, float]:
    # WMV: weight each answer by sum of exp(ORM score) of agreeing candidates.
    answers = [extract_final_answer(s) or "" for s in solutions]
    weight_map: dict = defaultdict(float)
    score_map:  dict = defaultdict(list)
    for s, a, sc in zip(solutions, answers, orm_scores):
        if a:
            weight_map[a] += math.exp(sc)        # exponential weighting
            score_map[a].append((sc, s))
    if not weight_map:
        return solutions[0], "", orm_scores[0]
    best_ans  = max(weight_map, key=lambda a: weight_map[a])
    best_sol  = max(score_map[best_ans], key=lambda x: x[0])[1]
    total_w   = sum(weight_map.values())
    conf      = weight_map[best_ans] / total_w
    print(f"WMV winner: {best_ans}  confidence: {conf:.3f}")
    return best_sol, best_ans, conf

def compare_selection_methods(solutions: List[str],
                               orm_scores: List[float]) -> None:
    # Compare ORM-only, majority vote, and WMV on the same candidate pool.
    orm_best  = solutions[max(range(len(solutions)), key=lambda i: orm_scores[i])]
    mv_sol, mv_ans = majority_vote(solutions, None)
    wm_sol, wm_ans, wm_conf = weighted_majority_vote(solutions, orm_scores)
    print(f"ORM best answer : {extract_final_answer(orm_best)}")
    print(f"Majority vote   : {mv_ans}")
    print(f"Weighted MV     : {wm_ans} (conf={wm_conf:.3f})")
```

> **Accuracy-Cost Sweet Spot**: Best-of-4 with a lightweight ORM typically achieves 80-90% of the gain of best-of-64 at 1/16 the cost — always benchmark the accuracy-cost curve before committing to a large N. For most production use cases, N=8 to N=16 with ORM selection provides an excellent accuracy-cost trade-off: 6-12 percentage points of MATH accuracy improvement over greedy at 8-16x the inference cost. Reserve N=64+ for offline batch evaluation or high-value queries where latency is not a constraint.

## Scaling Laws for Best-of-N

The BoN accuracy-compute relationship follows an approximate power law: accuracy(N) ≈ oracle_pass_rate - (oracle_pass_rate - pass@1) * N^{-alpha}, where alpha depends on the selector quality and the problem difficulty distribution. For a well-calibrated ORM on MATH, alpha ≈ 0.3-0.5, meaning accuracy scales roughly as the square root of the number of samples — doubling N from 16 to 32 gives roughly the same accuracy gain as the jump from 8 to 16. This sub-linear scaling means that the marginal value of additional samples decreases rapidly. A useful rule of thumb: 80% of the gap between pass@1 and oracle pass@N is captured by N ≈ (oracle_pass_rate / (1-pass@1))^{1/alpha}. For a model with 32% pass@1 and 84% oracle pass@64, reaching 90% of the oracle requires N ≈ 32. Fitting the power law on a small validation set (N=1,2,4,8,16,32) and extrapolating to larger N is an effective way to estimate the N needed to hit a target accuracy without running the full benchmark.

```python
import numpy as np
from scipy.optimize import curve_fit
from typing import List, Tuple

def power_law_fit(n_values: List[int],
                  accuracies: List[float]) -> Tuple[float, float, float]:
    # Fit accuracy(N) = oracle - (oracle - base) * N^(-alpha)
    # Returns (oracle_rate, base_rate, alpha)
    n_arr = np.array(n_values, dtype=float)
    a_arr = np.array(accuracies, dtype=float)
    def model(n, oracle, base, alpha):
        return oracle - (oracle - base) * n**(-alpha)
    p0 = (0.84, a_arr[0], 0.4)
    popt, _ = curve_fit(model, n_arr, a_arr, p0=p0, maxfev=5000)
    oracle, base, alpha = popt
    print(f"Fitted power law: oracle={oracle:.3f}  base={base:.3f}  alpha={alpha:.3f}")
    return oracle, base, alpha

def optimal_n(target_acc: float, cost_per_sample: float,
               oracle: float, base: float, alpha: float) -> int:
    # Find smallest N achieving target_acc and estimate cost.
    n = 1
    while True:
        acc = oracle - (oracle - base) * (n ** (-alpha))
        if acc >= target_acc or n > 1024:
            break
        n *= 2
    cost = n * cost_per_sample
    print(f"N={n} achieves acc={oracle-(oracle-base)*n**(-alpha):.3f} cost=${cost:.4f}")
    return n

# Empirical MATH accuracy for Llama-2-7B + ORM across N values
n_values   = [1, 2, 4, 8, 16, 32, 64, 128]
accuracies = [0.32, 0.41, 0.51, 0.59, 0.65, 0.70, 0.72, 0.74]
oracle, base, alpha = power_law_fit(n_values, accuracies)
optimal_n(target_acc=0.70, cost_per_sample=0.0004, oracle=oracle,
          base=base, alpha=alpha)
```

## Key Takeaways

Best-of-N sampling is the most practical entry point for test-time compute scaling due to its simplicity, parallelisability, and strong empirical results. The three selection strategies — ORM selection, majority vote, and weighted majority vote — cover a broad range of deployment scenarios, from zero-additional-model (majority vote) to full ORM (WMV). The accuracy-compute curve follows a power law with diminishing returns; always benchmark N=1,4,16,64 and fit the curve before deciding on a production N. For most applications, N=8-16 with ORM selection captures the bulk of the accuracy gain at a manageable cost. Weighted majority vote is the recommended default when an ORM is available, since it exploits both the individual quality signal and the solution agreement signal at no additional latency cost. Beyond N=64, MCTS and other structured search methods begin to outperform flat BoN at equivalent token budgets by using the compute more efficiently through adaptive exploration.

- Generate N candidates in parallel at temperature 1.0; score with ORM; return the highest-scoring solution
- Majority vote (self-consistency) needs no ORM: return the plurality final answer across N samples
- Weighted majority vote: W(a) = sum of exp(ORM_score) for candidates agreeing on answer a — best of both
- Accuracy scales as a power law in N with alpha=0.3-0.5; fit on N=1,4,16,64 to estimate cost-accuracy curve
- Best-of-4 with ORM captures 80-90% of best-of-64 gain at 1/16 the cost — benchmark before scaling N
- Oracle pass@N is the upper bound; practical selectors achieve 70-85% of oracle with a good ORM
- Beyond N=64, consider MCTS or beam search which use compute more efficiently via adaptive search

