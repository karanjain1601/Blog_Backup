---
title: "Energy-Based Models — Boltzmann Distribution and MCMC"
slug: "energy-based-models"
description: "Understand energy-based models for anomaly detection: the Boltzmann distribution p(x)=exp(−E_θ(x))/Z, contrastive divergence training, Langevin dynamics MCMC for the negative phase, and score matching as an MCMC-free alternative to avoid the intractable partition function."
tags: ["anomaly-detection", "density-estimation", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Energy-based models (EBMs) define a probability distribution via an energy function: p_θ(x) = exp(−E_θ(x)) / Z(θ) where Z(θ) = ∫ exp(−E_θ(x)) dx is the partition function. The energy E_θ is parameterised by a neural network and can take any value — no architectural constraints like invertibility are required. The key challenge is that Z is generally intractable, complicating both training and normalised-probability computation. For anomaly detection this is not a fundamental barrier: low energy ↔ normal, high energy ↔ anomaly."},{"type":"heading","level":2,"content":"Energy Functions and the Boltzmann Distribution"},{"type":"text","content":"The Boltzmann distribution assigns high probability to regions of low energy and low probability to high-energy regions. During training we want the model to assign low energy to training data (positive phase) and high energy to other regions (negative phase). The log-likelihood gradient is: ∂/∂θ log p_θ(x) = −∂E_θ(x)/∂θ + E_{p_θ}[∂E_θ/∂θ]. The first term pushes down energy at observed data; the second term (the negative phase) pushes energy up at samples from the current model — requiring MCMC sampling."},{"type":"list","ordered":false,"items":["Unnormalised density: p_θ(x) ∝ exp(−E_θ(x)) — only the energy function needs to be learned.","Partition function Z(θ) = ∫exp(−E_θ)dx — intractable in general; makes MLE gradient hard to compute.","Negative phase: E_{p_θ}[∂E/∂θ] — expectation under the model; approximated by MCMC samples.","Contrastive divergence: approximate negative phase using short MCMC chains initialised at training data.","Score matching: sidestep Z by matching score functions ∇_x log p — avoids MCMC entirely."]},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\nclass EnergyNet(nn.Module):\n    def __init__(self, d_in):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(d_in, 64), nn.SiLU(),\n            nn.Linear(64, 64), nn.SiLU(),\n            nn.Linear(64, 1))\n    def forward(self, x):\n        return self.net(x).squeeze(-1)  # scalar energy per sample\n\ndef contrastive_divergence_step(ebm, x_pos, opt, n_steps=10, step_size=0.01):\n    \u0027\u0027\u0027One CD-k training step: positive phase minus negative phase.\u0027\u0027\u0027\n    ebm.train()\n    # Negative phase: run short Langevin chain from positive samples\n    x_neg = x_pos.detach().clone().requires_grad_(True)\n    for _ in range(n_steps):\n        e_neg = ebm(x_neg)\n        grad = torch.autograd.grad(e_neg.sum(), x_neg)[0]\n        x_neg = (x_neg - step_size * grad +\n                 (2 * step_size) ** 0.5 * torch.randn_like(x_neg)).detach()\n        x_neg.requires_grad_(True)\n    x_neg = x_neg.detach()\n    opt.zero_grad()\n    loss = ebm(x_pos).mean() - ebm(x_neg).mean()  # min E(pos), max E(neg)\n    loss.backward(); opt.step()\n    return loss.item()\n\ntorch.manual_seed(0)\nX_tr = torch.tensor(np.random.randn(600, 4), dtype=torch.float32)\nebm = EnergyNet(d_in=4)\nopt = torch.optim.Adam(ebm.parameters(), lr=1e-3)\nfor ep in range(20):\n    loss_val = contrastive_divergence_step(ebm, X_tr, opt)\n    if (ep+1) % 5 == 0:\n        print(f\u0027Epoch {ep+1:2d} | CD loss: {loss_val:.4f}\u0027)"},{"type":"heading","level":2,"content":"Training via Contrastive Divergence"},{"type":"text","content":"Contrastive Divergence (CD-k) approximates the negative phase with k steps of MCMC starting from training data. CD-1 (a single step) is the most common — cheap but biased. Persistent CD (PCD) maintains a persistent chain of fantasy particles across batches, which converges to true model samples as training progresses but requires storing and updating the chain. CD-k gradient quality increases with k but so does computational cost. For anomaly detection, exact normalisation is not needed — relative energy values suffice for ranking."},{"type":"heading","level":2,"content":"Langevin Dynamics for MCMC Sampling"},{"type":"text","content":"Langevin dynamics samples from p_θ(x) ∝ exp(−E_θ(x)) by simulating the SDE: xₜ₊₁ = xₜ − (η/2)∇_x E_θ(xₜ) + √η·ε where ε~N(0,I). The gradient term pulls particles toward low-energy regions; the noise term ensures exploration. With step size η→0 and enough steps, samples converge to p_θ. In practice, a finite η introduces a discretisation bias corrected by a Metropolis-Hastings accept/reject step (MALA). Langevin dynamics is the standard negative-phase sampler for deep EBMs."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef langevin_sample(ebm, n_samples, d, n_steps=100, step_size=0.01, noise_scale=1.0):\n    \u0027\u0027\u0027Sample from EBM via Langevin MCMC.\u0027\u0027\u0027\n    ebm.eval()\n    x = torch.randn(n_samples, d) * noise_scale\n    x.requires_grad_(True)\n    for i in range(n_steps):\n        energy = ebm(x)\n        grad = torch.autograd.grad(energy.sum(), x)[0]\n        with torch.no_grad():\n            x = x - 0.5 * step_size * grad + (step_size ** 0.5) * torch.randn_like(x)\n        x = x.detach().requires_grad_(True)\n        if (i + 1) % 25 == 0:\n            e_mean = ebm(x.detach()).mean().item()\n            print(f\u0027  Step {i+1:4d} | mean energy: {e_mean:.4f}\u0027)\n    return x.detach()\n\nprint(\u0027Langevin sampling from trained EBM (4D):\u0027)\nsamples = langevin_sample(ebm, n_samples=50, d=4, n_steps=100)\nprint(f\u0027Sample mean:  {samples.mean(dim=0).numpy().round(3)}\u0027)\nprint(f\u0027Sample std:   {samples.std(dim=0).numpy().round(3)}\u0027)\nprint(f\u0027Energy mean:  {ebm(samples).mean().item():.4f}\u0027)"},{"type":"heading","level":2,"content":"EBM Anomaly Detection"},{"type":"text","content":"Because p_θ(x) ∝ exp(−E_θ(x)), the energy E_θ(x) is a direct (unnormalised) anomaly score: low energy = high probability = normal; high energy = low probability = anomaly. This avoids the need to compute Z. The threshold is set from the distribution of energies on normal training data. EBM anomaly detection is robust to the choice of architecture as long as E_θ is flexible enough to model the normal manifold — any neural network suffices."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom sklearn.metrics import roc_auc_score\n\nnp.random.seed(5)\ntorch.manual_seed(5)\nX_train = torch.tensor(np.random.randn(500, 4), dtype=torch.float32)\nebm2 = EnergyNet(d_in=4)\nopt2 = torch.optim.Adam(ebm2.parameters(), lr=5e-4)\nfor _ in range(50):\n    contrastive_divergence_step(ebm2, X_train, opt2, n_steps=5)\n\n# Anomaly detection evaluation\nX_n_te = torch.tensor(np.random.randn(100, 4), dtype=torch.float32)\nX_a_te = torch.tensor(np.random.randn(25, 4)*0.2 + 3, dtype=torch.float32)\nX_all = torch.cat([X_n_te, X_a_te])\ny = np.array([0]*100 + [1]*25)\n\nebm2.eval()\nwith torch.no_grad():\n    energy_scores = ebm2(X_all).numpy()\n\nthr = np.percentile(energy_scores[:100], 95)\ndetected = (energy_scores[100:] \u003e thr).sum()\nauroc = roc_auc_score(y, energy_scores)\nprint(f\u0027AUROC (energy score):   {auroc:.4f}\u0027)\nprint(f\u0027Threshold (95th pct):   {thr:.4f}\u0027)\nprint(f\u0027Anomalies detected:     {detected}/{len(X_a_te)}\u0027)\nprint(f\u0027Normal energy mean:     {energy_scores[:100].mean():.4f}\u0027)\nprint(f\u0027Anomaly energy mean:    {energy_scores[100:].mean():.4f}\u0027)"},{"type":"callout","variant":"info","title":"EBM vs Normalizing Flows for Anomaly Detection","content":"EBMs require only forward passes through E_θ at inference — fast and architecturally flexible. Flows require an invertible architecture and can compute exact log p(x). EBMs are harder to train (MCMC negative phase) but can use arbitrary architectures including residual networks with batch norm. For anomaly detection where only a ranking (not absolute probability) is needed, EBM energy scores are often sufficient."},{"type":"heading","level":2,"content":"Score Matching — Avoiding the Partition Function"},{"type":"text","content":"Hyvärinen\u0027s score matching sidesteps Z entirely by matching the score function ∇_x log p_θ(x) = −∇_x E_θ(x) to the data score. The objective is: J(θ) = E_data[‖∇_x log p_θ(x)‖² / 2 + tr(∇_x² log p_θ(x))]. The first term is small when model and data scores agree; the second term (trace of the Hessian) regularises. Denoising score matching (DSM) simplifies computation by matching scores of noisy data: J_DSM = E_{x,ε}[‖∇_x log p_θ(x+σε) + ε/σ‖²]."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef denoising_score_matching_loss(ebm, x_clean, sigma=0.1):\n    \u0027\u0027\u0027DSM loss: match energy gradient to noise direction.\u0027\u0027\u0027\n    noise = torch.randn_like(x_clean) * sigma\n    x_noisy = x_clean + noise\n    x_noisy.requires_grad_(True)\n    energy = ebm(x_noisy)\n    score_model = -torch.autograd.grad(energy.sum(), x_noisy,\n                                        create_graph=True)[0]\n    target_score = -noise / (sigma ** 2)\n    loss = 0.5 * ((score_model - target_score) ** 2).sum(dim=-1).mean()\n    return loss\n\ntorch.manual_seed(3)\nX_sm = torch.tensor(np.random.randn(400, 4), dtype=torch.float32)\nebm_sm = EnergyNet(d_in=4)\nopt_sm = torch.optim.Adam(ebm_sm.parameters(), lr=1e-3)\nfor ep in range(30):\n    loss = denoising_score_matching_loss(ebm_sm, X_sm, sigma=0.2)\n    opt_sm.zero_grad()\n    loss.backward(); opt_sm.step()\n    if (ep + 1) % 10 == 0:\n        print(f\u0027Epoch {ep+1:2d} | DSM loss: {loss.item():.6f}\u0027)\nprint(\u0027Score matching avoids MCMC — no negative phase sampling required.\u0027)"},{"type":"heading","level":2,"content":"EBM Training Methods Comparison"},{"type":"table","headers":["Training Method","MCMC Needed","Gradient Quality","Training Cost","Partition Function","Practical Use"],"rows":[["Contrastive Divergence (CD-1)","Yes (1 step)","Biased but fast","Low","Ignored","Most common baseline"],["Persistent CD (PCD)","Yes (persistent chain)","Better — chain mixes","Medium","Ignored","Better quality than CD"],["Langevin MCMC (full)","Yes (100+ steps)","Good — near true model","High","Ignored","Slow but accurate"],["Score Matching","No","Unbiased (exact)","Medium — Hessian trace","Eliminated","For smooth energies"],["Noise Contrastive Estimation (NCE)","No","Unbiased","Medium","Estimated via noise","When Z estimate needed"]]},{"type":"list","ordered":false,"items":["EBM inference is just one forward pass through E_θ — no partition function needed at test time.","Use DSM when training data is clean and you want to avoid MCMC entirely; gradient computation is the only cost.","Use PCD when generation quality also matters — persistent chains produce better samples than CD-1.","Energy scores are unnormalised; for anomaly thresholding fit a Gaussian to training energies and flag points \u003e μ + 3σ.","JEM (Grathwohl et al., 2020) combines classifier and EBM: logits define energy, enabling joint generation and classification."]},{"type":"text","content":"For anomaly detection, contrastive divergence or denoising score matching are the most practical training choices. DSM avoids MCMC entirely and often trains faster. PCD gives better energy landscapes when generation quality also matters. In all cases, the inference anomaly score is just the forward pass through E_θ — fast and simple."},{"type":"divider"}]"
---
# Energy-Based Models — Boltzmann Distribution and MCMC

Energy-based models (EBMs) define a probability distribution via an energy function: p_θ(x) = exp(−E_θ(x)) / Z(θ) where Z(θ) = ∫ exp(−E_θ(x)) dx is the partition function. The energy E_θ is parameterised by a neural network and can take any value — no architectural constraints like invertibility are required. The key challenge is that Z is generally intractable, complicating both training and normalised-probability computation. For anomaly detection this is not a fundamental barrier: low energy ↔ normal, high energy ↔ anomaly.

## Energy Functions and the Boltzmann Distribution

The Boltzmann distribution assigns high probability to regions of low energy and low probability to high-energy regions. During training we want the model to assign low energy to training data (positive phase) and high energy to other regions (negative phase). The log-likelihood gradient is: ∂/∂θ log p_θ(x) = −∂E_θ(x)/∂θ + E_{p_θ}[∂E_θ/∂θ]. The first term pushes down energy at observed data; the second term (the negative phase) pushes energy up at samples from the current model — requiring MCMC sampling.

- Unnormalised density: p_θ(x) ∝ exp(−E_θ(x)) — only the energy function needs to be learned.
- Partition function Z(θ) = ∫exp(−E_θ)dx — intractable in general; makes MLE gradient hard to compute.
- Negative phase: E_{p_θ}[∂E/∂θ] — expectation under the model; approximated by MCMC samples.
- Contrastive divergence: approximate negative phase using short MCMC chains initialised at training data.
- Score matching: sidestep Z by matching score functions ∇_x log p — avoids MCMC entirely.

```python
import torch
import torch.nn as nn
import numpy as np

class EnergyNet(nn.Module):
    def __init__(self, d_in):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(d_in, 64), nn.SiLU(),
            nn.Linear(64, 64), nn.SiLU(),
            nn.Linear(64, 1))
    def forward(self, x):
        return self.net(x).squeeze(-1)  # scalar energy per sample

def contrastive_divergence_step(ebm, x_pos, opt, n_steps=10, step_size=0.01):
    '''One CD-k training step: positive phase minus negative phase.'''
    ebm.train()
    # Negative phase: run short Langevin chain from positive samples
    x_neg = x_pos.detach().clone().requires_grad_(True)
    for _ in range(n_steps):
        e_neg = ebm(x_neg)
        grad = torch.autograd.grad(e_neg.sum(), x_neg)[0]
        x_neg = (x_neg - step_size * grad +
                 (2 * step_size) ** 0.5 * torch.randn_like(x_neg)).detach()
        x_neg.requires_grad_(True)
    x_neg = x_neg.detach()
    opt.zero_grad()
    loss = ebm(x_pos).mean() - ebm(x_neg).mean()  # min E(pos), max E(neg)
    loss.backward(); opt.step()
    return loss.item()

torch.manual_seed(0)
X_tr = torch.tensor(np.random.randn(600, 4), dtype=torch.float32)
ebm = EnergyNet(d_in=4)
opt = torch.optim.Adam(ebm.parameters(), lr=1e-3)
for ep in range(20):
    loss_val = contrastive_divergence_step(ebm, X_tr, opt)
    if (ep+1) % 5 == 0:
        print(f'Epoch {ep+1:2d} | CD loss: {loss_val:.4f}')
```

## Training via Contrastive Divergence

Contrastive Divergence (CD-k) approximates the negative phase with k steps of MCMC starting from training data. CD-1 (a single step) is the most common — cheap but biased. Persistent CD (PCD) maintains a persistent chain of fantasy particles across batches, which converges to true model samples as training progresses but requires storing and updating the chain. CD-k gradient quality increases with k but so does computational cost. For anomaly detection, exact normalisation is not needed — relative energy values suffice for ranking.

## Langevin Dynamics for MCMC Sampling

Langevin dynamics samples from p_θ(x) ∝ exp(−E_θ(x)) by simulating the SDE: xₜ₊₁ = xₜ − (η/2)∇_x E_θ(xₜ) + √η·ε where ε~N(0,I). The gradient term pulls particles toward low-energy regions; the noise term ensures exploration. With step size η→0 and enough steps, samples converge to p_θ. In practice, a finite η introduces a discretisation bias corrected by a Metropolis-Hastings accept/reject step (MALA). Langevin dynamics is the standard negative-phase sampler for deep EBMs.

```python
import torch
import numpy as np

def langevin_sample(ebm, n_samples, d, n_steps=100, step_size=0.01, noise_scale=1.0):
    '''Sample from EBM via Langevin MCMC.'''
    ebm.eval()
    x = torch.randn(n_samples, d) * noise_scale
    x.requires_grad_(True)
    for i in range(n_steps):
        energy = ebm(x)
        grad = torch.autograd.grad(energy.sum(), x)[0]
        with torch.no_grad():
            x = x - 0.5 * step_size * grad + (step_size ** 0.5) * torch.randn_like(x)
        x = x.detach().requires_grad_(True)
        if (i + 1) % 25 == 0:
            e_mean = ebm(x.detach()).mean().item()
            print(f'  Step {i+1:4d} | mean energy: {e_mean:.4f}')
    return x.detach()

print('Langevin sampling from trained EBM (4D):')
samples = langevin_sample(ebm, n_samples=50, d=4, n_steps=100)
print(f'Sample mean:  {samples.mean(dim=0).numpy().round(3)}')
print(f'Sample std:   {samples.std(dim=0).numpy().round(3)}')
print(f'Energy mean:  {ebm(samples).mean().item():.4f}')
```

## EBM Anomaly Detection

Because p_θ(x) ∝ exp(−E_θ(x)), the energy E_θ(x) is a direct (unnormalised) anomaly score: low energy = high probability = normal; high energy = low probability = anomaly. This avoids the need to compute Z. The threshold is set from the distribution of energies on normal training data. EBM anomaly detection is robust to the choice of architecture as long as E_θ is flexible enough to model the normal manifold — any neural network suffices.

```python
import torch
import numpy as np
from sklearn.metrics import roc_auc_score

np.random.seed(5)
torch.manual_seed(5)
X_train = torch.tensor(np.random.randn(500, 4), dtype=torch.float32)
ebm2 = EnergyNet(d_in=4)
opt2 = torch.optim.Adam(ebm2.parameters(), lr=5e-4)
for _ in range(50):
    contrastive_divergence_step(ebm2, X_train, opt2, n_steps=5)

# Anomaly detection evaluation
X_n_te = torch.tensor(np.random.randn(100, 4), dtype=torch.float32)
X_a_te = torch.tensor(np.random.randn(25, 4)*0.2 + 3, dtype=torch.float32)
X_all = torch.cat([X_n_te, X_a_te])
y = np.array([0]*100 + [1]*25)

ebm2.eval()
with torch.no_grad():
    energy_scores = ebm2(X_all).numpy()

thr = np.percentile(energy_scores[:100], 95)
detected = (energy_scores[100:] > thr).sum()
auroc = roc_auc_score(y, energy_scores)
print(f'AUROC (energy score):   {auroc:.4f}')
print(f'Threshold (95th pct):   {thr:.4f}')
print(f'Anomalies detected:     {detected}/{len(X_a_te)}')
print(f'Normal energy mean:     {energy_scores[:100].mean():.4f}')
print(f'Anomaly energy mean:    {energy_scores[100:].mean():.4f}')
```

> **EBM vs Normalizing Flows for Anomaly Detection**: EBMs require only forward passes through E_θ at inference — fast and architecturally flexible. Flows require an invertible architecture and can compute exact log p(x). EBMs are harder to train (MCMC negative phase) but can use arbitrary architectures including residual networks with batch norm. For anomaly detection where only a ranking (not absolute probability) is needed, EBM energy scores are often sufficient.

## Score Matching — Avoiding the Partition Function

Hyvärinen's score matching sidesteps Z entirely by matching the score function ∇_x log p_θ(x) = −∇_x E_θ(x) to the data score. The objective is: J(θ) = E_data[‖∇_x log p_θ(x)‖² / 2 + tr(∇_x² log p_θ(x))]. The first term is small when model and data scores agree; the second term (trace of the Hessian) regularises. Denoising score matching (DSM) simplifies computation by matching scores of noisy data: J_DSM = E_{x,ε}[‖∇_x log p_θ(x+σε) + ε/σ‖²].

```python
import torch
import numpy as np

def denoising_score_matching_loss(ebm, x_clean, sigma=0.1):
    '''DSM loss: match energy gradient to noise direction.'''
    noise = torch.randn_like(x_clean) * sigma
    x_noisy = x_clean + noise
    x_noisy.requires_grad_(True)
    energy = ebm(x_noisy)
    score_model = -torch.autograd.grad(energy.sum(), x_noisy,
                                        create_graph=True)[0]
    target_score = -noise / (sigma ** 2)
    loss = 0.5 * ((score_model - target_score) ** 2).sum(dim=-1).mean()
    return loss

torch.manual_seed(3)
X_sm = torch.tensor(np.random.randn(400, 4), dtype=torch.float32)
ebm_sm = EnergyNet(d_in=4)
opt_sm = torch.optim.Adam(ebm_sm.parameters(), lr=1e-3)
for ep in range(30):
    loss = denoising_score_matching_loss(ebm_sm, X_sm, sigma=0.2)
    opt_sm.zero_grad()
    loss.backward(); opt_sm.step()
    if (ep + 1) % 10 == 0:
        print(f'Epoch {ep+1:2d} | DSM loss: {loss.item():.6f}')
print('Score matching avoids MCMC — no negative phase sampling required.')
```

## EBM Training Methods Comparison

| Training Method | MCMC Needed | Gradient Quality | Training Cost | Partition Function | Practical Use |
| --- | --- | --- | --- | --- | --- |
| Contrastive Divergence (CD-1) | Yes (1 step) | Biased but fast | Low | Ignored | Most common baseline |
| Persistent CD (PCD) | Yes (persistent chain) | Better — chain mixes | Medium | Ignored | Better quality than CD |
| Langevin MCMC (full) | Yes (100+ steps) | Good — near true model | High | Ignored | Slow but accurate |
| Score Matching | No | Unbiased (exact) | Medium — Hessian trace | Eliminated | For smooth energies |
| Noise Contrastive Estimation (NCE) | No | Unbiased | Medium | Estimated via noise | When Z estimate needed |

- EBM inference is just one forward pass through E_θ — no partition function needed at test time.
- Use DSM when training data is clean and you want to avoid MCMC entirely; gradient computation is the only cost.
- Use PCD when generation quality also matters — persistent chains produce better samples than CD-1.
- Energy scores are unnormalised; for anomaly thresholding fit a Gaussian to training energies and flag points > μ + 3σ.
- JEM (Grathwohl et al., 2020) combines classifier and EBM: logits define energy, enabling joint generation and classification.

For anomaly detection, contrastive divergence or denoising score matching are the most practical training choices. DSM avoids MCMC entirely and often trains faster. PCD gives better energy landscapes when generation quality also matters. In all cases, the inference anomaly score is just the forward pass through E_θ — fast and simple.

---

