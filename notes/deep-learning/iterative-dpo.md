---
title: "Iterative DPO — Online Preference Learning with Self-Generated Pairs"
slug: "iterative-dpo"
description: "Iterative DPO addresses the off-policy distribution mismatch in standard DPO by regenerating preference pairs from the current policy at each training round, closing most of the performance gap between offline DPO and online PPO at significantly lower implementation complexity."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Direct Preference Optimization (DPO) is trained on a fixed dataset of (prompt, chosen, rejected) triples collected offline — typically from human labelers comparing outputs of the original SFT model. This static dataset has a critical limitation: as the policy improves during training, the preference pairs become increasingly off-policy relative to the current model distribution. Iterative DPO (also called online DPO) addresses this by periodically regenerating preference pairs from the current policy, ensuring training data stays on-policy and remains informative throughout training."},{"type":"heading","level":2,"content":"Why Static DPO Falls Short"},{"type":"text","content":"The DPO loss function implicitly assumes that the chosen and rejected responses are drawn from a distribution close to the reference model π_ref. When the policy π_θ drifts far from π_ref during training, the preference data becomes stale — the (chosen, rejected) pairs no longer represent the outputs the current policy would generate. This is the off-policy problem: the model is being trained to prefer response A over response B, but A and B were generated by a much weaker model, so the lesson is trivial for the now-stronger policy. On-policy preference data from the current π_θ provides a much harder and more informative training signal."},{"type":"heading","level":2,"content":"The Iterative DPO Algorithm"},{"type":"text","content":"Iterative DPO runs in rounds: (1) sample K completions per prompt from the current policy π_θ; (2) score them with a reward model or human rater; (3) form (chosen, rejected) pairs from highest- and lowest-scoring completions; (4) run a DPO update step with the new on-policy pairs; (5) repeat. The reference model π_ref can be kept fixed (original SFT) for stability or updated periodically. Key hyperparameters: how often to regenerate pairs (every N steps or every epoch), how many samples per prompt, and the DPO beta (KL penalty weight)."},{"type":"code","language":"python","content":"import torch\nfrom dataclasses import dataclass\nfrom typing import Callable\n\n@dataclass\nclass IterativeDPOConfig:\n    n_rounds: int = 3\n    samples_per_prompt: int = 2\n    dpo_beta: float = 0.1\n    dpo_epochs_per_round: int = 1\n    lr: float = 5e-7\n    ref_update_strategy: str = \u0027fixed\u0027  # \u0027fixed\u0027, \u0027ema\u0027, or \u0027copy\u0027\n\ndef iterative_dpo_round(\n    policy,\n    ref_model,\n    tokenizer,\n    reward_model,\n    prompts: list,\n    config: IterativeDPOConfig,\n    round_idx: int,\n    dpo_train_fn: Callable,\n) -\u003e dict:\n    # One round: generate on-policy pairs, score, run DPO update\n    print(f\u0027Round {round_idx+1}: sampling {config.samples_per_prompt} completions/prompt from current policy\u0027)\n    preference_dataset = generate_preference_pairs(\n        policy, tokenizer, reward_model, prompts, config.samples_per_prompt\n    )\n    n_pairs = len(preference_dataset[\u0027chosen\u0027])\n    print(f\u0027Round {round_idx+1}: DPO update on {n_pairs} on-policy pairs (beta={config.dpo_beta})\u0027)\n    dpo_train_fn(policy, ref_model, preference_dataset, config)\n    return {\u0027round\u0027: round_idx + 1, \u0027n_pairs\u0027: n_pairs}\n\nconfig = IterativeDPOConfig(n_rounds=3, samples_per_prompt=2, dpo_beta=0.1)\nprint(\u0027Iterative DPO: on-policy preference data from current pi_theta at each round\u0027)\nprint(\u0027Key: pairs generated by current policy are harder and more informative than SFT pairs\u0027)"},{"type":"heading","level":2,"content":"On-Policy Preference Pair Generation"},{"type":"text","content":"At each round, two completions are sampled from the current policy per prompt. The reward model scores both and determines which is preferred. Using only 2 samples is the simplest setting — the margin between best and worst reflects the policy\u0027s current uncertainty. Using more samples (4–8) and taking the highest and lowest score creates larger reward margins in the preference pairs, providing a cleaner learning signal. Filtering out pairs where the reward margin is below a threshold (margin filtering) removes ambiguous pairs that add noise to training."},{"type":"code","language":"python","content":"import torch\nfrom datasets import Dataset\n\ndef generate_preference_pairs(\n    policy,\n    tokenizer,\n    reward_model,\n    prompts: list,\n    n_samples: int = 2,\n    temperature: float = 0.8,\n    min_margin: float = 0.1,\n) -\u003e Dataset:\n    # Sample completions from current policy, use RM to determine preference\n    chosen_list, rejected_list, prompt_list = [], [], []\n    for prompt in prompts:\n        inputs = tokenizer(prompt, return_tensors=\u0027pt\u0027).to(policy.device)\n        completions = []\n        for _ in range(n_samples):\n            with torch.no_grad():\n                output = policy.generate(\n                    **inputs,\n                    max_new_tokens=128,\n                    do_sample=True,\n                    temperature=temperature,\n                    pad_token_id=tokenizer.eos_token_id,\n                )\n            gen = output[0][inputs[\u0027input_ids\u0027].shape[1]:]\n            completions.append(tokenizer.decode(gen, skip_special_tokens=True))\n        scores = []\n        for c in completions:\n            enc = tokenizer(prompt + c, return_tensors=\u0027pt\u0027, truncation=True).to(reward_model.device)\n            with torch.no_grad():\n                scores.append(reward_model(**enc).logits.squeeze().item())\n        best_idx = int(torch.tensor(scores).argmax())\n        worst_idx = int(torch.tensor(scores).argmin())\n        margin = scores[best_idx] - scores[worst_idx]\n        if margin \u003e= min_margin:\n            chosen_list.append(completions[best_idx])\n            rejected_list.append(completions[worst_idx])\n            prompt_list.append(prompt)\n    return Dataset.from_dict({\u0027prompt\u0027: prompt_list, \u0027chosen\u0027: chosen_list, \u0027rejected\u0027: rejected_list})\n\nprint(\u0027On-policy pairs: both chosen and rejected come from current pi_theta\u0027)\nprint(\u0027Margin filtering (min_margin=0.1) removes ambiguous pairs from training\u0027)"},{"type":"heading","level":2,"content":"Reference Model Update Strategies"},{"type":"text","content":"The reference model π_ref determines the KL penalty target — keeping π_θ from deviating too far. Three strategies exist: (A) fixed reference — keep the original SFT model as π_ref throughout all rounds, providing strong regularisation toward the SFT baseline; (B) EMA update — slowly track the policy with exponential moving average, softening regularisation; (C) copy per round — reset π_ref to the current π_θ at the start of each round, allowing the policy to drift further. Fixed reference is most stable and most commonly used; copy-per-round risks degeneration without other regularisation."},{"type":"code","language":"python","content":"import torch\nimport copy\nfrom transformers import AutoModelForCausalLM\n\ndef update_reference_model(\n    original_ref: AutoModelForCausalLM,\n    current_policy: AutoModelForCausalLM,\n    strategy: str = \u0027fixed\u0027,\n    polyak_tau: float = 0.01,\n) -\u003e AutoModelForCausalLM:\n    # Return updated reference model based on strategy\n    if strategy == \u0027fixed\u0027:\n        # Keep original SFT as reference throughout all rounds\n        return original_ref\n    elif strategy == \u0027ema\u0027:\n        # Slowly track policy with exponential moving average\n        with torch.no_grad():\n            for p_ref, p_policy in zip(original_ref.parameters(), current_policy.parameters()):\n                p_ref.data.mul_(1 - polyak_tau).add_(polyak_tau * p_policy.data)\n        return original_ref\n    elif strategy == \u0027copy\u0027:\n        # Reset reference to current policy each round\n        return copy.deepcopy(current_policy)\n    else:\n        raise ValueError(f\u0027Unknown strategy: {strategy}\u0027)\n\nstrategies = [\u0027fixed\u0027, \u0027ema\u0027, \u0027copy\u0027]\neffects = [\n    \u0027Strong regularisation toward SFT baseline; lowest risk of degeneration\u0027,\n    \u0027Softening KL penalty over training; moderate policy drift allowed\u0027,\n    \u0027No anchoring to SFT; highest drift risk — needs other regularisation\u0027,\n]\nprint(f\u0027{\"Strategy\":\u003c10}  {\"Effect\"}\u0027)\nprint(\u0027-\u0027 * 70)\nfor s, e in zip(strategies, effects):\n    print(f\u0027{s:\u003c10}  {e}\u0027)"},{"type":"heading","level":2,"content":"On-Policy vs Off-Policy Performance"},{"type":"text","content":"Empirical results consistently show iterative DPO outperforming static DPO, especially after the first training round where the policy has already shifted from the SFT baseline. The performance gap widens on harder tasks where the SFT model\u0027s output distribution is far from the optimal. On AlpacaEval 2.0 benchmarks, iterative DPO typically closes 50–70% of the gap between static DPO and PPO. The remaining gap comes from PPO\u0027s ability to explore the full response space rather than just comparing samples from the current policy."},{"type":"code","language":"python","content":"import numpy as np\n\ndef simulate_win_rate_trajectory(n_steps=500, on_policy=True, seed=42):\n    # Simulate win rate trajectory for on-policy vs off-policy DPO\n    rng = np.random.default_rng(seed)\n    win_rate = 0.55\n    trajectory = []\n    for step in range(n_steps):\n        if on_policy:\n            improvement = 0.00035 * (1 - win_rate) + rng.normal(0, 0.002)\n        else:\n            # Off-policy data becomes less informative as policy improves\n            decay = max(0, 1 - step / 250)\n            improvement = 0.00012 * (1 - win_rate) * decay + rng.normal(0, 0.003)\n        win_rate = float(np.clip(win_rate + improvement, 0.5, 0.95))\n        trajectory.append(win_rate)\n    return trajectory\n\non_traj = simulate_win_rate_trajectory(500, on_policy=True)\noff_traj = simulate_win_rate_trajectory(500, on_policy=False)\ncheckpoints = [0, 99, 249, 499]\nprint(f\u0027{\"Step\":\u003e6}  {\"On-Policy WR\":\u003e14}  {\"Off-Policy WR\":\u003e15}  {\"Delta\":\u003e8}\u0027)\nprint(\u0027-\u0027 * 52)\nfor step in checkpoints:\n    d = on_traj[step] - off_traj[step]\n    sign = \u0027+\u0027 if d \u003e= 0 else \u0027\u0027\n    print(f\u0027{step+1:\u003e6}  {on_traj[step]:\u003e14.4f}  {off_traj[step]:\u003e15.4f}  {sign}{d:\u003e7.4f}\u0027)\nprint(f\u0027Final: on-policy={on_traj[-1]:.4f}, off-policy={off_traj[-1]:.4f}\u0027)"},{"type":"heading","level":2,"content":"Online DPO Variants"},{"type":"text","content":"Several variants extend iterative DPO. Self-Play Fine-Tuning (SPIN, Chen et al. 2024) uses the current model vs the previous-round model for self-play: the current model generates chosen responses, the previous model generates rejected responses. SPPO (Self-Play Preference Optimization) reformulates preference optimization as a two-player game. Direct Nash Optimization (DNO) uses game-theoretic Nash equilibria as the optimization target. Online DPO (Guo et al. 2024) provides a unified framework with theoretical convergence guarantees. These variants differ in how they generate pairs and whether they use a reward model or rely on self-play dynamics."},{"type":"table","headers":["Method","Data Source","Online","Stability","Performance","Complexity"],"rows":[["Static DPO","Fixed human preference dataset from SFT model","No","High","Baseline","Low — offline SFT-like training"],["Iterative DPO","Current policy + RM scoring each round","Yes","High","Closes 50-70% gap vs PPO","Medium — needs RM + generation"],["SPIN","Current model (chosen) vs previous model (rejected)","Yes","Medium","Matches iterative DPO on many tasks","Low — no external RM needed"],["Online DPO","Continuous on-policy generation + RM","Yes (continuous)","Medium","Near PPO performance","High — requires stable online RM"],["PPO","Online rollouts with value function + RM","Yes (continuous)","Low","Best alignment quality","High — RL infrastructure required"]]},{"type":"heading","level":2,"content":"Implementation Considerations"},{"type":"text","content":"Memory requirements are the main practical constraint: iterative DPO needs the policy, the frozen reference model, and the reward model loaded simultaneously. With a 7B policy and 7B reference, this requires ~28 GB for BF16 weights alone, plus activations. LoRA for the policy (not the reference) reduces memory significantly while maintaining fine-tuning quality. The generation and DPO training steps can be batched to maximize GPU utilization — generate pairs for all prompts, then run one DPO epoch, rather than alternating per-batch."},{"type":"list","ordered":false,"items":["Use LoRA for the policy during iterative DPO — keeps reference model in full precision while the policy adapter trains efficiently.","Regenerate preference pairs every epoch rather than every batch — reduces inference overhead while staying effectively on-policy.","Monitor chosen_rewards and rejected_rewards separately — if both increase uniformly, the policy is reward-hacking rather than genuinely improving.","Use min_margin filtering (threshold 0.1–0.3 on normalized reward) to remove ambiguous pairs that add noise.","SPIN (self-play without RM) is a good fallback when a reliable reward model is unavailable — uses LM perplexity as the preference signal."]},{"type":"callout","variant":"info","title":"Iterative DPO vs PPO","content":"Iterative DPO closes most of the performance gap between DPO and PPO at lower complexity — on-policy preference data from the current model\u0027s distribution is significantly more informative than static preference data from the original SFT model. The remaining PPO advantage comes from its ability to explore the full response space rather than comparing policy samples."},{"type":"divider"}]"
---
# Iterative DPO — Online Preference Learning with Self-Generated Pairs

Direct Preference Optimization (DPO) is trained on a fixed dataset of (prompt, chosen, rejected) triples collected offline — typically from human labelers comparing outputs of the original SFT model. This static dataset has a critical limitation: as the policy improves during training, the preference pairs become increasingly off-policy relative to the current model distribution. Iterative DPO (also called online DPO) addresses this by periodically regenerating preference pairs from the current policy, ensuring training data stays on-policy and remains informative throughout training.

## Why Static DPO Falls Short

The DPO loss function implicitly assumes that the chosen and rejected responses are drawn from a distribution close to the reference model π_ref. When the policy π_θ drifts far from π_ref during training, the preference data becomes stale — the (chosen, rejected) pairs no longer represent the outputs the current policy would generate. This is the off-policy problem: the model is being trained to prefer response A over response B, but A and B were generated by a much weaker model, so the lesson is trivial for the now-stronger policy. On-policy preference data from the current π_θ provides a much harder and more informative training signal.

## The Iterative DPO Algorithm

Iterative DPO runs in rounds: (1) sample K completions per prompt from the current policy π_θ; (2) score them with a reward model or human rater; (3) form (chosen, rejected) pairs from highest- and lowest-scoring completions; (4) run a DPO update step with the new on-policy pairs; (5) repeat. The reference model π_ref can be kept fixed (original SFT) for stability or updated periodically. Key hyperparameters: how often to regenerate pairs (every N steps or every epoch), how many samples per prompt, and the DPO beta (KL penalty weight).

```python
import torch
from dataclasses import dataclass
from typing import Callable

@dataclass
class IterativeDPOConfig:
    n_rounds: int = 3
    samples_per_prompt: int = 2
    dpo_beta: float = 0.1
    dpo_epochs_per_round: int = 1
    lr: float = 5e-7
    ref_update_strategy: str = 'fixed'  # 'fixed', 'ema', or 'copy'

def iterative_dpo_round(
    policy,
    ref_model,
    tokenizer,
    reward_model,
    prompts: list,
    config: IterativeDPOConfig,
    round_idx: int,
    dpo_train_fn: Callable,
) -> dict:
    # One round: generate on-policy pairs, score, run DPO update
    print(f'Round {round_idx+1}: sampling {config.samples_per_prompt} completions/prompt from current policy')
    preference_dataset = generate_preference_pairs(
        policy, tokenizer, reward_model, prompts, config.samples_per_prompt
    )
    n_pairs = len(preference_dataset['chosen'])
    print(f'Round {round_idx+1}: DPO update on {n_pairs} on-policy pairs (beta={config.dpo_beta})')
    dpo_train_fn(policy, ref_model, preference_dataset, config)
    return {'round': round_idx + 1, 'n_pairs': n_pairs}

config = IterativeDPOConfig(n_rounds=3, samples_per_prompt=2, dpo_beta=0.1)
print('Iterative DPO: on-policy preference data from current pi_theta at each round')
print('Key: pairs generated by current policy are harder and more informative than SFT pairs')
```

## On-Policy Preference Pair Generation

At each round, two completions are sampled from the current policy per prompt. The reward model scores both and determines which is preferred. Using only 2 samples is the simplest setting — the margin between best and worst reflects the policy's current uncertainty. Using more samples (4–8) and taking the highest and lowest score creates larger reward margins in the preference pairs, providing a cleaner learning signal. Filtering out pairs where the reward margin is below a threshold (margin filtering) removes ambiguous pairs that add noise to training.

```python
import torch
from datasets import Dataset

def generate_preference_pairs(
    policy,
    tokenizer,
    reward_model,
    prompts: list,
    n_samples: int = 2,
    temperature: float = 0.8,
    min_margin: float = 0.1,
) -> Dataset:
    # Sample completions from current policy, use RM to determine preference
    chosen_list, rejected_list, prompt_list = [], [], []
    for prompt in prompts:
        inputs = tokenizer(prompt, return_tensors='pt').to(policy.device)
        completions = []
        for _ in range(n_samples):
            with torch.no_grad():
                output = policy.generate(
                    **inputs,
                    max_new_tokens=128,
                    do_sample=True,
                    temperature=temperature,
                    pad_token_id=tokenizer.eos_token_id,
                )
            gen = output[0][inputs['input_ids'].shape[1]:]
            completions.append(tokenizer.decode(gen, skip_special_tokens=True))
        scores = []
        for c in completions:
            enc = tokenizer(prompt + c, return_tensors='pt', truncation=True).to(reward_model.device)
            with torch.no_grad():
                scores.append(reward_model(**enc).logits.squeeze().item())
        best_idx = int(torch.tensor(scores).argmax())
        worst_idx = int(torch.tensor(scores).argmin())
        margin = scores[best_idx] - scores[worst_idx]
        if margin >= min_margin:
            chosen_list.append(completions[best_idx])
            rejected_list.append(completions[worst_idx])
            prompt_list.append(prompt)
    return Dataset.from_dict({'prompt': prompt_list, 'chosen': chosen_list, 'rejected': rejected_list})

print('On-policy pairs: both chosen and rejected come from current pi_theta')
print('Margin filtering (min_margin=0.1) removes ambiguous pairs from training')
```

## Reference Model Update Strategies

The reference model π_ref determines the KL penalty target — keeping π_θ from deviating too far. Three strategies exist: (A) fixed reference — keep the original SFT model as π_ref throughout all rounds, providing strong regularisation toward the SFT baseline; (B) EMA update — slowly track the policy with exponential moving average, softening regularisation; (C) copy per round — reset π_ref to the current π_θ at the start of each round, allowing the policy to drift further. Fixed reference is most stable and most commonly used; copy-per-round risks degeneration without other regularisation.

```python
import torch
import copy
from transformers import AutoModelForCausalLM

def update_reference_model(
    original_ref: AutoModelForCausalLM,
    current_policy: AutoModelForCausalLM,
    strategy: str = 'fixed',
    polyak_tau: float = 0.01,
) -> AutoModelForCausalLM:
    # Return updated reference model based on strategy
    if strategy == 'fixed':
        # Keep original SFT as reference throughout all rounds
        return original_ref
    elif strategy == 'ema':
        # Slowly track policy with exponential moving average
        with torch.no_grad():
            for p_ref, p_policy in zip(original_ref.parameters(), current_policy.parameters()):
                p_ref.data.mul_(1 - polyak_tau).add_(polyak_tau * p_policy.data)
        return original_ref
    elif strategy == 'copy':
        # Reset reference to current policy each round
        return copy.deepcopy(current_policy)
    else:
        raise ValueError(f'Unknown strategy: {strategy}')

strategies = ['fixed', 'ema', 'copy']
effects = [
    'Strong regularisation toward SFT baseline; lowest risk of degeneration',
    'Softening KL penalty over training; moderate policy drift allowed',
    'No anchoring to SFT; highest drift risk — needs other regularisation',
]
print(f'{"Strategy":<10}  {"Effect"}')
print('-' * 70)
for s, e in zip(strategies, effects):
    print(f'{s:<10}  {e}')
```

## On-Policy vs Off-Policy Performance

Empirical results consistently show iterative DPO outperforming static DPO, especially after the first training round where the policy has already shifted from the SFT baseline. The performance gap widens on harder tasks where the SFT model's output distribution is far from the optimal. On AlpacaEval 2.0 benchmarks, iterative DPO typically closes 50–70% of the gap between static DPO and PPO. The remaining gap comes from PPO's ability to explore the full response space rather than just comparing samples from the current policy.

```python
import numpy as np

def simulate_win_rate_trajectory(n_steps=500, on_policy=True, seed=42):
    # Simulate win rate trajectory for on-policy vs off-policy DPO
    rng = np.random.default_rng(seed)
    win_rate = 0.55
    trajectory = []
    for step in range(n_steps):
        if on_policy:
            improvement = 0.00035 * (1 - win_rate) + rng.normal(0, 0.002)
        else:
            # Off-policy data becomes less informative as policy improves
            decay = max(0, 1 - step / 250)
            improvement = 0.00012 * (1 - win_rate) * decay + rng.normal(0, 0.003)
        win_rate = float(np.clip(win_rate + improvement, 0.5, 0.95))
        trajectory.append(win_rate)
    return trajectory

on_traj = simulate_win_rate_trajectory(500, on_policy=True)
off_traj = simulate_win_rate_trajectory(500, on_policy=False)
checkpoints = [0, 99, 249, 499]
print(f'{"Step":>6}  {"On-Policy WR":>14}  {"Off-Policy WR":>15}  {"Delta":>8}')
print('-' * 52)
for step in checkpoints:
    d = on_traj[step] - off_traj[step]
    sign = '+' if d >= 0 else ''
    print(f'{step+1:>6}  {on_traj[step]:>14.4f}  {off_traj[step]:>15.4f}  {sign}{d:>7.4f}')
print(f'Final: on-policy={on_traj[-1]:.4f}, off-policy={off_traj[-1]:.4f}')
```

## Online DPO Variants

Several variants extend iterative DPO. Self-Play Fine-Tuning (SPIN, Chen et al. 2024) uses the current model vs the previous-round model for self-play: the current model generates chosen responses, the previous model generates rejected responses. SPPO (Self-Play Preference Optimization) reformulates preference optimization as a two-player game. Direct Nash Optimization (DNO) uses game-theoretic Nash equilibria as the optimization target. Online DPO (Guo et al. 2024) provides a unified framework with theoretical convergence guarantees. These variants differ in how they generate pairs and whether they use a reward model or rely on self-play dynamics.

| Method | Data Source | Online | Stability | Performance | Complexity |
| --- | --- | --- | --- | --- | --- |
| Static DPO | Fixed human preference dataset from SFT model | No | High | Baseline | Low — offline SFT-like training |
| Iterative DPO | Current policy + RM scoring each round | Yes | High | Closes 50-70% gap vs PPO | Medium — needs RM + generation |
| SPIN | Current model (chosen) vs previous model (rejected) | Yes | Medium | Matches iterative DPO on many tasks | Low — no external RM needed |
| Online DPO | Continuous on-policy generation + RM | Yes (continuous) | Medium | Near PPO performance | High — requires stable online RM |
| PPO | Online rollouts with value function + RM | Yes (continuous) | Low | Best alignment quality | High — RL infrastructure required |

## Implementation Considerations

Memory requirements are the main practical constraint: iterative DPO needs the policy, the frozen reference model, and the reward model loaded simultaneously. With a 7B policy and 7B reference, this requires ~28 GB for BF16 weights alone, plus activations. LoRA for the policy (not the reference) reduces memory significantly while maintaining fine-tuning quality. The generation and DPO training steps can be batched to maximize GPU utilization — generate pairs for all prompts, then run one DPO epoch, rather than alternating per-batch.

- Use LoRA for the policy during iterative DPO — keeps reference model in full precision while the policy adapter trains efficiently.
- Regenerate preference pairs every epoch rather than every batch — reduces inference overhead while staying effectively on-policy.
- Monitor chosen_rewards and rejected_rewards separately — if both increase uniformly, the policy is reward-hacking rather than genuinely improving.
- Use min_margin filtering (threshold 0.1–0.3 on normalized reward) to remove ambiguous pairs that add noise.
- SPIN (self-play without RM) is a good fallback when a reliable reward model is unavailable — uses LM perplexity as the preference signal.

> **Iterative DPO vs PPO**: Iterative DPO closes most of the performance gap between DPO and PPO at lower complexity — on-policy preference data from the current model's distribution is significantly more informative than static preference data from the original SFT model. The remaining PPO advantage comes from its ability to explore the full response space rather than comparing policy samples.

---

