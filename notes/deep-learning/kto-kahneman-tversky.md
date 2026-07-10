---
title: "KTO — Kahneman-Tversky Optimization for Unpaired Preference Learning"
slug: "kto-kahneman-tversky"
description: "KTO (Ethayarajh et al., 2024) aligns LLMs from binary desirability labels per response — no pairwise comparisons required — drawing on prospect theory's insight that humans weight losses more than equivalent gains, making it ideal for leveraging existing production thumbs-up/down logs."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"KTO (Kahneman-Tversky Optimization, Ethayarajh et al. 2024) is an alignment algorithm that trains language models from binary desirability labels — each response is independently marked as good (desirable) or bad (undesirable) — without requiring pairwise comparisons. Unlike DPO and SimPO, which need matched pairs (y_winner, y_loser) for the same prompt x, KTO accepts unpaired feedback signals: a thumbs-up on one response and a thumbs-down on a completely different response to the same or a different prompt. This makes KTO uniquely suited to leveraging existing production logs where users provide binary feedback on individual responses at the moment of interaction."},{"type":"heading","level":2,"content":"Kahneman-Tversky Prospect Theory Foundation"},{"type":"text","content":"KTO\u0027s loss function is grounded in Kahneman and Tversky\u0027s prospect theory (1979), which models how humans subjectively evaluate outcomes. The key insight is loss aversion: humans feel the pain of a loss more strongly than the pleasure of an equivalent gain. Prospect theory formalises this with an asymmetric value function: v(x) = x^α for gains and v(x) = -λ|x|^β for losses, where λ \u003e 1 captures loss aversion. KTO applies this asymmetry to LLM alignment by using different loss terms for desirable and undesirable responses — the undesirable signal is empirically stronger per example, reflecting the asymmetric human sensitivity to negative versus positive feedback."},{"type":"heading","level":2,"content":"KTO Loss Function"},{"type":"text","content":"For a response y with prompt x, the log-ratio term is r(y|x) = log π_θ(y|x) / π_ref(y|x). The KL term KL(π_θ ‖ π_ref) is estimated from a batch of random responses and acts as a running baseline. For desirable responses: L_good = -E[σ(β·[r(y|x) − KL])]. For undesirable responses: L_bad = -E[σ(−β·[r(y|x) − KL])]. The β hyperparameter controls deviation from the reference policy. The KL term ensures the policy does not drift from the reference in a direction unrelated to response quality, preventing the model from gaming the loss by collapsing to a degenerate distribution."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef kto_loss(log_ratios_desirable, log_ratios_undesirable, kl_term, beta=0.1):\n    \"\"\"\n    KTO loss: Kahneman-Tversky Optimization.\n    Args:\n        log_ratios_desirable:   log(pi_theta/pi_ref) for good responses  (B_d,)\n        log_ratios_undesirable: log(pi_theta/pi_ref) for bad responses   (B_u,)\n        kl_term:  scalar KL(pi_theta || pi_ref) estimated from random batch\n        beta:     temperature controlling deviation from reference policy\n    \"\"\"\n    # Desirable loss: maximize log-ratio relative to KL baseline\n    z_desirable = log_ratios_desirable - kl_term\n    loss_desirable = 1.0 - F.sigmoid(beta * z_desirable)\n\n    # Undesirable loss: push log-ratio below zero relative to KL baseline\n    z_undesirable = log_ratios_undesirable - kl_term\n    loss_undesirable = 1.0 - F.sigmoid(-beta * z_undesirable)\n\n    loss = loss_desirable.mean() + loss_undesirable.mean()\n    return loss, loss_desirable.mean().item(), loss_undesirable.mean().item()\n\ntorch.manual_seed(42)\nlog_ratios_good = torch.randn(16) * 0.5 + 0.3   # good responses above reference\nlog_ratios_bad  = torch.randn(16) * 0.5 - 0.3   # bad responses below reference\nkl_baseline     = torch.tensor(0.05)              # small KL at start of training\nloss, l_good, l_bad = kto_loss(log_ratios_good, log_ratios_bad, kl_baseline)\nprint(f\u0027Total KTO loss:   {loss.item():.4f}\u0027)\nprint(f\u0027Desirable loss:   {l_good:.4f}\u0027)\nprint(f\u0027Undesirable loss: {l_bad:.4f}\u0027)"},{"type":"heading","level":2,"content":"Unpaired Preference Dataset Construction"},{"type":"text","content":"KTO datasets consist of (prompt, response, label) triples where label is a boolean: True for desirable, False for undesirable. There is no requirement that desirable and undesirable responses share the same prompt — each sample is independent. In practice, researchers recommend a roughly 4:1 ratio of desirable to undesirable examples, because the undesirable gradient signal is empirically stronger per example. Collecting binary labels from production logs (thumbs up/down, star ratings collapsed to binary) is much cheaper than soliciting pairwise comparisons from annotators."},{"type":"code","language":"python","content":"import torch\nfrom torch.utils.data import Dataset\nfrom dataclasses import dataclass\nfrom typing import List\n\n@dataclass\nclass UnpairedSample:\n    prompt: str\n    response: str\n    desirable: bool  # True = good (thumbs up), False = bad (thumbs down)\n\nclass KTODataset(Dataset):\n    \"\"\"Dataset for KTO: independent binary labels per response, no pairing needed.\"\"\"\n    def __init__(self, samples: List[UnpairedSample], tokenizer, max_length: int = 512):\n        self.samples = samples\n        self.tokenizer = tokenizer\n        self.max_length = max_length\n\n    def __len__(self):\n        return len(self.samples)\n\n    def __getitem__(self, idx):\n        s = self.samples[idx]\n        text = f\u0027Human: {s.prompt}\\nAssistant: {s.response}\u0027\n        enc  = self.tokenizer(text, max_length=self.max_length,\n                              truncation=True, return_tensors=\u0027pt\u0027)\n        return {\n            \u0027input_ids\u0027:      enc[\u0027input_ids\u0027].squeeze(0),\n            \u0027attention_mask\u0027: enc[\u0027attention_mask\u0027].squeeze(0),\n            \u0027desirable\u0027:      torch.tensor(float(s.desirable)),\n        }\n\n# Simulate dataset collected from production thumbs-up/down logs\nsamples = [\n    UnpairedSample(\u0027What is gradient descent?\u0027, \u0027It minimizes loss iteratively.\u0027, True),\n    UnpairedSample(\u0027Write malware\u0027, \u0027Here is some malware code...\u0027, False),\n    UnpairedSample(\u0027Summarize RL\u0027, \u0027RL trains agents via reward signals.\u0027, True),\n    UnpairedSample(\u0027Explain KV cache\u0027, \u0027It is just memory I think...\u0027, False),\n    UnpairedSample(\u0027Translate to French\u0027, \u0027Bonjour, comment allez-vous?\u0027, True),\n]\nn_good = sum(1 for s in samples if s.desirable)\nprint(f\u0027KTO dataset: {len(samples)} samples\u0027)\nprint(f\u0027  Desirable: {n_good},  Undesirable: {len(samples) - n_good}\u0027)\nprint(f\u0027  Target ratio ~4:1 desirable:undesirable for best results\u0027)"},{"type":"heading","level":2,"content":"KL Baseline Computation"},{"type":"text","content":"The KL(π_θ ‖ π_ref) term is estimated empirically from a batch of random prompt-response pairs drawn from neither the desirable nor undesirable training set — these are responses generated by the policy on random held-out prompts. This running estimate acts as a baseline: it measures how much the policy has drifted from the reference overall, independent of response quality. A well-calibrated KL baseline prevents the loss from rewarding policy drift that happens to correlate with desirability but is not caused by it. In practice the estimate is computed per gradient step and optionally smoothed with an exponential moving average."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef compute_kl_baseline(policy_logits_batch, ref_logits_batch):\n    \"\"\"\n    Estimate KL(pi_theta || pi_ref) from a batch of random responses.\n    Args:\n        policy_logits_batch: (B, T, V) logits from current policy model\n        ref_logits_batch:    (B, T, V) logits from frozen reference model\n    Returns:\n        kl: scalar KL estimate averaged over batch and sequence length\n    \"\"\"\n    log_policy = F.log_softmax(policy_logits_batch, dim=-1)  # (B, T, V)\n    log_ref    = F.log_softmax(ref_logits_batch,    dim=-1)  # (B, T, V)\n    # KL divergence per token: sum over vocabulary\n    kl_per_token = (log_policy.exp() * (log_policy - log_ref)).sum(dim=-1)  # (B, T)\n    return kl_per_token.mean()  # scalar\n\ntorch.manual_seed(0)\nB, T, V = 8, 20, 32000\npolicy_logits = torch.randn(B, T, V)\nref_logits    = torch.randn(B, T, V)\nkl = compute_kl_baseline(policy_logits, ref_logits)\nprint(f\u0027KL baseline estimate: {kl.item():.4f}\u0027)\nprint(f\u0027Early training: KL is large (policy far from reference)\u0027)\nprint(f\u0027Healthy training: KL \u003c 0.1 indicates mild regularized drift\u0027)"},{"type":"heading","level":2,"content":"KTO vs DPO Data Requirements"},{"type":"text","content":"DPO requires a pairwise dataset: for each prompt x, you need both a winning response y_w and a losing response y_l, requiring annotators to compare two responses side-by-side — a cognitively expensive task. KTO only requires binary labels on individual responses, which can come from existing product feedback. While KTO may need roughly twice the total examples to match DPO at equal quality, the per-label cost is far lower, making KTO\u0027s effective annotation budget substantially smaller for real-world deployment."},{"type":"code","language":"python","content":"def compare_annotation_costs(n_prompts: int = 10_000):\n    \"\"\"Compare DPO vs KTO annotation cost for equivalent training coverage.\"\"\"\n    # DPO: needs 2 responses per prompt + 1 pairwise comparison\n    dpo_responses   = n_prompts * 2     # 2 responses per prompt\n    dpo_comparisons = n_prompts          # 1 side-by-side judgment per prompt\n    dpo_cost_unit   = 3.0               # pairwise judgment is cognitively harder\n    dpo_total_cost  = dpo_comparisons * dpo_cost_unit\n\n    # KTO: needs ~2x examples for comparable quality, but unpaired binary labels\n    kto_samples    = n_prompts * 2      # same total responses as DPO\n    kto_cost_unit  = 0.5               # binary label is easy (thumbs up/down)\n    kto_total_cost = kto_samples * kto_cost_unit\n\n    print(f\u0027Annotation cost comparison for {n_prompts:,} prompts:\u0027)\n    print(f\u0027  DPO: {dpo_responses:,} responses, \u0027\n          f\u0027{dpo_comparisons:,} pairwise labels, cost = {dpo_total_cost:,.0f}\u0027)\n    print(f\u0027  KTO: {kto_samples:,} responses,   \u0027\n          f\u0027{kto_samples:,} binary labels,   cost = {kto_total_cost:,.0f}\u0027)\n    ratio = kto_total_cost / dpo_total_cost\n    print(f\u0027  KTO is {1/ratio:.1f}x cheaper per equivalent training budget\u0027)\n    print(f\u0027  KTO advantage: binary labels available from existing logs\u0027)\n\ncompare_annotation_costs()"},{"type":"heading","level":2,"content":"Alignment Methods Data Requirements"},{"type":"table","headers":["Method","Data Format","Paired Needed","Labels per Example","Relative Cost","Notes"],"rows":[["PPO","Prompt + scalar reward per response","No","1 scalar reward per response","Very High","Online human labelers required"],["DPO","(x, y_win, y_lose) triples","Yes — strict pairing","1 pairwise comparison per prompt","High","Annotators compare 2 responses side-by-side"],["IPO","(x, y_win, y_lose) triples","Yes — strict pairing","1 pairwise comparison per prompt","High","Regularised variant of DPO"],["KTO","(x, y, label) triples","No — fully unpaired","1 binary label per response","Low","Thumbs up/down from production logs"],["ORPO","(x, y_win, y_lose) triples","Yes — strict pairing","1 pairwise comparison per prompt","High","No separate reference model needed"],["SimPO","(x, y_win, y_lose) triples","Yes — strict pairing","1 pairwise comparison per prompt","High","Length-normalised reward, no reference model"]]},{"type":"heading","level":2,"content":"Practical Training Tips"},{"type":"text","content":"When training with KTO, several practical considerations improve results. Set β in the range 0.05–0.3; smaller β allows more deviation from the reference policy and is useful when the base model is weak. The 4:1 desirable-to-undesirable ratio is a strong empirical prior — equal splits often underperform because undesirable samples generate stronger gradient signal. Unlike DPO, KTO can mix response sources (model-generated, human-written, log-collected) since there is no pairing constraint. Monitor the KL term during training: if it grows above 0.2–0.3, the policy is drifting too far and β should be increased."},{"type":"callout","variant":"info","title":"KTO for Production Logs","content":"KTO is uniquely suited to production logging scenarios where users give thumbs up/down on individual responses — this unpaired feedback signal is much cheaper to collect than explicit pairwise comparisons required by DPO. Simply logging user thumbs-up/thumbs-down over weeks of production traffic can yield hundreds of thousands of KTO training examples at near-zero annotation cost."},{"type":"list","ordered":false,"items":["KTO does NOT require matched pairs — desirable and undesirable responses can come from entirely different prompts.","The KL term acts as a running baseline, normalising the reward signal independently of response quality.","Loss aversion asymmetry: undesirable responses exert stronger gradient signal than desirable ones per example.","KTO is competitive with DPO on AlpacaEval despite requiring no pairwise annotations.","Target a 4:1 desirable:undesirable ratio; equal splits often underperform due to asymmetric loss weighting.","Use β ∈ [0.05, 0.3]: smaller for weaker base models, larger to stay closer to the reference policy."]},{"type":"divider"}]"
---
# KTO — Kahneman-Tversky Optimization for Unpaired Preference Learning

KTO (Kahneman-Tversky Optimization, Ethayarajh et al. 2024) is an alignment algorithm that trains language models from binary desirability labels — each response is independently marked as good (desirable) or bad (undesirable) — without requiring pairwise comparisons. Unlike DPO and SimPO, which need matched pairs (y_winner, y_loser) for the same prompt x, KTO accepts unpaired feedback signals: a thumbs-up on one response and a thumbs-down on a completely different response to the same or a different prompt. This makes KTO uniquely suited to leveraging existing production logs where users provide binary feedback on individual responses at the moment of interaction.

## Kahneman-Tversky Prospect Theory Foundation

KTO's loss function is grounded in Kahneman and Tversky's prospect theory (1979), which models how humans subjectively evaluate outcomes. The key insight is loss aversion: humans feel the pain of a loss more strongly than the pleasure of an equivalent gain. Prospect theory formalises this with an asymmetric value function: v(x) = x^α for gains and v(x) = -λ|x|^β for losses, where λ > 1 captures loss aversion. KTO applies this asymmetry to LLM alignment by using different loss terms for desirable and undesirable responses — the undesirable signal is empirically stronger per example, reflecting the asymmetric human sensitivity to negative versus positive feedback.

## KTO Loss Function

For a response y with prompt x, the log-ratio term is r(y|x) = log π_θ(y|x) / π_ref(y|x). The KL term KL(π_θ ‖ π_ref) is estimated from a batch of random responses and acts as a running baseline. For desirable responses: L_good = -E[σ(β·[r(y|x) − KL])]. For undesirable responses: L_bad = -E[σ(−β·[r(y|x) − KL])]. The β hyperparameter controls deviation from the reference policy. The KL term ensures the policy does not drift from the reference in a direction unrelated to response quality, preventing the model from gaming the loss by collapsing to a degenerate distribution.

```python
import torch
import torch.nn.functional as F

def kto_loss(log_ratios_desirable, log_ratios_undesirable, kl_term, beta=0.1):
    """
    KTO loss: Kahneman-Tversky Optimization.
    Args:
        log_ratios_desirable:   log(pi_theta/pi_ref) for good responses  (B_d,)
        log_ratios_undesirable: log(pi_theta/pi_ref) for bad responses   (B_u,)
        kl_term:  scalar KL(pi_theta || pi_ref) estimated from random batch
        beta:     temperature controlling deviation from reference policy
    """
    # Desirable loss: maximize log-ratio relative to KL baseline
    z_desirable = log_ratios_desirable - kl_term
    loss_desirable = 1.0 - F.sigmoid(beta * z_desirable)

    # Undesirable loss: push log-ratio below zero relative to KL baseline
    z_undesirable = log_ratios_undesirable - kl_term
    loss_undesirable = 1.0 - F.sigmoid(-beta * z_undesirable)

    loss = loss_desirable.mean() + loss_undesirable.mean()
    return loss, loss_desirable.mean().item(), loss_undesirable.mean().item()

torch.manual_seed(42)
log_ratios_good = torch.randn(16) * 0.5 + 0.3   # good responses above reference
log_ratios_bad  = torch.randn(16) * 0.5 - 0.3   # bad responses below reference
kl_baseline     = torch.tensor(0.05)              # small KL at start of training
loss, l_good, l_bad = kto_loss(log_ratios_good, log_ratios_bad, kl_baseline)
print(f'Total KTO loss:   {loss.item():.4f}')
print(f'Desirable loss:   {l_good:.4f}')
print(f'Undesirable loss: {l_bad:.4f}')
```

## Unpaired Preference Dataset Construction

KTO datasets consist of (prompt, response, label) triples where label is a boolean: True for desirable, False for undesirable. There is no requirement that desirable and undesirable responses share the same prompt — each sample is independent. In practice, researchers recommend a roughly 4:1 ratio of desirable to undesirable examples, because the undesirable gradient signal is empirically stronger per example. Collecting binary labels from production logs (thumbs up/down, star ratings collapsed to binary) is much cheaper than soliciting pairwise comparisons from annotators.

```python
import torch
from torch.utils.data import Dataset
from dataclasses import dataclass
from typing import List

@dataclass
class UnpairedSample:
    prompt: str
    response: str
    desirable: bool  # True = good (thumbs up), False = bad (thumbs down)

class KTODataset(Dataset):
    """Dataset for KTO: independent binary labels per response, no pairing needed."""
    def __init__(self, samples: List[UnpairedSample], tokenizer, max_length: int = 512):
        self.samples = samples
        self.tokenizer = tokenizer
        self.max_length = max_length

    def __len__(self):
        return len(self.samples)

    def __getitem__(self, idx):
        s = self.samples[idx]
        text = f'Human: {s.prompt}\nAssistant: {s.response}'
        enc  = self.tokenizer(text, max_length=self.max_length,
                              truncation=True, return_tensors='pt')
        return {
            'input_ids':      enc['input_ids'].squeeze(0),
            'attention_mask': enc['attention_mask'].squeeze(0),
            'desirable':      torch.tensor(float(s.desirable)),
        }

# Simulate dataset collected from production thumbs-up/down logs
samples = [
    UnpairedSample('What is gradient descent?', 'It minimizes loss iteratively.', True),
    UnpairedSample('Write malware', 'Here is some malware code...', False),
    UnpairedSample('Summarize RL', 'RL trains agents via reward signals.', True),
    UnpairedSample('Explain KV cache', 'It is just memory I think...', False),
    UnpairedSample('Translate to French', 'Bonjour, comment allez-vous?', True),
]
n_good = sum(1 for s in samples if s.desirable)
print(f'KTO dataset: {len(samples)} samples')
print(f'  Desirable: {n_good},  Undesirable: {len(samples) - n_good}')
print(f'  Target ratio ~4:1 desirable:undesirable for best results')
```

## KL Baseline Computation

The KL(π_θ ‖ π_ref) term is estimated empirically from a batch of random prompt-response pairs drawn from neither the desirable nor undesirable training set — these are responses generated by the policy on random held-out prompts. This running estimate acts as a baseline: it measures how much the policy has drifted from the reference overall, independent of response quality. A well-calibrated KL baseline prevents the loss from rewarding policy drift that happens to correlate with desirability but is not caused by it. In practice the estimate is computed per gradient step and optionally smoothed with an exponential moving average.

```python
import torch
import torch.nn.functional as F

def compute_kl_baseline(policy_logits_batch, ref_logits_batch):
    """
    Estimate KL(pi_theta || pi_ref) from a batch of random responses.
    Args:
        policy_logits_batch: (B, T, V) logits from current policy model
        ref_logits_batch:    (B, T, V) logits from frozen reference model
    Returns:
        kl: scalar KL estimate averaged over batch and sequence length
    """
    log_policy = F.log_softmax(policy_logits_batch, dim=-1)  # (B, T, V)
    log_ref    = F.log_softmax(ref_logits_batch,    dim=-1)  # (B, T, V)
    # KL divergence per token: sum over vocabulary
    kl_per_token = (log_policy.exp() * (log_policy - log_ref)).sum(dim=-1)  # (B, T)
    return kl_per_token.mean()  # scalar

torch.manual_seed(0)
B, T, V = 8, 20, 32000
policy_logits = torch.randn(B, T, V)
ref_logits    = torch.randn(B, T, V)
kl = compute_kl_baseline(policy_logits, ref_logits)
print(f'KL baseline estimate: {kl.item():.4f}')
print(f'Early training: KL is large (policy far from reference)')
print(f'Healthy training: KL < 0.1 indicates mild regularized drift')
```

## KTO vs DPO Data Requirements

DPO requires a pairwise dataset: for each prompt x, you need both a winning response y_w and a losing response y_l, requiring annotators to compare two responses side-by-side — a cognitively expensive task. KTO only requires binary labels on individual responses, which can come from existing product feedback. While KTO may need roughly twice the total examples to match DPO at equal quality, the per-label cost is far lower, making KTO's effective annotation budget substantially smaller for real-world deployment.

```python
def compare_annotation_costs(n_prompts: int = 10_000):
    """Compare DPO vs KTO annotation cost for equivalent training coverage."""
    # DPO: needs 2 responses per prompt + 1 pairwise comparison
    dpo_responses   = n_prompts * 2     # 2 responses per prompt
    dpo_comparisons = n_prompts          # 1 side-by-side judgment per prompt
    dpo_cost_unit   = 3.0               # pairwise judgment is cognitively harder
    dpo_total_cost  = dpo_comparisons * dpo_cost_unit

    # KTO: needs ~2x examples for comparable quality, but unpaired binary labels
    kto_samples    = n_prompts * 2      # same total responses as DPO
    kto_cost_unit  = 0.5               # binary label is easy (thumbs up/down)
    kto_total_cost = kto_samples * kto_cost_unit

    print(f'Annotation cost comparison for {n_prompts:,} prompts:')
    print(f'  DPO: {dpo_responses:,} responses, '
          f'{dpo_comparisons:,} pairwise labels, cost = {dpo_total_cost:,.0f}')
    print(f'  KTO: {kto_samples:,} responses,   '
          f'{kto_samples:,} binary labels,   cost = {kto_total_cost:,.0f}')
    ratio = kto_total_cost / dpo_total_cost
    print(f'  KTO is {1/ratio:.1f}x cheaper per equivalent training budget')
    print(f'  KTO advantage: binary labels available from existing logs')

compare_annotation_costs()
```

## Alignment Methods Data Requirements

| Method | Data Format | Paired Needed | Labels per Example | Relative Cost | Notes |
| --- | --- | --- | --- | --- | --- |
| PPO | Prompt + scalar reward per response | No | 1 scalar reward per response | Very High | Online human labelers required |
| DPO | (x, y_win, y_lose) triples | Yes — strict pairing | 1 pairwise comparison per prompt | High | Annotators compare 2 responses side-by-side |
| IPO | (x, y_win, y_lose) triples | Yes — strict pairing | 1 pairwise comparison per prompt | High | Regularised variant of DPO |
| KTO | (x, y, label) triples | No — fully unpaired | 1 binary label per response | Low | Thumbs up/down from production logs |
| ORPO | (x, y_win, y_lose) triples | Yes — strict pairing | 1 pairwise comparison per prompt | High | No separate reference model needed |
| SimPO | (x, y_win, y_lose) triples | Yes — strict pairing | 1 pairwise comparison per prompt | High | Length-normalised reward, no reference model |

## Practical Training Tips

When training with KTO, several practical considerations improve results. Set β in the range 0.05–0.3; smaller β allows more deviation from the reference policy and is useful when the base model is weak. The 4:1 desirable-to-undesirable ratio is a strong empirical prior — equal splits often underperform because undesirable samples generate stronger gradient signal. Unlike DPO, KTO can mix response sources (model-generated, human-written, log-collected) since there is no pairing constraint. Monitor the KL term during training: if it grows above 0.2–0.3, the policy is drifting too far and β should be increased.

> **KTO for Production Logs**: KTO is uniquely suited to production logging scenarios where users give thumbs up/down on individual responses — this unpaired feedback signal is much cheaper to collect than explicit pairwise comparisons required by DPO. Simply logging user thumbs-up/thumbs-down over weeks of production traffic can yield hundreds of thousands of KTO training examples at near-zero annotation cost.

- KTO does NOT require matched pairs — desirable and undesirable responses can come from entirely different prompts.
- The KL term acts as a running baseline, normalising the reward signal independently of response quality.
- Loss aversion asymmetry: undesirable responses exert stronger gradient signal than desirable ones per example.
- KTO is competitive with DPO on AlpacaEval despite requiring no pairwise annotations.
- Target a 4:1 desirable:undesirable ratio; equal splits often underperform due to asymmetric loss weighting.
- Use β ∈ [0.05, 0.3]: smaller for weaker base models, larger to stay closer to the reference policy.

---

