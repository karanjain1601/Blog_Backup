---
title: "LLM Training Dynamics — Warmup, Loss Spikes, and Gradient Norm Monitoring"
slug: "llm-training-dynamics"
description: "Practical guide to LLM pretraining stability: LR warmup schedules, cosine annealing, loss spike causes and recovery, gradient norm clipping, and checkpoint strategies for robust large-scale training."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Training large language models at scale surfaces a class of instability problems that do not appear at smaller scales: loss spikes that can derail a run after thousands of GPU-hours, gradient explosions that corrupt model weights, and scheduling bugs that cause silent underfitting. Understanding the interplay between the learning rate schedule, the Adam optimizer\u0027s moment estimates, and gradient norm dynamics is essential for anyone running or debugging LLM pretraining. This note covers the four most important levers: warmup, cosine annealing, gradient norm monitoring, and checkpoint rollback."},{"type":"heading","level":2,"content":"Learning Rate Warmup and the Adam Bias Problem"},{"type":"text","content":"At step 0, Adam\u0027s first-moment estimate m₀ = 0 and second-moment estimate v₀ = 0. The bias correction factors 1/(1 − β₁ᵗ) and 1/(1 − β₂ᵗ) partially compensate for this cold-start, but in practice the effective per-parameter step sizes are poorly calibrated for the first few hundred steps. Starting at the full target learning rate during this period causes large, noisy gradient updates that move parameters far from their initialization. Linear warmup from 0 to η_max over the first ~2000 steps allows the moment estimates to stabilize before the optimizer operates at full learning rate, dramatically reducing early-training divergence risk."},{"type":"list","ordered":false,"items":["Linear warmup: LR(t) = η_max × t / T_warmup for t \u003c T_warmup, typically T_warmup = 2000 steps","β₂ = 0.95–0.999 in large LLMs; higher β₂ means longer moment warm-up period","Skipping warmup with Adam at LR=3e-4 on a Transformer often causes divergence in first 100 steps","GPT-3 used T_warmup = 375M tokens; LLaMA used T_warmup ≈ 2000 steps at batch 4M tokens","bf16 training is more sensitive to early LR spikes than fp32 due to reduced precision range"]},{"type":"heading","level":2,"content":"Cosine Annealing After Warmup"},{"type":"text","content":"After warmup, the standard schedule for LLM pretraining is cosine annealing: LR(t) = η_min + (η_max − η_min) × cos(π × t / T) / 2, where T is the total training steps and η_min is a floor (typically 1e-5 or 10% of η_max). Cosine decay is preferred over step decay because it provides a smooth, continuous reduction that avoids sudden LR drops which can destabilize Adam\u0027s momentum estimates. The final 10% of training at near-zero LR often recovers 0.3–0.5 perplexity points compared to stopping cosine decay early."},{"type":"code","language":"python","content":"import math\nimport matplotlib.pyplot as plt\n\ndef get_lr(step, warmup_steps, total_steps, lr_max, lr_min=1e-5):\n    \"\"\"Linear warmup then cosine annealing to lr_min.\"\"\"\n    if step \u003c warmup_steps:\n        return lr_max * step / max(warmup_steps, 1)\n    progress = (step - warmup_steps) / max(total_steps - warmup_steps, 1)\n    return lr_min + 0.5 * (lr_max - lr_min) * (1 + math.cos(math.pi * progress))\n\nwarmup_steps, total_steps = 2000, 100_000\nlr_max, lr_min = 3e-4, 1e-5\n\nsteps = list(range(0, total_steps, 200))\nlrs   = [get_lr(s, warmup_steps, total_steps, lr_max, lr_min) for s in steps]\n\nfig, ax = plt.subplots(figsize=(10, 4))\nax.plot(steps, lrs, \u0027b-\u0027, linewidth=2, label=\u0027LR schedule\u0027)\nax.axvline(warmup_steps, color=\u0027orange\u0027, linestyle=\u0027--\u0027, label=f\u0027Warmup end ({warmup_steps} steps)\u0027)\nax.set_xlabel(\u0027Training Step\u0027); ax.set_ylabel(\u0027Learning Rate\u0027)\nax.set_title(\u0027LR: Linear Warmup + Cosine Annealing (eta_min=1e-5)\u0027)\nax.legend(); ax.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027lr_schedule.png\u0027, dpi=120)\nprint(f\"Peak LR: {max(lrs):.2e}  End LR: {lrs[-1]:.2e}  Warmup: {warmup_steps/total_steps:.1%} of training\")"},{"type":"heading","level":2,"content":"Loss Spikes — Causes and Detection"},{"type":"text","content":"A loss spike is a sudden sharp increase in training loss — typically 2–10× baseline — followed by gradual recovery over 100–500 steps. Spikes are the most common cause of catastrophic LLM pretraining failures. Most spikes self-heal if the LR is not too high; in severe cases the model never recovers and the run must be restarted from a checkpoint. The primary causes are data-related: malformed Unicode sequences cause tokenizer output anomalies; repeated tokens pad documents to extreme lengths; empty or near-empty documents produce undefined loss values. Hardware faults (NaN-producing FP operations) and LR schedule bugs are secondary causes."},{"type":"list","ordered":false,"items":["Data anomalies: malformed Unicode, encoding errors, empty documents, repeated-token padding","LR too high: gradient step overhoots loss minimum, causes chaotic wandering","Bad batch: single extremely high-loss document (corrupted label or length outlier)","Gradient overflow: fp16/bf16 gradients saturate; NaN propagates into weights via Adam update","Architecture bug: attention logit explosion in deep models with incorrect initialization"]},{"type":"callout","variant":"warning","title":"Warning","content":"Loss spikes from data quality issues (malformed Unicode, empty documents, repeated tokens) are the most common cause of LLM training instability — aggressive data filtering and document length capping prevent most spikes."},{"type":"heading","level":2,"content":"Gradient Norm Monitoring and Clipping"},{"type":"text","content":"The global gradient norm ‖∇L‖₂ = sqrt(Σᵢ ‖∇Lᵢ‖²) computed across all parameters is one of the most informative training diagnostics. A healthy LLM run shows gradient norms in the range 0.1–2.0. Sustained norms above 5.0 indicate instability that usually precedes a loss spike by 50–200 steps. Global norm clipping rescales the entire gradient vector when ‖g‖ \u003e clip_norm: g ← g × (clip_norm / ‖g‖). This prevents any single large gradient from driving a destructive parameter update without reducing smaller gradients. Standard clip_norm = 1.0 for most LLM training; some recipes use 0.5 for very deep models."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef compute_global_grad_norm(model):\n    \"\"\"Compute global L2 gradient norm across all parameters.\"\"\"\n    total_norm = 0.0\n    for p in model.parameters():\n        if p.grad is not None:\n            total_norm += p.grad.detach().norm(2).item() ** 2\n    return total_norm ** 0.5\n\ndef train_step_with_clip(model, optimizer, loss, clip_norm=1.0):\n    optimizer.zero_grad()\n    loss.backward()\n    pre_clip_norm = compute_global_grad_norm(model)\n    if pre_clip_norm \u003e clip_norm:\n        torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)\n    optimizer.step()\n    return pre_clip_norm, pre_clip_norm \u003e clip_norm\n\n# Simulate 10 training steps and log gradient norms\nmodel     = nn.Sequential(nn.Linear(128, 256), nn.GELU(), nn.Linear(256, 128))\noptimizer = torch.optim.AdamW(model.parameters(), lr=3e-4, betas=(0.9, 0.95))\nnorm_log  = []\nfor step in range(10):\n    x         = torch.randn(16, 128)\n    loss      = (model(x) ** 2).mean() + 0.01 * torch.randn(1).abs()\n    gnorm, clipped = train_step_with_clip(model, optimizer, loss, clip_norm=1.0)\n    norm_log.append(gnorm)\n    status = \u0027CLIPPED\u0027 if clipped else \u0027ok\u0027\n    print(f\"Step {step:2d}: grad_norm={gnorm:.4f}  [{status}]\")\nprint(f\"Mean norm: {sum(norm_log)/len(norm_log):.4f}  Max: {max(norm_log):.4f}\")"},{"type":"heading","level":2,"content":"Spike Detection and Checkpoint Rollback"},{"type":"text","content":"Automated spike detection compares the current loss to a rolling baseline computed over the last 50 steps. If the current loss exceeds the baseline by more than a threshold (typically 3×), the training loop triggers a rollback: load the most recent good checkpoint, reduce the learning rate by 20–50%, and resume training. Most training frameworks save checkpoints every 500–1000 steps; saving more frequently is expensive but allows finer-grained recovery. The key insight is that spike recovery is much faster when the checkpoint is close to the spike — resuming from step N-100 with reduced LR typically recovers in 200–500 steps."},{"type":"code","language":"python","content":"import torch\nimport os\n\ndef detect_spike(loss_history, current_loss, threshold=3.0, window=50):\n    \"\"\"Return True if current_loss is threshold× above recent baseline.\"\"\"\n    if len(loss_history) \u003c window:\n        return False\n    baseline = sum(loss_history[-window:]) / window\n    return current_loss \u003e baseline * threshold\n\ndef load_last_checkpoint(ckpt_dir, model, optimizer):\n    \"\"\"Load the most recent .pt checkpoint and return the step number.\"\"\"\n    ckpts = sorted([f for f in os.listdir(ckpt_dir) if f.endswith(\u0027.pt\u0027)])\n    if not ckpts:\n        print(\"No checkpoints found.\")\n        return 0\n    path = os.path.join(ckpt_dir, ckpts[-1])\n    ckpt = torch.load(path, map_location=\u0027cpu\u0027)\n    model.load_state_dict(ckpt[\u0027model\u0027])\n    optimizer.load_state_dict(ckpt[\u0027optimizer\u0027])\n    print(f\"Rolled back to step {ckpt[\u0027step\u0027]} (loss={ckpt[\u0027loss\u0027]:.4f})\")\n    return ckpt[\u0027step\u0027]\n\n# Simulate spike detection over 65 steps\nloss_history = [2.1 + 0.04 * (i % 4) for i in range(60)]\ntest_losses  = [(2.0, \u0027normal\u0027), (2.3, \u0027elevated\u0027), (7.8, \u0027SPIKE\u0027), (2.05, \u0027post-spike\u0027)]\nfor val, label in test_losses:\n    is_spike = detect_spike(loss_history, val, threshold=3.0)\n    action   = \u0027ROLLBACK + reduce LR\u0027 if is_spike else \u0027continue\u0027\n    print(f\"{label:12s}: loss={val:.2f}  spike={is_spike}  action={action}\")\n    if not is_spike:\n        loss_history.append(val)"},{"type":"heading","level":2,"content":"Training Metrics Logging"},{"type":"code","language":"python","content":"import csv, os, time\nimport torch\n\ndef log_metrics(step, loss, lr, grad_norm, log_file=\u0027training_log.csv\u0027, use_wandb=False):\n    \"\"\"Log step metrics to CSV and optionally to W\u0026B.\"\"\"\n    ppl = min(2 ** loss, 1e9) if loss \u003c 30 else float(\u0027inf\u0027)\n    row = {\n        \u0027step\u0027:       step,\n        \u0027loss\u0027:       round(loss, 4),\n        \u0027perplexity\u0027: round(ppl, 2),\n        \u0027lr\u0027:         f\u0027{lr:.2e}\u0027,\n        \u0027grad_norm\u0027:  round(grad_norm, 4),\n        \u0027gpu_mem_gb\u0027: round(torch.cuda.memory_allocated() / 1e9 if torch.cuda.is_available() else 0.0, 2),\n        \u0027timestamp\u0027:  time.strftime(\u0027%H:%M:%S\u0027),\n    }\n    write_header = not os.path.exists(log_file)\n    with open(log_file, \u0027a\u0027, newline=\u0027\u0027) as f:\n        w = csv.DictWriter(f, fieldnames=row.keys())\n        if write_header:\n            w.writeheader()\n        w.writerow(row)\n    if use_wandb:\n        import wandb\n        wandb.log({k: v for k, v in row.items() if k != \u0027timestamp\u0027}, step=step)\n    return row\n\n# Simulate 5 steps\nfor s in range(5):\n    m = log_metrics(s * 500, loss=2.5 - s * 0.07, lr=3e-4 * (1 - s * 0.015),\n                    grad_norm=0.72 + s * 0.04, log_file=\u0027training_metrics.csv\u0027)\n    print(f\"Step {m[\u0027step\u0027]}: loss={m[\u0027loss\u0027]}  ppl={m[\u0027perplexity\u0027]}  gnorm={m[\u0027grad_norm\u0027]}\")"},{"type":"heading","level":2,"content":"Healthy vs Pathological Training Signals"},{"type":"table","headers":["Metric","Healthy Range","Warning Sign","Likely Cause","Response Action"],"rows":[["Training loss","Smooth monotonic decrease","Spike \u003e3× rolling avg","Bad batch / LR too high","Rollback checkpoint, reduce LR 30%"],["Gradient norm ‖g‖","0.1 – 1.5 per step","Sustained \u003e5.0 or NaN","Exploding gradients / data anomaly","Reduce LR, check data pipeline"],["Perplexity","Consistent decrease","Plateau for \u003e10K steps","LR too low or data saturation","Check schedule, reshuffle data"],["LR (actual vs scheduled)","Follows schedule exactly","Drift or zero after resume","Optimizer state not restored","Verify checkpoint load + step counter"],["GPU memory (GB)","Stable across steps","Monotonic growth / OOM","Activation memory leak","Gradient checkpointing, reduce batch"],["Loss spike frequency","\u003c1 per 5K steps","\u003e3 spikes per 1K steps","Data quality issues","Filter malformed docs, cap doc length"]]},{"type":"heading","level":2,"content":"bf16 vs fp16 and Checkpointing Strategy"},{"type":"text","content":"bf16 (bfloat16) has the same 8-bit exponent as fp32 but only 7 mantissa bits versus fp16\u0027s 10. This means bf16 has a much wider dynamic range (same as fp32: ±3.4×10³⁸) but lower precision for small values. In practice, bf16 training suffers far fewer gradient overflow events than fp16 because activation and gradient magnitudes can span many orders of magnitude during a spike. fp16 training requires loss scaling to avoid underflow; bf16 does not. For checkpointing, save optimizer state (Adam m and v for every parameter), model weights, the random state for data sampling, and the scheduler step. Missing any of these causes silent divergence on resume."},{"type":"list","ordered":false,"items":["Save every 1000 steps minimum; every 500 steps if training is unstable or expensive","Checkpoint includes: model weights, optimizer state (m, v), scheduler step, RNG seeds","Use mixed precision: weights in fp32, forward/backward in bf16 (AMP with bf16)","Keep the last 3–5 checkpoints to allow rollback past multiple consecutive spikes","Validate checkpoint integrity after saving: load and check loss on a fixed validation batch"]}]"
---
# LLM Training Dynamics — Warmup, Loss Spikes, and Gradient Norm Monitoring

Training large language models at scale surfaces a class of instability problems that do not appear at smaller scales: loss spikes that can derail a run after thousands of GPU-hours, gradient explosions that corrupt model weights, and scheduling bugs that cause silent underfitting. Understanding the interplay between the learning rate schedule, the Adam optimizer's moment estimates, and gradient norm dynamics is essential for anyone running or debugging LLM pretraining. This note covers the four most important levers: warmup, cosine annealing, gradient norm monitoring, and checkpoint rollback.

## Learning Rate Warmup and the Adam Bias Problem

At step 0, Adam's first-moment estimate m₀ = 0 and second-moment estimate v₀ = 0. The bias correction factors 1/(1 − β₁ᵗ) and 1/(1 − β₂ᵗ) partially compensate for this cold-start, but in practice the effective per-parameter step sizes are poorly calibrated for the first few hundred steps. Starting at the full target learning rate during this period causes large, noisy gradient updates that move parameters far from their initialization. Linear warmup from 0 to η_max over the first ~2000 steps allows the moment estimates to stabilize before the optimizer operates at full learning rate, dramatically reducing early-training divergence risk.

- Linear warmup: LR(t) = η_max × t / T_warmup for t < T_warmup, typically T_warmup = 2000 steps
- β₂ = 0.95–0.999 in large LLMs; higher β₂ means longer moment warm-up period
- Skipping warmup with Adam at LR=3e-4 on a Transformer often causes divergence in first 100 steps
- GPT-3 used T_warmup = 375M tokens; LLaMA used T_warmup ≈ 2000 steps at batch 4M tokens
- bf16 training is more sensitive to early LR spikes than fp32 due to reduced precision range

## Cosine Annealing After Warmup

After warmup, the standard schedule for LLM pretraining is cosine annealing: LR(t) = η_min + (η_max − η_min) × cos(π × t / T) / 2, where T is the total training steps and η_min is a floor (typically 1e-5 or 10% of η_max). Cosine decay is preferred over step decay because it provides a smooth, continuous reduction that avoids sudden LR drops which can destabilize Adam's momentum estimates. The final 10% of training at near-zero LR often recovers 0.3–0.5 perplexity points compared to stopping cosine decay early.

```python
import math
import matplotlib.pyplot as plt

def get_lr(step, warmup_steps, total_steps, lr_max, lr_min=1e-5):
    """Linear warmup then cosine annealing to lr_min."""
    if step < warmup_steps:
        return lr_max * step / max(warmup_steps, 1)
    progress = (step - warmup_steps) / max(total_steps - warmup_steps, 1)
    return lr_min + 0.5 * (lr_max - lr_min) * (1 + math.cos(math.pi * progress))

warmup_steps, total_steps = 2000, 100_000
lr_max, lr_min = 3e-4, 1e-5

steps = list(range(0, total_steps, 200))
lrs   = [get_lr(s, warmup_steps, total_steps, lr_max, lr_min) for s in steps]

fig, ax = plt.subplots(figsize=(10, 4))
ax.plot(steps, lrs, 'b-', linewidth=2, label='LR schedule')
ax.axvline(warmup_steps, color='orange', linestyle='--', label=f'Warmup end ({warmup_steps} steps)')
ax.set_xlabel('Training Step'); ax.set_ylabel('Learning Rate')
ax.set_title('LR: Linear Warmup + Cosine Annealing (eta_min=1e-5)')
ax.legend(); ax.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('lr_schedule.png', dpi=120)
print(f"Peak LR: {max(lrs):.2e}  End LR: {lrs[-1]:.2e}  Warmup: {warmup_steps/total_steps:.1%} of training")
```

## Loss Spikes — Causes and Detection

A loss spike is a sudden sharp increase in training loss — typically 2–10× baseline — followed by gradual recovery over 100–500 steps. Spikes are the most common cause of catastrophic LLM pretraining failures. Most spikes self-heal if the LR is not too high; in severe cases the model never recovers and the run must be restarted from a checkpoint. The primary causes are data-related: malformed Unicode sequences cause tokenizer output anomalies; repeated tokens pad documents to extreme lengths; empty or near-empty documents produce undefined loss values. Hardware faults (NaN-producing FP operations) and LR schedule bugs are secondary causes.

- Data anomalies: malformed Unicode, encoding errors, empty documents, repeated-token padding
- LR too high: gradient step overhoots loss minimum, causes chaotic wandering
- Bad batch: single extremely high-loss document (corrupted label or length outlier)
- Gradient overflow: fp16/bf16 gradients saturate; NaN propagates into weights via Adam update
- Architecture bug: attention logit explosion in deep models with incorrect initialization

> **Warning**: Loss spikes from data quality issues (malformed Unicode, empty documents, repeated tokens) are the most common cause of LLM training instability — aggressive data filtering and document length capping prevent most spikes.

## Gradient Norm Monitoring and Clipping

The global gradient norm ‖∇L‖₂ = sqrt(Σᵢ ‖∇Lᵢ‖²) computed across all parameters is one of the most informative training diagnostics. A healthy LLM run shows gradient norms in the range 0.1–2.0. Sustained norms above 5.0 indicate instability that usually precedes a loss spike by 50–200 steps. Global norm clipping rescales the entire gradient vector when ‖g‖ > clip_norm: g ← g × (clip_norm / ‖g‖). This prevents any single large gradient from driving a destructive parameter update without reducing smaller gradients. Standard clip_norm = 1.0 for most LLM training; some recipes use 0.5 for very deep models.

```python
import torch
import torch.nn as nn

def compute_global_grad_norm(model):
    """Compute global L2 gradient norm across all parameters."""
    total_norm = 0.0
    for p in model.parameters():
        if p.grad is not None:
            total_norm += p.grad.detach().norm(2).item() ** 2
    return total_norm ** 0.5

def train_step_with_clip(model, optimizer, loss, clip_norm=1.0):
    optimizer.zero_grad()
    loss.backward()
    pre_clip_norm = compute_global_grad_norm(model)
    if pre_clip_norm > clip_norm:
        torch.nn.utils.clip_grad_norm_(model.parameters(), clip_norm)
    optimizer.step()
    return pre_clip_norm, pre_clip_norm > clip_norm

# Simulate 10 training steps and log gradient norms
model     = nn.Sequential(nn.Linear(128, 256), nn.GELU(), nn.Linear(256, 128))
optimizer = torch.optim.AdamW(model.parameters(), lr=3e-4, betas=(0.9, 0.95))
norm_log  = []
for step in range(10):
    x         = torch.randn(16, 128)
    loss      = (model(x) ** 2).mean() + 0.01 * torch.randn(1).abs()
    gnorm, clipped = train_step_with_clip(model, optimizer, loss, clip_norm=1.0)
    norm_log.append(gnorm)
    status = 'CLIPPED' if clipped else 'ok'
    print(f"Step {step:2d}: grad_norm={gnorm:.4f}  [{status}]")
print(f"Mean norm: {sum(norm_log)/len(norm_log):.4f}  Max: {max(norm_log):.4f}")
```

## Spike Detection and Checkpoint Rollback

Automated spike detection compares the current loss to a rolling baseline computed over the last 50 steps. If the current loss exceeds the baseline by more than a threshold (typically 3×), the training loop triggers a rollback: load the most recent good checkpoint, reduce the learning rate by 20–50%, and resume training. Most training frameworks save checkpoints every 500–1000 steps; saving more frequently is expensive but allows finer-grained recovery. The key insight is that spike recovery is much faster when the checkpoint is close to the spike — resuming from step N-100 with reduced LR typically recovers in 200–500 steps.

```python
import torch
import os

def detect_spike(loss_history, current_loss, threshold=3.0, window=50):
    """Return True if current_loss is threshold× above recent baseline."""
    if len(loss_history) < window:
        return False
    baseline = sum(loss_history[-window:]) / window
    return current_loss > baseline * threshold

def load_last_checkpoint(ckpt_dir, model, optimizer):
    """Load the most recent .pt checkpoint and return the step number."""
    ckpts = sorted([f for f in os.listdir(ckpt_dir) if f.endswith('.pt')])
    if not ckpts:
        print("No checkpoints found.")
        return 0
    path = os.path.join(ckpt_dir, ckpts[-1])
    ckpt = torch.load(path, map_location='cpu')
    model.load_state_dict(ckpt['model'])
    optimizer.load_state_dict(ckpt['optimizer'])
    print(f"Rolled back to step {ckpt['step']} (loss={ckpt['loss']:.4f})")
    return ckpt['step']

# Simulate spike detection over 65 steps
loss_history = [2.1 + 0.04 * (i % 4) for i in range(60)]
test_losses  = [(2.0, 'normal'), (2.3, 'elevated'), (7.8, 'SPIKE'), (2.05, 'post-spike')]
for val, label in test_losses:
    is_spike = detect_spike(loss_history, val, threshold=3.0)
    action   = 'ROLLBACK + reduce LR' if is_spike else 'continue'
    print(f"{label:12s}: loss={val:.2f}  spike={is_spike}  action={action}")
    if not is_spike:
        loss_history.append(val)
```

## Training Metrics Logging

```python
import csv, os, time
import torch

def log_metrics(step, loss, lr, grad_norm, log_file='training_log.csv', use_wandb=False):
    """Log step metrics to CSV and optionally to W&B."""
    ppl = min(2 ** loss, 1e9) if loss < 30 else float('inf')
    row = {
        'step':       step,
        'loss':       round(loss, 4),
        'perplexity': round(ppl, 2),
        'lr':         f'{lr:.2e}',
        'grad_norm':  round(grad_norm, 4),
        'gpu_mem_gb': round(torch.cuda.memory_allocated() / 1e9 if torch.cuda.is_available() else 0.0, 2),
        'timestamp':  time.strftime('%H:%M:%S'),
    }
    write_header = not os.path.exists(log_file)
    with open(log_file, 'a', newline='') as f:
        w = csv.DictWriter(f, fieldnames=row.keys())
        if write_header:
            w.writeheader()
        w.writerow(row)
    if use_wandb:
        import wandb
        wandb.log({k: v for k, v in row.items() if k != 'timestamp'}, step=step)
    return row

# Simulate 5 steps
for s in range(5):
    m = log_metrics(s * 500, loss=2.5 - s * 0.07, lr=3e-4 * (1 - s * 0.015),
                    grad_norm=0.72 + s * 0.04, log_file='training_metrics.csv')
    print(f"Step {m['step']}: loss={m['loss']}  ppl={m['perplexity']}  gnorm={m['grad_norm']}")
```

## Healthy vs Pathological Training Signals

| Metric | Healthy Range | Warning Sign | Likely Cause | Response Action |
| --- | --- | --- | --- | --- |
| Training loss | Smooth monotonic decrease | Spike >3× rolling avg | Bad batch / LR too high | Rollback checkpoint, reduce LR 30% |
| Gradient norm ‖g‖ | 0.1 – 1.5 per step | Sustained >5.0 or NaN | Exploding gradients / data anomaly | Reduce LR, check data pipeline |
| Perplexity | Consistent decrease | Plateau for >10K steps | LR too low or data saturation | Check schedule, reshuffle data |
| LR (actual vs scheduled) | Follows schedule exactly | Drift or zero after resume | Optimizer state not restored | Verify checkpoint load + step counter |
| GPU memory (GB) | Stable across steps | Monotonic growth / OOM | Activation memory leak | Gradient checkpointing, reduce batch |
| Loss spike frequency | <1 per 5K steps | >3 spikes per 1K steps | Data quality issues | Filter malformed docs, cap doc length |

## bf16 vs fp16 and Checkpointing Strategy

bf16 (bfloat16) has the same 8-bit exponent as fp32 but only 7 mantissa bits versus fp16's 10. This means bf16 has a much wider dynamic range (same as fp32: ±3.4×10³⁸) but lower precision for small values. In practice, bf16 training suffers far fewer gradient overflow events than fp16 because activation and gradient magnitudes can span many orders of magnitude during a spike. fp16 training requires loss scaling to avoid underflow; bf16 does not. For checkpointing, save optimizer state (Adam m and v for every parameter), model weights, the random state for data sampling, and the scheduler step. Missing any of these causes silent divergence on resume.

- Save every 1000 steps minimum; every 500 steps if training is unstable or expensive
- Checkpoint includes: model weights, optimizer state (m, v), scheduler step, RNG seeds
- Use mixed precision: weights in fp32, forward/backward in bf16 (AMP with bf16)
- Keep the last 3–5 checkpoints to allow rollback past multiple consecutive spikes
- Validate checkpoint integrity after saving: load and check loss on a fixed validation batch

