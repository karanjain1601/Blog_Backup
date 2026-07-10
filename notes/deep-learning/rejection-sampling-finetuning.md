---
title: "Rejection Sampling Fine-Tuning — Generate Many, Keep Best for SFT"
slug: "rejection-sampling-finetuning"
description: "Rejection sampling fine-tuning (ReST/RST-EM) generates N candidate completions per prompt from the current policy, scores them with a reward model, filters to the top-K by reward, and fine-tunes on the filtered dataset — an EM-style self-improvement loop simpler and more stable than PPO."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Rejection sampling fine-tuning (ReST, Gulcehre et al. 2023; RST-EM, Dong et al. 2023) is an alignment technique that frames policy improvement as an EM algorithm. In the E-step, the current policy generates N candidate completions per prompt and a reward model scores them. In the M-step, the top-K completions are kept and the policy is fine-tuned via standard SFT on these filtered (prompt, completion) pairs. The process repeats for multiple rounds, progressively moving the policy distribution toward higher-reward outputs without the complexity and instability of PPO."},{"type":"heading","level":2,"content":"The ReST Algorithm — EM for Alignment"},{"type":"text","content":"The EM framing is natural: in the E-step, the policy acts as the proposal distribution to generate diverse candidate completions; in the M-step, supervised fine-tuning on filtered data moves the policy toward the high-reward region. Unlike PPO, which requires online rollouts, importance sampling corrections, and a value function, ReST only needs: (1) batch inference for generation, (2) a reward model for scoring, and (3) standard SFT training. This makes it significantly simpler to implement and more stable to train. LLaMA-2\u0027s final alignment stage uses rejection sampling, as does Gemini\u0027s RLHF pipeline."},{"type":"heading","level":2,"content":"E-Step — Generating Diverse Completions"},{"type":"text","content":"Diversity in the E-step is critical: sampling at high temperature (0.8–1.0) spreads the distribution to explore the response space. The number of samples N per prompt (typically 10–100) controls the exploration-exploitation tradeoff. With N=1 there is no selection pressure; with N=100, the reward model can identify high-quality completions even if only 1% of samples are excellent. Batch generation is embarrassingly parallelizable across prompts, making large N computationally feasible with vLLM or other high-throughput inference engines."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\nfrom typing import Optional\n\ndef batch_generate_completions(\n    model: AutoModelForCausalLM,\n    tokenizer: AutoTokenizer,\n    prompts: list,\n    n_samples: int = 8,\n    temperature: float = 0.9,\n    max_new_tokens: int = 256,\n) -\u003e list:\n    # Generate N completions per prompt at high temperature for diversity\n    all_completions = []\n    for prompt in prompts:\n        inputs = tokenizer(prompt, return_tensors=\u0027pt\u0027).to(model.device)\n        completions = []\n        for _ in range(n_samples):\n            with torch.no_grad():\n                output_ids = model.generate(\n                    **inputs,\n                    max_new_tokens=max_new_tokens,\n                    do_sample=True,\n                    temperature=temperature,\n                    pad_token_id=tokenizer.eos_token_id,\n                )\n            gen_ids = output_ids[0][inputs[\u0027input_ids\u0027].shape[1]:]\n            completions.append(tokenizer.decode(gen_ids, skip_special_tokens=True))\n        all_completions.append(completions)\n    return all_completions\n\ndef score_completions(reward_model, tokenizer, prompts: list, completions_per_prompt: list) -\u003e list:\n    # Score each completion with reward model, return reward lists\n    scores = []\n    for prompt, completions in zip(prompts, completions_per_prompt):\n        prompt_scores = []\n        for completion in completions:\n            enc = tokenizer(prompt + completion, return_tensors=\u0027pt\u0027,\n                            truncation=True, max_length=512).to(reward_model.device)\n            with torch.no_grad():\n                reward = reward_model(**enc).logits.squeeze().item()\n            prompt_scores.append(reward)\n        scores.append(prompt_scores)\n    return scores\n\nprint(\u0027ReST E-step: N=8 samples per prompt at temperature=0.9 for diversity\u0027)\nprint(\u0027Score all completions with reward model, then keep top-K for M-step\u0027)"},{"type":"heading","level":2,"content":"M-Step — Top-K Selection and Fine-Tuning"},{"type":"text","content":"The M-step filters completions to a high-reward subset and runs SFT on the result. Two selection strategies exist: top-K (keep the K highest-scoring completions per prompt) and threshold-based (keep all completions above a reward threshold). Top-K guarantees exactly K training examples per prompt, maintaining dataset balance. Threshold-based selection discards all completions if none exceed the threshold, producing sparser but higher-quality training data. A hybrid approach — top-K among completions above a minimum threshold — combines both benefits."},{"type":"code","language":"python","content":"import torch\nfrom datasets import Dataset\nfrom typing import Optional\n\ndef select_top_k_completions(\n    prompts: list,\n    completions: list,\n    scores: list,\n    top_k: int = 2,\n    score_threshold: Optional[float] = None,\n) -\u003e tuple:\n    # Filter completions: keep top-K per prompt, optionally above threshold\n    selected_prompts, selected_completions = [], []\n    for prompt, comp_list, score_list in zip(prompts, completions, scores):\n        paired = sorted(zip(score_list, comp_list), reverse=True)\n        kept = [(s, c) for s, c in paired[:top_k]\n                if score_threshold is None or s \u003e= score_threshold]\n        for score, completion in kept:\n            selected_prompts.append(prompt)\n            selected_completions.append(completion)\n    return selected_prompts, selected_completions\n\ndef build_sft_dataset(prompts: list, completions: list) -\u003e Dataset:\n    # Create HuggingFace dataset from filtered (prompt, completion) pairs\n    return Dataset.from_dict({\n        \u0027prompt\u0027: prompts,\n        \u0027completion\u0027: completions,\n        \u0027text\u0027: [p + c for p, c in zip(prompts, completions)],\n    })\n\n# Example with mock data\nsample_prompts = [\u0027Explain gradient descent:\u0027, \u0027What is attention in transformers:\u0027]\nsample_completions = [[\u0027Good A1\u0027, \u0027Poor A1\u0027, \u0027OK A1\u0027], [\u0027Great A2\u0027, \u0027Poor A2\u0027, \u0027Medium A2\u0027]]\nsample_scores = [[0.8, 0.3, 0.5], [0.9, 0.2, 0.6]]\nsel_p, sel_c = select_top_k_completions(sample_prompts, sample_completions, sample_scores, top_k=1)\ndataset = build_sft_dataset(sel_p, sel_c)\nprint(f\u0027Selected {len(dataset)} pairs from {sum(len(c) for c in sample_completions)} total\u0027)\nprint(\u0027M-step: fine-tune policy on filtered SFT dataset for 1-3 epochs\u0027)"},{"type":"heading","level":2,"content":"Iterative Self-Improvement Loop"},{"type":"text","content":"Running multiple rounds of ReST progressively improves the policy. Early rounds improve performance on easy prompts where the initial policy already generates near-correct outputs. Later rounds target harder prompts as the policy improves. The EM-like dynamics mean the process converges: once the policy consistently generates high-reward completions, the filtered dataset stops changing and further fine-tuning yields diminishing returns. Typical setups run 3–5 rounds with N decreasing across rounds (more exploration early, more exploitation later)."},{"type":"code","language":"python","content":"from dataclasses import dataclass\nfrom typing import Callable\n\n@dataclass\nclass ReSTConfig:\n    n_rounds: int = 3\n    n_samples_per_prompt: int = 16\n    top_k: int = 4\n    temperature: float = 0.9\n    reward_threshold: float = 0.5\n\ndef rest_em_loop(\n    model,\n    tokenizer,\n    reward_model,\n    prompts: list,\n    config: ReSTConfig,\n    finetune_fn: Callable,\n) -\u003e list:\n    # Run full E-step / M-step loop for config.n_rounds\n    history = []\n    for round_idx in range(config.n_rounds):\n        print(f\u0027Round {round_idx+1}/{config.n_rounds}: E-step — generating {config.n_samples_per_prompt} samples/prompt\u0027)\n        completions = batch_generate_completions(model, tokenizer, prompts,\n                                                 config.n_samples_per_prompt, config.temperature)\n        scores = score_completions(reward_model, tokenizer, prompts, completions)\n        sel_p, sel_c = select_top_k_completions(prompts, completions, scores,\n                                                 config.top_k, config.reward_threshold)\n        avg_reward = sum(sum(s)/len(s) for s in scores) / len(scores)\n        print(f\u0027Round {round_idx+1}: M-step — fine-tuning on {len(sel_p)} pairs (avg reward={avg_reward:.3f})\u0027)\n        dataset = build_sft_dataset(sel_p, sel_c)\n        finetune_fn(model, dataset)\n        history.append({\u0027round\u0027: round_idx+1, \u0027n_pairs\u0027: len(sel_p), \u0027avg_reward\u0027: avg_reward})\n    return history\n\nconfig = ReSTConfig(n_rounds=3, n_samples_per_prompt=16, top_k=4)\nprint(\u0027ReST-EM converges when policy consistently generates high-reward completions\u0027)\nprint(\u0027Round 1: easy prompts improve; Round 3+: hard prompts targeted by better policy\u0027)"},{"type":"heading","level":2,"content":"Best-of-N Compute Analysis"},{"type":"text","content":"Best-of-N (BoN) sampling — generate N completions and return the highest-scoring one — is a simple baseline that provides useful compute-quality tradeoffs. The expected maximum reward of N i.i.d. Gaussian samples scales as μ + σ·Φ⁻¹(N/(N+1)), where Φ⁻¹ is the inverse CDF. BoN with N=64 often matches PPO-trained models at 1B parameter scale, but at the cost of N inference passes per prompt. ReST amortizes BoN\u0027s quality gain into the model weights so that inference cost remains 1 pass per prompt — the key practical advantage over pure BoN inference."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.stats import norm\n\ndef expected_max_reward(mu: float, sigma: float, n_values: list) -\u003e list:\n    # Expected maximum of N i.i.d. Gaussian rewards: mu + sigma * Phi^-1(N/(N+1))\n    return [mu + sigma * norm.ppf(n / (n + 1)) for n in n_values]\n\ndef bon_vs_ppo_analysis(n_values: list, ppo_reward: float, mu=0.0, sigma=1.0) -\u003e None:\n    # Compare Best-of-N expected reward vs PPO baseline reward\n    bon_rewards = expected_max_reward(mu, sigma, n_values)\n    print(f\u0027{\"N\":\u003e6}  {\"BoN E[R]\": \u003e12}  {\"vs PPO\":\u003e10}  {\"Inference NFE\":\u003e15}\u0027)\n    print(\u0027-\u0027 * 50)\n    for n, r in zip(n_values, bon_rewards):\n        delta = r - ppo_reward\n        sign = \u0027+\u0027 if delta \u003e= 0 else \u0027\u0027\n        print(f\u0027{n:\u003e6}  {r:\u003e12.4f}  {sign}{delta:\u003e9.4f}  {n:\u003e15}\u0027)\n\nn_values = [1, 4, 8, 16, 32, 64, 128]\nppo_equivalent = 1.15  # typical PPO reward at convergence (std Gaussian scale)\nbon_vs_ppo_analysis(n_values, ppo_equivalent, mu=0.0, sigma=1.0)\nprint()\nprint(\u0027ReST amortizes BoN quality into weights: inference cost = 1 pass (not N)\u0027)\nprint(\u0027PPO reaches similar quality but requires online RL infrastructure\u0027)"},{"type":"heading","level":2,"content":"Combining Rejection Sampling with DPO"},{"type":"text","content":"The same N samples generated per prompt can be used to create (best, worst) DPO preference pairs rather than only keeping the best for SFT. This hybrid approach — sometimes called Rejection Sampling DPO — uses the highest-scoring completion as the chosen response and the lowest-scoring as the rejected response. Because both completions come from the current policy, the preference pairs are on-policy with respect to the current model\u0027s distribution, which is more informative than static human labels from the original SFT model. Combining rejection sampling with DPO provides the best of both: diverse exploration from sampling and contrastive preference learning from DPO."},{"type":"table","headers":["Variant","N Samples","Selection Strategy","Rounds","Reward Model Type"],"rows":[["ReST (Gulcehre 2023)","10–64","Threshold: keep above R_min","1–3","Trained RM (LM-head on reward)"],["RST-EM (Dong 2023)","16–64","Top-K per prompt","3–5","Trained RM or verifier"],["LLaMA-2 RST","20–100","Top-1 (single best)","1","Human preference RM"],["STaR (Zelikman 2022)","Self-consistency majority vote","Correct final answer filter","Multiple","Ground truth verifier"],["Self-Play Fine-Tuning","Variable","Current vs previous model wins","Iterative","LM-as-judge or trained RM"]]},{"type":"heading","level":2,"content":"Practical Considerations"},{"type":"text","content":"Reward hacking is the primary failure mode: if the reward model has blind spots, the policy learns to exploit them rather than genuinely improve. Monitoring reward model correlation with human preferences across training rounds is essential. The reward threshold should increase across rounds as the policy improves — keeping an absolute threshold leads to all completions passing in later rounds, collapsing to standard SFT. Using a separate held-out set to track human eval win rate (not just RM score) catches reward hacking before it degrades human-perceived quality."},{"type":"list","ordered":false,"items":["Use temperature 0.8–1.0 for E-step generation — lower temperatures reduce diversity and limit selection pressure.","N=16–32 is often sufficient; beyond N=64 the marginal improvement per additional sample diminishes sharply.","Increase reward threshold across rounds to maintain selection pressure as the policy improves.","Monitor RM score vs human win rate correlation — divergence signals reward hacking.","Use vLLM or SGLang for E-step generation: batched sampling with N completions per prompt is memory-efficient."]},{"type":"callout","variant":"tip","title":"Combining Rejection Sampling with DPO","content":"Combining rejection sampling with DPO provides the best of both: use the same N samples to create (best, worst) DPO pairs — this generates diverse preference pairs aligned with the current policy\u0027s output distribution, which is more on-policy than static human labels and trains faster than PPO while maintaining DPO\u0027s simplicity."},{"type":"divider"}]"
---
# Rejection Sampling Fine-Tuning — Generate Many, Keep Best for SFT

Rejection sampling fine-tuning (ReST, Gulcehre et al. 2023; RST-EM, Dong et al. 2023) is an alignment technique that frames policy improvement as an EM algorithm. In the E-step, the current policy generates N candidate completions per prompt and a reward model scores them. In the M-step, the top-K completions are kept and the policy is fine-tuned via standard SFT on these filtered (prompt, completion) pairs. The process repeats for multiple rounds, progressively moving the policy distribution toward higher-reward outputs without the complexity and instability of PPO.

## The ReST Algorithm — EM for Alignment

The EM framing is natural: in the E-step, the policy acts as the proposal distribution to generate diverse candidate completions; in the M-step, supervised fine-tuning on filtered data moves the policy toward the high-reward region. Unlike PPO, which requires online rollouts, importance sampling corrections, and a value function, ReST only needs: (1) batch inference for generation, (2) a reward model for scoring, and (3) standard SFT training. This makes it significantly simpler to implement and more stable to train. LLaMA-2's final alignment stage uses rejection sampling, as does Gemini's RLHF pipeline.

## E-Step — Generating Diverse Completions

Diversity in the E-step is critical: sampling at high temperature (0.8–1.0) spreads the distribution to explore the response space. The number of samples N per prompt (typically 10–100) controls the exploration-exploitation tradeoff. With N=1 there is no selection pressure; with N=100, the reward model can identify high-quality completions even if only 1% of samples are excellent. Batch generation is embarrassingly parallelizable across prompts, making large N computationally feasible with vLLM or other high-throughput inference engines.

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer
from typing import Optional

def batch_generate_completions(
    model: AutoModelForCausalLM,
    tokenizer: AutoTokenizer,
    prompts: list,
    n_samples: int = 8,
    temperature: float = 0.9,
    max_new_tokens: int = 256,
) -> list:
    # Generate N completions per prompt at high temperature for diversity
    all_completions = []
    for prompt in prompts:
        inputs = tokenizer(prompt, return_tensors='pt').to(model.device)
        completions = []
        for _ in range(n_samples):
            with torch.no_grad():
                output_ids = model.generate(
                    **inputs,
                    max_new_tokens=max_new_tokens,
                    do_sample=True,
                    temperature=temperature,
                    pad_token_id=tokenizer.eos_token_id,
                )
            gen_ids = output_ids[0][inputs['input_ids'].shape[1]:]
            completions.append(tokenizer.decode(gen_ids, skip_special_tokens=True))
        all_completions.append(completions)
    return all_completions

def score_completions(reward_model, tokenizer, prompts: list, completions_per_prompt: list) -> list:
    # Score each completion with reward model, return reward lists
    scores = []
    for prompt, completions in zip(prompts, completions_per_prompt):
        prompt_scores = []
        for completion in completions:
            enc = tokenizer(prompt + completion, return_tensors='pt',
                            truncation=True, max_length=512).to(reward_model.device)
            with torch.no_grad():
                reward = reward_model(**enc).logits.squeeze().item()
            prompt_scores.append(reward)
        scores.append(prompt_scores)
    return scores

print('ReST E-step: N=8 samples per prompt at temperature=0.9 for diversity')
print('Score all completions with reward model, then keep top-K for M-step')
```

## M-Step — Top-K Selection and Fine-Tuning

The M-step filters completions to a high-reward subset and runs SFT on the result. Two selection strategies exist: top-K (keep the K highest-scoring completions per prompt) and threshold-based (keep all completions above a reward threshold). Top-K guarantees exactly K training examples per prompt, maintaining dataset balance. Threshold-based selection discards all completions if none exceed the threshold, producing sparser but higher-quality training data. A hybrid approach — top-K among completions above a minimum threshold — combines both benefits.

```python
import torch
from datasets import Dataset
from typing import Optional

def select_top_k_completions(
    prompts: list,
    completions: list,
    scores: list,
    top_k: int = 2,
    score_threshold: Optional[float] = None,
) -> tuple:
    # Filter completions: keep top-K per prompt, optionally above threshold
    selected_prompts, selected_completions = [], []
    for prompt, comp_list, score_list in zip(prompts, completions, scores):
        paired = sorted(zip(score_list, comp_list), reverse=True)
        kept = [(s, c) for s, c in paired[:top_k]
                if score_threshold is None or s >= score_threshold]
        for score, completion in kept:
            selected_prompts.append(prompt)
            selected_completions.append(completion)
    return selected_prompts, selected_completions

def build_sft_dataset(prompts: list, completions: list) -> Dataset:
    # Create HuggingFace dataset from filtered (prompt, completion) pairs
    return Dataset.from_dict({
        'prompt': prompts,
        'completion': completions,
        'text': [p + c for p, c in zip(prompts, completions)],
    })

# Example with mock data
sample_prompts = ['Explain gradient descent:', 'What is attention in transformers:']
sample_completions = [['Good A1', 'Poor A1', 'OK A1'], ['Great A2', 'Poor A2', 'Medium A2']]
sample_scores = [[0.8, 0.3, 0.5], [0.9, 0.2, 0.6]]
sel_p, sel_c = select_top_k_completions(sample_prompts, sample_completions, sample_scores, top_k=1)
dataset = build_sft_dataset(sel_p, sel_c)
print(f'Selected {len(dataset)} pairs from {sum(len(c) for c in sample_completions)} total')
print('M-step: fine-tune policy on filtered SFT dataset for 1-3 epochs')
```

## Iterative Self-Improvement Loop

Running multiple rounds of ReST progressively improves the policy. Early rounds improve performance on easy prompts where the initial policy already generates near-correct outputs. Later rounds target harder prompts as the policy improves. The EM-like dynamics mean the process converges: once the policy consistently generates high-reward completions, the filtered dataset stops changing and further fine-tuning yields diminishing returns. Typical setups run 3–5 rounds with N decreasing across rounds (more exploration early, more exploitation later).

```python
from dataclasses import dataclass
from typing import Callable

@dataclass
class ReSTConfig:
    n_rounds: int = 3
    n_samples_per_prompt: int = 16
    top_k: int = 4
    temperature: float = 0.9
    reward_threshold: float = 0.5

def rest_em_loop(
    model,
    tokenizer,
    reward_model,
    prompts: list,
    config: ReSTConfig,
    finetune_fn: Callable,
) -> list:
    # Run full E-step / M-step loop for config.n_rounds
    history = []
    for round_idx in range(config.n_rounds):
        print(f'Round {round_idx+1}/{config.n_rounds}: E-step — generating {config.n_samples_per_prompt} samples/prompt')
        completions = batch_generate_completions(model, tokenizer, prompts,
                                                 config.n_samples_per_prompt, config.temperature)
        scores = score_completions(reward_model, tokenizer, prompts, completions)
        sel_p, sel_c = select_top_k_completions(prompts, completions, scores,
                                                 config.top_k, config.reward_threshold)
        avg_reward = sum(sum(s)/len(s) for s in scores) / len(scores)
        print(f'Round {round_idx+1}: M-step — fine-tuning on {len(sel_p)} pairs (avg reward={avg_reward:.3f})')
        dataset = build_sft_dataset(sel_p, sel_c)
        finetune_fn(model, dataset)
        history.append({'round': round_idx+1, 'n_pairs': len(sel_p), 'avg_reward': avg_reward})
    return history

config = ReSTConfig(n_rounds=3, n_samples_per_prompt=16, top_k=4)
print('ReST-EM converges when policy consistently generates high-reward completions')
print('Round 1: easy prompts improve; Round 3+: hard prompts targeted by better policy')
```

## Best-of-N Compute Analysis

Best-of-N (BoN) sampling — generate N completions and return the highest-scoring one — is a simple baseline that provides useful compute-quality tradeoffs. The expected maximum reward of N i.i.d. Gaussian samples scales as μ + σ·Φ⁻¹(N/(N+1)), where Φ⁻¹ is the inverse CDF. BoN with N=64 often matches PPO-trained models at 1B parameter scale, but at the cost of N inference passes per prompt. ReST amortizes BoN's quality gain into the model weights so that inference cost remains 1 pass per prompt — the key practical advantage over pure BoN inference.

```python
import numpy as np
from scipy.stats import norm

def expected_max_reward(mu: float, sigma: float, n_values: list) -> list:
    # Expected maximum of N i.i.d. Gaussian rewards: mu + sigma * Phi^-1(N/(N+1))
    return [mu + sigma * norm.ppf(n / (n + 1)) for n in n_values]

def bon_vs_ppo_analysis(n_values: list, ppo_reward: float, mu=0.0, sigma=1.0) -> None:
    # Compare Best-of-N expected reward vs PPO baseline reward
    bon_rewards = expected_max_reward(mu, sigma, n_values)
    print(f'{"N":>6}  {"BoN E[R]": >12}  {"vs PPO":>10}  {"Inference NFE":>15}')
    print('-' * 50)
    for n, r in zip(n_values, bon_rewards):
        delta = r - ppo_reward
        sign = '+' if delta >= 0 else ''
        print(f'{n:>6}  {r:>12.4f}  {sign}{delta:>9.4f}  {n:>15}')

n_values = [1, 4, 8, 16, 32, 64, 128]
ppo_equivalent = 1.15  # typical PPO reward at convergence (std Gaussian scale)
bon_vs_ppo_analysis(n_values, ppo_equivalent, mu=0.0, sigma=1.0)
print()
print('ReST amortizes BoN quality into weights: inference cost = 1 pass (not N)')
print('PPO reaches similar quality but requires online RL infrastructure')
```

## Combining Rejection Sampling with DPO

The same N samples generated per prompt can be used to create (best, worst) DPO preference pairs rather than only keeping the best for SFT. This hybrid approach — sometimes called Rejection Sampling DPO — uses the highest-scoring completion as the chosen response and the lowest-scoring as the rejected response. Because both completions come from the current policy, the preference pairs are on-policy with respect to the current model's distribution, which is more informative than static human labels from the original SFT model. Combining rejection sampling with DPO provides the best of both: diverse exploration from sampling and contrastive preference learning from DPO.

| Variant | N Samples | Selection Strategy | Rounds | Reward Model Type |
| --- | --- | --- | --- | --- |
| ReST (Gulcehre 2023) | 10–64 | Threshold: keep above R_min | 1–3 | Trained RM (LM-head on reward) |
| RST-EM (Dong 2023) | 16–64 | Top-K per prompt | 3–5 | Trained RM or verifier |
| LLaMA-2 RST | 20–100 | Top-1 (single best) | 1 | Human preference RM |
| STaR (Zelikman 2022) | Self-consistency majority vote | Correct final answer filter | Multiple | Ground truth verifier |
| Self-Play Fine-Tuning | Variable | Current vs previous model wins | Iterative | LM-as-judge or trained RM |

## Practical Considerations

Reward hacking is the primary failure mode: if the reward model has blind spots, the policy learns to exploit them rather than genuinely improve. Monitoring reward model correlation with human preferences across training rounds is essential. The reward threshold should increase across rounds as the policy improves — keeping an absolute threshold leads to all completions passing in later rounds, collapsing to standard SFT. Using a separate held-out set to track human eval win rate (not just RM score) catches reward hacking before it degrades human-perceived quality.

- Use temperature 0.8–1.0 for E-step generation — lower temperatures reduce diversity and limit selection pressure.
- N=16–32 is often sufficient; beyond N=64 the marginal improvement per additional sample diminishes sharply.
- Increase reward threshold across rounds to maintain selection pressure as the policy improves.
- Monitor RM score vs human win rate correlation — divergence signals reward hacking.
- Use vLLM or SGLang for E-step generation: batched sampling with N completions per prompt is memory-efficient.

> **Combining Rejection Sampling with DPO**: Combining rejection sampling with DPO provides the best of both: use the same N samples to create (best, worst) DPO pairs — this generates diverse preference pairs aligned with the current policy's output distribution, which is more on-policy than static human labels and trains faster than PPO while maintaining DPO's simplicity.

---

