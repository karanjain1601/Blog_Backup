---
title: "PPO for RLHF — Policy Optimization with Reward Model and KL Penalty"
slug: "ppo-rlhf"
description: "Deep dive into PPO-RLHF: four-model architecture, per-token KL penalty, clipped surrogate objective, GAE advantage estimation, and the rollout training loop from InstructGPT."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"PPO-RLHF (Proximal Policy Optimization for Reinforcement Learning from Human Feedback) is the training algorithm behind InstructGPT and early ChatGPT. It fine-tunes a language model using human preference signals by formulating alignment as a reinforcement learning problem over token sequences. The key insight is to maximize expected reward while preventing the policy from deviating too far from a supervised fine-tuned baseline using a KL divergence penalty."},{"type":"heading","level":2,"content":"The Four Models in PPO-RLHF"},{"type":"text","content":"Four distinct neural networks operate simultaneously during PPO-RLHF training, each with a specific role. At 7B parameter scale, this requires roughly 4x the GPU memory of inference alone, making multi-GPU setups or LoRA adapters on the policy and value heads a practical necessity."},{"type":"list","ordered":false,"items":["Policy pi_theta: the LLM being trained, initialized from the SFT checkpoint, updated by PPO gradients each iteration","Reference policy pi_ref: frozen copy of the SFT model, provides the KL anchor that prevents reward hacking and degenerate outputs","Reward model r_phi: trained on human preference comparisons, scores (prompt, completion) pairs with a scalar reward signal","Value model V_psi: predicts expected future return from each token position, used for GAE advantage estimation during PPO updates"]},{"type":"heading","level":2,"content":"Objective Function and KL Penalty"},{"type":"text","content":"The RLHF objective maximizes E[r(x,y)] - beta * KL[pi_theta || pi_ref], where r(x,y) is the reward model score, beta controls the KL penalty strength, pi_theta is the policy being trained, and pi_ref is the frozen SFT reference. The KL term prevents the policy from exploiting reward model weaknesses by constraining it to stay close to human-like outputs. InstructGPT starts with beta=0.02 and uses an adaptive controller targeting 6 nats of divergence."},{"type":"heading","level":2,"content":"Per-Token KL and Shaped Reward"},{"type":"text","content":"PPO-RLHF applies a per-token KL penalty at each position t: KL_t = log pi_theta(a_t|s_t) - log pi_ref(a_t|s_t). The shaped reward signal is R_t = r(x,y) * 1[t=T] - beta * KL_t — the terminal reward model score minus ongoing KL penalties at every token position. This dense reward signal speeds up credit assignment compared to a purely terminal reward."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom typing import Tuple\n\ndef compute_ppo_rlhf_reward(\n    policy_logprobs: torch.Tensor,\n    ref_logprobs: torch.Tensor,\n    rm_scores: torch.Tensor,\n    beta: float = 0.1,\n    response_mask: torch.Tensor = None,\n) -\u003e torch.Tensor:\n    # Per-token KL: KL_t = log pi_theta(a_t) - log pi_ref(a_t)\n    per_token_kl = policy_logprobs - ref_logprobs  # [batch, seq_len]\n    # Initialize reward tensor with KL penalty at every token position\n    rewards = -beta * per_token_kl  # [batch, seq_len]\n    # Add terminal RM reward at the last response token\n    if response_mask is not None:\n        last_token_idx = response_mask.sum(dim=1).long() - 1\n    else:\n        last_token_idx = torch.full(\n            (rewards.size(0),), rewards.size(1) - 1, dtype=torch.long\n        )\n    for i, idx in enumerate(last_token_idx):\n        rewards[i, idx] += rm_scores[i]\n    # Zero out padding positions\n    if response_mask is not None:\n        rewards = rewards * response_mask\n    return rewards  # [batch, seq_len]"},{"type":"heading","level":2,"content":"PPO Clipped Objective"},{"type":"text","content":"PPO uses a clipped surrogate objective to prevent destructively large policy updates. The importance ratio r_t = pi_theta(a_t) / pi_old(a_t) measures policy drift from the rollout policy. Clipping r_t to [1-eps, 1+eps] bounds the gradient step. The L_CLIP objective takes the pessimistic minimum: min(r_t * A_t, clip(r_t, 1-eps, 1+eps) * A_t), preventing updates that exploit outlier advantages."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom typing import Tuple\n\ndef ppo_clipped_loss(\n    old_logprobs: torch.Tensor,\n    new_logprobs: torch.Tensor,\n    advantages: torch.Tensor,\n    response_mask: torch.Tensor,\n    clip_eps: float = 0.2,\n) -\u003e Tuple[torch.Tensor, dict]:\n    # Importance sampling ratio: r_t = pi_theta / pi_old\n    log_ratio = new_logprobs - old_logprobs\n    ratio = log_ratio.exp()  # [batch, seq_len]\n    # Clipped surrogate: min(r_t * A_t, clip(r_t, 1-eps, 1+eps) * A_t)\n    unclipped = ratio * advantages\n    clipped = ratio.clamp(1 - clip_eps, 1 + clip_eps) * advantages\n    policy_loss = -torch.min(unclipped, clipped)\n    # Average loss over valid response tokens only\n    masked_loss = (policy_loss * response_mask).sum() / response_mask.sum()\n    clip_frac = ((ratio - 1.0).abs() \u003e clip_eps).float().mean().item()\n    approx_kl = (log_ratio * response_mask).sum() / response_mask.sum()\n    return masked_loss, {\"clip_frac\": clip_frac, \"approx_kl\": approx_kl.item()}"},{"type":"heading","level":2,"content":"Value Function and GAE Estimation"},{"type":"text","content":"The value model V_psi estimates expected future return from each token position, enabling Generalized Advantage Estimation (GAE). With lambda=0.95, GAE computes advantages as exponentially weighted TD errors: A_t = sum((gamma*lambda)^l * delta_{t+l}) where delta_t = r_t + gamma * V(s_{t+1}) - V(s_t). Returns, which serve as value training targets, are computed as advantages plus value estimates."},{"type":"code","language":"python","content":"import torch\nfrom typing import Tuple\n\ndef compute_gae_returns(\n    rewards: torch.Tensor,\n    values: torch.Tensor,\n    response_mask: torch.Tensor,\n    gamma: float = 1.0,\n    lam: float = 0.95,\n) -\u003e Tuple[torch.Tensor, torch.Tensor]:\n    # Compute GAE advantages and returns for PPO-RLHF value training\n    batch, seq_len = rewards.shape\n    advantages = torch.zeros_like(rewards)\n    last_gae = torch.zeros(batch, device=rewards.device)\n    for t in reversed(range(seq_len)):\n        mask_t = response_mask[:, t]\n        if t \u003c seq_len - 1:\n            next_val = values[:, t + 1]\n        else:\n            next_val = torch.zeros(batch, device=values.device)\n        delta = rewards[:, t] + gamma * next_val - values[:, t]\n        last_gae = delta + gamma * lam * last_gae\n        advantages[:, t] = last_gae * mask_t\n    # Returns = advantages + values (targets for value function training)\n    returns = advantages + values\n    # Normalize advantages over valid response positions\n    adv_flat = advantages[response_mask.bool()]\n    advantages = (advantages - adv_flat.mean()) / (adv_flat.std() + 1e-8)\n    return advantages, returns"},{"type":"heading","level":2,"content":"RLHF Rollout Loop"},{"type":"text","content":"Each PPO iteration begins with a rollout phase: sample prompts from the dataset, generate completions with the current policy using temperature sampling, score with the reward model, compute per-token KL with the frozen reference, then use GAE to produce advantage estimates. Multiple PPO epochs then update the policy and value head using mini-batches from the rollout buffer. Typical setups use 512 rollouts per iteration with 4 PPO epochs."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef collect_rlhf_rollouts(\n    policy_model: AutoModelForCausalLM,\n    reward_model,\n    tokenizer: AutoTokenizer,\n    prompts: list,\n    max_new_tokens: int = 256,\n    device: str = \"cuda\",\n) -\u003e dict:\n    # Generate completions and score with reward model\n    policy_model.eval()\n    with torch.no_grad():\n        inputs = tokenizer(\n            prompts, return_tensors=\"pt\", padding=True, truncation=True\n        ).to(device)\n        outputs = policy_model.generate(\n            **inputs,\n            max_new_tokens=max_new_tokens,\n            do_sample=True,\n            temperature=0.9,\n            top_p=0.95,\n            return_dict_in_generate=True,\n        )\n        response_ids = outputs.sequences[:, inputs[\"input_ids\"].shape[1]:]\n        completions = tokenizer.batch_decode(response_ids, skip_special_tokens=True)\n        rm_inputs = tokenizer(\n            prompts, completions, return_tensors=\"pt\", padding=True\n        ).to(device)\n        rm_scores = reward_model(**rm_inputs).logits.squeeze(-1)\n    return {\"completions\": completions, \"rm_scores\": rm_scores, \"response_ids\": response_ids}"},{"type":"heading","level":2,"content":"PPO Hyperparameters for RLHF"},{"type":"table","headers":["Hyperparameter","Symbol","InstructGPT Value","Effect of Increasing"],"rows":[["KL coefficient","beta","0.02 (adaptive)","Stronger drift penalty, slower learning, less reward hacking"],["Clip epsilon","eps","0.2","Wider trust region, noisier updates, higher clip fraction"],["GAE lambda","lambda","0.95","More bias, less variance in advantage estimates"],["Rollout batch size","B","512 sequences","More diverse experience, slower per-iteration wall time"],["PPO mini-batch size","M","64 sequences","Noisier gradients but faster steps per rollout buffer"],["PPO epochs per rollout","E","4","More gradient reuse per rollout, risk of overfit to stale advantages"]]},{"type":"text","content":"The KL coefficient beta is the most sensitive hyperparameter in PPO-RLHF. Too small and the policy reward hacks; too large and learning stalls. InstructGPT uses an adaptive controller that increases beta when KL exceeds the target and decreases it when below, maintaining roughly 6 nats of divergence throughout training."},{"type":"callout","variant":"warning","title":"Warning","content":"PPO for RLHF requires 4 models simultaneously in GPU memory (policy, reference, reward, value) — typical 7B scale RLHF needs 4x the memory of inference, requiring multi-GPU or LoRA on policy/value heads. With full-precision 7B models each requiring ~14GB VRAM, a single 80GB A100 is insufficient for naive full-parameter RLHF at this scale."},{"type":"text","content":"PPO-RLHF remains the gold standard for aligning large language models with human preferences at scale. Its four-model architecture, per-token KL penalties, and clipped surrogate objective work together to produce helpful and harmless outputs — but the engineering complexity and memory requirements have driven the community toward simpler alternatives like DPO for smaller-scale experiments."}]"
---
# PPO for RLHF — Policy Optimization with Reward Model and KL Penalty

PPO-RLHF (Proximal Policy Optimization for Reinforcement Learning from Human Feedback) is the training algorithm behind InstructGPT and early ChatGPT. It fine-tunes a language model using human preference signals by formulating alignment as a reinforcement learning problem over token sequences. The key insight is to maximize expected reward while preventing the policy from deviating too far from a supervised fine-tuned baseline using a KL divergence penalty.

## The Four Models in PPO-RLHF

Four distinct neural networks operate simultaneously during PPO-RLHF training, each with a specific role. At 7B parameter scale, this requires roughly 4x the GPU memory of inference alone, making multi-GPU setups or LoRA adapters on the policy and value heads a practical necessity.

- Policy pi_theta: the LLM being trained, initialized from the SFT checkpoint, updated by PPO gradients each iteration
- Reference policy pi_ref: frozen copy of the SFT model, provides the KL anchor that prevents reward hacking and degenerate outputs
- Reward model r_phi: trained on human preference comparisons, scores (prompt, completion) pairs with a scalar reward signal
- Value model V_psi: predicts expected future return from each token position, used for GAE advantage estimation during PPO updates

## Objective Function and KL Penalty

The RLHF objective maximizes E[r(x,y)] - beta * KL[pi_theta || pi_ref], where r(x,y) is the reward model score, beta controls the KL penalty strength, pi_theta is the policy being trained, and pi_ref is the frozen SFT reference. The KL term prevents the policy from exploiting reward model weaknesses by constraining it to stay close to human-like outputs. InstructGPT starts with beta=0.02 and uses an adaptive controller targeting 6 nats of divergence.

## Per-Token KL and Shaped Reward

PPO-RLHF applies a per-token KL penalty at each position t: KL_t = log pi_theta(a_t|s_t) - log pi_ref(a_t|s_t). The shaped reward signal is R_t = r(x,y) * 1[t=T] - beta * KL_t — the terminal reward model score minus ongoing KL penalties at every token position. This dense reward signal speeds up credit assignment compared to a purely terminal reward.

```python
import torch
import torch.nn.functional as F
from typing import Tuple

def compute_ppo_rlhf_reward(
    policy_logprobs: torch.Tensor,
    ref_logprobs: torch.Tensor,
    rm_scores: torch.Tensor,
    beta: float = 0.1,
    response_mask: torch.Tensor = None,
) -> torch.Tensor:
    # Per-token KL: KL_t = log pi_theta(a_t) - log pi_ref(a_t)
    per_token_kl = policy_logprobs - ref_logprobs  # [batch, seq_len]
    # Initialize reward tensor with KL penalty at every token position
    rewards = -beta * per_token_kl  # [batch, seq_len]
    # Add terminal RM reward at the last response token
    if response_mask is not None:
        last_token_idx = response_mask.sum(dim=1).long() - 1
    else:
        last_token_idx = torch.full(
            (rewards.size(0),), rewards.size(1) - 1, dtype=torch.long
        )
    for i, idx in enumerate(last_token_idx):
        rewards[i, idx] += rm_scores[i]
    # Zero out padding positions
    if response_mask is not None:
        rewards = rewards * response_mask
    return rewards  # [batch, seq_len]
```

## PPO Clipped Objective

PPO uses a clipped surrogate objective to prevent destructively large policy updates. The importance ratio r_t = pi_theta(a_t) / pi_old(a_t) measures policy drift from the rollout policy. Clipping r_t to [1-eps, 1+eps] bounds the gradient step. The L_CLIP objective takes the pessimistic minimum: min(r_t * A_t, clip(r_t, 1-eps, 1+eps) * A_t), preventing updates that exploit outlier advantages.

```python
import torch
import torch.nn.functional as F
from typing import Tuple

def ppo_clipped_loss(
    old_logprobs: torch.Tensor,
    new_logprobs: torch.Tensor,
    advantages: torch.Tensor,
    response_mask: torch.Tensor,
    clip_eps: float = 0.2,
) -> Tuple[torch.Tensor, dict]:
    # Importance sampling ratio: r_t = pi_theta / pi_old
    log_ratio = new_logprobs - old_logprobs
    ratio = log_ratio.exp()  # [batch, seq_len]
    # Clipped surrogate: min(r_t * A_t, clip(r_t, 1-eps, 1+eps) * A_t)
    unclipped = ratio * advantages
    clipped = ratio.clamp(1 - clip_eps, 1 + clip_eps) * advantages
    policy_loss = -torch.min(unclipped, clipped)
    # Average loss over valid response tokens only
    masked_loss = (policy_loss * response_mask).sum() / response_mask.sum()
    clip_frac = ((ratio - 1.0).abs() > clip_eps).float().mean().item()
    approx_kl = (log_ratio * response_mask).sum() / response_mask.sum()
    return masked_loss, {"clip_frac": clip_frac, "approx_kl": approx_kl.item()}
```

## Value Function and GAE Estimation

The value model V_psi estimates expected future return from each token position, enabling Generalized Advantage Estimation (GAE). With lambda=0.95, GAE computes advantages as exponentially weighted TD errors: A_t = sum((gamma*lambda)^l * delta_{t+l}) where delta_t = r_t + gamma * V(s_{t+1}) - V(s_t). Returns, which serve as value training targets, are computed as advantages plus value estimates.

```python
import torch
from typing import Tuple

def compute_gae_returns(
    rewards: torch.Tensor,
    values: torch.Tensor,
    response_mask: torch.Tensor,
    gamma: float = 1.0,
    lam: float = 0.95,
) -> Tuple[torch.Tensor, torch.Tensor]:
    # Compute GAE advantages and returns for PPO-RLHF value training
    batch, seq_len = rewards.shape
    advantages = torch.zeros_like(rewards)
    last_gae = torch.zeros(batch, device=rewards.device)
    for t in reversed(range(seq_len)):
        mask_t = response_mask[:, t]
        if t < seq_len - 1:
            next_val = values[:, t + 1]
        else:
            next_val = torch.zeros(batch, device=values.device)
        delta = rewards[:, t] + gamma * next_val - values[:, t]
        last_gae = delta + gamma * lam * last_gae
        advantages[:, t] = last_gae * mask_t
    # Returns = advantages + values (targets for value function training)
    returns = advantages + values
    # Normalize advantages over valid response positions
    adv_flat = advantages[response_mask.bool()]
    advantages = (advantages - adv_flat.mean()) / (adv_flat.std() + 1e-8)
    return advantages, returns
```

## RLHF Rollout Loop

Each PPO iteration begins with a rollout phase: sample prompts from the dataset, generate completions with the current policy using temperature sampling, score with the reward model, compute per-token KL with the frozen reference, then use GAE to produce advantage estimates. Multiple PPO epochs then update the policy and value head using mini-batches from the rollout buffer. Typical setups use 512 rollouts per iteration with 4 PPO epochs.

```python
import torch
from transformers import AutoModelForCausalLM, AutoTokenizer

def collect_rlhf_rollouts(
    policy_model: AutoModelForCausalLM,
    reward_model,
    tokenizer: AutoTokenizer,
    prompts: list,
    max_new_tokens: int = 256,
    device: str = "cuda",
) -> dict:
    # Generate completions and score with reward model
    policy_model.eval()
    with torch.no_grad():
        inputs = tokenizer(
            prompts, return_tensors="pt", padding=True, truncation=True
        ).to(device)
        outputs = policy_model.generate(
            **inputs,
            max_new_tokens=max_new_tokens,
            do_sample=True,
            temperature=0.9,
            top_p=0.95,
            return_dict_in_generate=True,
        )
        response_ids = outputs.sequences[:, inputs["input_ids"].shape[1]:]
        completions = tokenizer.batch_decode(response_ids, skip_special_tokens=True)
        rm_inputs = tokenizer(
            prompts, completions, return_tensors="pt", padding=True
        ).to(device)
        rm_scores = reward_model(**rm_inputs).logits.squeeze(-1)
    return {"completions": completions, "rm_scores": rm_scores, "response_ids": response_ids}
```

## PPO Hyperparameters for RLHF

| Hyperparameter | Symbol | InstructGPT Value | Effect of Increasing |
| --- | --- | --- | --- |
| KL coefficient | beta | 0.02 (adaptive) | Stronger drift penalty, slower learning, less reward hacking |
| Clip epsilon | eps | 0.2 | Wider trust region, noisier updates, higher clip fraction |
| GAE lambda | lambda | 0.95 | More bias, less variance in advantage estimates |
| Rollout batch size | B | 512 sequences | More diverse experience, slower per-iteration wall time |
| PPO mini-batch size | M | 64 sequences | Noisier gradients but faster steps per rollout buffer |
| PPO epochs per rollout | E | 4 | More gradient reuse per rollout, risk of overfit to stale advantages |

The KL coefficient beta is the most sensitive hyperparameter in PPO-RLHF. Too small and the policy reward hacks; too large and learning stalls. InstructGPT uses an adaptive controller that increases beta when KL exceeds the target and decreases it when below, maintaining roughly 6 nats of divergence throughout training.

> **Warning**: PPO for RLHF requires 4 models simultaneously in GPU memory (policy, reference, reward, value) — typical 7B scale RLHF needs 4x the memory of inference, requiring multi-GPU or LoRA on policy/value heads. With full-precision 7B models each requiring ~14GB VRAM, a single 80GB A100 is insufficient for naive full-parameter RLHF at this scale.

PPO-RLHF remains the gold standard for aligning large language models with human preferences at scale. Its four-model architecture, per-token KL penalties, and clipped surrogate objective work together to produce helpful and harmless outputs — but the engineering complexity and memory requirements have driven the community toward simpler alternatives like DPO for smaller-scale experiments.

