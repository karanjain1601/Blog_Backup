---
title: "Consistency Models — Single-Step Distillation"
slug: "consistency-models"
description: "Consistency models define a function that maps any point on a diffusion trajectory to the same clean endpoint x_0, enabling single-step generation via consistency training or distillation from a diffusion teacher, with Latent Consistency Models bringing 4-step generation to Stable Diffusion."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Consistency models (Song et al. 2023) are a new family of generative models that produce high-quality samples in one or a few steps. The core idea is to train a consistency function f_θ(x_t, t) that maps any point on a diffusion trajectory — regardless of the noise level t — to the same clean data point x_0. Once such a function exists, generation is trivial: sample Gaussian noise, apply f_θ once, and obtain a sample. Multi-step refinement is also possible by alternating between adding small amounts of noise and re-applying f_θ, trading compute for quality."},{"type":"heading","level":2,"content":"Consistency Function and Boundary Condition"},{"type":"text","content":"The consistency function f_θ: (x_t, t) → x_0 must satisfy the self-consistency property: f_θ(x_t, t) = f_θ(x_s, s) for all t, s on the same trajectory starting from x_0. This means that denoising from any noise level returns the same endpoint. The boundary condition f_θ(x_0, 0) = x_0 is enforced architecturally by parameterising f_θ as a skip connection: f_θ(x,t) = c_skip(t)·x + c_out(t)·F_θ(x,t), where c_skip(0)=1 and c_out(0)=0 force the network to act as identity at t=0."},{"type":"heading","level":2,"content":"Consistency Training"},{"type":"text","content":"Consistency Training (CT) trains f_θ from scratch without a diffusion teacher by using a bootstrap target: an exponential moving average (EMA) of past parameters θ^- acts as a slow-moving target network. The CT loss enforces consistency between adjacent timestep pairs: L_CT = E[d(f_θ(x_{t_{n+1}}, t_{n+1}), f_{θ^-}(x̂_{t_n}, t_n))] where x̂_{t_n} is obtained by running one Euler step backward from x_{t_{n+1}} using the current EMA model. The EMA update θ^- ← μ·θ^- + (1-μ)·θ prevents the target from being identical to the student."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport copy\n\nclass ConsistencyModel(nn.Module):\n    \"\"\"Toy consistency model with skip-connection boundary condition.\"\"\"\n    def __init__(self, dim=2, hidden=128, t_min=0.002, t_max=80.0):\n        super().__init__()\n        self.t_min, self.t_max = t_min, t_max\n        self.net = nn.Sequential(\n            nn.Linear(dim + 1, hidden), nn.SiLU(),\n            nn.Linear(hidden, hidden), nn.SiLU(),\n            nn.Linear(hidden, dim)\n        )\n\n    def c_skip(self, t):\n        return self.t_min ** 2 / (t ** 2 + self.t_min ** 2)\n\n    def c_out(self, t):\n        return t * self.t_min / (t ** 2 + self.t_min ** 2) ** 0.5\n\n    def forward(self, x, t):\n        t_emb = t[:, None].expand(x.shape[0], 1)\n        F_out = self.net(torch.cat([x, t_emb], dim=-1))\n        skip = self.c_skip(t)[:, None] * x\n        out  = self.c_out(t)[:, None] * F_out\n        return skip + out  # boundary: at t=t_min this equals x\n\ndef ct_loss(student, ema_model, x0, t_n, t_n1, noise=None):\n    if noise is None:\n        noise = torch.randn_like(x0)\n    x_t1 = x0 + t_n1[:, None] * noise           # noisy at t_{n+1}\n    x_t0_hat = x_t1 - (t_n1 - t_n)[:, None] * noise  # Euler step to t_n\n    with torch.no_grad():\n        target = ema_model(x_t0_hat.detach(), t_n)\n    pred = student(x_t1, t_n1)\n    return F.mse_loss(pred, target)\n\nprint(\u0027CT: trains from scratch using EMA target — no teacher diffusion model needed\u0027)"},{"type":"heading","level":2,"content":"Consistency Distillation"},{"type":"text","content":"Consistency Distillation (CD) leverages a pretrained diffusion model as a teacher. The teacher\u0027s score function is used to compute accurate one-step estimates of x_0 from any x_t. The student consistency model is trained to match these teacher-derived x_0 estimates at adjacent time steps. CD typically achieves higher quality than CT at the same sparsity because the teacher provides better targets, but it requires a pretrained score model as a prerequisite."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef score_to_x0(x_t, t, score_pred, sigma):\n    \"\"\"Convert score prediction to x_0 estimate (Tweedie\u0027s formula).\"\"\"\n    return x_t + sigma[:, None] ** 2 * score_pred\n\ndef cd_loss(student, teacher_score_fn, x0, t_n, t_n1):\n    \"\"\"Consistency distillation: student matches teacher\u0027s x_0 estimate.\"\"\"\n    noise = torch.randn_like(x0)\n    sigma_n1 = t_n1\n    x_t1 = x0 + sigma_n1[:, None] * noise  # noisy sample at t_{n+1}\n\n    # Teacher predicts score at x_t1\n    with torch.no_grad():\n        score = teacher_score_fn(x_t1, t_n1)\n        x0_teacher = score_to_x0(x_t1, t_n1, score, sigma_n1)\n        # One Euler step to t_n using teacher\n        x_t0 = x_t1 + (t_n[:, None] - t_n1[:, None]) * score\n        target = student(x_t0, t_n).detach()\n\n    pred = student(x_t1, t_n1)\n    return F.mse_loss(pred, target) + 0.1 * F.mse_loss(pred, x0_teacher)\n\n# Demo teacher (random, replace with real pretrained score model)\nteacher = lambda x, t: -x / (t[:, None] + 1e-3)  # toy score\nstudent = nn.Sequential(nn.Linear(3, 64), nn.SiLU(), nn.Linear(64, 2))\nx0 = torch.randn(32, 2)\nt_n  = torch.rand(32) * 0.5\nt_n1 = t_n + 0.1\nprint(f\u0027CD requires teacher diffusion model — achieves higher quality than CT alone\u0027)"},{"type":"heading","level":2,"content":"Sampling with Consistency Models"},{"type":"text","content":"Single-step generation is straightforward: sample x_T ~ N(0, T²I) and apply f_θ(x_T, T) once to get x_0. Multi-step generation alternates between denoising and re-noising: apply f_θ to get x_0 estimate, add Gaussian noise at a lower level t_{n-1}, then apply f_θ again. Each additional step improves quality by allowing the model to refine its estimate. Typically 1-4 steps are sufficient to match or approach the quality of 1000-step DDPM."},{"type":"code","language":"python","content":"import torch\n\ndef cm_sample_multistep(model, n_samples=256, steps=None, device=\u0027cpu\u0027, t_max=80.0):\n    \"\"\"Multi-step consistency model sampling: denoise -\u003e add noise -\u003e denoise.\"\"\"\n    if steps is None:\n        steps = [t_max, 20.0, 5.0, 1.0]  # decreasing noise schedule\n    x = torch.randn(n_samples, 2, device=device) * t_max\n    with torch.no_grad():\n        # First denoising step from t_max\n        t = torch.full((n_samples,), steps[0], device=device)\n        x0_hat = model(x, t)\n        print(f\u0027Step 0 (t={steps[0]}): x0_hat mean={x0_hat.mean():.4f}\u0027)\n        for i, t_val in enumerate(steps[1:], 1):\n            # Add noise at level t_val, then denoise again\n            noise = torch.randn_like(x0_hat)\n            x_noisy = x0_hat + t_val * noise\n            t_batch = torch.full((n_samples,), t_val, device=device)\n            x0_hat = model(x_noisy, t_batch)\n            print(f\u0027Step {i} (t={t_val}): x0_hat mean={x0_hat.mean():.4f}\u0027)\n    return x0_hat\n\ntorch.manual_seed(42)\nmodel = torch.nn.Sequential(\n    torch.nn.Linear(3, 64), torch.nn.SiLU(), torch.nn.Linear(64, 2)\n)\nsamples = cm_sample_multistep(model, n_samples=64)\nprint(f\u0027Final samples shape: {samples.shape}\u0027)"},{"type":"heading","level":2,"content":"Latent Consistency Models"},{"type":"text","content":"Latent Consistency Models (LCM, Luo et al. 2023) apply consistency distillation to the latent space of Stable Diffusion, inheriting its VAE and CLIP text encoder while replacing the U-Net denoising process. LCM distills a pretrained SD model into a consistency model that generates 512×512 images in 4-8 steps instead of 25-50 DDIM steps, achieving a 5-10× speedup with minimal quality loss. LCM-LoRA further reduces the adapter to only 67M parameters, enabling efficient fine-tuning on top of any SD checkpoint."},{"type":"code","language":"python","content":"import torch\nfrom diffusers import DiffusionPipeline, LCMScheduler\n\ndef run_lcm_inference(prompt, n_steps=4, guidance_scale=1.0, seed=0):\n    \"\"\"LCM: 4-step latent consistency model generation.\"\"\"\n    device = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\n    dtype  = torch.float16 if device == \u0027cuda\u0027 else torch.float32\n    pipe = DiffusionPipeline.from_pretrained(\n        \u0027SimianLuo/LCM_Dreamshaper_v7\u0027,\n        torch_dtype=dtype,\n    ).to(device)\n    pipe.scheduler = LCMScheduler.from_config(pipe.scheduler.config)\n    generator = torch.Generator(device=device).manual_seed(seed)\n    with torch.inference_mode():\n        result = pipe(\n            prompt,\n            num_inference_steps=n_steps,\n            guidance_scale=guidance_scale,  # LCM works well with CFG=1.0\n            generator=generator,\n        )\n    img = result.images[0]\n    print(f\u0027LCM generated {img.size} image in {n_steps} steps (vs 25-50 for DDIM)\u0027)\n    return img\n\nprint(\u0027LCM pipeline stages:\u0027)\nprint(\u0027  1. Same CLIP encoder + VAE as SD 1.5\u0027)\nprint(\u0027  2. LCM scheduler: skipping-step consistency distillation\u0027)\nprint(\u0027  3. 4-step inference: t=[980,760,499,235] -\u003e decode VAE\u0027)\nprint(\u0027  4. CFG=1.0 works well — no unconditional pass needed\u0027)"},{"type":"heading","level":2,"content":"Historical Context and Impact"},{"type":"text","content":"Consistency models filled a critical gap in 2023 when DDIM and DPM-Solver had pushed DDPM to ~20-50 steps but further reduction seemed to require fundamentally new training objectives. CM showed that single-step generation with near-DDPM quality is achievable via a principled self-consistency objective. This inspired a wave of distillation approaches — ADD (Adversarial Diffusion Distillation), DMD (Distribution Matching Distillation), and Lightning T2I — each using different loss functions but sharing the goal of reducing NFE below 10. LCM-LoRA made this accessible to the community without full retraining."},{"type":"callout","variant":"warning","title":"CT vs CD Quality Gap","content":"Consistency Training (CT) trains from scratch and avoids the need for a teacher model but typically achieves higher FID than Consistency Distillation (CD) at the same number of steps. For production use where quality is critical, prefer CD over CT. The EMA target quality in CT degrades when the teacher (EMA model) is too far from the student — use a small EMA decay (μ=0.99-0.9999) and monitor the consistency loss carefully."},{"type":"table","headers":["Method","NFE","FID (ImageNet 64×64)","Training","Requires Teacher","Notable Use"],"rows":[["DDPM","1000","3.17","Score matching (denoising)","No","Baseline generative model"],["DDIM","50","4.67","Same as DDPM — no retraining","No (uses DDPM weights)","Fast inference from DDPM"],["CM (CD, 1-step)","1","6.20","Distillation from DDPM teacher","Yes","Fastest single-step generation"],["CM (CD, 2-step)","2","4.70","Distillation from DDPM teacher","Yes","Near-DDIM quality in 2 steps"],["LCM (SD latent)","4","~comparable to DDIM-25","CD in latent space","Yes (SD U-Net)","Fast SD-quality generation"]]},{"type":"list","ordered":false,"items":["The boundary condition c_skip(0)=1, c_out(0)=0 is architectural — hard-coded, not learned.","Multi-step CM sampling uses a geometric noise schedule: start at t_max, add decreasing amounts of noise at each step.","LCM-LoRA trains only 67M extra parameters on top of any SD checkpoint — it does not require a full retrain.","LCM guidance scale of 1.0-2.0 works well because consistency distillation bakes CFG into the model during training.","EMA decay μ in CT is critical: too small causes instability; too large slows learning. Start with μ=0.999 and increase to 0.9999 late in training."]},{"type":"heading","level":2,"content":"Relation to Other Fast Samplers"},{"type":"text","content":"DDIM and DPM-Solver++ accelerate inference by exploiting the ODE structure of the DDPM probability flow without retraining. They reduce NFE to 20-50 steps but cannot achieve single-step generation. Consistency models, by contrast, require a new training objective (distillation or CT) but achieve 1-4 NFE. ADD (Adversarial Diffusion Distillation) combines the distillation objective with a GAN discriminator, achieving SDXL-quality in 4 steps. Progressive distillation (Salimans \u0026 Ho 2022) halves the required steps iteratively and is a precursor to full consistency distillation."},{"type":"divider"}]"
---
# Consistency Models — Single-Step Distillation

Consistency models (Song et al. 2023) are a new family of generative models that produce high-quality samples in one or a few steps. The core idea is to train a consistency function f_θ(x_t, t) that maps any point on a diffusion trajectory — regardless of the noise level t — to the same clean data point x_0. Once such a function exists, generation is trivial: sample Gaussian noise, apply f_θ once, and obtain a sample. Multi-step refinement is also possible by alternating between adding small amounts of noise and re-applying f_θ, trading compute for quality.

## Consistency Function and Boundary Condition

The consistency function f_θ: (x_t, t) → x_0 must satisfy the self-consistency property: f_θ(x_t, t) = f_θ(x_s, s) for all t, s on the same trajectory starting from x_0. This means that denoising from any noise level returns the same endpoint. The boundary condition f_θ(x_0, 0) = x_0 is enforced architecturally by parameterising f_θ as a skip connection: f_θ(x,t) = c_skip(t)·x + c_out(t)·F_θ(x,t), where c_skip(0)=1 and c_out(0)=0 force the network to act as identity at t=0.

## Consistency Training

Consistency Training (CT) trains f_θ from scratch without a diffusion teacher by using a bootstrap target: an exponential moving average (EMA) of past parameters θ^- acts as a slow-moving target network. The CT loss enforces consistency between adjacent timestep pairs: L_CT = E[d(f_θ(x_{t_{n+1}}, t_{n+1}), f_{θ^-}(x̂_{t_n}, t_n))] where x̂_{t_n} is obtained by running one Euler step backward from x_{t_{n+1}} using the current EMA model. The EMA update θ^- ← μ·θ^- + (1-μ)·θ prevents the target from being identical to the student.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import copy

class ConsistencyModel(nn.Module):
    """Toy consistency model with skip-connection boundary condition."""
    def __init__(self, dim=2, hidden=128, t_min=0.002, t_max=80.0):
        super().__init__()
        self.t_min, self.t_max = t_min, t_max
        self.net = nn.Sequential(
            nn.Linear(dim + 1, hidden), nn.SiLU(),
            nn.Linear(hidden, hidden), nn.SiLU(),
            nn.Linear(hidden, dim)
        )

    def c_skip(self, t):
        return self.t_min ** 2 / (t ** 2 + self.t_min ** 2)

    def c_out(self, t):
        return t * self.t_min / (t ** 2 + self.t_min ** 2) ** 0.5

    def forward(self, x, t):
        t_emb = t[:, None].expand(x.shape[0], 1)
        F_out = self.net(torch.cat([x, t_emb], dim=-1))
        skip = self.c_skip(t)[:, None] * x
        out  = self.c_out(t)[:, None] * F_out
        return skip + out  # boundary: at t=t_min this equals x

def ct_loss(student, ema_model, x0, t_n, t_n1, noise=None):
    if noise is None:
        noise = torch.randn_like(x0)
    x_t1 = x0 + t_n1[:, None] * noise           # noisy at t_{n+1}
    x_t0_hat = x_t1 - (t_n1 - t_n)[:, None] * noise  # Euler step to t_n
    with torch.no_grad():
        target = ema_model(x_t0_hat.detach(), t_n)
    pred = student(x_t1, t_n1)
    return F.mse_loss(pred, target)

print('CT: trains from scratch using EMA target — no teacher diffusion model needed')
```

## Consistency Distillation

Consistency Distillation (CD) leverages a pretrained diffusion model as a teacher. The teacher's score function is used to compute accurate one-step estimates of x_0 from any x_t. The student consistency model is trained to match these teacher-derived x_0 estimates at adjacent time steps. CD typically achieves higher quality than CT at the same sparsity because the teacher provides better targets, but it requires a pretrained score model as a prerequisite.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def score_to_x0(x_t, t, score_pred, sigma):
    """Convert score prediction to x_0 estimate (Tweedie's formula)."""
    return x_t + sigma[:, None] ** 2 * score_pred

def cd_loss(student, teacher_score_fn, x0, t_n, t_n1):
    """Consistency distillation: student matches teacher's x_0 estimate."""
    noise = torch.randn_like(x0)
    sigma_n1 = t_n1
    x_t1 = x0 + sigma_n1[:, None] * noise  # noisy sample at t_{n+1}

    # Teacher predicts score at x_t1
    with torch.no_grad():
        score = teacher_score_fn(x_t1, t_n1)
        x0_teacher = score_to_x0(x_t1, t_n1, score, sigma_n1)
        # One Euler step to t_n using teacher
        x_t0 = x_t1 + (t_n[:, None] - t_n1[:, None]) * score
        target = student(x_t0, t_n).detach()

    pred = student(x_t1, t_n1)
    return F.mse_loss(pred, target) + 0.1 * F.mse_loss(pred, x0_teacher)

# Demo teacher (random, replace with real pretrained score model)
teacher = lambda x, t: -x / (t[:, None] + 1e-3)  # toy score
student = nn.Sequential(nn.Linear(3, 64), nn.SiLU(), nn.Linear(64, 2))
x0 = torch.randn(32, 2)
t_n  = torch.rand(32) * 0.5
t_n1 = t_n + 0.1
print(f'CD requires teacher diffusion model — achieves higher quality than CT alone')
```

## Sampling with Consistency Models

Single-step generation is straightforward: sample x_T ~ N(0, T²I) and apply f_θ(x_T, T) once to get x_0. Multi-step generation alternates between denoising and re-noising: apply f_θ to get x_0 estimate, add Gaussian noise at a lower level t_{n-1}, then apply f_θ again. Each additional step improves quality by allowing the model to refine its estimate. Typically 1-4 steps are sufficient to match or approach the quality of 1000-step DDPM.

```python
import torch

def cm_sample_multistep(model, n_samples=256, steps=None, device='cpu', t_max=80.0):
    """Multi-step consistency model sampling: denoise -> add noise -> denoise."""
    if steps is None:
        steps = [t_max, 20.0, 5.0, 1.0]  # decreasing noise schedule
    x = torch.randn(n_samples, 2, device=device) * t_max
    with torch.no_grad():
        # First denoising step from t_max
        t = torch.full((n_samples,), steps[0], device=device)
        x0_hat = model(x, t)
        print(f'Step 0 (t={steps[0]}): x0_hat mean={x0_hat.mean():.4f}')
        for i, t_val in enumerate(steps[1:], 1):
            # Add noise at level t_val, then denoise again
            noise = torch.randn_like(x0_hat)
            x_noisy = x0_hat + t_val * noise
            t_batch = torch.full((n_samples,), t_val, device=device)
            x0_hat = model(x_noisy, t_batch)
            print(f'Step {i} (t={t_val}): x0_hat mean={x0_hat.mean():.4f}')
    return x0_hat

torch.manual_seed(42)
model = torch.nn.Sequential(
    torch.nn.Linear(3, 64), torch.nn.SiLU(), torch.nn.Linear(64, 2)
)
samples = cm_sample_multistep(model, n_samples=64)
print(f'Final samples shape: {samples.shape}')
```

## Latent Consistency Models

Latent Consistency Models (LCM, Luo et al. 2023) apply consistency distillation to the latent space of Stable Diffusion, inheriting its VAE and CLIP text encoder while replacing the U-Net denoising process. LCM distills a pretrained SD model into a consistency model that generates 512×512 images in 4-8 steps instead of 25-50 DDIM steps, achieving a 5-10× speedup with minimal quality loss. LCM-LoRA further reduces the adapter to only 67M parameters, enabling efficient fine-tuning on top of any SD checkpoint.

```python
import torch
from diffusers import DiffusionPipeline, LCMScheduler

def run_lcm_inference(prompt, n_steps=4, guidance_scale=1.0, seed=0):
    """LCM: 4-step latent consistency model generation."""
    device = 'cuda' if torch.cuda.is_available() else 'cpu'
    dtype  = torch.float16 if device == 'cuda' else torch.float32
    pipe = DiffusionPipeline.from_pretrained(
        'SimianLuo/LCM_Dreamshaper_v7',
        torch_dtype=dtype,
    ).to(device)
    pipe.scheduler = LCMScheduler.from_config(pipe.scheduler.config)
    generator = torch.Generator(device=device).manual_seed(seed)
    with torch.inference_mode():
        result = pipe(
            prompt,
            num_inference_steps=n_steps,
            guidance_scale=guidance_scale,  # LCM works well with CFG=1.0
            generator=generator,
        )
    img = result.images[0]
    print(f'LCM generated {img.size} image in {n_steps} steps (vs 25-50 for DDIM)')
    return img

print('LCM pipeline stages:')
print('  1. Same CLIP encoder + VAE as SD 1.5')
print('  2. LCM scheduler: skipping-step consistency distillation')
print('  3. 4-step inference: t=[980,760,499,235] -> decode VAE')
print('  4. CFG=1.0 works well — no unconditional pass needed')
```

## Historical Context and Impact

Consistency models filled a critical gap in 2023 when DDIM and DPM-Solver had pushed DDPM to ~20-50 steps but further reduction seemed to require fundamentally new training objectives. CM showed that single-step generation with near-DDPM quality is achievable via a principled self-consistency objective. This inspired a wave of distillation approaches — ADD (Adversarial Diffusion Distillation), DMD (Distribution Matching Distillation), and Lightning T2I — each using different loss functions but sharing the goal of reducing NFE below 10. LCM-LoRA made this accessible to the community without full retraining.

> **CT vs CD Quality Gap**: Consistency Training (CT) trains from scratch and avoids the need for a teacher model but typically achieves higher FID than Consistency Distillation (CD) at the same number of steps. For production use where quality is critical, prefer CD over CT. The EMA target quality in CT degrades when the teacher (EMA model) is too far from the student — use a small EMA decay (μ=0.99-0.9999) and monitor the consistency loss carefully.

| Method | NFE | FID (ImageNet 64×64) | Training | Requires Teacher | Notable Use |
| --- | --- | --- | --- | --- | --- |
| DDPM | 1000 | 3.17 | Score matching (denoising) | No | Baseline generative model |
| DDIM | 50 | 4.67 | Same as DDPM — no retraining | No (uses DDPM weights) | Fast inference from DDPM |
| CM (CD, 1-step) | 1 | 6.20 | Distillation from DDPM teacher | Yes | Fastest single-step generation |
| CM (CD, 2-step) | 2 | 4.70 | Distillation from DDPM teacher | Yes | Near-DDIM quality in 2 steps |
| LCM (SD latent) | 4 | ~comparable to DDIM-25 | CD in latent space | Yes (SD U-Net) | Fast SD-quality generation |

- The boundary condition c_skip(0)=1, c_out(0)=0 is architectural — hard-coded, not learned.
- Multi-step CM sampling uses a geometric noise schedule: start at t_max, add decreasing amounts of noise at each step.
- LCM-LoRA trains only 67M extra parameters on top of any SD checkpoint — it does not require a full retrain.
- LCM guidance scale of 1.0-2.0 works well because consistency distillation bakes CFG into the model during training.
- EMA decay μ in CT is critical: too small causes instability; too large slows learning. Start with μ=0.999 and increase to 0.9999 late in training.

## Relation to Other Fast Samplers

DDIM and DPM-Solver++ accelerate inference by exploiting the ODE structure of the DDPM probability flow without retraining. They reduce NFE to 20-50 steps but cannot achieve single-step generation. Consistency models, by contrast, require a new training objective (distillation or CT) but achieve 1-4 NFE. ADD (Adversarial Diffusion Distillation) combines the distillation objective with a GAN discriminator, achieving SDXL-quality in 4 steps. Progressive distillation (Salimans & Ho 2022) halves the required steps iteratively and is a precursor to full consistency distillation.

---

