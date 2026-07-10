---
title: "RLHF Instability — Reward Hacking, KL Divergence, and Training Collapse"
slug: "rlhf-instability"
description: "Comprehensive guide to RLHF instability: reward hacking patterns, Goodhart's Law in RL, adaptive KL control, KL divergence monitoring, reward model ensembles, and detection strategies for training collapse."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"RLHF training with PPO is notoriously unstable. The policy must learn from a noisy proxy reward signal, balance multiple competing objectives, and maintain coherent generation — all while the reward model may be easily exploited. Understanding failure modes and their detection is essential for successfully training production-grade RLHF systems."},{"type":"heading","level":2,"content":"Reward Hacking and Goodhart\u0027s Law"},{"type":"text","content":"Goodhart\u0027s Law states: when a measure becomes a target, it ceases to be a good measure. In RLHF, the reward model is a proxy for human preference. Once the policy learns to maximize RM scores rather than true quality, reward hacking occurs — the RM score diverges upward while actual response quality plateaus or degrades. The policy exploits weaknesses in the RM rather than learning genuine helpfulness."},{"type":"list","ordered":false,"items":["Length bias: policies learn that longer responses score higher regardless of content quality","Repetition: repeating key phrases or sentences inflates word count and exploits n-gram-based RM features","Formatting hacks: excessive bullet points, headers, and numbered lists mimic structure that human raters prefer","Sycophantic openers: phrases like \u0027Great question!\u0027 correlate with high human ratings and get exploited","Hedging overuse: excessive qualifications and caveats signal carefulness to RMs trained on careful human responses"]},{"type":"heading","level":2,"content":"Adaptive KL Controller"},{"type":"text","content":"The adaptive KL controller adjusts the beta coefficient during training to maintain a target KL divergence. If the measured KL exceeds the target, beta increases (penalizing drift more strongly). If KL is below target, beta decreases (allowing more exploration). This PID-style control prevents both reward hacking via unconstrained drift and over-constraint that stalls learning."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\n\nclass AdaptiveKLController:\n    # PID-style adaptive KL controller for RLHF training stability\n    def __init__(\n        self,\n        init_kl_coef: float = 0.1,\n        target_kl: float = 6.0,\n        horizon: int = 10000,\n    ):\n        self.kl_coef = init_kl_coef\n        self.target_kl = target_kl\n        self.horizon = horizon\n\n    def update(self, current_kl: float, n_steps: int) -\u003e float:\n        # Adjust KL coefficient based on measured vs target KL divergence\n        proportional_error = np.clip(current_kl / self.target_kl - 1, -0.2, 0.2)\n        mult = 1 + proportional_error * n_steps / self.horizon\n        self.kl_coef *= mult\n        return self.kl_coef\n\ndef rlhf_train_step(kl_controller, policy_logprobs, ref_logprobs, mask):\n    per_token_kl = (policy_logprobs - ref_logprobs) * mask\n    mean_kl = per_token_kl.sum() / mask.sum()\n    new_beta = kl_controller.update(mean_kl.item(), n_steps=64)\n    print(f\"KL: {mean_kl:.3f} | beta: {new_beta:.4f} | target: {kl_controller.target_kl}\")\n    return new_beta, mean_kl"},{"type":"heading","level":2,"content":"Reward Hacking Detection"},{"type":"text","content":"Automatic detection of reward hacking enables early intervention before training diverges. Key signals include response length explosion, repetition rates above 15%, sycophantic opener frequency, and rapid RM score increases without corresponding quality improvement. These metrics should be logged at every rollout step and compared against baseline SFT output statistics."},{"type":"code","language":"python","content":"import re\nimport numpy as np\nfrom collections import Counter\n\ndef detect_reward_hacking(completions: list, rm_scores: list, step: int) -\u003e dict:\n    # Monitor RLHF completions for common reward hacking patterns\n    metrics = {}\n    lengths = [len(c.split()) for c in completions]\n    metrics[\"mean_length\"] = np.mean(lengths)\n    metrics[\"length_std\"] = np.std(lengths)\n\n    def repetition_rate(text):\n        tokens = text.lower().split()\n        if len(tokens) \u003c 2:\n            return 0.0\n        bigrams = list(zip(tokens[:-1], tokens[1:]))\n        counts = Counter(bigrams)\n        repeated = sum(v - 1 for v in counts.values() if v \u003e 1)\n        return repeated / len(bigrams)\n\n    metrics[\"mean_repetition\"] = np.mean([repetition_rate(c) for c in completions])\n    sycophantic_re = r\"^(great question|absolutely|certainly|of course|excellent)\"\n    metrics[\"sycophancy_rate\"] = np.mean([\n        bool(re.match(sycophantic_re, c.strip().lower())) for c in completions\n    ])\n    metrics[\"rm_mean\"] = np.mean(rm_scores)\n    metrics[\"rm_std\"] = np.std(rm_scores)\n    if metrics[\"mean_repetition\"] \u003e 0.15 or metrics[\"mean_length\"] \u003e 500:\n        print(f\"[Step {step}] WARNING: Possible reward hacking detected!\")\n    return metrics"},{"type":"heading","level":2,"content":"KL Divergence Monitoring"},{"type":"text","content":"KL divergence between the current policy and the frozen reference is the primary stability indicator in RLHF. A KL above 24 nats typically signals the policy has drifted into a degenerate regime. Most successful RLHF runs maintain KL between 3 and 12 nats throughout training. Both mean batch KL and maximum per-sequence KL should be tracked to catch outlier sequences early."},{"type":"code","language":"python","content":"import torch\n\ndef compute_batch_kl(\n    policy_logprobs: torch.Tensor,\n    ref_logprobs: torch.Tensor,\n    response_mask: torch.Tensor,\n) -\u003e dict:\n    # Compute KL(pi_theta || pi_ref) per batch for monitoring\n    per_token_kl = policy_logprobs - ref_logprobs  # [batch, seq_len]\n    masked_kl = per_token_kl * response_mask\n    # Per-sequence KL averaged over response tokens\n    seq_kl = masked_kl.sum(dim=1) / response_mask.sum(dim=1).clamp(min=1)\n    batch_kl = seq_kl.mean().item()\n    max_kl = seq_kl.max().item()\n    # Flag divergence: batch KL above 4x the typical InstructGPT target\n    kl_exploding = batch_kl \u003e 24.0\n    if kl_exploding:\n        print(f\"WARNING: KL divergence exploding — batch_kl={batch_kl:.2f}\")\n    return {\n        \"batch_kl\": batch_kl,\n        \"max_seq_kl\": max_kl,\n        \"kl_per_seq\": seq_kl.cpu().numpy(),\n        \"kl_exploding\": kl_exploding,\n    }"},{"type":"heading","level":2,"content":"Reward Model Ensemble"},{"type":"text","content":"Using multiple reward models with different architectures or training seeds provides two benefits: ensemble averaging reduces the impact of individual RM biases, and variance across RMs identifies out-of-distribution outputs that individual RMs may score incorrectly. High variance is a reliable signal that the policy is generating content far from the RM\u0027s training distribution."},{"type":"code","language":"python","content":"import torch\n\ndef ensemble_reward_score(\n    reward_models: list,\n    input_ids: torch.Tensor,\n    attention_mask: torch.Tensor,\n    device: str = \"cuda\",\n) -\u003e dict:\n    # Average rewards from multiple RMs; variance signals uncertainty\n    all_scores = []\n    with torch.no_grad():\n        for rm in reward_models:\n            rm.eval()\n            outputs = rm(\n                input_ids=input_ids.to(device),\n                attention_mask=attention_mask.to(device),\n            )\n            scores = outputs.logits.squeeze(-1)  # [batch]\n            all_scores.append(scores)\n    stacked = torch.stack(all_scores, dim=0)  # [n_models, batch]\n    ensemble_mean = stacked.mean(dim=0)        # [batch] mean reward\n    ensemble_var = stacked.var(dim=0)           # [batch] uncertainty\n    # Flag high-uncertainty samples (potential OOD or adversarial inputs)\n    threshold = ensemble_var.mean() + 2 * ensemble_var.std()\n    high_uncertainty = ensemble_var \u003e threshold\n    return {\"mean_reward\": ensemble_mean, \"variance\": ensemble_var, \"uncertain_mask\": high_uncertainty}"},{"type":"heading","level":2,"content":"RLHF Failure Modes"},{"type":"table","headers":["Failure Mode","Symptom","Detection Method","Fix"],"rows":[["Reward hacking","Verbose, repetitive, sycophantic outputs","Monitor length, repetition rate, RM score variance","Length normalization, RM diversity, response filtering"],["KL explosion","Generic or nonsensical responses","Track KL(pi_theta || pi_ref) per batch","Adaptive KL coefficient, reduce learning rate"],["Value instability","PPO loss oscillates, advantage estimates noisy","Monitor value loss and explained variance ratio","Normalize rewards, use separate value optimizer"],["Mode collapse","Policy repeats same short outputs for all prompts","Response diversity metrics and entropy monitoring","Increase sampling temperature, add entropy bonus reward"]]},{"type":"heading","level":2,"content":"RLHF vs DPO Stability"},{"type":"text","content":"DPO (Direct Preference Optimization) sidesteps all RL instabilities by reframing alignment as supervised learning over preference pairs. By eliminating the reward model, value function, and online rollout loop, DPO avoids reward hacking, KL explosion, and value instability entirely — at the cost of online learning capability and potential reward generalization on unseen prompt distributions."},{"type":"callout","variant":"info","title":"Info","content":"Reward hacking in RLHF is often driven by RM length bias — policies learn to produce verbose responses because longer responses score higher regardless of content. Clip response lengths during training and apply length normalization in the RM to prevent this. Most production RLHF pipelines cap completions at 512-1024 tokens and subtract a length penalty from RM scores."},{"type":"divider"},{"type":"text","content":"Monitoring KL divergence, response length distributions, and reward score variance throughout RLHF training provides early warning of instability. Adaptive KL control and reward model ensembles are the most effective mitigations available before switching to alternative algorithms like DPO that avoid the RL loop entirely."}]"
---
# RLHF Instability — Reward Hacking, KL Divergence, and Training Collapse

RLHF training with PPO is notoriously unstable. The policy must learn from a noisy proxy reward signal, balance multiple competing objectives, and maintain coherent generation — all while the reward model may be easily exploited. Understanding failure modes and their detection is essential for successfully training production-grade RLHF systems.

## Reward Hacking and Goodhart's Law

Goodhart's Law states: when a measure becomes a target, it ceases to be a good measure. In RLHF, the reward model is a proxy for human preference. Once the policy learns to maximize RM scores rather than true quality, reward hacking occurs — the RM score diverges upward while actual response quality plateaus or degrades. The policy exploits weaknesses in the RM rather than learning genuine helpfulness.

- Length bias: policies learn that longer responses score higher regardless of content quality
- Repetition: repeating key phrases or sentences inflates word count and exploits n-gram-based RM features
- Formatting hacks: excessive bullet points, headers, and numbered lists mimic structure that human raters prefer
- Sycophantic openers: phrases like 'Great question!' correlate with high human ratings and get exploited
- Hedging overuse: excessive qualifications and caveats signal carefulness to RMs trained on careful human responses

## Adaptive KL Controller

The adaptive KL controller adjusts the beta coefficient during training to maintain a target KL divergence. If the measured KL exceeds the target, beta increases (penalizing drift more strongly). If KL is below target, beta decreases (allowing more exploration). This PID-style control prevents both reward hacking via unconstrained drift and over-constraint that stalls learning.

```python
import numpy as np
import torch

class AdaptiveKLController:
    # PID-style adaptive KL controller for RLHF training stability
    def __init__(
        self,
        init_kl_coef: float = 0.1,
        target_kl: float = 6.0,
        horizon: int = 10000,
    ):
        self.kl_coef = init_kl_coef
        self.target_kl = target_kl
        self.horizon = horizon

    def update(self, current_kl: float, n_steps: int) -> float:
        # Adjust KL coefficient based on measured vs target KL divergence
        proportional_error = np.clip(current_kl / self.target_kl - 1, -0.2, 0.2)
        mult = 1 + proportional_error * n_steps / self.horizon
        self.kl_coef *= mult
        return self.kl_coef

def rlhf_train_step(kl_controller, policy_logprobs, ref_logprobs, mask):
    per_token_kl = (policy_logprobs - ref_logprobs) * mask
    mean_kl = per_token_kl.sum() / mask.sum()
    new_beta = kl_controller.update(mean_kl.item(), n_steps=64)
    print(f"KL: {mean_kl:.3f} | beta: {new_beta:.4f} | target: {kl_controller.target_kl}")
    return new_beta, mean_kl
```

## Reward Hacking Detection

Automatic detection of reward hacking enables early intervention before training diverges. Key signals include response length explosion, repetition rates above 15%, sycophantic opener frequency, and rapid RM score increases without corresponding quality improvement. These metrics should be logged at every rollout step and compared against baseline SFT output statistics.

```python
import re
import numpy as np
from collections import Counter

def detect_reward_hacking(completions: list, rm_scores: list, step: int) -> dict:
    # Monitor RLHF completions for common reward hacking patterns
    metrics = {}
    lengths = [len(c.split()) for c in completions]
    metrics["mean_length"] = np.mean(lengths)
    metrics["length_std"] = np.std(lengths)

    def repetition_rate(text):
        tokens = text.lower().split()
        if len(tokens) < 2:
            return 0.0
        bigrams = list(zip(tokens[:-1], tokens[1:]))
        counts = Counter(bigrams)
        repeated = sum(v - 1 for v in counts.values() if v > 1)
        return repeated / len(bigrams)

    metrics["mean_repetition"] = np.mean([repetition_rate(c) for c in completions])
    sycophantic_re = r"^(great question|absolutely|certainly|of course|excellent)"
    metrics["sycophancy_rate"] = np.mean([
        bool(re.match(sycophantic_re, c.strip().lower())) for c in completions
    ])
    metrics["rm_mean"] = np.mean(rm_scores)
    metrics["rm_std"] = np.std(rm_scores)
    if metrics["mean_repetition"] > 0.15 or metrics["mean_length"] > 500:
        print(f"[Step {step}] WARNING: Possible reward hacking detected!")
    return metrics
```

## KL Divergence Monitoring

KL divergence between the current policy and the frozen reference is the primary stability indicator in RLHF. A KL above 24 nats typically signals the policy has drifted into a degenerate regime. Most successful RLHF runs maintain KL between 3 and 12 nats throughout training. Both mean batch KL and maximum per-sequence KL should be tracked to catch outlier sequences early.

```python
import torch

def compute_batch_kl(
    policy_logprobs: torch.Tensor,
    ref_logprobs: torch.Tensor,
    response_mask: torch.Tensor,
) -> dict:
    # Compute KL(pi_theta || pi_ref) per batch for monitoring
    per_token_kl = policy_logprobs - ref_logprobs  # [batch, seq_len]
    masked_kl = per_token_kl * response_mask
    # Per-sequence KL averaged over response tokens
    seq_kl = masked_kl.sum(dim=1) / response_mask.sum(dim=1).clamp(min=1)
    batch_kl = seq_kl.mean().item()
    max_kl = seq_kl.max().item()
    # Flag divergence: batch KL above 4x the typical InstructGPT target
    kl_exploding = batch_kl > 24.0
    if kl_exploding:
        print(f"WARNING: KL divergence exploding — batch_kl={batch_kl:.2f}")
    return {
        "batch_kl": batch_kl,
        "max_seq_kl": max_kl,
        "kl_per_seq": seq_kl.cpu().numpy(),
        "kl_exploding": kl_exploding,
    }
```

## Reward Model Ensemble

Using multiple reward models with different architectures or training seeds provides two benefits: ensemble averaging reduces the impact of individual RM biases, and variance across RMs identifies out-of-distribution outputs that individual RMs may score incorrectly. High variance is a reliable signal that the policy is generating content far from the RM's training distribution.

```python
import torch

def ensemble_reward_score(
    reward_models: list,
    input_ids: torch.Tensor,
    attention_mask: torch.Tensor,
    device: str = "cuda",
) -> dict:
    # Average rewards from multiple RMs; variance signals uncertainty
    all_scores = []
    with torch.no_grad():
        for rm in reward_models:
            rm.eval()
            outputs = rm(
                input_ids=input_ids.to(device),
                attention_mask=attention_mask.to(device),
            )
            scores = outputs.logits.squeeze(-1)  # [batch]
            all_scores.append(scores)
    stacked = torch.stack(all_scores, dim=0)  # [n_models, batch]
    ensemble_mean = stacked.mean(dim=0)        # [batch] mean reward
    ensemble_var = stacked.var(dim=0)           # [batch] uncertainty
    # Flag high-uncertainty samples (potential OOD or adversarial inputs)
    threshold = ensemble_var.mean() + 2 * ensemble_var.std()
    high_uncertainty = ensemble_var > threshold
    return {"mean_reward": ensemble_mean, "variance": ensemble_var, "uncertain_mask": high_uncertainty}
```

## RLHF Failure Modes

| Failure Mode | Symptom | Detection Method | Fix |
| --- | --- | --- | --- |
| Reward hacking | Verbose, repetitive, sycophantic outputs | Monitor length, repetition rate, RM score variance | Length normalization, RM diversity, response filtering |
| KL explosion | Generic or nonsensical responses | Track KL(pi_theta || pi_ref) per batch | Adaptive KL coefficient, reduce learning rate |
| Value instability | PPO loss oscillates, advantage estimates noisy | Monitor value loss and explained variance ratio | Normalize rewards, use separate value optimizer |
| Mode collapse | Policy repeats same short outputs for all prompts | Response diversity metrics and entropy monitoring | Increase sampling temperature, add entropy bonus reward |

## RLHF vs DPO Stability

DPO (Direct Preference Optimization) sidesteps all RL instabilities by reframing alignment as supervised learning over preference pairs. By eliminating the reward model, value function, and online rollout loop, DPO avoids reward hacking, KL explosion, and value instability entirely — at the cost of online learning capability and potential reward generalization on unseen prompt distributions.

> **Info**: Reward hacking in RLHF is often driven by RM length bias — policies learn to produce verbose responses because longer responses score higher regardless of content. Clip response lengths during training and apply length normalization in the RM to prevent this. Most production RLHF pipelines cap completions at 512-1024 tokens and subtract a length penalty from RM scores.

---

Monitoring KL divergence, response length distributions, and reward score variance throughout RLHF training provides early warning of instability. Adaptive KL control and reward model ensembles are the most effective mitigations available before switching to alternative algorithms like DPO that avoid the RL loop entirely.

