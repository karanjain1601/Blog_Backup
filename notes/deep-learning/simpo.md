---
title: "SimPO — Simple Preference Optimization with Length-Normalized Rewards"
slug: "simpo"
description: "SimPO (Meng et al., 2024) eliminates DPO's reference model and length bias by using average per-token log-probability as the implicit reward, combined with a target margin gamma that prevents preference collapse, consistently outperforming DPO on AlpacaEval 2 LC-WR."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"SimPO (Simple Preference Optimization, Meng et al. 2024) addresses two independent problems with DPO that have different roots but interact harmfully: (1) DPO requires a reference model, doubling GPU memory; (2) DPO\u0027s implicit reward — the total log-probability under the policy — is biased toward longer responses regardless of quality. SimPO fixes both problems in a single design: replace the reference-model-relative reward with a length-normalized average log-probability, and add a target margin gamma that prevents the optimization from collapsing when chosen and rejected rewards are similar. The result is a simpler, cheaper, and empirically stronger alignment algorithm."},{"type":"heading","level":2,"content":"DPO\u0027s Length Bias: Why Verbose Responses Win"},{"type":"text","content":"DPO\u0027s implicit reward for a response y given prompt x is r_DPO(x,y) = beta * log pi_theta(y|x) - beta * log pi_ref(y|x). The term log pi_theta(y|x) = sum_{t=1}^{|y|} log pi_theta(y_t | x, y_{\u003ct}) is a SUM over tokens — it grows linearly with sequence length even if per-token quality is identical. Consider two responses with the same per-token log-probability mu: a 50-token response has total log-prob 50*mu, while a 200-token response has 200*mu. DPO would rank the 200-token response as 4× better. This creates an incentive for models to produce verbose responses: the DPO policy learns that adding filler text (\u0027Great question! I am happy to explain...\u0027) increases its own reward even if it reduces per-token quality."},{"type":"heading","level":2,"content":"SimPO Implicit Reward: Length-Normalized Log-Probs"},{"type":"text","content":"SimPO replaces DPO\u0027s total log-prob reward with an average per-token log-probability: r_SimPO(x,y) = (beta / |y|) * sum_{t=1}^{|y|} log pi_theta(y_t | x, y_{\u003ct}). This is the mean conditional log-likelihood of the response tokens, scaled by beta. Length normalization makes the reward length-agnostic: a 50-token response and a 200-token response with the same per-token quality receive identical rewards. Crucially, SimPO has no reference model — the reward is purely from the current policy — which eliminates the need to store pi_ref in GPU memory."},{"type":"heading","level":2,"content":"SimPO Loss with Target Margin gamma"},{"type":"text","content":"Without a reference model, the preference margin can collapse to zero if the policy learns to assign similar rewards to chosen and rejected responses. SimPO adds a target margin gamma: L_SimPO = -E[log sigma(r(x,y_w) - r(x,y_l) - gamma)] = -E[log sigma(beta*(avg_logp(y_w) - avg_logp(y_l)) - gamma)]. The margin gamma enforces that chosen responses must be preferred by at least gamma in the reward space — the optimization is non-trivially satisfied when the margin exactly equals gamma. Default values from the paper: beta=2.5, gamma=0.5. SimPO consistently outperforms DPO on AlpacaEval 2 LC-WR (length-controlled win rate) with these hyperparameters on Mistral and Llama base models."},{"type":"heading","level":2,"content":"SimPO Loss Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef simpo_loss(\n    policy_chosen_logps,      # sum of log-probs over response tokens\n    policy_rejected_logps,\n    chosen_lengths,            # response token counts for normalization\n    rejected_lengths,\n    beta=2.5,\n    gamma=0.5,\n):\n    # Length-normalized average log-prob = SimPO implicit reward r(x,y)\n    r_chosen   = policy_chosen_logps   / chosen_lengths.float()\n    r_rejected = policy_rejected_logps / rejected_lengths.float()\n    # Enforce beta*(r_w - r_l) \u003e gamma (target margin prevents collapse)\n    reward_diff = beta * (r_chosen - r_rejected) - gamma\n    loss = -F.logsigmoid(reward_diff).mean()\n    return loss, r_chosen.detach(), r_rejected.detach()\n\nbsz = 8\nchosen_lens   = torch.randint(80, 150, (bsz,))\nrejected_lens = torch.randint(50, 250, (bsz,))  # rejected can be longer or shorter\nchosen_logps   = -chosen_lens.float() * 0.9      # sum logp proportional to length\nrejected_logps = -rejected_lens.float() * 1.1    # rejected has worse per-token logp\nloss, rw, rr = simpo_loss(chosen_logps, rejected_logps, chosen_lens, rejected_lens)\nprint(f\u0027SimPO loss: {loss:.4f}  avg reward chosen: {rw.mean():.3f}  rejected: {rr.mean():.3f}\u0027)"},{"type":"heading","level":2,"content":"Length Normalization: DPO vs SimPO Reward Assignment"},{"type":"text","content":"The key empirical test of length bias is: given two responses with identical per-token quality but different lengths, which does the algorithm prefer? DPO, using total log-prob, prefers the longer one in proportion to its length advantage. SimPO, using average log-prob, assigns identical rewards to both. This is not merely a theoretical concern — on AlpacaEval 2, DPO-trained models produce responses that are on average 30-50% longer than the reference, while SimPO-trained models match reference length, explaining SimPO\u0027s superior LC-WR (length-controlled win rate) despite often having lower raw win rate."},{"type":"code","language":"python","content":"import torch\n\ndef dpo_reward(logps_sum, ref_logps_sum, beta=0.1):\n    # DPO: unnormalized total log-prob difference\n    return beta * (logps_sum - ref_logps_sum)\n\ndef simpo_reward(logps_sum, length, beta=2.5):\n    # SimPO: average per-token log-prob (length-normalized)\n    return beta * logps_sum / length.float()\n\n# Two responses: same per-token quality, 4x length difference\nper_tok = -1.2\nshort_len, long_len = torch.tensor(60), torch.tensor(240)\nshort_logps = per_tok * short_len.float()\nlong_logps  = per_tok * long_len.float()\nref_short   = per_tok * 0.9 * short_len.float()\nref_long    = per_tok * 0.9 * long_len.float()\n\ndpo_s  = dpo_reward(short_logps, ref_short)\ndpo_l  = dpo_reward(long_logps,  ref_long)\nsimpo_s = simpo_reward(short_logps, short_len)\nsimpo_l = simpo_reward(long_logps,  long_len)\nprint(f\u0027Equal per-token quality. DPO: short={dpo_s:.1f}, long={dpo_l:.1f}  -\u003e long wins by {dpo_l/dpo_s:.1f}x\u0027)\nprint(f\u0027SimPO:                        short={simpo_s:.3f}, long={simpo_l:.3f} -\u003e length-neutral\u0027)"},{"type":"heading","level":2,"content":"SimPO Training Loop Without Reference Model"},{"type":"text","content":"SimPO\u0027s training loop differs from DPO in two key ways: no reference model forward pass, and explicit length tracking for the normalization. The response length is the number of non-padding tokens in the response portion of the sequence (not the full prompt+response length). In practice, this requires a response mask that marks which tokens are part of the assistant\u0027s response, separate from the prompt tokens. This is important: normalizing by the total sequence length (including prompt) would penalize long prompts unfairly."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom torch.optim import AdamW\n\ndef compute_response_logps(model, input_ids, attention_mask, response_start):\n    # Compute sum and count of log-probs over response tokens only (not prompt)\n    outputs  = model(input_ids=input_ids, attention_mask=attention_mask)\n    logits   = outputs.logits[:, :-1].contiguous()\n    labels   = input_ids[:, 1:].contiguous()\n    lp       = F.log_softmax(logits, dim=-1)\n    tok_lp   = lp.gather(2, labels.unsqueeze(-1)).squeeze(-1)\n    resp_mask = torch.zeros_like(tok_lp)\n    resp_mask[:, response_start:] = attention_mask[:, response_start + 1:].float()\n    sum_lp  = (tok_lp * resp_mask).sum(dim=1)\n    lengths = resp_mask.sum(dim=1)\n    return sum_lp, lengths\n\ndef simpo_train_step(model, optimizer, chosen_ids, rejected_ids,\n                     c_mask, r_mask, resp_start, beta=2.5, gamma=0.5):\n    optimizer.zero_grad()\n    logps_c, lens_c = compute_response_logps(model, chosen_ids,   c_mask, resp_start)\n    logps_r, lens_r = compute_response_logps(model, rejected_ids, r_mask, resp_start)\n    r_c   = beta * logps_c / lens_c\n    r_r   = beta * logps_r / lens_r\n    loss  = -F.logsigmoid(r_c - r_r - gamma).mean()\n    loss.backward()\n    optimizer.step()\n    return loss.item()\n\nprint(\u0027SimPO: 1 model in GPU, response-only length normalization, margin gamma=0.5\u0027)"},{"type":"heading","level":2,"content":"Margin Sensitivity Analysis"},{"type":"text","content":"The gamma margin in SimPO serves as a minimum acceptable preference gap. When gamma=0, the loss reduces to a simple contrastive loss without an explicit target — the optimization is satisfied whenever chosen reward exceeds rejected reward by any amount, which can lead to small, noisy gradients. As gamma increases, the effective win-rate threshold rises (the model must achieve a stronger preference to satisfy the loss), which provides larger gradients when the policy is near the decision boundary but harder optimization when the data is noisy."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ntorch.manual_seed(0)\nbeta  = 2.5\nr_w   = torch.randn(1000) * 0.4 + 0.8   # chosen avg log-prob\nr_l   = torch.randn(1000) * 0.4 + 0.0   # rejected avg log-prob\nrew_diff = beta * (r_w - r_l)\n\ngammas = [0.0, 0.2, 0.5, 1.0, 2.0, 3.0]\nprint(f\u0027  gamma   win_rate   loss       grad_magnitude\u0027)\nprint(\u0027-\u0027 * 50)\nfor g in gammas:\n    probs = torch.sigmoid(rew_diff - g)\n    loss  = -F.logsigmoid(rew_diff - g).mean()\n    grad  = torch.sigmoid(-(rew_diff - g)).mean()  # gradient weight\n    print(f\u0027  {g:.1f}     {probs.mean():.3f}    {loss.item():.4f}    {grad.item():.4f}\u0027)\nprint()\nprint(\u0027Larger gamma: fewer satisfied pairs, larger gradients on unsatisfied ones\u0027)"},{"type":"table","headers":["Method","Reference Model","Length Norm","Margin Term","Memory 7B","AlpacaEval 2 LC-WR"],"rows":[["DPO","Yes (frozen)","No (total logp)","No","~28 GB","Baseline"],["SimPO","No","Yes (avg logp)","Yes (gamma)","~14 GB","+3 to +5 pts vs DPO"],["ORPO","No","Partial (mean tok)","No","~14 GB","Competitive with DPO"]]},{"type":"callout","variant":"info","title":"SimPO\u0027s Length-Normalized Reward","content":"SimPO\u0027s length-normalized reward is theoretically equivalent to maximizing per-token conditional log-likelihood of chosen over rejected — this directly prevents the \u0027add filler text\u0027 failure mode where DPO policies learn to be verbose to maximize total log-prob. The length-controlled win rate (LC-WR) metric on AlpacaEval 2 measures quality independent of response length, making it the right metric for evaluating SimPO\u0027s advantage over DPO."},{"type":"text","content":"SimPO hyperparameter guidance: beta=2.5 and gamma=0.5 are the defaults from the paper, validated across Mistral-7B, Llama-3-8B, and Llama-3-70B base models. For smaller models (\u003c 3B), reduce gamma to 0.2-0.3 since the reward distribution has higher variance. For models trained with more SFT data (reducing the gap between chosen and rejected base probabilities), increase beta to 3.0-4.0 to amplify the preference signal. Always evaluate using LC-WR rather than raw win rate when comparing against DPO baselines."},{"type":"divider"},{"type":"text","content":"SimPO demonstrates that the two most impactful changes to DPO — removing the reference model and normalizing by length — can be made independently and are complementary. Its consistent empirical superiority on AlpacaEval 2 LC-WR across multiple model families, combined with the theoretical clarity of the per-token log-probability reward, makes SimPO a strong default choice for offline preference optimization when memory efficiency and alignment quality are both priorities. The DPO-to-SimPO comparison is a case study in how a small algorithmic insight (divide by length) can have large practical impact on alignment outcomes."}]"
---
# SimPO — Simple Preference Optimization with Length-Normalized Rewards

SimPO (Simple Preference Optimization, Meng et al. 2024) addresses two independent problems with DPO that have different roots but interact harmfully: (1) DPO requires a reference model, doubling GPU memory; (2) DPO's implicit reward — the total log-probability under the policy — is biased toward longer responses regardless of quality. SimPO fixes both problems in a single design: replace the reference-model-relative reward with a length-normalized average log-probability, and add a target margin gamma that prevents the optimization from collapsing when chosen and rejected rewards are similar. The result is a simpler, cheaper, and empirically stronger alignment algorithm.

## DPO's Length Bias: Why Verbose Responses Win

DPO's implicit reward for a response y given prompt x is r_DPO(x,y) = beta * log pi_theta(y|x) - beta * log pi_ref(y|x). The term log pi_theta(y|x) = sum_{t=1}^{|y|} log pi_theta(y_t | x, y_{<t}) is a SUM over tokens — it grows linearly with sequence length even if per-token quality is identical. Consider two responses with the same per-token log-probability mu: a 50-token response has total log-prob 50*mu, while a 200-token response has 200*mu. DPO would rank the 200-token response as 4× better. This creates an incentive for models to produce verbose responses: the DPO policy learns that adding filler text ('Great question! I am happy to explain...') increases its own reward even if it reduces per-token quality.

## SimPO Implicit Reward: Length-Normalized Log-Probs

SimPO replaces DPO's total log-prob reward with an average per-token log-probability: r_SimPO(x,y) = (beta / |y|) * sum_{t=1}^{|y|} log pi_theta(y_t | x, y_{<t}). This is the mean conditional log-likelihood of the response tokens, scaled by beta. Length normalization makes the reward length-agnostic: a 50-token response and a 200-token response with the same per-token quality receive identical rewards. Crucially, SimPO has no reference model — the reward is purely from the current policy — which eliminates the need to store pi_ref in GPU memory.

## SimPO Loss with Target Margin gamma

Without a reference model, the preference margin can collapse to zero if the policy learns to assign similar rewards to chosen and rejected responses. SimPO adds a target margin gamma: L_SimPO = -E[log sigma(r(x,y_w) - r(x,y_l) - gamma)] = -E[log sigma(beta*(avg_logp(y_w) - avg_logp(y_l)) - gamma)]. The margin gamma enforces that chosen responses must be preferred by at least gamma in the reward space — the optimization is non-trivially satisfied when the margin exactly equals gamma. Default values from the paper: beta=2.5, gamma=0.5. SimPO consistently outperforms DPO on AlpacaEval 2 LC-WR (length-controlled win rate) with these hyperparameters on Mistral and Llama base models.

## SimPO Loss Implementation

```python
import torch
import torch.nn.functional as F

def simpo_loss(
    policy_chosen_logps,      # sum of log-probs over response tokens
    policy_rejected_logps,
    chosen_lengths,            # response token counts for normalization
    rejected_lengths,
    beta=2.5,
    gamma=0.5,
):
    # Length-normalized average log-prob = SimPO implicit reward r(x,y)
    r_chosen   = policy_chosen_logps   / chosen_lengths.float()
    r_rejected = policy_rejected_logps / rejected_lengths.float()
    # Enforce beta*(r_w - r_l) > gamma (target margin prevents collapse)
    reward_diff = beta * (r_chosen - r_rejected) - gamma
    loss = -F.logsigmoid(reward_diff).mean()
    return loss, r_chosen.detach(), r_rejected.detach()

bsz = 8
chosen_lens   = torch.randint(80, 150, (bsz,))
rejected_lens = torch.randint(50, 250, (bsz,))  # rejected can be longer or shorter
chosen_logps   = -chosen_lens.float() * 0.9      # sum logp proportional to length
rejected_logps = -rejected_lens.float() * 1.1    # rejected has worse per-token logp
loss, rw, rr = simpo_loss(chosen_logps, rejected_logps, chosen_lens, rejected_lens)
print(f'SimPO loss: {loss:.4f}  avg reward chosen: {rw.mean():.3f}  rejected: {rr.mean():.3f}')
```

## Length Normalization: DPO vs SimPO Reward Assignment

The key empirical test of length bias is: given two responses with identical per-token quality but different lengths, which does the algorithm prefer? DPO, using total log-prob, prefers the longer one in proportion to its length advantage. SimPO, using average log-prob, assigns identical rewards to both. This is not merely a theoretical concern — on AlpacaEval 2, DPO-trained models produce responses that are on average 30-50% longer than the reference, while SimPO-trained models match reference length, explaining SimPO's superior LC-WR (length-controlled win rate) despite often having lower raw win rate.

```python
import torch

def dpo_reward(logps_sum, ref_logps_sum, beta=0.1):
    # DPO: unnormalized total log-prob difference
    return beta * (logps_sum - ref_logps_sum)

def simpo_reward(logps_sum, length, beta=2.5):
    # SimPO: average per-token log-prob (length-normalized)
    return beta * logps_sum / length.float()

# Two responses: same per-token quality, 4x length difference
per_tok = -1.2
short_len, long_len = torch.tensor(60), torch.tensor(240)
short_logps = per_tok * short_len.float()
long_logps  = per_tok * long_len.float()
ref_short   = per_tok * 0.9 * short_len.float()
ref_long    = per_tok * 0.9 * long_len.float()

dpo_s  = dpo_reward(short_logps, ref_short)
dpo_l  = dpo_reward(long_logps,  ref_long)
simpo_s = simpo_reward(short_logps, short_len)
simpo_l = simpo_reward(long_logps,  long_len)
print(f'Equal per-token quality. DPO: short={dpo_s:.1f}, long={dpo_l:.1f}  -> long wins by {dpo_l/dpo_s:.1f}x')
print(f'SimPO:                        short={simpo_s:.3f}, long={simpo_l:.3f} -> length-neutral')
```

## SimPO Training Loop Without Reference Model

SimPO's training loop differs from DPO in two key ways: no reference model forward pass, and explicit length tracking for the normalization. The response length is the number of non-padding tokens in the response portion of the sequence (not the full prompt+response length). In practice, this requires a response mask that marks which tokens are part of the assistant's response, separate from the prompt tokens. This is important: normalizing by the total sequence length (including prompt) would penalize long prompts unfairly.

```python
import torch
import torch.nn.functional as F
from torch.optim import AdamW

def compute_response_logps(model, input_ids, attention_mask, response_start):
    # Compute sum and count of log-probs over response tokens only (not prompt)
    outputs  = model(input_ids=input_ids, attention_mask=attention_mask)
    logits   = outputs.logits[:, :-1].contiguous()
    labels   = input_ids[:, 1:].contiguous()
    lp       = F.log_softmax(logits, dim=-1)
    tok_lp   = lp.gather(2, labels.unsqueeze(-1)).squeeze(-1)
    resp_mask = torch.zeros_like(tok_lp)
    resp_mask[:, response_start:] = attention_mask[:, response_start + 1:].float()
    sum_lp  = (tok_lp * resp_mask).sum(dim=1)
    lengths = resp_mask.sum(dim=1)
    return sum_lp, lengths

def simpo_train_step(model, optimizer, chosen_ids, rejected_ids,
                     c_mask, r_mask, resp_start, beta=2.5, gamma=0.5):
    optimizer.zero_grad()
    logps_c, lens_c = compute_response_logps(model, chosen_ids,   c_mask, resp_start)
    logps_r, lens_r = compute_response_logps(model, rejected_ids, r_mask, resp_start)
    r_c   = beta * logps_c / lens_c
    r_r   = beta * logps_r / lens_r
    loss  = -F.logsigmoid(r_c - r_r - gamma).mean()
    loss.backward()
    optimizer.step()
    return loss.item()

print('SimPO: 1 model in GPU, response-only length normalization, margin gamma=0.5')
```

## Margin Sensitivity Analysis

The gamma margin in SimPO serves as a minimum acceptable preference gap. When gamma=0, the loss reduces to a simple contrastive loss without an explicit target — the optimization is satisfied whenever chosen reward exceeds rejected reward by any amount, which can lead to small, noisy gradients. As gamma increases, the effective win-rate threshold rises (the model must achieve a stronger preference to satisfy the loss), which provides larger gradients when the policy is near the decision boundary but harder optimization when the data is noisy.

```python
import torch
import torch.nn.functional as F

torch.manual_seed(0)
beta  = 2.5
r_w   = torch.randn(1000) * 0.4 + 0.8   # chosen avg log-prob
r_l   = torch.randn(1000) * 0.4 + 0.0   # rejected avg log-prob
rew_diff = beta * (r_w - r_l)

gammas = [0.0, 0.2, 0.5, 1.0, 2.0, 3.0]
print(f'  gamma   win_rate   loss       grad_magnitude')
print('-' * 50)
for g in gammas:
    probs = torch.sigmoid(rew_diff - g)
    loss  = -F.logsigmoid(rew_diff - g).mean()
    grad  = torch.sigmoid(-(rew_diff - g)).mean()  # gradient weight
    print(f'  {g:.1f}     {probs.mean():.3f}    {loss.item():.4f}    {grad.item():.4f}')
print()
print('Larger gamma: fewer satisfied pairs, larger gradients on unsatisfied ones')
```

| Method | Reference Model | Length Norm | Margin Term | Memory 7B | AlpacaEval 2 LC-WR |
| --- | --- | --- | --- | --- | --- |
| DPO | Yes (frozen) | No (total logp) | No | ~28 GB | Baseline |
| SimPO | No | Yes (avg logp) | Yes (gamma) | ~14 GB | +3 to +5 pts vs DPO |
| ORPO | No | Partial (mean tok) | No | ~14 GB | Competitive with DPO |

> **SimPO's Length-Normalized Reward**: SimPO's length-normalized reward is theoretically equivalent to maximizing per-token conditional log-likelihood of chosen over rejected — this directly prevents the 'add filler text' failure mode where DPO policies learn to be verbose to maximize total log-prob. The length-controlled win rate (LC-WR) metric on AlpacaEval 2 measures quality independent of response length, making it the right metric for evaluating SimPO's advantage over DPO.

SimPO hyperparameter guidance: beta=2.5 and gamma=0.5 are the defaults from the paper, validated across Mistral-7B, Llama-3-8B, and Llama-3-70B base models. For smaller models (< 3B), reduce gamma to 0.2-0.3 since the reward distribution has higher variance. For models trained with more SFT data (reducing the gap between chosen and rejected base probabilities), increase beta to 3.0-4.0 to amplify the preference signal. Always evaluate using LC-WR rather than raw win rate when comparing against DPO baselines.

---

SimPO demonstrates that the two most impactful changes to DPO — removing the reference model and normalizing by length — can be made independently and are complementary. Its consistent empirical superiority on AlpacaEval 2 LC-WR across multiple model families, combined with the theoretical clarity of the per-token log-probability reward, makes SimPO a strong default choice for offline preference optimization when memory efficiency and alignment quality are both priorities. The DPO-to-SimPO comparison is a case study in how a small algorithmic insight (divide by length) can have large practical impact on alignment outcomes.

