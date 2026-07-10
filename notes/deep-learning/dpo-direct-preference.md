---
title: "DPO — Direct Preference Optimization Without the RL Loop"
slug: "dpo-direct-preference"
description: "Complete treatment of DPO: derivation from the KL-constrained RL objective, loss implementation, training loop with frozen reference, implicit reward interpretation, and comparison against PPO-RLHF."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"DPO (Direct Preference Optimization, Rafailov et al. 2023) eliminates the reward model and RL training loop entirely. By deriving a closed-form relationship between the optimal policy, the reference policy, and human preferences, DPO converts RLHF into a supervised classification problem over preference pairs — making alignment training substantially more stable and computationally efficient than PPO-RLHF."},{"type":"heading","level":2,"content":"DPO Derivation from Optimal Policy"},{"type":"text","content":"DPO starts from the KL-constrained RL objective: max_pi E[r(x,y)] - beta * KL[pi || pi_ref]. The optimal policy satisfies pi*(y|x) proportional to pi_ref(y|x) * exp(r*(x,y)/beta). Rearranging: r*(x,y) = beta * log[pi*(y|x) / pi_ref(y|x)] + beta * log Z(x). Substituting into the Bradley-Terry preference model eliminates both r* and the partition function Z(x), yielding the DPO loss directly from paired preferences (x, y_w, y_l) without ever training a reward model."},{"type":"heading","level":2,"content":"DPO Loss Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom typing import Tuple\n\ndef dpo_loss(\n    policy_chosen_logps: torch.Tensor,\n    policy_rejected_logps: torch.Tensor,\n    ref_chosen_logps: torch.Tensor,\n    ref_rejected_logps: torch.Tensor,\n    beta: float = 0.1,\n) -\u003e Tuple[torch.Tensor, dict]:\n    # DPO loss: -E[log sigma(beta * (log_ratio_chosen - log_ratio_rejected))]\n    # Log ratio: log[pi_theta(y|x) / pi_ref(y|x)]\n    chosen_log_ratio = policy_chosen_logps - ref_chosen_logps\n    rejected_log_ratio = policy_rejected_logps - ref_rejected_logps\n    logits = beta * (chosen_log_ratio - rejected_log_ratio)\n    loss = -F.logsigmoid(logits).mean()\n    # Implicit rewards for monitoring preference alignment\n    chosen_rewards = beta * chosen_log_ratio.detach()\n    rejected_rewards = beta * rejected_log_ratio.detach()\n    reward_margin = (chosen_rewards - rejected_rewards).mean().item()\n    accuracy = (logits \u003e 0).float().mean().item()\n    return loss, {\n        \"reward_margin\": reward_margin,\n        \"dpo_accuracy\": accuracy,\n        \"chosen_reward\": chosen_rewards.mean().item(),\n        \"rejected_reward\": rejected_rewards.mean().item(),\n    }"},{"type":"heading","level":2,"content":"DPO Training Loop"},{"type":"text","content":"The DPO training setup requires only two models: the frozen reference pi_ref (the SFT checkpoint) and the trainable policy pi_theta. Both models forward-pass through each sequence to compute log-probabilities, but only the policy receives gradient updates. The reference model serves as a soft constraint preventing the policy from drifting too far from natural language distributions."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoModelForCausalLM\nfrom torch.optim import AdamW\nfrom typing import Tuple\n\ndef get_sequence_logps(model, input_ids, attention_mask, labels, device):\n    outputs = model(\n        input_ids=input_ids.to(device),\n        attention_mask=attention_mask.to(device),\n    )\n    logits = outputs.logits[:, :-1]  # shift for next-token prediction\n    log_probs = torch.log_softmax(logits, dim=-1)\n    token_logps = log_probs.gather(2, labels[:, 1:].to(device).unsqueeze(2)).squeeze(2)\n    label_mask = (labels[:, 1:].to(device) != -100).float()\n    return (token_logps * label_mask).sum(dim=1) / label_mask.sum(dim=1).clamp(min=1)\n\ndef dpo_training_step(policy_model, ref_model, batch, optimizer, beta=0.1, device=\"cuda\"):\n    # Forward both chosen and rejected through policy and frozen reference\n    optimizer.zero_grad()\n    p_chosen = get_sequence_logps(\n        policy_model, batch[\"chosen_ids\"], batch[\"chosen_mask\"], batch[\"chosen_labels\"], device\n    )\n    p_rejected = get_sequence_logps(\n        policy_model, batch[\"rejected_ids\"], batch[\"rejected_mask\"], batch[\"rejected_labels\"], device\n    )\n    with torch.no_grad():\n        r_chosen = get_sequence_logps(\n            ref_model, batch[\"chosen_ids\"], batch[\"chosen_mask\"], batch[\"chosen_labels\"], device\n        )\n        r_rejected = get_sequence_logps(\n            ref_model, batch[\"rejected_ids\"], batch[\"rejected_mask\"], batch[\"rejected_labels\"], device\n        )\n    loss, metrics = dpo_loss(p_chosen, p_rejected, r_chosen, r_rejected, beta)\n    loss.backward()\n    optimizer.step()\n    return metrics"},{"type":"heading","level":2,"content":"Implicit Reward"},{"type":"text","content":"DPO\u0027s implicit reward beta * log[pi_theta(y|x) / pi_ref(y|x)] emerges from the policy\u0027s log-probability ratio with the reference. This reward is not explicitly trained — it arises as a natural consequence of the policy learning to prefer chosen responses over rejected ones. Monitoring this implicit reward during training helps diagnose whether DPO is learning meaningful preferences or overfitting to surface artifacts."},{"type":"code","language":"python","content":"import torch\n\ndef compute_dpo_implicit_reward(\n    policy_model,\n    ref_model,\n    input_ids: torch.Tensor,\n    attention_mask: torch.Tensor,\n    labels: torch.Tensor,\n    beta: float = 0.1,\n    device: str = \"cuda\",\n) -\u003e torch.Tensor:\n    # DPO implicit reward: beta * log[pi_theta(y|x) / pi_ref(y|x)]\n    def sequence_logps(model, ids, mask, lbls):\n        with torch.no_grad():\n            out = model(\n                input_ids=ids.to(device), attention_mask=mask.to(device)\n            )\n            lp = torch.log_softmax(out.logits[:, :-1], dim=-1)\n            tok_lp = lp.gather(2, lbls[:, 1:].to(device).unsqueeze(2)).squeeze(2)\n            lbl_mask = (lbls[:, 1:].to(device) != -100).float()\n            return (tok_lp * lbl_mask).sum(1) / lbl_mask.sum(1).clamp(min=1)\n    policy_logps = sequence_logps(policy_model, input_ids, attention_mask, labels)\n    ref_logps = sequence_logps(ref_model, input_ids, attention_mask, labels)\n    # Positive value means policy assigns higher probability than reference\n    return beta * (policy_logps - ref_logps)  # [batch]"},{"type":"heading","level":2,"content":"Monitoring Chosen vs Rejected Log-Probabilities"},{"type":"text","content":"During successful DPO training, the log-probability ratio for chosen responses should increase while the ratio for rejected responses decreases. The margin (chosen_ratio - rejected_ratio) is the most diagnostic signal — a stagnant or decreasing margin indicates the policy is not learning to distinguish preferences. Track both ratios at every step; if chosen_ratio decreases over any 5-step window, reduce the learning rate."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\n\ndef monitor_dpo_logprob_evolution(\n    policy_chosen_logps: torch.Tensor,\n    policy_rejected_logps: torch.Tensor,\n    ref_chosen_logps: torch.Tensor,\n    ref_rejected_logps: torch.Tensor,\n    step: int,\n    history: list,\n) -\u003e dict:\n    # Track log-prob ratios during DPO training to detect divergence\n    chosen_ratio = (policy_chosen_logps - ref_chosen_logps).mean().item()\n    rejected_ratio = (policy_rejected_logps - ref_rejected_logps).mean().item()\n    metrics = {\n        \"step\": step,\n        \"chosen_logp_ratio\": chosen_ratio,\n        \"rejected_logp_ratio\": rejected_ratio,\n        \"margin\": chosen_ratio - rejected_ratio,\n    }\n    history.append(metrics)\n    if len(history) \u003e 10:\n        recent = np.mean([h[\"chosen_logp_ratio\"] for h in history[-5:]])\n        earlier = np.mean([h[\"chosen_logp_ratio\"] for h in history[-10:-5]])\n        if recent \u003c earlier:\n            print(f\"[Step {step}] WARNING: Chosen log-prob ratio decreasing — check LR\")\n    return metrics"},{"type":"heading","level":2,"content":"PPO-RLHF vs DPO Comparison"},{"type":"table","headers":["Aspect","PPO-RLHF","DPO"],"rows":[["Models needed","4 (policy, reference, reward model, value)","2 (policy, frozen reference)"],["Compute","High — online rollouts and RM scoring each step","Low — offline supervised training only"],["Data requirement","Preference labels plus prompts for rollouts","Paired (chosen, rejected) completions"],["Training stability","Unstable (reward hacking, KL explosion possible)","Stable (cross-entropy style loss)"],["Reward generalization","Better — explicit RM trained on varied prompts","Weaker — implicit, offline, no online signal"],["Performance","Higher ceiling with compute and scale","Competitive at moderate scale and data budget"]]},{"type":"heading","level":2,"content":"DPO Variants and Limitations"},{"type":"text","content":"Several DPO variants address its core limitations: reliance on paired preferences, no online learning capability, and weaker reward generalization compared to an explicit reward model. Each variant makes a different tradeoff between data requirements, compute, and alignment quality."},{"type":"list","ordered":false,"items":["IPO (Identity Preference Optimization): adds a regularization term to prevent overfitting to preference pairs when data is scarce","ORPO (Odds Ratio Preference Optimization): replaces the reference model with an odds ratio, enabling single-model training","SimPO (Simple Preference Optimization): length-normalized reward margin without requiring a separate reference model","Online DPO: periodically regenerates preference pairs using the current policy to enable online learning and distribution shift","KTO (Kahneman-Tversky Optimization): aligns from binary good/bad feedback without requiring paired comparisons"]},{"type":"callout","variant":"tip","title":"Tip","content":"DPO\u0027s implicit reward beta * log[pi_theta(y|x) / pi_ref(y|x)] can be negative if the policy has been pushed away from some responses during SFT — always initialize DPO from the SFT checkpoint that generated the preference data to avoid distribution mismatch. Using a different SFT checkpoint from the one that produced the preference pairs causes reference log-probs to be miscalibrated and destabilizes training."},{"type":"divider"},{"type":"text","content":"DPO has become the preferred alignment method for academic and small-scale production settings due to its simplicity, stability, and competitive performance. Its main limitation — offline-only learning from fixed preference datasets — is addressed by online DPO variants that periodically regenerate preference pairs from the current policy, combining the stability of DPO with the online learning benefits of PPO-RLHF."}]"
---
# DPO — Direct Preference Optimization Without the RL Loop

DPO (Direct Preference Optimization, Rafailov et al. 2023) eliminates the reward model and RL training loop entirely. By deriving a closed-form relationship between the optimal policy, the reference policy, and human preferences, DPO converts RLHF into a supervised classification problem over preference pairs — making alignment training substantially more stable and computationally efficient than PPO-RLHF.

## DPO Derivation from Optimal Policy

DPO starts from the KL-constrained RL objective: max_pi E[r(x,y)] - beta * KL[pi || pi_ref]. The optimal policy satisfies pi*(y|x) proportional to pi_ref(y|x) * exp(r*(x,y)/beta). Rearranging: r*(x,y) = beta * log[pi*(y|x) / pi_ref(y|x)] + beta * log Z(x). Substituting into the Bradley-Terry preference model eliminates both r* and the partition function Z(x), yielding the DPO loss directly from paired preferences (x, y_w, y_l) without ever training a reward model.

## DPO Loss Implementation

```python
import torch
import torch.nn.functional as F
from typing import Tuple

def dpo_loss(
    policy_chosen_logps: torch.Tensor,
    policy_rejected_logps: torch.Tensor,
    ref_chosen_logps: torch.Tensor,
    ref_rejected_logps: torch.Tensor,
    beta: float = 0.1,
) -> Tuple[torch.Tensor, dict]:
    # DPO loss: -E[log sigma(beta * (log_ratio_chosen - log_ratio_rejected))]
    # Log ratio: log[pi_theta(y|x) / pi_ref(y|x)]
    chosen_log_ratio = policy_chosen_logps - ref_chosen_logps
    rejected_log_ratio = policy_rejected_logps - ref_rejected_logps
    logits = beta * (chosen_log_ratio - rejected_log_ratio)
    loss = -F.logsigmoid(logits).mean()
    # Implicit rewards for monitoring preference alignment
    chosen_rewards = beta * chosen_log_ratio.detach()
    rejected_rewards = beta * rejected_log_ratio.detach()
    reward_margin = (chosen_rewards - rejected_rewards).mean().item()
    accuracy = (logits > 0).float().mean().item()
    return loss, {
        "reward_margin": reward_margin,
        "dpo_accuracy": accuracy,
        "chosen_reward": chosen_rewards.mean().item(),
        "rejected_reward": rejected_rewards.mean().item(),
    }
```

## DPO Training Loop

The DPO training setup requires only two models: the frozen reference pi_ref (the SFT checkpoint) and the trainable policy pi_theta. Both models forward-pass through each sequence to compute log-probabilities, but only the policy receives gradient updates. The reference model serves as a soft constraint preventing the policy from drifting too far from natural language distributions.

```python
import torch
from transformers import AutoModelForCausalLM
from torch.optim import AdamW
from typing import Tuple

def get_sequence_logps(model, input_ids, attention_mask, labels, device):
    outputs = model(
        input_ids=input_ids.to(device),
        attention_mask=attention_mask.to(device),
    )
    logits = outputs.logits[:, :-1]  # shift for next-token prediction
    log_probs = torch.log_softmax(logits, dim=-1)
    token_logps = log_probs.gather(2, labels[:, 1:].to(device).unsqueeze(2)).squeeze(2)
    label_mask = (labels[:, 1:].to(device) != -100).float()
    return (token_logps * label_mask).sum(dim=1) / label_mask.sum(dim=1).clamp(min=1)

def dpo_training_step(policy_model, ref_model, batch, optimizer, beta=0.1, device="cuda"):
    # Forward both chosen and rejected through policy and frozen reference
    optimizer.zero_grad()
    p_chosen = get_sequence_logps(
        policy_model, batch["chosen_ids"], batch["chosen_mask"], batch["chosen_labels"], device
    )
    p_rejected = get_sequence_logps(
        policy_model, batch["rejected_ids"], batch["rejected_mask"], batch["rejected_labels"], device
    )
    with torch.no_grad():
        r_chosen = get_sequence_logps(
            ref_model, batch["chosen_ids"], batch["chosen_mask"], batch["chosen_labels"], device
        )
        r_rejected = get_sequence_logps(
            ref_model, batch["rejected_ids"], batch["rejected_mask"], batch["rejected_labels"], device
        )
    loss, metrics = dpo_loss(p_chosen, p_rejected, r_chosen, r_rejected, beta)
    loss.backward()
    optimizer.step()
    return metrics
```

## Implicit Reward

DPO's implicit reward beta * log[pi_theta(y|x) / pi_ref(y|x)] emerges from the policy's log-probability ratio with the reference. This reward is not explicitly trained — it arises as a natural consequence of the policy learning to prefer chosen responses over rejected ones. Monitoring this implicit reward during training helps diagnose whether DPO is learning meaningful preferences or overfitting to surface artifacts.

```python
import torch

def compute_dpo_implicit_reward(
    policy_model,
    ref_model,
    input_ids: torch.Tensor,
    attention_mask: torch.Tensor,
    labels: torch.Tensor,
    beta: float = 0.1,
    device: str = "cuda",
) -> torch.Tensor:
    # DPO implicit reward: beta * log[pi_theta(y|x) / pi_ref(y|x)]
    def sequence_logps(model, ids, mask, lbls):
        with torch.no_grad():
            out = model(
                input_ids=ids.to(device), attention_mask=mask.to(device)
            )
            lp = torch.log_softmax(out.logits[:, :-1], dim=-1)
            tok_lp = lp.gather(2, lbls[:, 1:].to(device).unsqueeze(2)).squeeze(2)
            lbl_mask = (lbls[:, 1:].to(device) != -100).float()
            return (tok_lp * lbl_mask).sum(1) / lbl_mask.sum(1).clamp(min=1)
    policy_logps = sequence_logps(policy_model, input_ids, attention_mask, labels)
    ref_logps = sequence_logps(ref_model, input_ids, attention_mask, labels)
    # Positive value means policy assigns higher probability than reference
    return beta * (policy_logps - ref_logps)  # [batch]
```

## Monitoring Chosen vs Rejected Log-Probabilities

During successful DPO training, the log-probability ratio for chosen responses should increase while the ratio for rejected responses decreases. The margin (chosen_ratio - rejected_ratio) is the most diagnostic signal — a stagnant or decreasing margin indicates the policy is not learning to distinguish preferences. Track both ratios at every step; if chosen_ratio decreases over any 5-step window, reduce the learning rate.

```python
import numpy as np
import torch

def monitor_dpo_logprob_evolution(
    policy_chosen_logps: torch.Tensor,
    policy_rejected_logps: torch.Tensor,
    ref_chosen_logps: torch.Tensor,
    ref_rejected_logps: torch.Tensor,
    step: int,
    history: list,
) -> dict:
    # Track log-prob ratios during DPO training to detect divergence
    chosen_ratio = (policy_chosen_logps - ref_chosen_logps).mean().item()
    rejected_ratio = (policy_rejected_logps - ref_rejected_logps).mean().item()
    metrics = {
        "step": step,
        "chosen_logp_ratio": chosen_ratio,
        "rejected_logp_ratio": rejected_ratio,
        "margin": chosen_ratio - rejected_ratio,
    }
    history.append(metrics)
    if len(history) > 10:
        recent = np.mean([h["chosen_logp_ratio"] for h in history[-5:]])
        earlier = np.mean([h["chosen_logp_ratio"] for h in history[-10:-5]])
        if recent < earlier:
            print(f"[Step {step}] WARNING: Chosen log-prob ratio decreasing — check LR")
    return metrics
```

## PPO-RLHF vs DPO Comparison

| Aspect | PPO-RLHF | DPO |
| --- | --- | --- |
| Models needed | 4 (policy, reference, reward model, value) | 2 (policy, frozen reference) |
| Compute | High — online rollouts and RM scoring each step | Low — offline supervised training only |
| Data requirement | Preference labels plus prompts for rollouts | Paired (chosen, rejected) completions |
| Training stability | Unstable (reward hacking, KL explosion possible) | Stable (cross-entropy style loss) |
| Reward generalization | Better — explicit RM trained on varied prompts | Weaker — implicit, offline, no online signal |
| Performance | Higher ceiling with compute and scale | Competitive at moderate scale and data budget |

## DPO Variants and Limitations

Several DPO variants address its core limitations: reliance on paired preferences, no online learning capability, and weaker reward generalization compared to an explicit reward model. Each variant makes a different tradeoff between data requirements, compute, and alignment quality.

- IPO (Identity Preference Optimization): adds a regularization term to prevent overfitting to preference pairs when data is scarce
- ORPO (Odds Ratio Preference Optimization): replaces the reference model with an odds ratio, enabling single-model training
- SimPO (Simple Preference Optimization): length-normalized reward margin without requiring a separate reference model
- Online DPO: periodically regenerates preference pairs using the current policy to enable online learning and distribution shift
- KTO (Kahneman-Tversky Optimization): aligns from binary good/bad feedback without requiring paired comparisons

> **Tip**: DPO's implicit reward beta * log[pi_theta(y|x) / pi_ref(y|x)] can be negative if the policy has been pushed away from some responses during SFT — always initialize DPO from the SFT checkpoint that generated the preference data to avoid distribution mismatch. Using a different SFT checkpoint from the one that produced the preference pairs causes reference log-probs to be miscalibrated and destabilizes training.

---

DPO has become the preferred alignment method for academic and small-scale production settings due to its simplicity, stability, and competitive performance. Its main limitation — offline-only learning from fixed preference datasets — is addressed by online DPO variants that periodically regenerate preference pairs from the current policy, combining the stability of DPO with the online learning benefits of PPO-RLHF.

