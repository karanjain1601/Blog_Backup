---
title: "Classifier Guidance — Conditional Generation via Gradient Steering"
slug: "classifier-guidance-diffusion"
description: "Derive classifier guidance from the conditional score, implement a noisy classifier trained at all noise levels, integrate classifier gradients into the DDPM denoising loop, sweep the guidance scale, and compare quality-diversity tradeoffs against unconditional and CFG baselines."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Classifier guidance (Dhariwal \u0026 Nichol 2021) was the first method to reliably push class-conditional diffusion models past GANs on ImageNet. The core idea: sample from p(x|y) ∝ p(x)·p(y|x) by steering each denoising step with the gradient of a classifier. The unconditional diffusion model provides the score ∇_x log p(x), while a separately trained classifier provides ∇_x log p(y|x). Combining them yields the conditional score — no conditional retraining of the diffusion model is required."},{"type":"heading","level":2,"content":"Conditional Generation via Bayes\u0027 Rule"},{"type":"text","content":"The conditional distribution p(x|y) = p(x)·p(y|x)/p(y). Taking log-gradients: ∇_x log p(x|y) = ∇_x log p(x) + ∇_x log p(y|x). The first term is the unconditional score (provided by the diffusion model); the second is the classifier gradient at x. At each denoising step t, we work with the noisy versions: ∇_{x_t} log p(x_t|y) = ∇_{x_t} log p_t(x_t) + ∇_{x_t} log p_φ(y|x_t). The modified epsilon is then ε̃ = ε_θ(x_t,t) − √(1−ᾱ_t)·s·∇_{x_t} log p_φ(y|x_t), where s \u003e 1 is the guidance scale."},{"type":"heading","level":2,"content":"Noisy Classifier Training"},{"type":"text","content":"The classifier p_φ(y|x_t) must be trained on noisy images at all noise levels t, not clean images. A classifier trained on clean images cannot provide reliable gradients in high-noise regions where x_t looks like pure noise. During training, the noise level t is sampled uniformly, x_t = √ᾱ_t·x + √(1−ᾱ_t)·ε is computed, and the classifier predicts the class from x_t. This trains the classifier to extract class signal from corrupted inputs across the full noise spectrum, enabling meaningful gradient signals at every denoising step."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport numpy as np\n\nclass NoisyClassifier(nn.Module):\n    def __init__(self, in_dim=32, n_classes=10, T=1000):\n        super().__init__()\n        self.time_embed = nn.Embedding(T, 16)\n        self.net = nn.Sequential(\n            nn.Linear(in_dim + 16, 128), nn.SiLU(),\n            nn.Linear(128, 64), nn.SiLU(),\n            nn.Linear(64, n_classes)\n        )\n    def forward(self, x_t, t):\n        t_emb = self.time_embed(t)\n        return self.net(torch.cat([x_t, t_emb], dim=-1))\n\ndef train_noisy_classifier(clf, data, labels, alpha_bar, n_steps=300):\n    opt = torch.optim.Adam(clf.parameters(), lr=1e-3)\n    T = len(alpha_bar)\n    for step in range(n_steps):\n        idx = torch.randint(0, len(data), (64,))\n        x0, y = data[idx], labels[idx]\n        t = torch.randint(0, T, (64,))\n        eps = torch.randn_like(x0)\n        ab = alpha_bar[t].unsqueeze(1)\n        x_t = torch.sqrt(ab) * x0 + torch.sqrt(1 - ab) * eps\n        logits = clf(x_t, t)\n        loss = F.cross_entropy(logits, y)\n        opt.zero_grad(); loss.backward(); opt.step()\n        if step % 100 == 0:\n            print(f\u0027Step {step}: classifier loss = {loss.item():.4f}\u0027)\n    return clf\n\ntorch.manual_seed(0)\nalpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)\ndata = torch.randn(500, 32)\nlabels = torch.randint(0, 10, (500,))\nclf = NoisyClassifier(in_dim=32)\ntrain_noisy_classifier(clf, data, labels, alpha_bar, n_steps=300)"},{"type":"heading","level":2,"content":"Classifier Guidance in the Denoising Loop"},{"type":"text","content":"At each denoising step, the classifier gradient steers the epsilon prediction toward higher class probability. The perturbed epsilon is: ε̃ = ε_θ(x_t,t) − s·√(1−ᾱ_t)·∇_{x_t} log p_φ(y|x_t). The factor √(1−ᾱ_t) converts the gradient from x-space to epsilon-space (since ε and ∇_{x_t} log p_t are related by this factor). The guidance scale s \u003e 1 amplifies the class signal beyond what the training distribution supports, trading diversity for fidelity. For s=1 this reduces to simple Bayesian conditioning; for s=5–10 the mode-seeking effect is strong."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n@torch.no_grad()\ndef guided_sampling(eps_model, classifier, y, alpha_bar,\n                    timesteps, guidance_scale=3.0, shape=(4, 32)):\n    \"\"\"Classifier-guided DDPM sampling loop.\"\"\"\n    x = torch.randn(shape)\n    B = shape[0]\n    for t in timesteps:\n        ab_t = alpha_bar[t]\n        ab_prev = alpha_bar[t - 1] if t \u003e 0 else torch.tensor(1.0)\n        t_batch = torch.full((B,), t, dtype=torch.long)\n        # Unconditional score (epsilon prediction)\n        eps_uncond = eps_model(x, t_batch)\n        # Classifier gradient\n        x_grad = x.detach().requires_grad_(True)\n        with torch.enable_grad():\n            logits = classifier(x_grad, t_batch)\n            log_prob = logits.log_softmax(dim=-1)[range(B), y]\n            grad = torch.autograd.grad(log_prob.sum(), x_grad)[0]\n        # Perturb epsilon by classifier gradient\n        eps_guided = eps_uncond - guidance_scale * torch.sqrt(1 - ab_t) * grad.detach()\n        # Standard DDPM reverse step\n        coef1 = 1.0 / torch.sqrt(1 - alpha_bar[t] / ab_prev)\n        x_prev_mean = coef1 * (x - (1 - ab_t/ab_prev) / torch.sqrt(1 - ab_t) * eps_guided)\n        noise = torch.randn_like(x) * torch.sqrt(1 - ab_prev) if t \u003e 0 else 0.0\n        x = x_prev_mean + noise\n    return x\n\nprint(\u0027Classifier guidance: steer eps at each step by classifier log-prob gradient\u0027)"},{"type":"heading","level":2,"content":"ADM Architecture"},{"type":"text","content":"Dhariwal \u0026 Nichol (2021) also introduced ADM (Ablated Diffusion Model) — a U-Net with adaptive group normalization, attention at multiple resolutions, and BigGAN residual blocks. ADM with classifier guidance achieved FID 4.59 on ImageNet 256×256, surpassing the best GANs (BigGAN-deep: FID 6.95). Key architectural improvements: attention heads with 64 channels instead of 128, multi-resolution attention (32×32, 16×16, 8×8), and increased depth. These architectural gains combined with classifier guidance established diffusion models as the new state-of-the-art on high-resolution class-conditional synthesis."},{"type":"heading","level":2,"content":"Guidance Scale Trade-off"},{"type":"text","content":"The guidance scale s controls the fidelity-diversity trade-off. At s=1, samples are drawn from the true conditional distribution p(x|y). At s \u003e 1, the sampling steers beyond the support of the training distribution toward high-class-probability modes. FID improves with s up to a point (typically s=2–5 for ImageNet), then degrades as samples become over-sharpened artifacts with unnatural colors. Inception Score (IS) measures class fidelity and keeps increasing with s. The s that minimizes FID ≠ the s that maximizes IS — practitioners plot both curves."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef simulate_guidance_tradeoff(guidance_scales, n_samples=200, seed=0):\n    \"\"\"Simulate FID vs IS tradeoff as guidance scale increases.\"\"\"\n    torch.manual_seed(seed)\n    results = []\n    for s in guidance_scales:\n        # Simulate quality (lower variance = higher fidelity but less diverse)\n        # At s=1: diverse but impure modes; at high s: mode-collapsed\n        rng = np.random.RandomState(seed)\n        # FID: U-shaped around optimal guidance\n        fid = 10.0 + (s - 3.5) ** 2 * 1.2 + rng.randn() * 0.3\n        # IS: monotonically increases with guidance (class fidelity)\n        inception_score = 20.0 + 8.0 * np.log(s + 1) + rng.randn() * 0.5\n        # Diversity (recall): decreases with guidance\n        recall = 0.60 * np.exp(-0.15 * (s - 1)) + rng.randn() * 0.02\n        results.append((s, max(fid, 1.0), inception_score, max(recall, 0.05)))\n    return results\n\nscales = [1, 1.5, 2, 3, 4, 5, 7, 10]\nprint(f\u0027{\"Scale\":\u003e6} | {\"FID\":\u003e6} | {\"IS\":\u003e8} | {\"Recall\":\u003e7}\u0027)\nprint(\u0027-\u0027 * 36)\nfor s, fid, IS, rec in simulate_guidance_tradeoff(scales):\n    print(f\u0027{s:6.1f} | {fid:6.2f} | {IS:8.2f} | {rec:7.3f}\u0027)"},{"type":"heading","level":2,"content":"Unconditional vs Guided Generation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef compare_guidance(eps_model, classifier, alpha_bar, n_steps=50, D=16, B=8):\n    \"\"\"Compare unconditional vs guided sampling at same NFE budget.\"\"\"\n    timesteps = list(range(0, 1000, 1000 // n_steps))[::-1]\n    y = torch.zeros(B, dtype=torch.long)  # class 0\n\n    def sample(guidance_scale):\n        torch.manual_seed(42)\n        x = torch.randn(B, D)\n        for t in timesteps:\n            ab = alpha_bar[t]\n            t_b = torch.full((B,), t, dtype=torch.long)\n            eps = eps_model(x, t_b)\n            if guidance_scale \u003e 1.0:\n                x_g = x.detach().requires_grad_(True)\n                with torch.enable_grad():\n                    lp = classifier(x_g, t_b).log_softmax(-1)[range(B), y]\n                    grad = torch.autograd.grad(lp.sum(), x_g)[0].detach()\n                eps = eps - guidance_scale * torch.sqrt(1 - ab) * grad\n            ab_p = alpha_bar[max(t-20, 0)]\n            x0 = (x - torch.sqrt(1-ab)*eps) / torch.sqrt(ab)\n            x = torch.sqrt(ab_p)*x0.clamp(-1,1) + torch.sqrt(1-ab_p)*eps\n        return x\n\n    for s in [1.0, 3.0, 7.0]:\n        out = sample(s)\n        print(f\u0027guidance_scale={s:4.1f}: norm={out.norm():.2f} std={out.std():.3f}\u0027)\n\nclass DummyEps(nn.Module):\n    def forward(self, x, t): return x * 0.05\nclass DummyClf(nn.Module):\n    def forward(self, x, t): return x[:, :10]  # treat first 10 dims as logits\nalpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)\ncompare_guidance(DummyEps(), DummyClf(), alpha_bar)"},{"type":"heading","level":2,"content":"Limitations of Classifier Guidance"},{"type":"text","content":"Classifier guidance has three practical limitations: (1) It requires a separately trained noisy classifier — double the training cost and complexity. (2) Every denoising step requires a gradient computation through the classifier (torch.autograd.grad), adding ~50% compute per step. (3) The classifier is trained on noisy images which is an unusual distribution — small training bugs can produce misleading gradients. These limitations motivated classifier-free guidance (Ho \u0026 Salimans 2022), which achieves the same effect using a single network with conditioning dropout."},{"type":"table","headers":["Method","Requires classifier","Guidance formula","FID (ImageNet 256)","Diversity","Practical complexity"],"rows":[["Unconditional DDPM","No","ε_θ(x_t, t) only","~26 (class-agnostic)","High","Low — one network"],["Classifier Guidance (s=3)","Yes — noisy classifier","ε_θ − s·√(1−ᾱ)·∇ log p(y|x_t)","~4.6 (ADM+guidance)","Medium","High — two networks, grad at each step"],["CFG (w=7)","No — joint model","ε_uncond + w·(ε_cond − ε_uncond)","~3.8 (LDM)","Medium","Low — one network, two forward passes"]]},{"type":"callout","variant":"warning","title":"Gradient Quality Degrades at High Noise","content":"Classifier gradients ∇_{x_t} log p_φ(y|x_t) become unreliable at high noise levels (t close to T) where x_t is nearly pure noise. If you see diverging samples or NaN outputs, check the gradient magnitude at high t — consider clipping the guidance signal (e.g. clamp gradient norm to 1.0) for the first 20% of denoising steps."},{"type":"list","ordered":false,"items":["Classifier guidance samples from p(x|y) ∝ p(x)·p(y|x) — theoretically grounded Bayesian conditioning.","The noisy classifier must be trained on {x_t, t} pairs across all t — training on only clean images fails.","Guidance scale s \u003e 1 amplifies class signal beyond the training distribution, trading recall for precision.","ADM + classifier guidance first beat GANs on ImageNet 256×256 (FID 4.59 vs BigGAN-deep 6.95).","Every step requires autograd through the classifier — adds ~50% compute vs unconditional sampling.","Classifier-free guidance (CFG) achieves similar or better quality without a separate classifier."]},{"type":"divider"}]"
---
# Classifier Guidance — Conditional Generation via Gradient Steering

Classifier guidance (Dhariwal & Nichol 2021) was the first method to reliably push class-conditional diffusion models past GANs on ImageNet. The core idea: sample from p(x|y) ∝ p(x)·p(y|x) by steering each denoising step with the gradient of a classifier. The unconditional diffusion model provides the score ∇_x log p(x), while a separately trained classifier provides ∇_x log p(y|x). Combining them yields the conditional score — no conditional retraining of the diffusion model is required.

## Conditional Generation via Bayes' Rule

The conditional distribution p(x|y) = p(x)·p(y|x)/p(y). Taking log-gradients: ∇_x log p(x|y) = ∇_x log p(x) + ∇_x log p(y|x). The first term is the unconditional score (provided by the diffusion model); the second is the classifier gradient at x. At each denoising step t, we work with the noisy versions: ∇_{x_t} log p(x_t|y) = ∇_{x_t} log p_t(x_t) + ∇_{x_t} log p_φ(y|x_t). The modified epsilon is then ε̃ = ε_θ(x_t,t) − √(1−ᾱ_t)·s·∇_{x_t} log p_φ(y|x_t), where s > 1 is the guidance scale.

## Noisy Classifier Training

The classifier p_φ(y|x_t) must be trained on noisy images at all noise levels t, not clean images. A classifier trained on clean images cannot provide reliable gradients in high-noise regions where x_t looks like pure noise. During training, the noise level t is sampled uniformly, x_t = √ᾱ_t·x + √(1−ᾱ_t)·ε is computed, and the classifier predicts the class from x_t. This trains the classifier to extract class signal from corrupted inputs across the full noise spectrum, enabling meaningful gradient signals at every denoising step.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np

class NoisyClassifier(nn.Module):
    def __init__(self, in_dim=32, n_classes=10, T=1000):
        super().__init__()
        self.time_embed = nn.Embedding(T, 16)
        self.net = nn.Sequential(
            nn.Linear(in_dim + 16, 128), nn.SiLU(),
            nn.Linear(128, 64), nn.SiLU(),
            nn.Linear(64, n_classes)
        )
    def forward(self, x_t, t):
        t_emb = self.time_embed(t)
        return self.net(torch.cat([x_t, t_emb], dim=-1))

def train_noisy_classifier(clf, data, labels, alpha_bar, n_steps=300):
    opt = torch.optim.Adam(clf.parameters(), lr=1e-3)
    T = len(alpha_bar)
    for step in range(n_steps):
        idx = torch.randint(0, len(data), (64,))
        x0, y = data[idx], labels[idx]
        t = torch.randint(0, T, (64,))
        eps = torch.randn_like(x0)
        ab = alpha_bar[t].unsqueeze(1)
        x_t = torch.sqrt(ab) * x0 + torch.sqrt(1 - ab) * eps
        logits = clf(x_t, t)
        loss = F.cross_entropy(logits, y)
        opt.zero_grad(); loss.backward(); opt.step()
        if step % 100 == 0:
            print(f'Step {step}: classifier loss = {loss.item():.4f}')
    return clf

torch.manual_seed(0)
alpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)
data = torch.randn(500, 32)
labels = torch.randint(0, 10, (500,))
clf = NoisyClassifier(in_dim=32)
train_noisy_classifier(clf, data, labels, alpha_bar, n_steps=300)
```

## Classifier Guidance in the Denoising Loop

At each denoising step, the classifier gradient steers the epsilon prediction toward higher class probability. The perturbed epsilon is: ε̃ = ε_θ(x_t,t) − s·√(1−ᾱ_t)·∇_{x_t} log p_φ(y|x_t). The factor √(1−ᾱ_t) converts the gradient from x-space to epsilon-space (since ε and ∇_{x_t} log p_t are related by this factor). The guidance scale s > 1 amplifies the class signal beyond what the training distribution supports, trading diversity for fidelity. For s=1 this reduces to simple Bayesian conditioning; for s=5–10 the mode-seeking effect is strong.

```python
import torch
import torch.nn as nn

@torch.no_grad()
def guided_sampling(eps_model, classifier, y, alpha_bar,
                    timesteps, guidance_scale=3.0, shape=(4, 32)):
    """Classifier-guided DDPM sampling loop."""
    x = torch.randn(shape)
    B = shape[0]
    for t in timesteps:
        ab_t = alpha_bar[t]
        ab_prev = alpha_bar[t - 1] if t > 0 else torch.tensor(1.0)
        t_batch = torch.full((B,), t, dtype=torch.long)
        # Unconditional score (epsilon prediction)
        eps_uncond = eps_model(x, t_batch)
        # Classifier gradient
        x_grad = x.detach().requires_grad_(True)
        with torch.enable_grad():
            logits = classifier(x_grad, t_batch)
            log_prob = logits.log_softmax(dim=-1)[range(B), y]
            grad = torch.autograd.grad(log_prob.sum(), x_grad)[0]
        # Perturb epsilon by classifier gradient
        eps_guided = eps_uncond - guidance_scale * torch.sqrt(1 - ab_t) * grad.detach()
        # Standard DDPM reverse step
        coef1 = 1.0 / torch.sqrt(1 - alpha_bar[t] / ab_prev)
        x_prev_mean = coef1 * (x - (1 - ab_t/ab_prev) / torch.sqrt(1 - ab_t) * eps_guided)
        noise = torch.randn_like(x) * torch.sqrt(1 - ab_prev) if t > 0 else 0.0
        x = x_prev_mean + noise
    return x

print('Classifier guidance: steer eps at each step by classifier log-prob gradient')
```

## ADM Architecture

Dhariwal & Nichol (2021) also introduced ADM (Ablated Diffusion Model) — a U-Net with adaptive group normalization, attention at multiple resolutions, and BigGAN residual blocks. ADM with classifier guidance achieved FID 4.59 on ImageNet 256×256, surpassing the best GANs (BigGAN-deep: FID 6.95). Key architectural improvements: attention heads with 64 channels instead of 128, multi-resolution attention (32×32, 16×16, 8×8), and increased depth. These architectural gains combined with classifier guidance established diffusion models as the new state-of-the-art on high-resolution class-conditional synthesis.

## Guidance Scale Trade-off

The guidance scale s controls the fidelity-diversity trade-off. At s=1, samples are drawn from the true conditional distribution p(x|y). At s > 1, the sampling steers beyond the support of the training distribution toward high-class-probability modes. FID improves with s up to a point (typically s=2–5 for ImageNet), then degrades as samples become over-sharpened artifacts with unnatural colors. Inception Score (IS) measures class fidelity and keeps increasing with s. The s that minimizes FID ≠ the s that maximizes IS — practitioners plot both curves.

```python
import torch
import torch.nn as nn
import numpy as np

def simulate_guidance_tradeoff(guidance_scales, n_samples=200, seed=0):
    """Simulate FID vs IS tradeoff as guidance scale increases."""
    torch.manual_seed(seed)
    results = []
    for s in guidance_scales:
        # Simulate quality (lower variance = higher fidelity but less diverse)
        # At s=1: diverse but impure modes; at high s: mode-collapsed
        rng = np.random.RandomState(seed)
        # FID: U-shaped around optimal guidance
        fid = 10.0 + (s - 3.5) ** 2 * 1.2 + rng.randn() * 0.3
        # IS: monotonically increases with guidance (class fidelity)
        inception_score = 20.0 + 8.0 * np.log(s + 1) + rng.randn() * 0.5
        # Diversity (recall): decreases with guidance
        recall = 0.60 * np.exp(-0.15 * (s - 1)) + rng.randn() * 0.02
        results.append((s, max(fid, 1.0), inception_score, max(recall, 0.05)))
    return results

scales = [1, 1.5, 2, 3, 4, 5, 7, 10]
print(f'{"Scale":>6} | {"FID":>6} | {"IS":>8} | {"Recall":>7}')
print('-' * 36)
for s, fid, IS, rec in simulate_guidance_tradeoff(scales):
    print(f'{s:6.1f} | {fid:6.2f} | {IS:8.2f} | {rec:7.3f}')
```

## Unconditional vs Guided Generation

```python
import torch
import torch.nn as nn
import numpy as np

def compare_guidance(eps_model, classifier, alpha_bar, n_steps=50, D=16, B=8):
    """Compare unconditional vs guided sampling at same NFE budget."""
    timesteps = list(range(0, 1000, 1000 // n_steps))[::-1]
    y = torch.zeros(B, dtype=torch.long)  # class 0

    def sample(guidance_scale):
        torch.manual_seed(42)
        x = torch.randn(B, D)
        for t in timesteps:
            ab = alpha_bar[t]
            t_b = torch.full((B,), t, dtype=torch.long)
            eps = eps_model(x, t_b)
            if guidance_scale > 1.0:
                x_g = x.detach().requires_grad_(True)
                with torch.enable_grad():
                    lp = classifier(x_g, t_b).log_softmax(-1)[range(B), y]
                    grad = torch.autograd.grad(lp.sum(), x_g)[0].detach()
                eps = eps - guidance_scale * torch.sqrt(1 - ab) * grad
            ab_p = alpha_bar[max(t-20, 0)]
            x0 = (x - torch.sqrt(1-ab)*eps) / torch.sqrt(ab)
            x = torch.sqrt(ab_p)*x0.clamp(-1,1) + torch.sqrt(1-ab_p)*eps
        return x

    for s in [1.0, 3.0, 7.0]:
        out = sample(s)
        print(f'guidance_scale={s:4.1f}: norm={out.norm():.2f} std={out.std():.3f}')

class DummyEps(nn.Module):
    def forward(self, x, t): return x * 0.05
class DummyClf(nn.Module):
    def forward(self, x, t): return x[:, :10]  # treat first 10 dims as logits
alpha_bar = torch.cumprod(1 - torch.linspace(1e-4, 0.02, 1000), dim=0)
compare_guidance(DummyEps(), DummyClf(), alpha_bar)
```

## Limitations of Classifier Guidance

Classifier guidance has three practical limitations: (1) It requires a separately trained noisy classifier — double the training cost and complexity. (2) Every denoising step requires a gradient computation through the classifier (torch.autograd.grad), adding ~50% compute per step. (3) The classifier is trained on noisy images which is an unusual distribution — small training bugs can produce misleading gradients. These limitations motivated classifier-free guidance (Ho & Salimans 2022), which achieves the same effect using a single network with conditioning dropout.

| Method | Requires classifier | Guidance formula | FID (ImageNet 256) | Diversity | Practical complexity |
| --- | --- | --- | --- | --- | --- |
| Unconditional DDPM | No | ε_θ(x_t, t) only | ~26 (class-agnostic) | High | Low — one network |
| Classifier Guidance (s=3) | Yes — noisy classifier | ε_θ − s·√(1−ᾱ)·∇ log p(y|x_t) | ~4.6 (ADM+guidance) | Medium | High — two networks, grad at each step |
| CFG (w=7) | No — joint model | ε_uncond + w·(ε_cond − ε_uncond) | ~3.8 (LDM) | Medium | Low — one network, two forward passes |

> **Gradient Quality Degrades at High Noise**: Classifier gradients ∇_{x_t} log p_φ(y|x_t) become unreliable at high noise levels (t close to T) where x_t is nearly pure noise. If you see diverging samples or NaN outputs, check the gradient magnitude at high t — consider clipping the guidance signal (e.g. clamp gradient norm to 1.0) for the first 20% of denoising steps.

- Classifier guidance samples from p(x|y) ∝ p(x)·p(y|x) — theoretically grounded Bayesian conditioning.
- The noisy classifier must be trained on {x_t, t} pairs across all t — training on only clean images fails.
- Guidance scale s > 1 amplifies class signal beyond the training distribution, trading recall for precision.
- ADM + classifier guidance first beat GANs on ImageNet 256×256 (FID 4.59 vs BigGAN-deep 6.95).
- Every step requires autograd through the classifier — adds ~50% compute vs unconditional sampling.
- Classifier-free guidance (CFG) achieves similar or better quality without a separate classifier.

---

