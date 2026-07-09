---
title: "Sharp vs Flat Minima and Generalization"
slug: "sharp-flat-minima-generalization"
description: "Theoretical and empirical analysis of sharpness measures, PAC-Bayes generalization bounds, SAM optimizer, and why SGD noise biases training toward flat minima with better test performance."
tags: ["optimization", "generalization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Not all minima of a neural network's training loss are created equal: some generalize well to held-out data, others memorize the training set. The geometry of the minimum — specifically its sharpness (curvature) — predicts this difference. A flat minimum is one where the loss changes slowly as weights move in any direction; a sharp minimum has directions of high curvature where small weight perturbations cause large loss spikes. This note builds from formal sharpness measures through the PAC-Bayes bound that explains why flat minima generalize better, to the SAM optimizer that explicitly targets flat minima, and the connection between SGD noise and implicit regularization toward flat regions."}, {"type": "heading", "level": 2, "content": "Measuring Sharpness"}, {"type": "text", "content": "The largest Hessian eigenvalue λ_max measures sharpness in the worst-case direction: even one direction of high curvature makes a minimum sharp. The Hessian trace tr(H) = Σλᵢ measures average curvature over all directions — cheaper to estimate than λ_max (Hutchinson's estimator uses tr(H) ≈ Eᵥ[vᵀHv] with random ±1 vectors v). The sharpness ratio ρ_sharp = max_{‖δ‖≤ρ} [L(θ+δ) − L(θ)] asks: how much does loss increase if we perturb weights by at most ρ in any direction? Hochreiter and Schmidhuber (1997) gave a Minimum Description Length argument: a flat minimum can be encoded with lower weight precision (fewer bits) because small quantization errors leave the loss unchanged; fewer bits → shorter description → better generalization by MDL/Occam's razor. Practically: two models with the same training loss but different sharpness will have different test loss; the flatter model generalizes better by an amount predicted by the PAC-Bayes bound."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\nimport torch.nn as nn\nfrom torch.autograd.functional import hvp\n\ndef hutchinson_trace(model, loss_fn, X, y, n_samples=20):\n    \"\"\"Estimate Hessian trace via Hutchinson's method.\"\"\"\n    loss = loss_fn(model(X), y)\n    params = [p for p in model.parameters() if p.requires_grad]\n    grads = torch.autograd.grad(loss, params, create_graph=True)\n    grad_vec = torch.cat([g.flatten() for g in grads])\n    trace_est = 0.0\n    for _ in range(n_samples):\n        v = torch.randint(0, 2, grad_vec.shape).float() * 2 - 1\n        Hv = torch.autograd.grad(grad_vec @ v.detach(), params,\n                                  retain_graph=True)\n        Hv_flat = torch.cat([h.flatten() for h in Hv])\n        trace_est += (v * Hv_flat).sum().item()\n    return trace_est / n_samples\n\ntorch.manual_seed(0)\nX = torch.randn(64, 10)\ny = torch.randn(64, 1)\nmodel_sharp = nn.Sequential(nn.Linear(10, 4), nn.ReLU(), nn.Linear(4, 1))\nmodel_flat = nn.Sequential(nn.Linear(10, 4), nn.ReLU(), nn.Linear(4, 1))\nnn.init.normal_(list(model_sharp.parameters())[0], std=2.0)\nloss_fn = nn.MSELoss()\ntrace_sharp = hutchinson_trace(model_sharp, loss_fn, X, y)\ntrace_flat = hutchinson_trace(model_flat, loss_fn, X, y)\nprint(f\"Sharp model Hessian trace estimate: {trace_sharp:.2f}\")\nprint(f\"Flat model Hessian trace estimate:  {trace_flat:.2f}\")"}, {"type": "heading", "level": 2, "content": "PAC-Bayes Bound and Sharpness"}, {"type": "text", "content": "PAC-Bayes theorem (McAllester 1999): for any prior P and posterior Q over hypotheses, with probability at least 1−δ over samples of size n: L_test(Q) ≤ L_train(Q) + sqrt((KL(Q||P) + log(1/δ)) / (2n)). Setting Q = N(θ*, σ²I) (Gaussian posterior around the solution) and P = N(0, σ²I) (standard prior), the KL divergence KL(Q||P) ≈ ‖θ*‖²/(2σ²). Foret et al. (2021) interpret the sharpness-aware objective as minimizing an upper bound from this theorem: maximizing σ (allowed perturbation radius) to keep the loss stable is equivalent to minimizing the maximum loss in a ball of radius ρ around θ*. The SAM objective max_{‖ε‖≤ρ} L(θ+ε) directly measures the worst-case perturbation loss, and minimizing it simultaneously pushes down training loss and the KL term in the PAC-Bayes bound, giving a theoretical guarantee of better generalization."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom torch.utils.data import TensorDataset, DataLoader\n\nclass SAM(optim.Optimizer):\n    \"\"\"Sharpness-Aware Minimization optimizer (Foret et al. 2021).\"\"\"\n    def __init__(self, params, base_optimizer, rho=0.05, **kwargs):\n        defaults = dict(rho=rho, **kwargs)\n        super().__init__(params, defaults)\n        self.base_optimizer = base_optimizer(self.param_groups, **kwargs)\n\n    @torch.no_grad()\n    def first_step(self, zero_grad=False):\n        \"\"\"Perturb weights: w̃ = w + rho * grad/||grad||.\"\"\"\n        grad_norm = torch.stack([p.grad.norm()\n            for group in self.param_groups\n            for p in group['params'] if p.grad is not None]).norm()\n        for group in self.param_groups:\n            scale = group['rho'] / (grad_norm + 1e-12)\n            for p in group['params']:\n                if p.grad is None: continue\n                e_w = p.grad * scale\n                p.add_(e_w)\n                self.state[p]['e_w'] = e_w\n        if zero_grad: self.zero_grad()\n\n    @torch.no_grad()\n    def second_step(self, zero_grad=False):\n        \"\"\"Restore weights and apply update using perturbed gradient.\"\"\"\n        for group in self.param_groups:\n            for p in group['params']:\n                if p.grad is None: continue\n                p.sub_(self.state[p]['e_w'])  # restore\n        self.base_optimizer.step()\n        if zero_grad: self.zero_grad()\n\ntorch.manual_seed(1)\nprint(\"SAM optimizer implemented — ready for training loop\")"}, {"type": "heading", "level": 2, "content": "Why SGD Finds Flat Minima"}, {"type": "text", "content": "SGD with learning rate η and batch size B generates gradient noise whose covariance is proportional to ηC/B, where C is the empirical gradient covariance (Fisher information matrix). This noise acts as an implicit regularizer: the stationary distribution of SGD's stochastic process is not the minimizer of L(θ) itself, but of a penalized objective L(θ) + (η/4B)·tr(H(θ)). The penalty term tr(H) is the Hessian trace — precisely the average sharpness measure. Therefore: smaller batch size B → larger penalty coefficient → stronger preference for flat minima. This prediction matches empirical observations precisely: large-batch SGD finds sharper minima (Keskar et al. 2017), generalizes worse at the same training loss, and requires learning rate scaling or SAM to compensate. The implication for practitioners is that the batch size and learning rate jointly control an implicit regularization strength — the 'linear scaling rule' (LR ∝ B) attempts to keep this implicit regularization constant, but it only holds approximately in the linear regime and breaks for very large batch sizes."}, {"type": "heading", "level": 2, "content": "SAM Optimizer: Sharpness-Aware Minimization"}, {"type": "text", "content": "SAM (Foret et al. 2021) implements two-step updates that explicitly minimize worst-case perturbation loss. Step 1 (perturbation): compute ε̂ = ρ·∇L(θ)/‖∇L(θ)‖ and set w̃ = θ + ε̂ (perturb weights in the gradient direction by ρ, typically 0.05). Step 2 (update): compute gradient at the perturbed point ∇L(w̃), then update from the ORIGINAL θ: θ ← θ − η·∇L(w̃). This costs twice the compute of SGD (two forward-backward passes per step) but targets the flat-minima objective directly. ASAM (Adaptive SAM) scales the perturbation per parameter: ε̂ = ρ·|θ|·∇L/‖|θ|·∇L‖, making the perturbation scale-invariant and more effective for parameters with different magnitudes. Practical variants: GSAM (gradient magnitude-based SAM), mSAM (mini-batch SAM with gradient accumulation, halving compute overhead), SAM with EMA. On ImageNet with ResNet-50, SAM improves top-1 accuracy by 0.5-1.5% depending on data augmentation; on CIFAR-100, improvements of 1-3% are common."}, {"type": "code", "language": "python", "content": "import torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom torch.utils.data import TensorDataset, DataLoader\n\ndef sam_training_step(model, sam_optimizer, data, target, loss_fn):\n    \"\"\"Complete SAM two-step update.\"\"\"\n    # First forward-backward: compute gradient at current weights\n    sam_optimizer.zero_grad()\n    output = model(data)\n    loss = loss_fn(output, target)\n    loss.backward()\n    # First step: perturb weights\n    sam_optimizer.first_step(zero_grad=True)\n    # Second forward-backward: compute gradient at perturbed weights\n    loss_fn(model(data), target).backward()\n    # Second step: restore weights, apply update\n    sam_optimizer.second_step(zero_grad=True)\n    return loss.item()\n\ntorch.manual_seed(42)\nX = torch.randn(200, 8)\ny = (X[:, 0] + X[:, 1] > 0).long()\ndataset = TensorDataset(X, y)\nloader = DataLoader(dataset, batch_size=32, shuffle=True)\nmodel = nn.Sequential(nn.Linear(8, 16), nn.ReLU(), nn.Linear(16, 2))\nbase_opt = optim.SGD\nsam_opt = SAM(model.parameters(), base_opt, lr=0.01, momentum=0.9, rho=0.05)\nloss_fn = nn.CrossEntropyLoss()\nfor epoch in range(3):\n    total = sum(sam_training_step(model, sam_opt, xb, yb, loss_fn)\n                for xb, yb in loader)\n    print(f\"Epoch {epoch+1}: avg loss {total/len(loader):.4f}\")"}, {"type": "heading", "level": 2, "content": "ML Connections: Batch Size, LR, and Flatness"}, {"type": "text", "content": "The flat minima connection unifies several empirical observations that previously seemed unrelated. First, large-batch training finds sharper minima because the noise covariance η·C/B is smaller at large B, weakening the implicit flat-minima regularization — this is why naive large-batch training generalizes worse and why SAM is especially effective when combined with large batches. Second, a higher learning rate η increases noise, biasing toward flatter minima within the stable training range — this is why the 'linear scaling rule' (double LR when doubling batch size) approximately preserves generalization. Third, dropout is another noise source that implicitly encourages flat minima by making the model robust to random unit deactivation, analogous to weight perturbation. Fourth, model soups (Wortsman et al. 2022) and SWA work because averaging multiple checkpoints moves the effective weights toward the geometric center of a flat valley, giving better calibration and generalization than any single checkpoint. Fifth, in self-supervised learning, the momentum encoder in BYOL/DINO tracks an exponential moving average of the online encoder, which implicitly samples from a flat region of weight space and provides more stable targets for representation learning."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom torch.utils.data import TensorDataset, DataLoader\n\ndef make_data(n=300, seed=0):\n    torch.manual_seed(seed)\n    X = torch.randn(n, 6)\n    y = (X[:, 0] - X[:, 1] + 0.5 * X[:, 2] > 0).long()\n    return X, y\n\ndef train_model(X, y, batch_size, lr, use_sam=False, epochs=20):\n    model = nn.Sequential(nn.Linear(6, 12), nn.ReLU(), nn.Linear(12, 2))\n    loader = DataLoader(TensorDataset(X[:240], y[:240]), batch_size=batch_size)\n    if use_sam:\n        opt = SAM(model.parameters(), optim.SGD, lr=lr, rho=0.05)\n    else:\n        opt = optim.SGD(model.parameters(), lr=lr)\n    loss_fn = nn.CrossEntropyLoss()\n    for _ in range(epochs):\n        for xb, yb in loader:\n            if use_sam:\n                opt.zero_grad()\n                loss_fn(model(xb), yb).backward()\n                opt.first_step(zero_grad=True)\n                loss_fn(model(xb), yb).backward()\n                opt.second_step(zero_grad=True)\n            else:\n                opt.zero_grad()\n                loss_fn(model(xb), yb).backward()\n                opt.step()\n    with torch.no_grad():\n        preds = model(X[240:]).argmax(1)\n        return (preds == y[240:]).float().mean().item()\n\nX, y = make_data()\nprint(f\"SGD small batch (B=16):  test acc = {train_model(X, y, 16, 0.05):.3f}\")\nprint(f\"SGD large batch (B=128): test acc = {train_model(X, y, 128, 0.05):.3f}\")\nprint(f\"SAM large batch (B=128): test acc = {train_model(X, y, 128, 0.05, use_sam=True):.3f}\")"}, {"type": "heading", "level": 2, "content": "Implementation Pitfalls"}, {"type": "text", "content": "Four pitfalls when implementing SAM and flat-minima techniques. First, forgetting to restore weights after the first step: if the model parameters are not restored before the second gradient computation, the second gradient is computed at the perturbed point but the update is also applied at the perturbed point — losing the flat-minima objective entirely. Always save and restore original parameters. Second, using SAM with gradient accumulation without reducing per-step loss by the accumulation factor: accumulation inflates gradient norms, making the perturbation radius effectively larger than intended. Third, monitoring only training loss: SAM sometimes causes training loss to plateau while test loss continues to improve — this is a feature, not a bug, but can be misinterpreted as lack of progress. Fourth, using SAM when the generalization gap is small: if train and test accuracy are already within 1%, SAM adds compute overhead without meaningful benefit. Profile the generalization gap before adding SAM."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Practical guidelines for applying flat-minima insights. Choose batch size and learning rate together: use the largest batch size that fits in memory, then scale LR proportionally (linear scaling rule: LR = base_LR × B/256), and add SAM if the generalization gap is still larger than expected. For monitoring sharpness cheaply: log the gradient norm after backward() before clipping — gradient norm at critical points correlates with sharpness (higher gradient norm → sharper curvature along the trajectory). Use SWA as a free improvement: after the main training schedule, run 10-20 more epochs with a cyclic LR schedule (SWA-style) and average the checkpoints; this typically gains 0.3-0.5% accuracy with no architecture changes. For fine-tuning pre-trained models, start with lower ρ (e.g., 0.01 instead of 0.05) in SAM to avoid disrupting the pre-trained features, and increase ρ only if the generalization gap warrants it."}, {"type": "callout", "title": "Warning", "content": "SAM doubles compute cost — only use it when the generalization gap (train accuracy minus test accuracy) exceeds 2%. Monitor train and test loss separately throughout SAM training: if both decrease together, SAM is working as expected. If train loss stops decreasing but test loss keeps improving, the model has found a flat minimum and you may safely reduce ρ to accelerate convergence. Never use SAM as a substitute for proper regularization (weight decay, dropout, data augmentation) — those should be in place first."}, {"type": "table", "headers": ["Optimizer", "Sharpness", "Generalization", "Compute Overhead", "Memory Overhead"], "rows": [["SGD small batch (B≤32)", "Low (flat)", "Best", "1×", "1×"], ["SGD large batch (B≥512)", "High (sharp)", "Worse at same LR", "1× (fast steps)", "1×"], ["Adam", "Medium-high", "Good (adaptive LR)", "1.3× (moment buffers)", "2× (m, v buffers)"], ["SAM + SGD", "Low (explicit)", "Best in class", "2× (two passes)", "1× + e_w buffer"], ["SWA", "Low (center of valley)", "Very good", "1× + averaging step", "2× (model + SWA model)"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "items": ["Sharpness is measured by λ_max (largest Hessian eigenvalue, worst-case curvature) or tr(H) (average curvature, cheaper via Hutchinson's estimator).", "PAC-Bayes theorem formalizes why flat minima generalize better: the generalization bound is controlled by KL(Q||P), which is smaller when the model is robust to weight perturbations.", "SAM minimizes max_{‖ε‖≤ρ} L(θ+ε): perturb weights in gradient direction, compute gradient at perturbed point, update from original weights — explicitly targeting the PAC-Bayes bound.", "SGD implicitly biases toward flat minima via gradient noise with scale η/B; large batch size weakens this bias, explaining the generalization gap of large-batch training.", "SWA (Stochastic Weight Averaging) places the model at the flat geometric center of a loss valley by averaging late-training checkpoints — free 0.3-0.5% improvement.", "Use SAM only when the generalization gap exceeds 2%; profile train/test loss separately and reduce ρ when both losses align.", "The linear scaling rule (LR ∝ B) approximately preserves the implicit flat-minima regularization when scaling batch size, but breaks at very large batches where the noise is no longer well-modeled as Gaussian."]}]"
---

# Sharp vs Flat Minima and Generalization

Not all minima of a neural network's training loss are created equal: some generalize well to held-out data, others memorize the training set. The geometry of the minimum — specifically its sharpness (curvature) — predicts this difference. A flat minimum is one where the loss changes slowly as weights move in any direction; a sharp minimum has directions of high curvature where small weight perturbations cause large loss spikes. This note builds from formal sharpness measures through the PAC-Bayes bound that explains why flat minima generalize better, to the SAM optimizer that explicitly targets flat minima, and the connection between SGD noise and implicit regularization toward flat regions.

## Measuring Sharpness

The largest Hessian eigenvalue λ_max measures sharpness in the worst-case direction: even one direction of high curvature makes a minimum sharp. The Hessian trace tr(H) = Σλᵢ measures average curvature over all directions — cheaper to estimate than λ_max (Hutchinson's estimator uses tr(H) ≈ Eᵥ[vᵀHv] with random ±1 vectors v). The sharpness ratio ρ_sharp = max_{‖δ‖≤ρ} [L(θ+δ) − L(θ)] asks: how much does loss increase if we perturb weights by at most ρ in any direction? Hochreiter and Schmidhuber (1997) gave a Minimum Description Length argument: a flat minimum can be encoded with lower weight precision (fewer bits) because small quantization errors leave the loss unchanged; fewer bits → shorter description → better generalization by MDL/Occam's razor. Practically: two models with the same training loss but different sharpness will have different test loss; the flatter model generalizes better by an amount predicted by the PAC-Bayes bound.

```python
import numpy as np
import torch
import torch.nn as nn
from torch.autograd.functional import hvp

def hutchinson_trace(model, loss_fn, X, y, n_samples=20):
    """Estimate Hessian trace via Hutchinson's method."""
    loss = loss_fn(model(X), y)
    params = [p for p in model.parameters() if p.requires_grad]
    grads = torch.autograd.grad(loss, params, create_graph=True)
    grad_vec = torch.cat([g.flatten() for g in grads])
    trace_est = 0.0
    for _ in range(n_samples):
        v = torch.randint(0, 2, grad_vec.shape).float() * 2 - 1
        Hv = torch.autograd.grad(grad_vec @ v.detach(), params,
                                  retain_graph=True)
        Hv_flat = torch.cat([h.flatten() for h in Hv])
        trace_est += (v * Hv_flat).sum().item()
    return trace_est / n_samples

torch.manual_seed(0)
X = torch.randn(64, 10)
y = torch.randn(64, 1)
model_sharp = nn.Sequential(nn.Linear(10, 4), nn.ReLU(), nn.Linear(4, 1))
model_flat = nn.Sequential(nn.Linear(10, 4), nn.ReLU(), nn.Linear(4, 1))
nn.init.normal_(list(model_sharp.parameters())[0], std=2.0)
loss_fn = nn.MSELoss()
trace_sharp = hutchinson_trace(model_sharp, loss_fn, X, y)
trace_flat = hutchinson_trace(model_flat, loss_fn, X, y)
print(f"Sharp model Hessian trace estimate: {trace_sharp:.2f}")
print(f"Flat model Hessian trace estimate:  {trace_flat:.2f}")
```

## PAC-Bayes Bound and Sharpness

PAC-Bayes theorem (McAllester 1999): for any prior P and posterior Q over hypotheses, with probability at least 1−δ over samples of size n: L_test(Q) ≤ L_train(Q) + sqrt((KL(Q||P) + log(1/δ)) / (2n)). Setting Q = N(θ*, σ²I) (Gaussian posterior around the solution) and P = N(0, σ²I) (standard prior), the KL divergence KL(Q||P) ≈ ‖θ*‖²/(2σ²). Foret et al. (2021) interpret the sharpness-aware objective as minimizing an upper bound from this theorem: maximizing σ (allowed perturbation radius) to keep the loss stable is equivalent to minimizing the maximum loss in a ball of radius ρ around θ*. The SAM objective max_{‖ε‖≤ρ} L(θ+ε) directly measures the worst-case perturbation loss, and minimizing it simultaneously pushes down training loss and the KL term in the PAC-Bayes bound, giving a theoretical guarantee of better generalization.

```python
import torch
import torch.nn as nn
import torch.optim as optim
from torch.utils.data import TensorDataset, DataLoader

class SAM(optim.Optimizer):
    """Sharpness-Aware Minimization optimizer (Foret et al. 2021)."""
    def __init__(self, params, base_optimizer, rho=0.05, **kwargs):
        defaults = dict(rho=rho, **kwargs)
        super().__init__(params, defaults)
        self.base_optimizer = base_optimizer(self.param_groups, **kwargs)

    @torch.no_grad()
    def first_step(self, zero_grad=False):
        """Perturb weights: w̃ = w + rho * grad/||grad||."""
        grad_norm = torch.stack([p.grad.norm()
            for group in self.param_groups
            for p in group['params'] if p.grad is not None]).norm()
        for group in self.param_groups:
            scale = group['rho'] / (grad_norm + 1e-12)
            for p in group['params']:
                if p.grad is None: continue
                e_w = p.grad * scale
                p.add_(e_w)
                self.state[p]['e_w'] = e_w
        if zero_grad: self.zero_grad()

    @torch.no_grad()
    def second_step(self, zero_grad=False):
        """Restore weights and apply update using perturbed gradient."""
        for group in self.param_groups:
            for p in group['params']:
                if p.grad is None: continue
                p.sub_(self.state[p]['e_w'])  # restore
        self.base_optimizer.step()
        if zero_grad: self.zero_grad()

torch.manual_seed(1)
print("SAM optimizer implemented — ready for training loop")
```

## Why SGD Finds Flat Minima

SGD with learning rate η and batch size B generates gradient noise whose covariance is proportional to ηC/B, where C is the empirical gradient covariance (Fisher information matrix). This noise acts as an implicit regularizer: the stationary distribution of SGD's stochastic process is not the minimizer of L(θ) itself, but of a penalized objective L(θ) + (η/4B)·tr(H(θ)). The penalty term tr(H) is the Hessian trace — precisely the average sharpness measure. Therefore: smaller batch size B → larger penalty coefficient → stronger preference for flat minima. This prediction matches empirical observations precisely: large-batch SGD finds sharper minima (Keskar et al. 2017), generalizes worse at the same training loss, and requires learning rate scaling or SAM to compensate. The implication for practitioners is that the batch size and learning rate jointly control an implicit regularization strength — the 'linear scaling rule' (LR ∝ B) attempts to keep this implicit regularization constant, but it only holds approximately in the linear regime and breaks for very large batch sizes.

## SAM Optimizer: Sharpness-Aware Minimization

SAM (Foret et al. 2021) implements two-step updates that explicitly minimize worst-case perturbation loss. Step 1 (perturbation): compute ε̂ = ρ·∇L(θ)/‖∇L(θ)‖ and set w̃ = θ + ε̂ (perturb weights in the gradient direction by ρ, typically 0.05). Step 2 (update): compute gradient at the perturbed point ∇L(w̃), then update from the ORIGINAL θ: θ ← θ − η·∇L(w̃). This costs twice the compute of SGD (two forward-backward passes per step) but targets the flat-minima objective directly. ASAM (Adaptive SAM) scales the perturbation per parameter: ε̂ = ρ·|θ|·∇L/‖|θ|·∇L‖, making the perturbation scale-invariant and more effective for parameters with different magnitudes. Practical variants: GSAM (gradient magnitude-based SAM), mSAM (mini-batch SAM with gradient accumulation, halving compute overhead), SAM with EMA. On ImageNet with ResNet-50, SAM improves top-1 accuracy by 0.5-1.5% depending on data augmentation; on CIFAR-100, improvements of 1-3% are common.

```python
import torch
import torch.nn as nn
import torch.optim as optim
from torch.utils.data import TensorDataset, DataLoader

def sam_training_step(model, sam_optimizer, data, target, loss_fn):
    """Complete SAM two-step update."""
    # First forward-backward: compute gradient at current weights
    sam_optimizer.zero_grad()
    output = model(data)
    loss = loss_fn(output, target)
    loss.backward()
    # First step: perturb weights
    sam_optimizer.first_step(zero_grad=True)
    # Second forward-backward: compute gradient at perturbed weights
    loss_fn(model(data), target).backward()
    # Second step: restore weights, apply update
    sam_optimizer.second_step(zero_grad=True)
    return loss.item()

torch.manual_seed(42)
X = torch.randn(200, 8)
y = (X[:, 0] + X[:, 1] > 0).long()
dataset = TensorDataset(X, y)
loader = DataLoader(dataset, batch_size=32, shuffle=True)
model = nn.Sequential(nn.Linear(8, 16), nn.ReLU(), nn.Linear(16, 2))
base_opt = optim.SGD
sam_opt = SAM(model.parameters(), base_opt, lr=0.01, momentum=0.9, rho=0.05)
loss_fn = nn.CrossEntropyLoss()
for epoch in range(3):
    total = sum(sam_training_step(model, sam_opt, xb, yb, loss_fn)
                for xb, yb in loader)
    print(f"Epoch {epoch+1}: avg loss {total/len(loader):.4f}")
```

## ML Connections: Batch Size, LR, and Flatness

The flat minima connection unifies several empirical observations that previously seemed unrelated. First, large-batch training finds sharper minima because the noise covariance η·C/B is smaller at large B, weakening the implicit flat-minima regularization — this is why naive large-batch training generalizes worse and why SAM is especially effective when combined with large batches. Second, a higher learning rate η increases noise, biasing toward flatter minima within the stable training range — this is why the 'linear scaling rule' (double LR when doubling batch size) approximately preserves generalization. Third, dropout is another noise source that implicitly encourages flat minima by making the model robust to random unit deactivation, analogous to weight perturbation. Fourth, model soups (Wortsman et al. 2022) and SWA work because averaging multiple checkpoints moves the effective weights toward the geometric center of a flat valley, giving better calibration and generalization than any single checkpoint. Fifth, in self-supervised learning, the momentum encoder in BYOL/DINO tracks an exponential moving average of the online encoder, which implicitly samples from a flat region of weight space and provides more stable targets for representation learning.

```python
import numpy as np
import torch
import torch.nn as nn
import torch.optim as optim
from torch.utils.data import TensorDataset, DataLoader

def make_data(n=300, seed=0):
    torch.manual_seed(seed)
    X = torch.randn(n, 6)
    y = (X[:, 0] - X[:, 1] + 0.5 * X[:, 2] > 0).long()
    return X, y

def train_model(X, y, batch_size, lr, use_sam=False, epochs=20):
    model = nn.Sequential(nn.Linear(6, 12), nn.ReLU(), nn.Linear(12, 2))
    loader = DataLoader(TensorDataset(X[:240], y[:240]), batch_size=batch_size)
    if use_sam:
        opt = SAM(model.parameters(), optim.SGD, lr=lr, rho=0.05)
    else:
        opt = optim.SGD(model.parameters(), lr=lr)
    loss_fn = nn.CrossEntropyLoss()
    for _ in range(epochs):
        for xb, yb in loader:
            if use_sam:
                opt.zero_grad()
                loss_fn(model(xb), yb).backward()
                opt.first_step(zero_grad=True)
                loss_fn(model(xb), yb).backward()
                opt.second_step(zero_grad=True)
            else:
                opt.zero_grad()
                loss_fn(model(xb), yb).backward()
                opt.step()
    with torch.no_grad():
        preds = model(X[240:]).argmax(1)
        return (preds == y[240:]).float().mean().item()

X, y = make_data()
print(f"SGD small batch (B=16):  test acc = {train_model(X, y, 16, 0.05):.3f}")
print(f"SGD large batch (B=128): test acc = {train_model(X, y, 128, 0.05):.3f}")
print(f"SAM large batch (B=128): test acc = {train_model(X, y, 128, 0.05, use_sam=True):.3f}")
```

## Implementation Pitfalls

Four pitfalls when implementing SAM and flat-minima techniques. First, forgetting to restore weights after the first step: if the model parameters are not restored before the second gradient computation, the second gradient is computed at the perturbed point but the update is also applied at the perturbed point — losing the flat-minima objective entirely. Always save and restore original parameters. Second, using SAM with gradient accumulation without reducing per-step loss by the accumulation factor: accumulation inflates gradient norms, making the perturbation radius effectively larger than intended. Third, monitoring only training loss: SAM sometimes causes training loss to plateau while test loss continues to improve — this is a feature, not a bug, but can be misinterpreted as lack of progress. Fourth, using SAM when the generalization gap is small: if train and test accuracy are already within 1%, SAM adds compute overhead without meaningful benefit. Profile the generalization gap before adding SAM.

## Practical Guidance

Practical guidelines for applying flat-minima insights. Choose batch size and learning rate together: use the largest batch size that fits in memory, then scale LR proportionally (linear scaling rule: LR = base_LR × B/256), and add SAM if the generalization gap is still larger than expected. For monitoring sharpness cheaply: log the gradient norm after backward() before clipping — gradient norm at critical points correlates with sharpness (higher gradient norm → sharper curvature along the trajectory). Use SWA as a free improvement: after the main training schedule, run 10-20 more epochs with a cyclic LR schedule (SWA-style) and average the checkpoints; this typically gains 0.3-0.5% accuracy with no architecture changes. For fine-tuning pre-trained models, start with lower ρ (e.g., 0.01 instead of 0.05) in SAM to avoid disrupting the pre-trained features, and increase ρ only if the generalization gap warrants it.

> **Warning**: SAM doubles compute cost — only use it when the generalization gap (train accuracy minus test accuracy) exceeds 2%. Monitor train and test loss separately throughout SAM training: if both decrease together, SAM is working as expected. If train loss stops decreasing but test loss keeps improving, the model has found a flat minimum and you may safely reduce ρ to accelerate convergence. Never use SAM as a substitute for proper regularization (weight decay, dropout, data augmentation) — those should be in place first.

| Optimizer | Sharpness | Generalization | Compute Overhead | Memory Overhead |
|---|---|---|---|---|
| SGD small batch (B≤32) | Low (flat) | Best | 1× | 1× |
| SGD large batch (B≥512) | High (sharp) | Worse at same LR | 1× (fast steps) | 1× |
| Adam | Medium-high | Good (adaptive LR) | 1.3× (moment buffers) | 2× (m, v buffers) |
| SAM + SGD | Low (explicit) | Best in class | 2× (two passes) | 1× + e_w buffer |
| SWA | Low (center of valley) | Very good | 1× + averaging step | 2× (model + SWA model) |

---

## Key Takeaways

- Sharpness is measured by λ_max (largest Hessian eigenvalue, worst-case curvature) or tr(H) (average curvature, cheaper via Hutchinson's estimator).
- PAC-Bayes theorem formalizes why flat minima generalize better: the generalization bound is controlled by KL(Q||P), which is smaller when the model is robust to weight perturbations.
- SAM minimizes max_{‖ε‖≤ρ} L(θ+ε): perturb weights in gradient direction, compute gradient at perturbed point, update from original weights — explicitly targeting the PAC-Bayes bound.
- SGD implicitly biases toward flat minima via gradient noise with scale η/B; large batch size weakens this bias, explaining the generalization gap of large-batch training.
- SWA (Stochastic Weight Averaging) places the model at the flat geometric center of a loss valley by averaging late-training checkpoints — free 0.3-0.5% improvement.
- Use SAM only when the generalization gap exceeds 2%; profile train/test loss separately and reduce ρ when both losses align.
- The linear scaling rule (LR ∝ B) approximately preserves the implicit flat-minima regularization when scaling batch size, but breaks at very large batches where the noise is no longer well-modeled as Gaussian.

