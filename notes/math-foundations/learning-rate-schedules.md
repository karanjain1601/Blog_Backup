---
title: "Learning Rate Schedules"
slug: "learning-rate-schedules"
description: "Covers constant LR pitfalls, linear warmup rationale, cosine annealing, the 1-cycle policy, learning rate finder range test, and the WSD (Warmup-Stable-Decay) schedule used in LLM pretraining."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The learning rate is the single most important optimizer hyperparameter, yet a constant LR is almost never optimal. Modern training recipes combine a warmup phase (ramp from near-zero to peak LR), a main training phase, and a decay phase. Understanding why each phase exists — and how to find the right peak LR — is essential for training stable, well-converged models."},{"type":"heading","level":2,"content":"Why Constant LR Fails"},{"type":"text","content":"A constant LR that is too large causes divergence (loss spikes, NaN) because gradient steps overshoot the loss surface. A constant LR that is too small converges slowly and may land in a sharp, poorly generalizing minimum. Schedules combine a large LR early (to escape bad initialization) with a small LR late (to settle into a smooth minimum)."},{"type":"heading","level":2,"content":"Linear Warmup: Why It Matters"},{"type":"text","content":"In Adam, the second moment v̂ = v/(1-β₂ᵗ) is near zero at initialization — Adam\u0027s bias correction compensates, but in practice early steps can still be large and unstable. Warmup starts at lr=0 (or a small fraction) and ramps linearly to peak_lr over warmup_steps. This lets v̂ stabilize before taking large steps, and avoids catastrophic early updates that can destroy freshly initialized weights."},{"type":"callout","variant":"info","title":"How Long to Warm Up","content":"Typical warmup is 1–5% of total training steps. For LLM pretraining at 100k steps: 1000–5000 warmup steps. For fine-tuning short runs: 50–100 steps. Longer warmup is safer but delays reaching peak LR. The WSD schedule uses a fixed warmup of ~1% and then holds the LR stable for most of training."},{"type":"heading","level":2,"content":"Cosine Annealing"},{"type":"text","content":"Cosine annealing smoothly decays the LR: η(t) = η_min + (η_max − η_min)/2 · (1 + cos(πt/T)). At t=0 it equals η_max; at t=T it equals η_min. The smooth decay avoids the abrupt LR drops of step decay, which can cause sudden loss changes. Cosine annealing with warm restarts (SGDR) periodically resets t to 0, allowing the model to escape local minima."},{"type":"code","language":"python","content":"import numpy as np\nimport math\n\ndef cosine_anneal(step, T, eta_max=1e-3, eta_min=1e-6):\n    # eta(t) = eta_min + (eta_max - eta_min)/2 * (1 + cos(pi*t/T))\n    return eta_min + (eta_max - eta_min) * 0.5 * (1.0 + math.cos(math.pi * step / T))\n\ndef warmup_cosine(step, warmup, total, eta_max=1e-3, eta_min=1e-6):\n    # Phase 1: linear warmup  [0, warmup)\n    # Phase 2: cosine decay   [warmup, total]\n    if step \u003c warmup:\n        return eta_max * step / max(warmup, 1)\n    progress = (step - warmup) / max(total - warmup, 1)\n    return eta_min + (eta_max - eta_min) * 0.5 * (1.0 + math.cos(math.pi * progress))\n\ntotal, warmup = 1000, 100\n\nprint(\u0027Warmup + cosine annealing schedule:\u0027)\nprint(\u0027%-6s  %-12s  %s\u0027 % (\u0027Step\u0027, \u0027LR\u0027, \u0027Bar\u0027))\nfor t in [0, 25, 50, 100, 200, 400, 600, 800, 999]:\n    lr  = warmup_cosine(t, warmup, total)\n    bar = \u0027#\u0027 * int(lr / 1e-3 * 30)\n    print(\u0027%6d  %.4e    %s\u0027 % (t, lr, bar))\n\nlrs = [warmup_cosine(t, warmup, total) for t in range(total)]\nprint(\u0027\u0027)\nprint(\u0027Peak LR: %.2e  |  Final LR: %.2e\u0027 % (max(lrs), lrs[-1]))\nprint(\u0027Warmup: %d steps  |  Cosine decay: %d steps\u0027 % (warmup, total - warmup))"},{"type":"heading","level":2,"content":"The 1-Cycle Policy"},{"type":"text","content":"The 1-cycle policy (Smith 2017) uses a triangular LR schedule: ramp up from base_lr to max_lr over pct_start fraction of training, then decay from max_lr back to base_lr/div_factor. A final phase decays to base_lr/final_div_factor. This enables \u0027super-convergence\u0027 — training in far fewer iterations than step decay. PyTorch provides OneCycleLR out of the box."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\nmodel = nn.Linear(10, 2)\noptimizer = optim.AdamW(model.parameters(), lr=1e-3)\n\n# 1. OneCycleLR: warmup -\u003e peak -\u003e cosine anneal\none_cycle = optim.lr_scheduler.OneCycleLR(\n    optimizer,\n    max_lr=1e-2,\n    total_steps=1000,\n    pct_start=0.1,           # 10% warmup\n    anneal_strategy=\u0027cos\u0027,\n    div_factor=25,            # start lr = max_lr / 25\n    final_div_factor=1e4      # end lr = start_lr / 1e4\n)\n\n# 2. CosineAnnealingLR\ncos_sched = optim.lr_scheduler.CosineAnnealingLR(\n    optimizer, T_max=1000, eta_min=1e-6)\n\n# 3. Linear warmup -\u003e Cosine decay (SequentialLR)\nwarmup_sched = optim.lr_scheduler.LinearLR(\n    optimizer, start_factor=0.01, end_factor=1.0, total_iters=100)\ncosine_sched = optim.lr_scheduler.CosineAnnealingLR(\n    optimizer, T_max=900, eta_min=1e-6)\nseq_sched = optim.lr_scheduler.SequentialLR(\n    optimizer, schedulers=[warmup_sched, cosine_sched], milestones=[100])\n\nprint(\u0027Scheduler types available in torch.optim.lr_scheduler:\u0027)\nschedulers = [\u0027StepLR\u0027, \u0027MultiStepLR\u0027, \u0027CosineAnnealingLR\u0027, \u0027OneCycleLR\u0027,\n              \u0027CosineAnnealingWarmRestarts\u0027, \u0027ReduceLROnPlateau\u0027,\n              \u0027LinearLR\u0027, \u0027SequentialLR\u0027, \u0027ChainedScheduler\u0027]\nfor s in schedulers:\n    print(\u0027  -\u0027, s)"},{"type":"heading","level":2,"content":"Learning Rate Finder (Range Test)"},{"type":"text","content":"The LR range test (Smith 2015) sweeps the LR log-linearly from a tiny value (1e-7) to a large value (10), training for one step per LR value. The loss initially decreases, reaches a minimum, then explodes. The optimal LR for training is roughly one order of magnitude below the LR where loss starts to diverge."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nimport math\n\ndef lr_range_test(model, loss_fn, data_iter, start_lr=1e-7,\n                  end_lr=10.0, num_steps=100):\n    # Sweep lr log-linearly; record loss at each step\n    lrs, losses = [], []\n    lr = start_lr\n    factor = (end_lr / start_lr) ** (1.0 / num_steps)\n\n    opt = optim.SGD(model.parameters(), lr=lr, momentum=0.9)\n\n    for step, (x, y) in enumerate(data_iter):\n        if step \u003e= num_steps:\n            break\n        for pg in opt.param_groups:\n            pg[\u0027lr\u0027] = lr\n        pred = model(x)\n        loss = loss_fn(pred, y)\n        opt.zero_grad()\n        loss.backward()\n        opt.step()\n        lrs.append(lr)\n        losses.append(loss.item())\n        lr *= factor\n\n    # Find steepest negative slope\n    best_idx, best_slope = 1, 0\n    for i in range(1, len(losses) - 1):\n        slope = losses[i+1] - losses[i-1]\n        if slope \u003c best_slope:\n            best_slope, best_idx = slope, i\n\n    print(\u0027LR range test complete (%d steps).\u0027 % num_steps)\n    print(\u0027Steepest descent at lr: %.2e\u0027 % lrs[best_idx])\n    print(\u0027Suggested training lr:  %.2e  (10x below steepest)\u0027 % (lrs[best_idx]/10))\n    return lrs, losses, lrs[best_idx]"},{"type":"heading","level":2,"content":"WSD Schedule for LLM Pretraining"},{"type":"text","content":"The Warmup-Stable-Decay (WSD) schedule is favored for LLM pretraining (MiniCPM, Llama 3 variants). It has three phases: (1) linear warmup to peak LR, (2) hold LR constant for the bulk of training (stable phase), (3) cosine decay to near-zero. The stable phase allows continued data scaling without the overhead of scheduling. The sharp final decay is what produces most of the loss improvement in the last ~10% of training."},{"type":"code","language":"python","content":"import math\n\ndef wsd_schedule(step, T_w, T_s, T_d, eta_max, eta_min=0.0):\n    # Warmup-Stable-Decay (WSD) schedule\n    # Phase 1 [0, T_w):          linear warmup\n    # Phase 2 [T_w, T_w+T_s):   stable (constant at eta_max)\n    # Phase 3 [T_w+T_s, total): cosine decay to eta_min\n    if step \u003c T_w:\n        return eta_max * step / max(T_w, 1)\n    elif step \u003c T_w + T_s:\n        return eta_max\n    else:\n        t = step - T_w - T_s\n        return eta_min + (eta_max - eta_min) * 0.5 * (1 + math.cos(math.pi * t / max(T_d, 1)))\n\n# Typical LLM pretraining budget: 100k steps\nT_w, T_s, T_d = 1000, 89000, 10000\neta_max = 3e-4\neta_min = 3e-5\nT_total = T_w + T_s + T_d\n\nprint(\u0027WSD schedule (%d total steps):\u0027 % T_total)\nprint(\u0027  Warmup: %d  Stable: %d  Decay: %d\u0027 % (T_w, T_s, T_d))\nprint(\u0027\u0027)\nprint(\u0027%-10s %-12s %s\u0027 % (\u0027Step\u0027, \u0027LR\u0027, \u0027Phase\u0027))\nfor step in [0, 500, 1000, 5000, 50000, 89000, 90000, 95000, 99999]:\n    if step \u003c T_total:\n        lr = wsd_schedule(step, T_w, T_s, T_d, eta_max, eta_min)\n        if step \u003c T_w:\n            phase = \u0027warmup\u0027\n        elif step \u003c T_w + T_s:\n            phase = \u0027stable\u0027\n        else:\n            phase = \u0027decay\u0027\n        print(\u0027%-10d %-12.2e %s\u0027 % (step, lr, phase))\nprint(\u0027\u0027)\nprint(\u0027Most compute budget in stable phase; decay delivers final convergence.\u0027)"},{"type":"table","headers":["Schedule","Formula / Shape","Key Hyperparameters","Best For"],"rows":[["Constant","η(t) = η₀","η₀","Prototyping, RL baselines"],["Step decay","η₀ · γ^⌊t/step_size⌋","η₀, γ, step_size","ResNets, CV training"],["Cosine annealing","η_min + (η_max−η_min)/2·(1+cos(πt/T))","η_min, η_max, T","Most deep learning tasks"],["1-Cycle","Warmup → peak → cosine decay","max_lr, pct_start","Fast training, super-convergence"],["WSD","Linear warmup → stable → cosine decay","η_max, T_w, T_s, T_d","LLM pretraining at scale"],["Cyclical LR","Repeated triangle waves","base_lr, max_lr, step_size","Escaping sharp minima"],["ReduceLROnPlateau","Decay when metric stops improving","factor, patience","Fine-tuning, unknown budgets"]]},{"type":"callout","variant":"tip","title":"LR Finder Before Committing to a Full Run","content":"Always run a 100-step LR range test before a full training run. Set your training LR to ≈1/10 of the LR where loss starts diverging. For Adam/AdamW, typical optimal LRs fall in [1e-4, 3e-3]; for Lion, divide by 10; for SGD with momentum, the range is much wider (0.01–0.1)."},{"type":"heading","level":2,"content":"Cyclical LR and Super-Convergence"},{"type":"text","content":"Cyclical learning rates (CLR, Smith 2017) oscillate between base_lr and max_lr with a fixed cycle length. The periodic increase lets the optimizer escape sharp minima (which often have narrow basins). Super-convergence is the empirical finding that CLR with a large max_lr can converge to good solutions in 5-10× fewer steps than step decay, at least for some architectures and datasets."},{"type":"list","ordered":false,"items":["CLR cycles between base_lr and max_lr — periodic LR increases help escape sharp minima","Super-convergence: 1-cycle with large max_lr can train ResNets in \u003c10 epochs (vs 100+)","Cosine annealing with warm restarts (SGDR): restart cycle at T_i, double period each restart","WSD: stable phase enables continued training without schedule engineering","For LLMs: WSD outperforms cosine decay on the longest training runs (100k+ steps)","ReduceLROnPlateau: adaptive schedule based on validation metric — useful for fine-tuning"]},{"type":"divider"},{"type":"text","content":"No single schedule is universally optimal. The right schedule depends on training duration, batch size (larger batches need higher LR by the linear scaling rule), optimizer (Adam vs SGD vs Lion), and whether you have a fixed compute budget. The LR finder, combined with WSD or cosine annealing, covers the majority of practical training scenarios."}]"
---
# Learning Rate Schedules

The learning rate is the single most important optimizer hyperparameter, yet a constant LR is almost never optimal. Modern training recipes combine a warmup phase (ramp from near-zero to peak LR), a main training phase, and a decay phase. Understanding why each phase exists — and how to find the right peak LR — is essential for training stable, well-converged models.

## Why Constant LR Fails

A constant LR that is too large causes divergence (loss spikes, NaN) because gradient steps overshoot the loss surface. A constant LR that is too small converges slowly and may land in a sharp, poorly generalizing minimum. Schedules combine a large LR early (to escape bad initialization) with a small LR late (to settle into a smooth minimum).

## Linear Warmup: Why It Matters

In Adam, the second moment v̂ = v/(1-β₂ᵗ) is near zero at initialization — Adam's bias correction compensates, but in practice early steps can still be large and unstable. Warmup starts at lr=0 (or a small fraction) and ramps linearly to peak_lr over warmup_steps. This lets v̂ stabilize before taking large steps, and avoids catastrophic early updates that can destroy freshly initialized weights.

> **How Long to Warm Up**: Typical warmup is 1–5% of total training steps. For LLM pretraining at 100k steps: 1000–5000 warmup steps. For fine-tuning short runs: 50–100 steps. Longer warmup is safer but delays reaching peak LR. The WSD schedule uses a fixed warmup of ~1% and then holds the LR stable for most of training.

## Cosine Annealing

Cosine annealing smoothly decays the LR: η(t) = η_min + (η_max − η_min)/2 · (1 + cos(πt/T)). At t=0 it equals η_max; at t=T it equals η_min. The smooth decay avoids the abrupt LR drops of step decay, which can cause sudden loss changes. Cosine annealing with warm restarts (SGDR) periodically resets t to 0, allowing the model to escape local minima.

```python
import numpy as np
import math

def cosine_anneal(step, T, eta_max=1e-3, eta_min=1e-6):
    # eta(t) = eta_min + (eta_max - eta_min)/2 * (1 + cos(pi*t/T))
    return eta_min + (eta_max - eta_min) * 0.5 * (1.0 + math.cos(math.pi * step / T))

def warmup_cosine(step, warmup, total, eta_max=1e-3, eta_min=1e-6):
    # Phase 1: linear warmup  [0, warmup)
    # Phase 2: cosine decay   [warmup, total]
    if step < warmup:
        return eta_max * step / max(warmup, 1)
    progress = (step - warmup) / max(total - warmup, 1)
    return eta_min + (eta_max - eta_min) * 0.5 * (1.0 + math.cos(math.pi * progress))

total, warmup = 1000, 100

print('Warmup + cosine annealing schedule:')
print('%-6s  %-12s  %s' % ('Step', 'LR', 'Bar'))
for t in [0, 25, 50, 100, 200, 400, 600, 800, 999]:
    lr  = warmup_cosine(t, warmup, total)
    bar = '#' * int(lr / 1e-3 * 30)
    print('%6d  %.4e    %s' % (t, lr, bar))

lrs = [warmup_cosine(t, warmup, total) for t in range(total)]
print('')
print('Peak LR: %.2e  |  Final LR: %.2e' % (max(lrs), lrs[-1]))
print('Warmup: %d steps  |  Cosine decay: %d steps' % (warmup, total - warmup))
```

## The 1-Cycle Policy

The 1-cycle policy (Smith 2017) uses a triangular LR schedule: ramp up from base_lr to max_lr over pct_start fraction of training, then decay from max_lr back to base_lr/div_factor. A final phase decays to base_lr/final_div_factor. This enables 'super-convergence' — training in far fewer iterations than step decay. PyTorch provides OneCycleLR out of the box.

```python
import torch
import torch.nn as nn
import torch.optim as optim

model = nn.Linear(10, 2)
optimizer = optim.AdamW(model.parameters(), lr=1e-3)

# 1. OneCycleLR: warmup -> peak -> cosine anneal
one_cycle = optim.lr_scheduler.OneCycleLR(
    optimizer,
    max_lr=1e-2,
    total_steps=1000,
    pct_start=0.1,           # 10% warmup
    anneal_strategy='cos',
    div_factor=25,            # start lr = max_lr / 25
    final_div_factor=1e4      # end lr = start_lr / 1e4
)

# 2. CosineAnnealingLR
cos_sched = optim.lr_scheduler.CosineAnnealingLR(
    optimizer, T_max=1000, eta_min=1e-6)

# 3. Linear warmup -> Cosine decay (SequentialLR)
warmup_sched = optim.lr_scheduler.LinearLR(
    optimizer, start_factor=0.01, end_factor=1.0, total_iters=100)
cosine_sched = optim.lr_scheduler.CosineAnnealingLR(
    optimizer, T_max=900, eta_min=1e-6)
seq_sched = optim.lr_scheduler.SequentialLR(
    optimizer, schedulers=[warmup_sched, cosine_sched], milestones=[100])

print('Scheduler types available in torch.optim.lr_scheduler:')
schedulers = ['StepLR', 'MultiStepLR', 'CosineAnnealingLR', 'OneCycleLR',
              'CosineAnnealingWarmRestarts', 'ReduceLROnPlateau',
              'LinearLR', 'SequentialLR', 'ChainedScheduler']
for s in schedulers:
    print('  -', s)
```

## Learning Rate Finder (Range Test)

The LR range test (Smith 2015) sweeps the LR log-linearly from a tiny value (1e-7) to a large value (10), training for one step per LR value. The loss initially decreases, reaches a minimum, then explodes. The optimal LR for training is roughly one order of magnitude below the LR where loss starts to diverge.

```python
import torch
import torch.nn as nn
import torch.optim as optim
import math

def lr_range_test(model, loss_fn, data_iter, start_lr=1e-7,
                  end_lr=10.0, num_steps=100):
    # Sweep lr log-linearly; record loss at each step
    lrs, losses = [], []
    lr = start_lr
    factor = (end_lr / start_lr) ** (1.0 / num_steps)

    opt = optim.SGD(model.parameters(), lr=lr, momentum=0.9)

    for step, (x, y) in enumerate(data_iter):
        if step >= num_steps:
            break
        for pg in opt.param_groups:
            pg['lr'] = lr
        pred = model(x)
        loss = loss_fn(pred, y)
        opt.zero_grad()
        loss.backward()
        opt.step()
        lrs.append(lr)
        losses.append(loss.item())
        lr *= factor

    # Find steepest negative slope
    best_idx, best_slope = 1, 0
    for i in range(1, len(losses) - 1):
        slope = losses[i+1] - losses[i-1]
        if slope < best_slope:
            best_slope, best_idx = slope, i

    print('LR range test complete (%d steps).' % num_steps)
    print('Steepest descent at lr: %.2e' % lrs[best_idx])
    print('Suggested training lr:  %.2e  (10x below steepest)' % (lrs[best_idx]/10))
    return lrs, losses, lrs[best_idx]
```

## WSD Schedule for LLM Pretraining

The Warmup-Stable-Decay (WSD) schedule is favored for LLM pretraining (MiniCPM, Llama 3 variants). It has three phases: (1) linear warmup to peak LR, (2) hold LR constant for the bulk of training (stable phase), (3) cosine decay to near-zero. The stable phase allows continued data scaling without the overhead of scheduling. The sharp final decay is what produces most of the loss improvement in the last ~10% of training.

```python
import math

def wsd_schedule(step, T_w, T_s, T_d, eta_max, eta_min=0.0):
    # Warmup-Stable-Decay (WSD) schedule
    # Phase 1 [0, T_w):          linear warmup
    # Phase 2 [T_w, T_w+T_s):   stable (constant at eta_max)
    # Phase 3 [T_w+T_s, total): cosine decay to eta_min
    if step < T_w:
        return eta_max * step / max(T_w, 1)
    elif step < T_w + T_s:
        return eta_max
    else:
        t = step - T_w - T_s
        return eta_min + (eta_max - eta_min) * 0.5 * (1 + math.cos(math.pi * t / max(T_d, 1)))

# Typical LLM pretraining budget: 100k steps
T_w, T_s, T_d = 1000, 89000, 10000
eta_max = 3e-4
eta_min = 3e-5
T_total = T_w + T_s + T_d

print('WSD schedule (%d total steps):' % T_total)
print('  Warmup: %d  Stable: %d  Decay: %d' % (T_w, T_s, T_d))
print('')
print('%-10s %-12s %s' % ('Step', 'LR', 'Phase'))
for step in [0, 500, 1000, 5000, 50000, 89000, 90000, 95000, 99999]:
    if step < T_total:
        lr = wsd_schedule(step, T_w, T_s, T_d, eta_max, eta_min)
        if step < T_w:
            phase = 'warmup'
        elif step < T_w + T_s:
            phase = 'stable'
        else:
            phase = 'decay'
        print('%-10d %-12.2e %s' % (step, lr, phase))
print('')
print('Most compute budget in stable phase; decay delivers final convergence.')
```

| Schedule | Formula / Shape | Key Hyperparameters | Best For |
| --- | --- | --- | --- |
| Constant | η(t) = η₀ | η₀ | Prototyping, RL baselines |
| Step decay | η₀ · γ^⌊t/step_size⌋ | η₀, γ, step_size | ResNets, CV training |
| Cosine annealing | η_min + (η_max−η_min)/2·(1+cos(πt/T)) | η_min, η_max, T | Most deep learning tasks |
| 1-Cycle | Warmup → peak → cosine decay | max_lr, pct_start | Fast training, super-convergence |
| WSD | Linear warmup → stable → cosine decay | η_max, T_w, T_s, T_d | LLM pretraining at scale |
| Cyclical LR | Repeated triangle waves | base_lr, max_lr, step_size | Escaping sharp minima |
| ReduceLROnPlateau | Decay when metric stops improving | factor, patience | Fine-tuning, unknown budgets |

> **LR Finder Before Committing to a Full Run**: Always run a 100-step LR range test before a full training run. Set your training LR to ≈1/10 of the LR where loss starts diverging. For Adam/AdamW, typical optimal LRs fall in [1e-4, 3e-3]; for Lion, divide by 10; for SGD with momentum, the range is much wider (0.01–0.1).

## Cyclical LR and Super-Convergence

Cyclical learning rates (CLR, Smith 2017) oscillate between base_lr and max_lr with a fixed cycle length. The periodic increase lets the optimizer escape sharp minima (which often have narrow basins). Super-convergence is the empirical finding that CLR with a large max_lr can converge to good solutions in 5-10× fewer steps than step decay, at least for some architectures and datasets.

- CLR cycles between base_lr and max_lr — periodic LR increases help escape sharp minima
- Super-convergence: 1-cycle with large max_lr can train ResNets in <10 epochs (vs 100+)
- Cosine annealing with warm restarts (SGDR): restart cycle at T_i, double period each restart
- WSD: stable phase enables continued training without schedule engineering
- For LLMs: WSD outperforms cosine decay on the longest training runs (100k+ steps)
- ReduceLROnPlateau: adaptive schedule based on validation metric — useful for fine-tuning

---

No single schedule is universally optimal. The right schedule depends on training duration, batch size (larger batches need higher LR by the linear scaling rule), optimizer (Adam vs SGD vs Lion), and whether you have a fixed compute budget. The LR finder, combined with WSD or cosine annealing, covers the majority of practical training scenarios.

