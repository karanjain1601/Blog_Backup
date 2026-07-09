---
title: "Sharp vs Flat Minima and Generalization"
slug: "sharp-flat-minima-generalization"
description: "How the curvature of the loss minimum — measured by Hessian eigenvalues — predicts generalization, why SGD finds flat minima, and how SAM explicitly seeks them."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Two models can achieve identical training loss yet differ dramatically in test performance. One key geometric factor: the curvature of the loss surface at the minimum. A sharp minimum is surrounded by high-curvature walls — a tiny perturbation to weights causes a large loss increase, and when the train/test distributions differ slightly (as they always do), the model generalizes poorly. A flat minimum is robust to perturbations and tends to generalize better."},{"type":"heading","level":2,"content":"Understanding Sharp and Flat Minima"},{"type":"text","content":"Sharpness is formally quantified by the Hessian ∇²L(θ) at the minimum θ*. The largest eigenvalue λ_max(∇²L) gives the worst-case curvature: a perturbation ε in the direction of the top eigenvector increases loss by approximately (λ_max/2)‖ε‖². For a flat minimum λ_max is small; for a sharp minimum it can be millions. PAC-Bayes bounds connect sharpness to the generalization gap: generalization_gap ≈ O(√(λ_max/n)) where n is training set size."},{"type":"callout","variant":"info","title":"Hochreiter \u0026 Schmidhuber 1997","content":"The original flat minima paper argued from an MDL perspective: a flat minimum can be described with fewer bits than a sharp one (you can quantize the weights more aggressively without changing the loss). Lower description length implies better generalization by Occam\u0027s razor / MDL principle. Modern PAC-Bayes theory formalizes this into quantitative generalization bounds."},{"type":"heading","level":2,"content":"Measuring Sharpness"},{"type":"text","content":"Computing the full Hessian of a neural network is O(n²) in memory and O(n³) to diagonalize — completely infeasible for large models. Several efficient proxies exist: the largest Hessian eigenvalue via power iteration (Lanczos), the Hessian trace via Hutchinson\u0027s estimator, and expected sharpness (average loss over Gaussian weight perturbations). Each captures a different aspect of the curvature geometry."},{"type":"table","headers":["Metric","Formula","Computational Cost","Interpretation"],"rows":[["Max eigenvalue λ_max","λ_max(∇²L)","O(n) per power iteration step","Worst-case curvature direction"],["Hessian trace","Tr(∇²L) = Σᵢλᵢ","O(kn) via Hutchinson estimator","Average curvature across all directions"],["Expected sharpness","E_δ[L(θ+δ)−L(θ)], δ~N(0,σ²I)","MC sampling, O(kn) per estimate","Average loss increase under random perturbation"],["ρ-sharpness (SAM)","max_{‖ε‖≤ρ} L(θ+ε)−L(θ)","One gradient ascent step O(n)","Worst-case perturbation loss increase in ρ-ball"]]},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef largest_hessian_eigenvalue(model, loss_fn, X, y, n_iters=40, tol=1e-5):\n    \"\"\"Power iteration to estimate λ_max(∇²L) — the sharpness metric.\"\"\"\n    params = [p for p in model.parameters() if p.requires_grad]\n\n    # Initialize random unit vector\n    v = [torch.randn_like(p) for p in params]\n    v_norm = torch.sqrt(sum((vi**2).sum() for vi in v))\n    v = [vi / v_norm for vi in v]\n\n    eigenvalue = 0.0\n    for it in range(n_iters):\n        # Forward pass\n        loss = loss_fn(model(X), y)\n        grads = torch.autograd.grad(loss, params, create_graph=True)\n\n        # Hessian-vector product: d/dθ (grads · v)\n        gv_dot = sum((g * vi).sum() for g, vi in zip(grads, v))\n        Hv = torch.autograd.grad(gv_dot, params, retain_graph=False)\n\n        # Rayleigh quotient\n        new_eig = sum((hvi * vi).sum() for hvi, vi in zip(Hv, v)).item()\n\n        # Normalize for next iteration\n        Hv_norm = torch.sqrt(sum((hvi**2).sum() for hvi in Hv)) + 1e-12\n        v = [hvi / Hv_norm for hvi in Hv]\n\n        if abs(new_eig - eigenvalue) \u003c tol:\n            print(f\"  Converged at iteration {it+1}\")\n            break\n        eigenvalue = new_eig\n\n    return eigenvalue\n\ntorch.manual_seed(0)\nmodel = nn.Sequential(nn.Linear(4, 16), nn.ReLU(), nn.Linear(16, 1))\nX, y = torch.randn(64, 4), torch.randn(64, 1)\nsharpness = largest_hessian_eigenvalue(model, nn.MSELoss(), X, y)\nprint(f\"λ_max (sharpness): {sharpness:.4f}\")\nprint(\"Higher λ_max → sharper minimum → expected worse generalization.\")"},{"type":"heading","level":2,"content":"Theoretical Connections to Generalization"},{"type":"text","content":"PAC-Bayes theory bounds the expected test loss in terms of the KL divergence between a perturbed posterior Q (weights + Gaussian noise) and a prior P. Minimizing this bound encourages finding flat regions where adding noise doesn\u0027t hurt loss. The connection to sharpness: KL(Q‖P) ∝ λ_max when the noise covariance is isotropic. Large batch training tends to find sharp minima (Keskar et al. 2017) because large batches provide accurate gradients that converge to the nearest minimum rather than exploring; small batches add noise that helps escape sharp regions."},{"type":"list","ordered":false,"items":["Large batch → low gradient noise → converges to sharp minima → poor generalization","Small batch → high gradient noise → biases toward flat minima → better generalization","High learning rate acts similarly: noisy updates prevent settling in sharp narrow basins","SGD noise scale: ∝ η·σ²/B where η=learning rate, σ²=gradient variance, B=batch size","Linear scaling rule (Goyal 2017): scale LR proportional to batch size to maintain noise level"]},{"type":"heading","level":2,"content":"SAM: Sharpness-Aware Minimization"},{"type":"text","content":"SAM (Foret et al. 2021) explicitly minimizes the worst-case loss in a ρ-ball around current weights. Instead of minimizing L(θ), it minimizes max_{‖ε‖≤ρ} L(θ+ε). Each SAM step has two gradient computations: (1) gradient ascent to find the worst-case perturbation ε̂ = ρ·∇L/‖∇L‖, (2) gradient at the perturbed point θ+ε̂ used to update θ. The result is a model that sits in a flat region — any perturbation within the ρ-ball still has low loss."},{"type":"list","ordered":true,"items":["Compute gradient ∇L(θ) with current weights","Compute perturbation ε̂ = ρ · ∇L(θ) / ‖∇L(θ)‖ (normalized gradient scaled by ρ)","Evaluate gradient at perturbed weights: ∇L(θ + ε̂)","Update original weights: θ ← θ − η · ∇L(θ + ε̂)","Cost: 2× forward/backward passes per step vs SGD\u0027s 1×"]},{"type":"code","language":"python","content":"import torch\n\nclass SAM(torch.optim.Optimizer):\n    \"\"\"Sharpness-Aware Minimization (Foret et al. 2021).\"\"\"\n\n    def __init__(self, params, base_optimizer_cls, rho=0.05, **kwargs):\n        defaults = dict(rho=rho, **kwargs)\n        super().__init__(params, defaults)\n        self.base_optimizer = base_optimizer_cls(self.param_groups, **kwargs)\n        self.param_groups = self.base_optimizer.param_groups\n\n    @torch.no_grad()\n    def first_step(self, zero_grad=False):\n        \"\"\"Climb to the worst-case perturbation point θ + ε̂.\"\"\"\n        grad_norm = self._grad_norm()\n        for group in self.param_groups:\n            scale = group[\"rho\"] / (grad_norm + 1e-12)\n            for p in group[\"params\"]:\n                if p.grad is None:\n                    continue\n                e_w = p.grad * scale.to(p)\n                p.add_(e_w)\n                self.state[p][\"e_w\"] = e_w\n        if zero_grad:\n            self.zero_grad()\n\n    @torch.no_grad()\n    def second_step(self, zero_grad=False):\n        \"\"\"Restore θ, then apply base optimizer step using perturbed gradient.\"\"\"\n        for group in self.param_groups:\n            for p in group[\"params\"]:\n                if p.grad is None:\n                    continue\n                p.sub_(self.state[p][\"e_w\"])\n        self.base_optimizer.step()\n        if zero_grad:\n            self.zero_grad()\n\n    def _grad_norm(self):\n        device = self.param_groups[0][\"params\"][0].device\n        norms = [p.grad.norm(2).to(device)\n                 for g in self.param_groups for p in g[\"params\"]\n                 if p.grad is not None]\n        return torch.stack(norms).norm(2)\n\n# Quick usage demo\ntorch.manual_seed(42)\nnet = torch.nn.Linear(4, 1)\nopt = SAM(net.parameters(), torch.optim.SGD, rho=0.05, lr=0.05)\nX, y = torch.randn(32, 4), torch.randn(32, 1)\nloss_fn = torch.nn.MSELoss()\nfor step in range(4):\n    loss = loss_fn(net(X), y)\n    loss.backward()\n    opt.first_step(zero_grad=True)\n    loss_fn(net(X), y).backward()\n    opt.second_step(zero_grad=True)\n    print(f\"Step {step+1}: loss={loss.item():.4f}\")"},{"type":"callout","variant":"tip","title":"SAM Hyperparameter ρ","content":"ρ is the radius of the perturbation ball. Larger ρ → stronger sharpness regularization but more aggressive perturbation. For CIFAR-10 / ResNet, ρ=0.05 works well. For transformers, ρ=0.02–0.1. If ρ is too large, the perturbation overshoots and SAM diverges. mSAM uses per-micro-batch sharpness; ASAM uses adaptive (per-parameter) normalization."},{"type":"heading","level":2,"content":"Comparing SAM vs SGD"},{"type":"text","content":"On image classification benchmarks, SAM consistently improves test accuracy by 1–2% over SGD with the same training budget. The improvement is largest when training data is limited (high generalization gap). SAM also improves robustness to label noise and distribution shift. The 2× compute cost is the main drawback; scheduled SAM (apply SAM only in later epochs) recovers most of the benefit at lower cost."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef train_model(model, optimizer, X_tr, y_tr, use_sam=False, epochs=60):\n    loss_fn = nn.MSELoss()\n    for epoch in range(epochs):\n        model.train()\n        for i in range(0, len(X_tr), 16):\n            xb, yb = X_tr[i:i+16], y_tr[i:i+16]\n            if use_sam:\n                loss = loss_fn(model(xb), yb)\n                loss.backward()\n                optimizer.first_step(zero_grad=True)\n                loss_fn(model(xb), yb).backward()\n                optimizer.second_step(zero_grad=True)\n            else:\n                optimizer.zero_grad()\n                loss = loss_fn(model(xb), yb)\n                loss.backward()\n                optimizer.step()\n\ntorch.manual_seed(0)\nnp.random.seed(0)\nn_tr, n_te = 80, 40\nX_tr = torch.randn(n_tr, 10)\nw_true = torch.randn(10, 1)\ny_tr = X_tr @ w_true + 0.5 * torch.randn(n_tr, 1)\nX_te = torch.randn(n_te, 10)\ny_te = X_te @ w_true + 0.5 * torch.randn(n_te, 1)\n\nresults = {}\nfor method, use_sam in [(\"SGD\", False), (\"SAM\", True)]:\n    torch.manual_seed(1)\n    model = nn.Sequential(nn.Linear(10, 32), nn.ReLU(), nn.Linear(32, 1))\n    if use_sam:\n        opt = SAM(model.parameters(), torch.optim.SGD, rho=0.05, lr=0.05)\n    else:\n        opt = torch.optim.SGD(model.parameters(), lr=0.05)\n    train_model(model, opt, X_tr, y_tr, use_sam=use_sam)\n    with torch.no_grad():\n        test_mse = nn.MSELoss()(model(X_te), y_te).item()\n    results[method] = test_mse\n    print(f\"{method}: test MSE = {test_mse:.4f}\")\nprint(f\"SAM improvement: {100*(results[\u0027SGD\u0027]-results[\u0027SAM\u0027])/results[\u0027SGD\u0027]:.1f}%\")"},{"type":"heading","level":2,"content":"Visualizing the Loss Landscape"},{"type":"text","content":"We can compare the local loss geometry around two minima by sampling loss values within a small ball. A sharp minimum shows rapidly increasing loss even for small perturbations; a flat minimum maintains low loss across the entire ball. This directly explains generalization: the train-test distribution shift acts like a weight perturbation, so sharp minima suffer a larger test loss increase."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sample_perturbation_losses(center_weights, loss_fn, n_samples=300, radii=(0.1, 0.3, 0.5)):\n    \"\"\"Sample loss at random perturbations of different radii from the minimum.\"\"\"\n    results = {}\n    for r in radii:\n        perturbed_losses = []\n        for _ in range(n_samples):\n            perturbed = [w + np.random.randn(*w.shape) * r for w in center_weights]\n            perturbed_losses.append(loss_fn(perturbed))\n        results[r] = np.array(perturbed_losses)\n    return results\n\ndef sharp_loss(ws):  # High curvature: 100 * ||w||^2\n    return sum(100.0 * np.sum(w**2) for w in ws)\n\ndef flat_loss(ws):   # Low curvature: 1.0 * ||w||^2\n    return sum(1.0 * np.sum(w**2) for w in ws)\n\nnp.random.seed(3)\ncenter = [np.zeros((6,)), np.zeros((4,))]  # at the global minimum\n\nsharp_stats = sample_perturbation_losses(center, sharp_loss)\nflat_stats  = sample_perturbation_losses(center, flat_loss)\n\nprint(f\"{\u0027Radius\u0027:\u003c8} {\u0027Sharp Mean\u0027:\u003e12} {\u0027Sharp Std\u0027:\u003e12} {\u0027Flat Mean\u0027:\u003e12} {\u0027Flat Std\u0027:\u003e10}\")\nfor r in (0.1, 0.3, 0.5):\n    sm, ss = sharp_stats[r].mean(), sharp_stats[r].std()\n    fm, fs = flat_stats[r].mean(),  flat_stats[r].std()\n    print(f\"{r:\u003c8.1f} {sm:\u003e12.4f} {ss:\u003e12.4f} {fm:\u003e12.4f} {fs:\u003e10.4f}\")\nprint(\"\\nSharp minimum: loss grows rapidly with perturbation radius.\")\nprint(\"Flat minimum: loss stays near zero even for large perturbations.\")"},{"type":"heading","level":2,"content":"Extensions and Variants"},{"type":"text","content":"Several SAM variants improve efficiency or effectiveness. m-SAM computes sharpness on individual micro-batches rather than the full batch, finding sharper per-sample sharpness estimates. ASAM (Adaptive SAM) normalizes the perturbation per parameter by its magnitude, removing the scale sensitivity of fixed-ρ SAM. Scheduled ρ anneals ρ during training — large ρ early for exploration, small ρ later for refinement. Lookahead + SAM combines slow/fast weight averaging with sharpness awareness."},{"type":"list","ordered":false,"items":["mSAM (micro-batch SAM): sharpness computed per micro-batch — finds sharper, more harmful minima","ASAM: adaptive per-parameter normalization ε̂ᵢ = ρ|θᵢ|·gᵢ/‖|θ|·g‖ — scale invariant","GSAM: gradient decomposition into sharpness and task directions for more stable training","SWA (Stochastic Weight Averaging): average weights along SGD trajectory → flat region implicitly","SAM + large batch: partially recovers the flatness bias that small batches provide naturally"]},{"type":"divider"}]"
---
# Sharp vs Flat Minima and Generalization

Two models can achieve identical training loss yet differ dramatically in test performance. One key geometric factor: the curvature of the loss surface at the minimum. A sharp minimum is surrounded by high-curvature walls — a tiny perturbation to weights causes a large loss increase, and when the train/test distributions differ slightly (as they always do), the model generalizes poorly. A flat minimum is robust to perturbations and tends to generalize better.

## Understanding Sharp and Flat Minima

Sharpness is formally quantified by the Hessian ∇²L(θ) at the minimum θ*. The largest eigenvalue λ_max(∇²L) gives the worst-case curvature: a perturbation ε in the direction of the top eigenvector increases loss by approximately (λ_max/2)‖ε‖². For a flat minimum λ_max is small; for a sharp minimum it can be millions. PAC-Bayes bounds connect sharpness to the generalization gap: generalization_gap ≈ O(√(λ_max/n)) where n is training set size.

> **Hochreiter & Schmidhuber 1997**: The original flat minima paper argued from an MDL perspective: a flat minimum can be described with fewer bits than a sharp one (you can quantize the weights more aggressively without changing the loss). Lower description length implies better generalization by Occam's razor / MDL principle. Modern PAC-Bayes theory formalizes this into quantitative generalization bounds.

## Measuring Sharpness

Computing the full Hessian of a neural network is O(n²) in memory and O(n³) to diagonalize — completely infeasible for large models. Several efficient proxies exist: the largest Hessian eigenvalue via power iteration (Lanczos), the Hessian trace via Hutchinson's estimator, and expected sharpness (average loss over Gaussian weight perturbations). Each captures a different aspect of the curvature geometry.

| Metric | Formula | Computational Cost | Interpretation |
| --- | --- | --- | --- |
| Max eigenvalue λ_max | λ_max(∇²L) | O(n) per power iteration step | Worst-case curvature direction |
| Hessian trace | Tr(∇²L) = Σᵢλᵢ | O(kn) via Hutchinson estimator | Average curvature across all directions |
| Expected sharpness | E_δ[L(θ+δ)−L(θ)], δ~N(0,σ²I) | MC sampling, O(kn) per estimate | Average loss increase under random perturbation |
| ρ-sharpness (SAM) | max_{‖ε‖≤ρ} L(θ+ε)−L(θ) | One gradient ascent step O(n) | Worst-case perturbation loss increase in ρ-ball |

```python
import torch
import torch.nn as nn

def largest_hessian_eigenvalue(model, loss_fn, X, y, n_iters=40, tol=1e-5):
    """Power iteration to estimate λ_max(∇²L) — the sharpness metric."""
    params = [p for p in model.parameters() if p.requires_grad]

    # Initialize random unit vector
    v = [torch.randn_like(p) for p in params]
    v_norm = torch.sqrt(sum((vi**2).sum() for vi in v))
    v = [vi / v_norm for vi in v]

    eigenvalue = 0.0
    for it in range(n_iters):
        # Forward pass
        loss = loss_fn(model(X), y)
        grads = torch.autograd.grad(loss, params, create_graph=True)

        # Hessian-vector product: d/dθ (grads · v)
        gv_dot = sum((g * vi).sum() for g, vi in zip(grads, v))
        Hv = torch.autograd.grad(gv_dot, params, retain_graph=False)

        # Rayleigh quotient
        new_eig = sum((hvi * vi).sum() for hvi, vi in zip(Hv, v)).item()

        # Normalize for next iteration
        Hv_norm = torch.sqrt(sum((hvi**2).sum() for hvi in Hv)) + 1e-12
        v = [hvi / Hv_norm for hvi in Hv]

        if abs(new_eig - eigenvalue) < tol:
            print(f"  Converged at iteration {it+1}")
            break
        eigenvalue = new_eig

    return eigenvalue

torch.manual_seed(0)
model = nn.Sequential(nn.Linear(4, 16), nn.ReLU(), nn.Linear(16, 1))
X, y = torch.randn(64, 4), torch.randn(64, 1)
sharpness = largest_hessian_eigenvalue(model, nn.MSELoss(), X, y)
print(f"λ_max (sharpness): {sharpness:.4f}")
print("Higher λ_max → sharper minimum → expected worse generalization.")
```

## Theoretical Connections to Generalization

PAC-Bayes theory bounds the expected test loss in terms of the KL divergence between a perturbed posterior Q (weights + Gaussian noise) and a prior P. Minimizing this bound encourages finding flat regions where adding noise doesn't hurt loss. The connection to sharpness: KL(Q‖P) ∝ λ_max when the noise covariance is isotropic. Large batch training tends to find sharp minima (Keskar et al. 2017) because large batches provide accurate gradients that converge to the nearest minimum rather than exploring; small batches add noise that helps escape sharp regions.

- Large batch → low gradient noise → converges to sharp minima → poor generalization
- Small batch → high gradient noise → biases toward flat minima → better generalization
- High learning rate acts similarly: noisy updates prevent settling in sharp narrow basins
- SGD noise scale: ∝ η·σ²/B where η=learning rate, σ²=gradient variance, B=batch size
- Linear scaling rule (Goyal 2017): scale LR proportional to batch size to maintain noise level

## SAM: Sharpness-Aware Minimization

SAM (Foret et al. 2021) explicitly minimizes the worst-case loss in a ρ-ball around current weights. Instead of minimizing L(θ), it minimizes max_{‖ε‖≤ρ} L(θ+ε). Each SAM step has two gradient computations: (1) gradient ascent to find the worst-case perturbation ε̂ = ρ·∇L/‖∇L‖, (2) gradient at the perturbed point θ+ε̂ used to update θ. The result is a model that sits in a flat region — any perturbation within the ρ-ball still has low loss.

1. Compute gradient ∇L(θ) with current weights
2. Compute perturbation ε̂ = ρ · ∇L(θ) / ‖∇L(θ)‖ (normalized gradient scaled by ρ)
3. Evaluate gradient at perturbed weights: ∇L(θ + ε̂)
4. Update original weights: θ ← θ − η · ∇L(θ + ε̂)
5. Cost: 2× forward/backward passes per step vs SGD's 1×

```python
import torch

class SAM(torch.optim.Optimizer):
    """Sharpness-Aware Minimization (Foret et al. 2021)."""

    def __init__(self, params, base_optimizer_cls, rho=0.05, **kwargs):
        defaults = dict(rho=rho, **kwargs)
        super().__init__(params, defaults)
        self.base_optimizer = base_optimizer_cls(self.param_groups, **kwargs)
        self.param_groups = self.base_optimizer.param_groups

    @torch.no_grad()
    def first_step(self, zero_grad=False):
        """Climb to the worst-case perturbation point θ + ε̂."""
        grad_norm = self._grad_norm()
        for group in self.param_groups:
            scale = group["rho"] / (grad_norm + 1e-12)
            for p in group["params"]:
                if p.grad is None:
                    continue
                e_w = p.grad * scale.to(p)
                p.add_(e_w)
                self.state[p]["e_w"] = e_w
        if zero_grad:
            self.zero_grad()

    @torch.no_grad()
    def second_step(self, zero_grad=False):
        """Restore θ, then apply base optimizer step using perturbed gradient."""
        for group in self.param_groups:
            for p in group["params"]:
                if p.grad is None:
                    continue
                p.sub_(self.state[p]["e_w"])
        self.base_optimizer.step()
        if zero_grad:
            self.zero_grad()

    def _grad_norm(self):
        device = self.param_groups[0]["params"][0].device
        norms = [p.grad.norm(2).to(device)
                 for g in self.param_groups for p in g["params"]
                 if p.grad is not None]
        return torch.stack(norms).norm(2)

# Quick usage demo
torch.manual_seed(42)
net = torch.nn.Linear(4, 1)
opt = SAM(net.parameters(), torch.optim.SGD, rho=0.05, lr=0.05)
X, y = torch.randn(32, 4), torch.randn(32, 1)
loss_fn = torch.nn.MSELoss()
for step in range(4):
    loss = loss_fn(net(X), y)
    loss.backward()
    opt.first_step(zero_grad=True)
    loss_fn(net(X), y).backward()
    opt.second_step(zero_grad=True)
    print(f"Step {step+1}: loss={loss.item():.4f}")
```

> **SAM Hyperparameter ρ**: ρ is the radius of the perturbation ball. Larger ρ → stronger sharpness regularization but more aggressive perturbation. For CIFAR-10 / ResNet, ρ=0.05 works well. For transformers, ρ=0.02–0.1. If ρ is too large, the perturbation overshoots and SAM diverges. mSAM uses per-micro-batch sharpness; ASAM uses adaptive (per-parameter) normalization.

## Comparing SAM vs SGD

On image classification benchmarks, SAM consistently improves test accuracy by 1–2% over SGD with the same training budget. The improvement is largest when training data is limited (high generalization gap). SAM also improves robustness to label noise and distribution shift. The 2× compute cost is the main drawback; scheduled SAM (apply SAM only in later epochs) recovers most of the benefit at lower cost.

```python
import torch
import torch.nn as nn
import numpy as np

def train_model(model, optimizer, X_tr, y_tr, use_sam=False, epochs=60):
    loss_fn = nn.MSELoss()
    for epoch in range(epochs):
        model.train()
        for i in range(0, len(X_tr), 16):
            xb, yb = X_tr[i:i+16], y_tr[i:i+16]
            if use_sam:
                loss = loss_fn(model(xb), yb)
                loss.backward()
                optimizer.first_step(zero_grad=True)
                loss_fn(model(xb), yb).backward()
                optimizer.second_step(zero_grad=True)
            else:
                optimizer.zero_grad()
                loss = loss_fn(model(xb), yb)
                loss.backward()
                optimizer.step()

torch.manual_seed(0)
np.random.seed(0)
n_tr, n_te = 80, 40
X_tr = torch.randn(n_tr, 10)
w_true = torch.randn(10, 1)
y_tr = X_tr @ w_true + 0.5 * torch.randn(n_tr, 1)
X_te = torch.randn(n_te, 10)
y_te = X_te @ w_true + 0.5 * torch.randn(n_te, 1)

results = {}
for method, use_sam in [("SGD", False), ("SAM", True)]:
    torch.manual_seed(1)
    model = nn.Sequential(nn.Linear(10, 32), nn.ReLU(), nn.Linear(32, 1))
    if use_sam:
        opt = SAM(model.parameters(), torch.optim.SGD, rho=0.05, lr=0.05)
    else:
        opt = torch.optim.SGD(model.parameters(), lr=0.05)
    train_model(model, opt, X_tr, y_tr, use_sam=use_sam)
    with torch.no_grad():
        test_mse = nn.MSELoss()(model(X_te), y_te).item()
    results[method] = test_mse
    print(f"{method}: test MSE = {test_mse:.4f}")
print(f"SAM improvement: {100*(results['SGD']-results['SAM'])/results['SGD']:.1f}%")
```

## Visualizing the Loss Landscape

We can compare the local loss geometry around two minima by sampling loss values within a small ball. A sharp minimum shows rapidly increasing loss even for small perturbations; a flat minimum maintains low loss across the entire ball. This directly explains generalization: the train-test distribution shift acts like a weight perturbation, so sharp minima suffer a larger test loss increase.

```python
import numpy as np

def sample_perturbation_losses(center_weights, loss_fn, n_samples=300, radii=(0.1, 0.3, 0.5)):
    """Sample loss at random perturbations of different radii from the minimum."""
    results = {}
    for r in radii:
        perturbed_losses = []
        for _ in range(n_samples):
            perturbed = [w + np.random.randn(*w.shape) * r for w in center_weights]
            perturbed_losses.append(loss_fn(perturbed))
        results[r] = np.array(perturbed_losses)
    return results

def sharp_loss(ws):  # High curvature: 100 * ||w||^2
    return sum(100.0 * np.sum(w**2) for w in ws)

def flat_loss(ws):   # Low curvature: 1.0 * ||w||^2
    return sum(1.0 * np.sum(w**2) for w in ws)

np.random.seed(3)
center = [np.zeros((6,)), np.zeros((4,))]  # at the global minimum

sharp_stats = sample_perturbation_losses(center, sharp_loss)
flat_stats  = sample_perturbation_losses(center, flat_loss)

print(f"{'Radius':<8} {'Sharp Mean':>12} {'Sharp Std':>12} {'Flat Mean':>12} {'Flat Std':>10}")
for r in (0.1, 0.3, 0.5):
    sm, ss = sharp_stats[r].mean(), sharp_stats[r].std()
    fm, fs = flat_stats[r].mean(),  flat_stats[r].std()
    print(f"{r:<8.1f} {sm:>12.4f} {ss:>12.4f} {fm:>12.4f} {fs:>10.4f}")
print("\nSharp minimum: loss grows rapidly with perturbation radius.")
print("Flat minimum: loss stays near zero even for large perturbations.")
```

## Extensions and Variants

Several SAM variants improve efficiency or effectiveness. m-SAM computes sharpness on individual micro-batches rather than the full batch, finding sharper per-sample sharpness estimates. ASAM (Adaptive SAM) normalizes the perturbation per parameter by its magnitude, removing the scale sensitivity of fixed-ρ SAM. Scheduled ρ anneals ρ during training — large ρ early for exploration, small ρ later for refinement. Lookahead + SAM combines slow/fast weight averaging with sharpness awareness.

- mSAM (micro-batch SAM): sharpness computed per micro-batch — finds sharper, more harmful minima
- ASAM: adaptive per-parameter normalization ε̂ᵢ = ρ|θᵢ|·gᵢ/‖|θ|·g‖ — scale invariant
- GSAM: gradient decomposition into sharpness and task directions for more stable training
- SWA (Stochastic Weight Averaging): average weights along SGD trajectory → flat region implicitly
- SAM + large batch: partially recovers the flatness bias that small batches provide naturally

---

