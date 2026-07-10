---
title: "ORPO — Odds Ratio Preference Optimization Without a Reference Model"
slug: "orpo-odds-ratio"
description: "ORPO (Hong et al., 2024) eliminates the reference model entirely by combining supervised fine-tuning and preference alignment into a single training stage, using an odds ratio loss that directly contrasts chosen and rejected sequences through probability ratios rather than log-ratio differences."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"ORPO (Odds Ratio Preference Optimization, Hong et al. 2024) takes a fundamentally different approach to LLM alignment: it removes the reference model entirely and combines supervised fine-tuning (SFT) with preference learning into a single training stage. Previous methods — PPO, DPO, IPO — all require a frozen reference policy pi_ref to anchor the optimization via a KL divergence constraint. This reference model doubles (or quadruples, in PPO\u0027s case) the GPU memory requirement. ORPO\u0027s insight is that the SFT loss itself provides the reference signal: by jointly maximizing chosen response likelihood and the odds ratio between chosen and rejected responses, the model learns both task competence and preference alignment simultaneously."},{"type":"heading","level":2,"content":"Eliminating the Reference Model"},{"type":"text","content":"DPO and IPO use the reference model pi_ref as a baseline: the policy is rewarded for increasing its probability ratio relative to what pi_ref assigns. This KL anchoring prevents the policy from diverging arbitrarily. ORPO replaces this external baseline with the SFT loss: by directly maximizing log pi_theta(y_w|x), the model is prevented from collapsing to degenerate behavior. The SFT component keeps the policy near a competent language model; the odds ratio component pushes it to prefer chosen over rejected sequences. Together, they provide the same alignment stability as a reference model without requiring one to be stored."},{"type":"heading","level":2,"content":"ORPO Loss: Combined SFT and Odds Ratio"},{"type":"text","content":"The ORPO total loss is: L_ORPO = L_SFT + lambda * L_OR where L_SFT = -log pi_theta(y_w|x) (standard causal language model loss on chosen sequences) and L_OR = -log sigma(log [odds_theta(y_w|x) / odds_theta(y_l|x)]) where odds(y|x) = P(y|x)/(1-P(y|x)). The log odds ratio log[odds_w/odds_l] = log[P(y_w|x)/(1-P(y_w|x))] - log[P(y_l|x)/(1-P(y_l|x))]. In log space: log_odds(y|x) = log P(y|x) - log(1 - P(y|x)) = logp(y|x) - log1p(-exp(logp(y|x))). The hyperparameter lambda balances SFT and alignment; typical values are 0.1 to 1.0."},{"type":"text","content":"The odds ratio is chosen over the probability ratio for a theoretical reason: for long sequences where P(y|x) is very small (which is typical — a 100-token sequence with per-token average log-prob -1.2 has total probability exp(-120) ~ 10^{-52}), the odds ratio and probability ratio are numerically equivalent. This means ORPO\u0027s L_OR is approximately equivalent to a log-probability ratio loss when applied to realistic language model outputs, while being more theoretically grounded and numerically stable."},{"type":"heading","level":2,"content":"ORPO Loss Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef orpo_loss(policy_chosen_logps, policy_rejected_logps, lam=0.1):\n    # ORPO (Hong et al., 2024): L_SFT + lambda * L_OR, no reference model needed\n    sft_loss = -policy_chosen_logps.mean()\n    # log_odds(y|x) = logp - log(1 - exp(logp)); clamp for numerical stability\n    log_odds_c = policy_chosen_logps   - torch.log1p(-policy_chosen_logps.exp().clamp(max=0.9999))\n    log_odds_r = policy_rejected_logps - torch.log1p(-policy_rejected_logps.exp().clamp(max=0.9999))\n    log_odds_ratio = log_odds_c - log_odds_r\n    or_loss = -F.logsigmoid(log_odds_ratio).mean()\n    total = sft_loss + lam * or_loss\n    return total, sft_loss.detach(), or_loss.detach()\n\nbsz = 8\nchosen_logps   = torch.full((bsz,), -1.2) + torch.randn(bsz) * 0.1\nrejected_logps = torch.full((bsz,), -1.8) + torch.randn(bsz) * 0.1\nloss, sft, oratio = orpo_loss(chosen_logps, rejected_logps, lam=0.1)\nprint(f\u0027ORPO total: {loss:.4f}   SFT: {sft:.4f}   OR: {oratio:.4f}\u0027)\nprint(f\u0027Models in GPU: 1 (ORPO) vs 2 (DPO) vs 4 (PPO)\u0027)"},{"type":"heading","level":2,"content":"Odds Ratio vs Probability Ratio for Long Sequences"},{"type":"text","content":"The equivalence of odds ratio and probability ratio in the small-probability regime is crucial for ORPO\u0027s practical validity. For a sequence of length L with per-token average log-prob mu, the sequence probability is exp(L*mu). For L=100 and mu=-1.0, P(y|x) = exp(-100) ≈ 3.7×10^{-44}. In this regime, odds(y|x) = P/(1-P) ≈ P since 1-P ≈ 1. Therefore the odds ratio ≈ probability ratio, and ORPO\u0027s L_OR ≈ -log sigma(log pi_theta(y_w|x)/pi_theta(y_l|x)), which is a contrastive loss without a reference model."},{"type":"code","language":"python","content":"import torch\n\ndef odds_from_logp(logp):\n    # odds = P(y|x) / (1 - P(y|x))\n    p = logp.exp()\n    return p / (1.0 - p + 1e-15)\n\n# For realistic sequence probabilities (very small), odds ≈ probability\nlogps  = torch.linspace(-8.0, -0.5, 10)\nprobs  = logps.exp()\nodds   = odds_from_logp(logps)\nprint(f\u0027  logp     prob           odds           abs_diff\u0027)\nprint(\u0027-\u0027 * 56)\nfor lp, p, o in zip(logps, probs, odds):\n    diff = abs(p.item() - o.item())\n    print(f\u0027  {lp:.2f}  {p.item():.8f}   {o.item():.8f}   {diff:.2e}\u0027)\nprint()\nprint(\u0027Conclusion: for logp \u003c -1.0 (typical sequences), odds ≈ prob to \u003c1% error\u0027)"},{"type":"heading","level":2,"content":"ORPO Single-Model Training Loop"},{"type":"text","content":"ORPO\u0027s training loop is simpler than DPO\u0027s because there is no need to run a second forward pass through a frozen reference model. Both chosen and rejected sequences are processed through the same policy model in a single forward pass (or two forward passes through the same model). The gradient accumulates from both the SFT loss (over chosen tokens) and the odds ratio loss (comparing chosen vs rejected). This halves peak GPU memory compared to DPO and eliminates the need to synchronize two model copies."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom torch.optim import AdamW\n\ndef compute_mean_logp(model, input_ids, attention_mask):\n    # Forward pass and compute mean per-token log-probability\n    outputs = model(input_ids=input_ids, attention_mask=attention_mask)\n    logits  = outputs.logits[:, :-1].contiguous()\n    labels  = input_ids[:, 1:].contiguous()\n    lp      = F.log_softmax(logits, dim=-1)\n    tok_lp  = lp.gather(2, labels.unsqueeze(-1)).squeeze(-1)\n    mask    = attention_mask[:, 1:].float()\n    return (tok_lp * mask).sum(dim=1) / (mask.sum(dim=1) + 1e-9)\n\ndef orpo_train_step(model, optimizer, chosen_ids, rejected_ids, c_mask, r_mask, lam=0.1):\n    optimizer.zero_grad()\n    logp_c = compute_mean_logp(model, chosen_ids,   c_mask)\n    logp_r = compute_mean_logp(model, rejected_ids, r_mask)\n    sft_loss    = -logp_c.mean()\n    log_odds_c  = logp_c - torch.log1p(-logp_c.exp().clamp(max=0.9999))\n    log_odds_r  = logp_r - torch.log1p(-logp_r.exp().clamp(max=0.9999))\n    or_loss     = -F.logsigmoid(log_odds_c - log_odds_r).mean()\n    total_loss  = sft_loss + lam * or_loss\n    total_loss.backward()\n    optimizer.step()\n    return total_loss.item(), sft_loss.item(), or_loss.item()\n\nprint(\u0027ORPO step: one model, two forward passes, no frozen reference, joint SFT+alignment\u0027)"},{"type":"heading","level":2,"content":"Memory Footprint Across Alignment Methods"},{"type":"code","language":"python","content":"import torch\n\ndef model_memory_gb(params_B, bits=16):\n    # Weights only; optimizer states (Adam ~2x) not included\n    return params_B * 1e9 * (bits / 8) / 1e9\n\nsizes = [7.0, 13.0, 34.0, 70.0]\nprint(f\u0027  Size(B)   PPO(4 mdls)  DPO/IPO(2)  ORPO/SimPO(1)  Saving_vs_DPO\u0027)\nprint(\u0027-\u0027 * 70)\nfor s in sizes:\n    per  = model_memory_gb(s, 16)     # bfloat16\n    ppo  = per * 4\n    dpo  = per * 2\n    orpo = per * 1\n    save = (dpo - orpo) / dpo * 100\n    print(f\u0027  {s:\u003e7.0f}   {ppo:\u003e8.1f} GB  {dpo:\u003e7.1f} GB   {orpo:\u003e8.1f} GB  {save:\u003e8.0f}%\u0027)\nprint()\nprint(\u0027Adam optimizer states add ~2x per trainable model (not shown above)\u0027)"},{"type":"heading","level":2,"content":"Reference Model Usage in Alignment Methods"},{"type":"table","headers":["Method","Reference Model","Models in GPU","SFT Separate","Memory 7B bf16","Notes"],"rows":[["PPO","Yes (frozen)","4 (policy, ref, reward, value)","Yes","~56 GB","Full RL loop"],["DPO","Yes (frozen)","2 (policy + ref)","Yes","~28 GB","Offline, pairwise"],["IPO","Yes (frozen)","2 (policy + ref)","Yes","~28 GB","Quadratic loss"],["ORPO","No","1 (policy only)","No (joint)","~14 GB","SFT + alignment"],["SimPO","No","1 (policy only)","Yes","~14 GB","Length normalized"]]},{"type":"callout","variant":"tip","title":"ORPO Memory Savings","content":"ORPO\u0027s single-model design makes it ideal for resource-constrained fine-tuning — the eliminated reference model saves ~50% GPU memory compared to DPO, making 7B model alignment feasible on a single 80GB A100. Combined with LoRA (where only adapter weights are trained), ORPO can align a 7B model using less than 20 GB of GPU memory while maintaining competitive alignment quality."},{"type":"text","content":"ORPO\u0027s limitations should be considered when choosing it over DPO or IPO: (1) the SFT and preference signals are entangled — it is harder to diagnose whether poor alignment comes from insufficient SFT quality or a miscalibrated lambda; (2) ablation studies show that removing L_SFT (using L_OR alone) dramatically hurts performance, confirming that the SFT loss is doing real work as a reference proxy, not merely a regularizer; (3) ORPO is less well-studied than DPO on very large models (70B+) where the SFT-alignment interaction may differ."},{"type":"text","content":"When to use ORPO: (1) you have a single GPU or memory-constrained setup; (2) you want to combine instruction tuning and preference alignment in one stage; (3) your preference data is reliable and the lambda hyperparameter can be tuned on a small held-out set. For high-quality preference data where maximizing alignment is critical, DPO or IPO with a well-trained reference model may outperform ORPO despite the added memory cost."},{"type":"divider"},{"type":"text","content":"ORPO represents a practical engineering advance in LLM alignment — the elimination of the reference model is not merely a memory saving but a conceptual simplification that makes alignment more accessible. By combining SFT and preference learning into a single loss, ORPO reduces the number of training stages from two to one, lowers GPU requirements by 50% compared to DPO, and produces alignment quality competitive with reference-model-based methods on standard benchmarks. Understanding its odds ratio formulation and the conditions under which it approximates a probability ratio is essential for practitioners applying it to real-world alignment tasks."}]"
---
# ORPO — Odds Ratio Preference Optimization Without a Reference Model

ORPO (Odds Ratio Preference Optimization, Hong et al. 2024) takes a fundamentally different approach to LLM alignment: it removes the reference model entirely and combines supervised fine-tuning (SFT) with preference learning into a single training stage. Previous methods — PPO, DPO, IPO — all require a frozen reference policy pi_ref to anchor the optimization via a KL divergence constraint. This reference model doubles (or quadruples, in PPO's case) the GPU memory requirement. ORPO's insight is that the SFT loss itself provides the reference signal: by jointly maximizing chosen response likelihood and the odds ratio between chosen and rejected responses, the model learns both task competence and preference alignment simultaneously.

## Eliminating the Reference Model

DPO and IPO use the reference model pi_ref as a baseline: the policy is rewarded for increasing its probability ratio relative to what pi_ref assigns. This KL anchoring prevents the policy from diverging arbitrarily. ORPO replaces this external baseline with the SFT loss: by directly maximizing log pi_theta(y_w|x), the model is prevented from collapsing to degenerate behavior. The SFT component keeps the policy near a competent language model; the odds ratio component pushes it to prefer chosen over rejected sequences. Together, they provide the same alignment stability as a reference model without requiring one to be stored.

## ORPO Loss: Combined SFT and Odds Ratio

The ORPO total loss is: L_ORPO = L_SFT + lambda * L_OR where L_SFT = -log pi_theta(y_w|x) (standard causal language model loss on chosen sequences) and L_OR = -log sigma(log [odds_theta(y_w|x) / odds_theta(y_l|x)]) where odds(y|x) = P(y|x)/(1-P(y|x)). The log odds ratio log[odds_w/odds_l] = log[P(y_w|x)/(1-P(y_w|x))] - log[P(y_l|x)/(1-P(y_l|x))]. In log space: log_odds(y|x) = log P(y|x) - log(1 - P(y|x)) = logp(y|x) - log1p(-exp(logp(y|x))). The hyperparameter lambda balances SFT and alignment; typical values are 0.1 to 1.0.

The odds ratio is chosen over the probability ratio for a theoretical reason: for long sequences where P(y|x) is very small (which is typical — a 100-token sequence with per-token average log-prob -1.2 has total probability exp(-120) ~ 10^{-52}), the odds ratio and probability ratio are numerically equivalent. This means ORPO's L_OR is approximately equivalent to a log-probability ratio loss when applied to realistic language model outputs, while being more theoretically grounded and numerically stable.

## ORPO Loss Implementation

```python
import torch
import torch.nn.functional as F

def orpo_loss(policy_chosen_logps, policy_rejected_logps, lam=0.1):
    # ORPO (Hong et al., 2024): L_SFT + lambda * L_OR, no reference model needed
    sft_loss = -policy_chosen_logps.mean()
    # log_odds(y|x) = logp - log(1 - exp(logp)); clamp for numerical stability
    log_odds_c = policy_chosen_logps   - torch.log1p(-policy_chosen_logps.exp().clamp(max=0.9999))
    log_odds_r = policy_rejected_logps - torch.log1p(-policy_rejected_logps.exp().clamp(max=0.9999))
    log_odds_ratio = log_odds_c - log_odds_r
    or_loss = -F.logsigmoid(log_odds_ratio).mean()
    total = sft_loss + lam * or_loss
    return total, sft_loss.detach(), or_loss.detach()

bsz = 8
chosen_logps   = torch.full((bsz,), -1.2) + torch.randn(bsz) * 0.1
rejected_logps = torch.full((bsz,), -1.8) + torch.randn(bsz) * 0.1
loss, sft, oratio = orpo_loss(chosen_logps, rejected_logps, lam=0.1)
print(f'ORPO total: {loss:.4f}   SFT: {sft:.4f}   OR: {oratio:.4f}')
print(f'Models in GPU: 1 (ORPO) vs 2 (DPO) vs 4 (PPO)')
```

## Odds Ratio vs Probability Ratio for Long Sequences

The equivalence of odds ratio and probability ratio in the small-probability regime is crucial for ORPO's practical validity. For a sequence of length L with per-token average log-prob mu, the sequence probability is exp(L*mu). For L=100 and mu=-1.0, P(y|x) = exp(-100) ≈ 3.7×10^{-44}. In this regime, odds(y|x) = P/(1-P) ≈ P since 1-P ≈ 1. Therefore the odds ratio ≈ probability ratio, and ORPO's L_OR ≈ -log sigma(log pi_theta(y_w|x)/pi_theta(y_l|x)), which is a contrastive loss without a reference model.

```python
import torch

def odds_from_logp(logp):
    # odds = P(y|x) / (1 - P(y|x))
    p = logp.exp()
    return p / (1.0 - p + 1e-15)

# For realistic sequence probabilities (very small), odds ≈ probability
logps  = torch.linspace(-8.0, -0.5, 10)
probs  = logps.exp()
odds   = odds_from_logp(logps)
print(f'  logp     prob           odds           abs_diff')
print('-' * 56)
for lp, p, o in zip(logps, probs, odds):
    diff = abs(p.item() - o.item())
    print(f'  {lp:.2f}  {p.item():.8f}   {o.item():.8f}   {diff:.2e}')
print()
print('Conclusion: for logp < -1.0 (typical sequences), odds ≈ prob to <1% error')
```

## ORPO Single-Model Training Loop

ORPO's training loop is simpler than DPO's because there is no need to run a second forward pass through a frozen reference model. Both chosen and rejected sequences are processed through the same policy model in a single forward pass (or two forward passes through the same model). The gradient accumulates from both the SFT loss (over chosen tokens) and the odds ratio loss (comparing chosen vs rejected). This halves peak GPU memory compared to DPO and eliminates the need to synchronize two model copies.

```python
import torch
import torch.nn.functional as F
from torch.optim import AdamW

def compute_mean_logp(model, input_ids, attention_mask):
    # Forward pass and compute mean per-token log-probability
    outputs = model(input_ids=input_ids, attention_mask=attention_mask)
    logits  = outputs.logits[:, :-1].contiguous()
    labels  = input_ids[:, 1:].contiguous()
    lp      = F.log_softmax(logits, dim=-1)
    tok_lp  = lp.gather(2, labels.unsqueeze(-1)).squeeze(-1)
    mask    = attention_mask[:, 1:].float()
    return (tok_lp * mask).sum(dim=1) / (mask.sum(dim=1) + 1e-9)

def orpo_train_step(model, optimizer, chosen_ids, rejected_ids, c_mask, r_mask, lam=0.1):
    optimizer.zero_grad()
    logp_c = compute_mean_logp(model, chosen_ids,   c_mask)
    logp_r = compute_mean_logp(model, rejected_ids, r_mask)
    sft_loss    = -logp_c.mean()
    log_odds_c  = logp_c - torch.log1p(-logp_c.exp().clamp(max=0.9999))
    log_odds_r  = logp_r - torch.log1p(-logp_r.exp().clamp(max=0.9999))
    or_loss     = -F.logsigmoid(log_odds_c - log_odds_r).mean()
    total_loss  = sft_loss + lam * or_loss
    total_loss.backward()
    optimizer.step()
    return total_loss.item(), sft_loss.item(), or_loss.item()

print('ORPO step: one model, two forward passes, no frozen reference, joint SFT+alignment')
```

## Memory Footprint Across Alignment Methods

```python
import torch

def model_memory_gb(params_B, bits=16):
    # Weights only; optimizer states (Adam ~2x) not included
    return params_B * 1e9 * (bits / 8) / 1e9

sizes = [7.0, 13.0, 34.0, 70.0]
print(f'  Size(B)   PPO(4 mdls)  DPO/IPO(2)  ORPO/SimPO(1)  Saving_vs_DPO')
print('-' * 70)
for s in sizes:
    per  = model_memory_gb(s, 16)     # bfloat16
    ppo  = per * 4
    dpo  = per * 2
    orpo = per * 1
    save = (dpo - orpo) / dpo * 100
    print(f'  {s:>7.0f}   {ppo:>8.1f} GB  {dpo:>7.1f} GB   {orpo:>8.1f} GB  {save:>8.0f}%')
print()
print('Adam optimizer states add ~2x per trainable model (not shown above)')
```

## Reference Model Usage in Alignment Methods

| Method | Reference Model | Models in GPU | SFT Separate | Memory 7B bf16 | Notes |
| --- | --- | --- | --- | --- | --- |
| PPO | Yes (frozen) | 4 (policy, ref, reward, value) | Yes | ~56 GB | Full RL loop |
| DPO | Yes (frozen) | 2 (policy + ref) | Yes | ~28 GB | Offline, pairwise |
| IPO | Yes (frozen) | 2 (policy + ref) | Yes | ~28 GB | Quadratic loss |
| ORPO | No | 1 (policy only) | No (joint) | ~14 GB | SFT + alignment |
| SimPO | No | 1 (policy only) | Yes | ~14 GB | Length normalized |

> **ORPO Memory Savings**: ORPO's single-model design makes it ideal for resource-constrained fine-tuning — the eliminated reference model saves ~50% GPU memory compared to DPO, making 7B model alignment feasible on a single 80GB A100. Combined with LoRA (where only adapter weights are trained), ORPO can align a 7B model using less than 20 GB of GPU memory while maintaining competitive alignment quality.

ORPO's limitations should be considered when choosing it over DPO or IPO: (1) the SFT and preference signals are entangled — it is harder to diagnose whether poor alignment comes from insufficient SFT quality or a miscalibrated lambda; (2) ablation studies show that removing L_SFT (using L_OR alone) dramatically hurts performance, confirming that the SFT loss is doing real work as a reference proxy, not merely a regularizer; (3) ORPO is less well-studied than DPO on very large models (70B+) where the SFT-alignment interaction may differ.

When to use ORPO: (1) you have a single GPU or memory-constrained setup; (2) you want to combine instruction tuning and preference alignment in one stage; (3) your preference data is reliable and the lambda hyperparameter can be tuned on a small held-out set. For high-quality preference data where maximizing alignment is critical, DPO or IPO with a well-trained reference model may outperform ORPO despite the added memory cost.

---

ORPO represents a practical engineering advance in LLM alignment — the elimination of the reference model is not merely a memory saving but a conceptual simplification that makes alignment more accessible. By combining SFT and preference learning into a single loss, ORPO reduces the number of training stages from two to one, lowers GPU requirements by 50% compared to DPO, and produces alignment quality competitive with reference-model-based methods on standard benchmarks. Understanding its odds ratio formulation and the conditions under which it approximates a probability ratio is essential for practitioners applying it to real-world alignment tasks.

