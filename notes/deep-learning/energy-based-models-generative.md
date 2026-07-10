---
title: "Energy-Based Models — Contrastive Divergence and Langevin Sampling"
slug: "energy-based-models-generative"
description: "Energy-based models define unnormalized densities via a learned energy function and train via contrastive divergence with MCMC sampling, with Langevin dynamics providing a gradient-based sampler that connects EBMs to score-based models and enables out-of-distribution detection."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Energy-Based Models (EBMs) define a probability distribution via an energy function E_θ(x): p_θ(x) = exp(-E_θ(x)) / Z(θ), where Z(θ) = ∫exp(-E_θ(x))dx is the partition function. Low energy corresponds to high probability — the model assigns low energy to data-like samples and high energy to unlikely ones. The central challenge is that Z(θ) is intractable for continuous high-dimensional x, so maximum likelihood training requires approximating the gradient of log Z with MCMC sampling. EBMs are a flexible framework that unifies Boltzmann machines, denoising autoencoders, and score-based models."},{"type":"heading","level":2,"content":"Energy Function and Unnormalized Density"},{"type":"text","content":"The gradient of the log-likelihood decomposes into two terms: ∇_θ log p_θ(x) = -∇_θ E_θ(x) + E_{p_θ}[∇_θ E_θ(x)]. The first term (data term) pushes down energy at real data points. The second term (model term) pushes up energy at model samples, computed by MCMC. If the model samples are high quality, this gradient correctly shapes the energy landscape. The data term is exact; the model term is estimated via k steps of Markov chain Monte Carlo from the current model distribution, making EBM training fundamentally tied to MCMC quality."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass EnergyNet(nn.Module):\n    \"\"\"Neural network energy function: maps input to scalar energy (lower = more likely).\"\"\"\n    def __init__(self, input_dim, hidden=256):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(input_dim, hidden), nn.LeakyReLU(0.2),\n            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),\n            nn.Linear(hidden, 1)\n        )\n\n    def energy(self, x):\n        return self.net(x).squeeze(-1)  # (B,)\n\n    def unnorm_log_prob(self, x):\n        return -self.energy(x)          # log p*(x) without Z\n\n# Demo: energy landscape over 2D grid\nebm = EnergyNet(input_dim=2)\ntorch.manual_seed(0)\ngrid = torch.stack(torch.meshgrid(\n    torch.linspace(-3, 3, 30), torch.linspace(-3, 3, 30), indexing=\u0027ij\u0027\n), dim=-1).reshape(-1, 2)\nwith torch.no_grad():\n    energies = ebm.energy(grid)\nprint(f\u0027Grid energy range: [{energies.min():.3f}, {energies.max():.3f}]\u0027)\nprint(f\u0027Energy at origin: {ebm.energy(torch.zeros(1, 2)).item():.4f}\u0027)\nprint(f\u0027Unnorm log-prob at origin: {ebm.unnorm_log_prob(torch.zeros(1, 2)).item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Contrastive Divergence"},{"type":"text","content":"Contrastive Divergence (CD, Hinton 2002) approximates the intractable model expectation by running a short Markov chain starting from data points instead of from noise. CD-k initialises chains at data x ~ p_data and runs k Gibbs or Langevin steps to get \u0027negative\u0027 samples x^- that approximate p_θ. The gradient estimate is: ∇_θ L ≈ E_data[∇_θ E_θ(x)] - E[∇_θ E_θ(x^-)]. With k=1, CD is biased but computationally cheap and works well for shallow models like RBMs. The bias comes from the chains not mixing to the true model distribution."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef langevin_step(ebm, x, step_size=0.01, noise_scale=0.005):\n    \"\"\"Single Langevin MCMC step toward lower energy regions.\"\"\"\n    x = x.detach().requires_grad_(True)\n    energy = ebm.energy(x).sum()\n    energy.backward()\n    with torch.no_grad():\n        x_new = x - step_size * x.grad + noise_scale * torch.randn_like(x)\n    return x_new.detach()\n\ndef cd_k_update(ebm, x_data, k=1, lr=1e-3, step_size=0.01):\n    \"\"\"CD-k: run k Langevin steps from data, compute contrastive gradient.\"\"\"\n    optimizer = torch.optim.Adam(ebm.parameters(), lr=lr)\n    x_neg = x_data.clone().detach()\n    for _ in range(k):\n        x_neg = langevin_step(ebm, x_neg, step_size=step_size)\n    energy_pos = ebm.energy(x_data)\n    energy_neg = ebm.energy(x_neg.detach())\n    # Minimize energy at data, maximize at model samples\n    loss = energy_pos.mean() - energy_neg.mean()\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    return loss.item(), x_neg\n\nebm = EnergyNet(input_dim=2)\ntorch.manual_seed(0)\nx_data = torch.randn(64, 2) * 0.5 + 2.0  # data cluster at (2,2)\nfor step in range(50):\n    loss, x_neg = cd_k_update(ebm, x_data, k=5)\n    if step % 10 == 0:\n        print(f\u0027Step {step}: CD loss={loss:.4f}  E_data={ebm.energy(x_data).mean():.4f}\u0027)"},{"type":"heading","level":2,"content":"Persistent Contrastive Divergence"},{"type":"text","content":"Persistent CD (PCD, Tieleman 2008) maintains a set of persistent Markov chains across parameter updates instead of restarting from data each step. The chains accumulate mixing history and eventually sample from the true model distribution (given slow enough parameter updates). PCD produces better model samples than CD-k at the cost of memory for storing chain states. The tradeoff: if learning rate is too large, parameters change faster than chains can mix, causing the persistent samples to lag behind the true model distribution."},{"type":"heading","level":2,"content":"Langevin Dynamics MCMC"},{"type":"text","content":"Stochastic Gradient Langevin Dynamics (SGLD) samples from p_θ using the gradient of the energy: x_{t+1} = x_t - ε·∇_x E_θ(x_t) + √(2ε)·ξ where ξ ~ N(0,I). This is gradient descent on the energy with injected noise to prevent collapse to a single mode. In the limit ε→0 with step count T→∞, SGLD samples exactly from p_θ. In practice, finite ε introduces bias — this is the fundamental tension in EBM training. The gradient ∇_x E_θ(x) connects EBMs directly to score-based models: score = -∇_x E_θ(x) = ∇_x log p_θ(x)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef langevin_sample(ebm, n_samples=256, n_steps=100, step_size=0.1,\n                    noise_scale=0.01, device=\u0027cpu\u0027):\n    \"\"\"SGLD sampler: gradient descent on energy + Gaussian noise injection.\"\"\"\n    x = torch.randn(n_samples, 2, device=device)  # start from noise\n    trajectory_energies = []\n    for step in range(n_steps):\n        x = x.detach().requires_grad_(True)\n        energy = ebm.energy(x).sum()\n        energy.backward()\n        with torch.no_grad():\n            # Gradient step toward low-energy regions + Langevin noise\n            x = x - step_size * x.grad + (2 * step_size) ** 0.5 * noise_scale * torch.randn_like(x)\n        if step % 20 == 0:\n            with torch.no_grad():\n                e = ebm.energy(x.detach()).mean().item()\n            trajectory_energies.append(e)\n    return x.detach(), trajectory_energies\n\nebm = EnergyNet(input_dim=2)\ntorch.manual_seed(42)\nsamples, energies = langevin_sample(ebm, n_samples=128, n_steps=100)\nprint(f\u0027Langevin MCMC: {len(energies)} checkpoints\u0027)\nfor i, e in enumerate(energies):\n    print(f\u0027  Step {i*20:3d}: mean energy = {e:.4f}\u0027)"},{"type":"heading","level":2,"content":"Connection to Score Matching"},{"type":"text","content":"The score function s(x) = ∇_x log p(x) = -∇_x E_θ(x) directly links EBMs to denoising score matching and diffusion models. Score matching (Hyvärinen 2005) avoids the partition function entirely by training on the Stein identity: E[||∇_x log p_θ(x) - ∇_x log p_data(x)||²] can be computed without knowing Z. Denoising score matching further converts this to a regression problem: predict the score from noisy samples. This insight — that training EBMs and score models are equivalent — underlies why diffusion models can be interpreted as hierarchical EBMs with different noise levels."},{"type":"heading","level":2,"content":"EBMs for OOD Detection"},{"type":"text","content":"EBMs provide a principled framework for out-of-distribution detection: in-distribution samples should have low energy (high probability) and OOD samples should have high energy. This is in contrast to classifiers, which can be arbitrarily confident on OOD inputs. Grathwohl et al. (JEM, 2020) showed that training a joint energy-based model — where the same network serves as both classifier and energy function — achieves strong OOD detection while maintaining classification accuracy."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport numpy as np\n\nclass JEMClassifier(nn.Module):\n    \"\"\"Joint Energy Model: classifier that also computes free energy for OOD detection.\"\"\"\n    def __init__(self, input_dim, n_classes, hidden=128):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(input_dim, hidden), nn.GELU(),\n            nn.Linear(hidden, hidden), nn.GELU(),\n            nn.Linear(hidden, n_classes)\n        )\n    def forward(self, x):\n        return self.net(x)  # logits\n    def free_energy(self, x):\n        logits = self.forward(x)\n        return -torch.logsumexp(logits, dim=-1)  # -log sum_c exp(f_c(x))\n\ntorch.manual_seed(0)\nmodel = JEMClassifier(input_dim=10, n_classes=4)\n\n# In-distribution data (MNIST-like, features in [-1, 1])\nx_in  = torch.randn(100, 10) * 0.5\n# OOD data (very different distribution)\nx_ood = torch.randn(100, 10) * 5.0 + 10.0\n\nwith torch.no_grad():\n    e_in  = model.free_energy(x_in)\n    e_ood = model.free_energy(x_ood)\nprint(f\u0027In-distribution free energy:  mean={e_in.mean():.3f} std={e_in.std():.3f}\u0027)\nprint(f\u0027OOD free energy:              mean={e_ood.mean():.3f} std={e_ood.std():.3f}\u0027)\nauroc_proxy = (e_ood \u003e e_in.median()).float().mean()  # higher energy = OOD\nprint(f\u0027AUROC proxy (higher E = OOD): {auroc_proxy:.3f}\u0027)"},{"type":"heading","level":2,"content":"Practical Considerations"},{"type":"callout","variant":"warning","title":"MCMC Instability in EBM Training","content":"EBM training is notoriously unstable because the model samples used for the contrastive gradient are themselves produced by the current model. If the MCMC chains do not mix (e.g., step size too small, too few steps), the model samples cluster near data points and the energy landscape does not learn to push up energy in between modes. Monitor the energy gap between data and model samples — a shrinking gap indicates the chains are not exploring. Use spectral normalisation on the energy network to stabilise training."},{"type":"table","headers":["Model","Likelihood Tractable","Sample Quality","Training Stability","MCMC Needed","OOD Detection"],"rows":[["VAE","Yes (ELBO lower bound)","Moderate — blurry","High — stable KL objective","No","Poor — decoder uncertainty"],["GAN","No","High — sharp samples","Low — mode collapse, oscillation","No","Possible via discriminator"],["EBM","No (intractable Z)","Moderate — mode-seeking","Low — MCMC instability","Yes — at train and test time","Excellent — free energy threshold"],["Diffusion","Approximate (ELBO)","Very high — SoTA","High — stable MSE objective","No (deterministic at test)","Good via likelihood proxy"]]},{"type":"list","ordered":false,"items":["The partition function Z is intractable — never attempt to compute it exactly; use MCMC approximations.","CD-1 is biased but fast and works for shallow models; use PCD for deeper networks where mixing is slower.","Langevin step size ε controls the bias-variance tradeoff: small ε = low bias, many steps needed; large ε = fast but biased.","Spectral normalisation on energy network weights bounds the Lipschitz constant and stabilises training.","JEM combines EBM + classifier in one network — the free energy serves as an OOD score at negligible extra cost."]},{"type":"divider"}]"
---
# Energy-Based Models — Contrastive Divergence and Langevin Sampling

Energy-Based Models (EBMs) define a probability distribution via an energy function E_θ(x): p_θ(x) = exp(-E_θ(x)) / Z(θ), where Z(θ) = ∫exp(-E_θ(x))dx is the partition function. Low energy corresponds to high probability — the model assigns low energy to data-like samples and high energy to unlikely ones. The central challenge is that Z(θ) is intractable for continuous high-dimensional x, so maximum likelihood training requires approximating the gradient of log Z with MCMC sampling. EBMs are a flexible framework that unifies Boltzmann machines, denoising autoencoders, and score-based models.

## Energy Function and Unnormalized Density

The gradient of the log-likelihood decomposes into two terms: ∇_θ log p_θ(x) = -∇_θ E_θ(x) + E_{p_θ}[∇_θ E_θ(x)]. The first term (data term) pushes down energy at real data points. The second term (model term) pushes up energy at model samples, computed by MCMC. If the model samples are high quality, this gradient correctly shapes the energy landscape. The data term is exact; the model term is estimated via k steps of Markov chain Monte Carlo from the current model distribution, making EBM training fundamentally tied to MCMC quality.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class EnergyNet(nn.Module):
    """Neural network energy function: maps input to scalar energy (lower = more likely)."""
    def __init__(self, input_dim, hidden=256):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(input_dim, hidden), nn.LeakyReLU(0.2),
            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),
            nn.Linear(hidden, 1)
        )

    def energy(self, x):
        return self.net(x).squeeze(-1)  # (B,)

    def unnorm_log_prob(self, x):
        return -self.energy(x)          # log p*(x) without Z

# Demo: energy landscape over 2D grid
ebm = EnergyNet(input_dim=2)
torch.manual_seed(0)
grid = torch.stack(torch.meshgrid(
    torch.linspace(-3, 3, 30), torch.linspace(-3, 3, 30), indexing='ij'
), dim=-1).reshape(-1, 2)
with torch.no_grad():
    energies = ebm.energy(grid)
print(f'Grid energy range: [{energies.min():.3f}, {energies.max():.3f}]')
print(f'Energy at origin: {ebm.energy(torch.zeros(1, 2)).item():.4f}')
print(f'Unnorm log-prob at origin: {ebm.unnorm_log_prob(torch.zeros(1, 2)).item():.4f}')
```

## Contrastive Divergence

Contrastive Divergence (CD, Hinton 2002) approximates the intractable model expectation by running a short Markov chain starting from data points instead of from noise. CD-k initialises chains at data x ~ p_data and runs k Gibbs or Langevin steps to get 'negative' samples x^- that approximate p_θ. The gradient estimate is: ∇_θ L ≈ E_data[∇_θ E_θ(x)] - E[∇_θ E_θ(x^-)]. With k=1, CD is biased but computationally cheap and works well for shallow models like RBMs. The bias comes from the chains not mixing to the true model distribution.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def langevin_step(ebm, x, step_size=0.01, noise_scale=0.005):
    """Single Langevin MCMC step toward lower energy regions."""
    x = x.detach().requires_grad_(True)
    energy = ebm.energy(x).sum()
    energy.backward()
    with torch.no_grad():
        x_new = x - step_size * x.grad + noise_scale * torch.randn_like(x)
    return x_new.detach()

def cd_k_update(ebm, x_data, k=1, lr=1e-3, step_size=0.01):
    """CD-k: run k Langevin steps from data, compute contrastive gradient."""
    optimizer = torch.optim.Adam(ebm.parameters(), lr=lr)
    x_neg = x_data.clone().detach()
    for _ in range(k):
        x_neg = langevin_step(ebm, x_neg, step_size=step_size)
    energy_pos = ebm.energy(x_data)
    energy_neg = ebm.energy(x_neg.detach())
    # Minimize energy at data, maximize at model samples
    loss = energy_pos.mean() - energy_neg.mean()
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    return loss.item(), x_neg

ebm = EnergyNet(input_dim=2)
torch.manual_seed(0)
x_data = torch.randn(64, 2) * 0.5 + 2.0  # data cluster at (2,2)
for step in range(50):
    loss, x_neg = cd_k_update(ebm, x_data, k=5)
    if step % 10 == 0:
        print(f'Step {step}: CD loss={loss:.4f}  E_data={ebm.energy(x_data).mean():.4f}')
```

## Persistent Contrastive Divergence

Persistent CD (PCD, Tieleman 2008) maintains a set of persistent Markov chains across parameter updates instead of restarting from data each step. The chains accumulate mixing history and eventually sample from the true model distribution (given slow enough parameter updates). PCD produces better model samples than CD-k at the cost of memory for storing chain states. The tradeoff: if learning rate is too large, parameters change faster than chains can mix, causing the persistent samples to lag behind the true model distribution.

## Langevin Dynamics MCMC

Stochastic Gradient Langevin Dynamics (SGLD) samples from p_θ using the gradient of the energy: x_{t+1} = x_t - ε·∇_x E_θ(x_t) + √(2ε)·ξ where ξ ~ N(0,I). This is gradient descent on the energy with injected noise to prevent collapse to a single mode. In the limit ε→0 with step count T→∞, SGLD samples exactly from p_θ. In practice, finite ε introduces bias — this is the fundamental tension in EBM training. The gradient ∇_x E_θ(x) connects EBMs directly to score-based models: score = -∇_x E_θ(x) = ∇_x log p_θ(x).

```python
import torch
import torch.nn as nn

def langevin_sample(ebm, n_samples=256, n_steps=100, step_size=0.1,
                    noise_scale=0.01, device='cpu'):
    """SGLD sampler: gradient descent on energy + Gaussian noise injection."""
    x = torch.randn(n_samples, 2, device=device)  # start from noise
    trajectory_energies = []
    for step in range(n_steps):
        x = x.detach().requires_grad_(True)
        energy = ebm.energy(x).sum()
        energy.backward()
        with torch.no_grad():
            # Gradient step toward low-energy regions + Langevin noise
            x = x - step_size * x.grad + (2 * step_size) ** 0.5 * noise_scale * torch.randn_like(x)
        if step % 20 == 0:
            with torch.no_grad():
                e = ebm.energy(x.detach()).mean().item()
            trajectory_energies.append(e)
    return x.detach(), trajectory_energies

ebm = EnergyNet(input_dim=2)
torch.manual_seed(42)
samples, energies = langevin_sample(ebm, n_samples=128, n_steps=100)
print(f'Langevin MCMC: {len(energies)} checkpoints')
for i, e in enumerate(energies):
    print(f'  Step {i*20:3d}: mean energy = {e:.4f}')
```

## Connection to Score Matching

The score function s(x) = ∇_x log p(x) = -∇_x E_θ(x) directly links EBMs to denoising score matching and diffusion models. Score matching (Hyvärinen 2005) avoids the partition function entirely by training on the Stein identity: E[||∇_x log p_θ(x) - ∇_x log p_data(x)||²] can be computed without knowing Z. Denoising score matching further converts this to a regression problem: predict the score from noisy samples. This insight — that training EBMs and score models are equivalent — underlies why diffusion models can be interpreted as hierarchical EBMs with different noise levels.

## EBMs for OOD Detection

EBMs provide a principled framework for out-of-distribution detection: in-distribution samples should have low energy (high probability) and OOD samples should have high energy. This is in contrast to classifiers, which can be arbitrarily confident on OOD inputs. Grathwohl et al. (JEM, 2020) showed that training a joint energy-based model — where the same network serves as both classifier and energy function — achieves strong OOD detection while maintaining classification accuracy.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np

class JEMClassifier(nn.Module):
    """Joint Energy Model: classifier that also computes free energy for OOD detection."""
    def __init__(self, input_dim, n_classes, hidden=128):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(input_dim, hidden), nn.GELU(),
            nn.Linear(hidden, hidden), nn.GELU(),
            nn.Linear(hidden, n_classes)
        )
    def forward(self, x):
        return self.net(x)  # logits
    def free_energy(self, x):
        logits = self.forward(x)
        return -torch.logsumexp(logits, dim=-1)  # -log sum_c exp(f_c(x))

torch.manual_seed(0)
model = JEMClassifier(input_dim=10, n_classes=4)

# In-distribution data (MNIST-like, features in [-1, 1])
x_in  = torch.randn(100, 10) * 0.5
# OOD data (very different distribution)
x_ood = torch.randn(100, 10) * 5.0 + 10.0

with torch.no_grad():
    e_in  = model.free_energy(x_in)
    e_ood = model.free_energy(x_ood)
print(f'In-distribution free energy:  mean={e_in.mean():.3f} std={e_in.std():.3f}')
print(f'OOD free energy:              mean={e_ood.mean():.3f} std={e_ood.std():.3f}')
auroc_proxy = (e_ood > e_in.median()).float().mean()  # higher energy = OOD
print(f'AUROC proxy (higher E = OOD): {auroc_proxy:.3f}')
```

## Practical Considerations

> **MCMC Instability in EBM Training**: EBM training is notoriously unstable because the model samples used for the contrastive gradient are themselves produced by the current model. If the MCMC chains do not mix (e.g., step size too small, too few steps), the model samples cluster near data points and the energy landscape does not learn to push up energy in between modes. Monitor the energy gap between data and model samples — a shrinking gap indicates the chains are not exploring. Use spectral normalisation on the energy network to stabilise training.

| Model | Likelihood Tractable | Sample Quality | Training Stability | MCMC Needed | OOD Detection |
| --- | --- | --- | --- | --- | --- |
| VAE | Yes (ELBO lower bound) | Moderate — blurry | High — stable KL objective | No | Poor — decoder uncertainty |
| GAN | No | High — sharp samples | Low — mode collapse, oscillation | No | Possible via discriminator |
| EBM | No (intractable Z) | Moderate — mode-seeking | Low — MCMC instability | Yes — at train and test time | Excellent — free energy threshold |
| Diffusion | Approximate (ELBO) | Very high — SoTA | High — stable MSE objective | No (deterministic at test) | Good via likelihood proxy |

- The partition function Z is intractable — never attempt to compute it exactly; use MCMC approximations.
- CD-1 is biased but fast and works for shallow models; use PCD for deeper networks where mixing is slower.
- Langevin step size ε controls the bias-variance tradeoff: small ε = low bias, many steps needed; large ε = fast but biased.
- Spectral normalisation on energy network weights bounds the Lipschitz constant and stabilises training.
- JEM combines EBM + classifier in one network — the free energy serves as an OOD score at negligible extra cost.

---

