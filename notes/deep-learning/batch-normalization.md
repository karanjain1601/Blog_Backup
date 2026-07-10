---
title: "Batch Normalization — Running Stats, Train vs Eval, and Gradients"
slug: "batch-normalization"
description: "Implement batch norm from scratch with train and eval modes, derive its gradient analytically, demonstrate the critical importance of model.eval(), examine batch size effects, and compare BN to layer norm, instance norm, and group norm."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Batch Normalisation (BN) normalises the pre-activations of each layer to have zero mean and unit variance within a mini-batch, then re-scales with learnable parameters γ and β. It dramatically accelerates training by allowing higher learning rates, reduces sensitivity to initialisation, and provides mild regularisation through the noise in batch statistics. Understanding the difference between train mode (batch stats) and eval mode (running stats) is critical — confusing them is one of the most common bugs in deep learning."},{"type":"heading","level":2,"content":"Batch Norm Forward Pass"},{"type":"text","content":"For a mini-batch of m activations x ∈ ℝ^{m × d}: μ_B = (1/m)Σxᵢ ∈ ℝ^d, σ²_B = (1/m)Σ(xᵢ-μ_B)² ∈ ℝ^d, x̂ᵢ = (xᵢ-μ_B)/√(σ²_B+ε), yᵢ = γ⊙x̂ᵢ + β. ε is a small constant (typically 1e-5) for numerical stability. γ ∈ ℝ^d and β ∈ ℝ^d are learnable: γ starts at 1, β at 0. This allows the network to undo normalisation if it helps — BN is strictly more expressive than not having it, since γ=std, β=mean recovers the original distribution."},{"type":"heading","level":2,"content":"Running Statistics and Train vs Eval"},{"type":"text","content":"At training time, BN uses per-batch statistics μ_B and σ²_B. At inference time, using batch stats is problematic: (1) the batch may have a single sample (m=1, σ²=0); (2) batch statistics introduce randomness into deterministic inference. Solution: maintain exponential moving averages during training: μ_running ← (1-momentum)·μ_running + momentum·μ_B, and similarly for σ²_running. At eval time, use μ_running and σ²_running instead of batch stats. PyTorch\u0027s model.train() and model.eval() switch this behaviour — forgetting model.eval() before inference is a common and silent bug."},{"type":"code","language":"python","content":"import numpy as np\n\nclass BatchNorm1d:\n    \"\"\"Batch Normalization for 2D input (m, d) with train/eval modes.\"\"\"\n    def __init__(self, d, eps=1e-5, momentum=0.1):\n        self.gamma = np.ones(d)\n        self.beta  = np.zeros(d)\n        self.eps   = eps\n        self.momentum = momentum\n        self.running_mean = np.zeros(d)\n        self.running_var  = np.ones(d)\n        self.training = True\n        self._cache = None\n\n    def __call__(self, x):\n        if self.training:\n            mu  = x.mean(axis=0)                      # (d,)\n            var = x.var(axis=0)                        # (d,)\n            x_hat = (x - mu) / np.sqrt(var + self.eps)\n            # Update running statistics\n            self.running_mean = ((1 - self.momentum) * self.running_mean\n                                 + self.momentum * mu)\n            self.running_var  = ((1 - self.momentum) * self.running_var\n                                 + self.momentum * var)\n            self._cache = (x, x_hat, mu, var)\n        else:\n            # Use running stats — deterministic inference\n            x_hat = (x - self.running_mean) / np.sqrt(self.running_var + self.eps)\n        return self.gamma * x_hat + self.beta\n\n    def train(self): self.training = True\n    def eval(self):  self.training = False\n\nnp.random.seed(0)\nbn = BatchNorm1d(8)\nX_train = np.random.randn(64, 8) * 3 + 5  # mean≈5, std≈3\n\n# Simulate a few training steps\nfor i in range(20):\n    batch = X_train[np.random.choice(64, 16, replace=False)]\n    out = bn(batch)\n\nprint(f\u0027After 20 train steps:\u0027)\nprint(f\u0027  running_mean: {bn.running_mean[:4].round(3)}\u0027)\nprint(f\u0027  running_var:  {bn.running_var[:4].round(3)}\u0027)\n\n# Train mode on a single sample\nbn.eval()\nout_eval = bn(X_train[[0]])\nprint(f\u0027Eval mode output (deterministic): {out_eval[0, :4].round(4)}\u0027)"},{"type":"heading","level":2,"content":"Critical: model.eval() Matters"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(0)\nmodel = nn.Sequential(\n    nn.Linear(16, 64),\n    nn.BatchNorm1d(64),\n    nn.ReLU(),\n    nn.Linear(64, 4)\n)\n\n# Simulate training: update running stats\nmodel.train()\nfor _ in range(100):\n    xb = torch.randn(32, 16) * 5 + 3  # non-standard distribution\n    _ = model(xb)\n\n# Test point\nx_test = torch.randn(1, 16) * 5 + 3\n\nwith torch.no_grad():\n    # WRONG: model still in train mode\n    model.train()\n    out_train = model(x_test).numpy()\n\n    # CORRECT: switch to eval mode\n    model.eval()\n    out_eval = model(x_test).numpy()\n\nprint(\u0027Output with model.train() (batch stats, stochastic):\u0027)\nprint(\u0027 \u0027, out_train.round(4))\nprint(\u0027Output with model.eval() (running stats, deterministic):\u0027)\nprint(\u0027 \u0027, out_eval.round(4))\nprint(\u0027Max difference:\u0027, np.abs(out_train - out_eval).max().round(4))\nprint(\u0027\\nRunning mean of BN layer:\u0027, model[1].running_mean[:4].numpy().round(3))"},{"type":"callout","variant":"warning","title":"Always Call model.eval() Before Inference","content":"Forgetting model.eval() causes BatchNorm to use the current mini-batch statistics instead of the learned running statistics. With m=1 at inference, variance is 0 and outputs can be NaN or wildly off. Dropout also remains active in train mode. Always call model.eval() before any inference, evaluation loop, or export — and model.train() before resuming training."},{"type":"heading","level":2,"content":"Batch Norm Gradient Derivation"},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\ndef bn_backward_analytical(dout, cache):\n    \"\"\"Analytical backward pass for batch norm.\"\"\"\n    x, x_hat, mu, var, gamma, eps = cache\n    m, d = x.shape\n    # Gradients of learnable params\n    dgamma = (dout * x_hat).sum(axis=0)   # (d,)\n    dbeta  = dout.sum(axis=0)              # (d,)\n    # Gradient wrt x_hat\n    dx_hat = dout * gamma                  # (m, d)\n    # Gradient wrt variance\n    std_inv = 1.0 / np.sqrt(var + eps)\n    dvar = (dx_hat * (x - mu) * -0.5 * std_inv**3).sum(axis=0)\n    # Gradient wrt mean\n    dmu = (dx_hat * (-std_inv)).sum(axis=0) + dvar * (-2.0 / m) * (x - mu).sum(axis=0)\n    # Gradient wrt x\n    dx = (dx_hat * std_inv\n          + dvar * 2.0 * (x - mu) / m\n          + dmu / m)\n    return dx, dgamma, dbeta\n\nnp.random.seed(1)\nm, d = 32, 8\nX_np = np.random.randn(m, d) * 2 + 1\ngamma_np = np.random.rand(d) + 0.5\nbeta_np  = np.random.randn(d)\neps = 1e-5\n\nmu  = X_np.mean(0); var = X_np.var(0)\nx_hat = (X_np - mu) / np.sqrt(var + eps)\nout   = gamma_np * x_hat + beta_np\ndout  = np.random.randn(m, d)\ncache = (X_np, x_hat, mu, var, gamma_np, eps)\n\ndx_analytical, dgamma_a, dbeta_a = bn_backward_analytical(dout, cache)\n\n# Compare with PyTorch autograd\nX_t = torch.tensor(X_np, dtype=torch.float64, requires_grad=True)\ng_t = torch.tensor(gamma_np, dtype=torch.float64, requires_grad=True)\nb_t = torch.tensor(beta_np,  dtype=torch.float64, requires_grad=True)\nmu_t = X_t.mean(0); var_t = X_t.var(0, unbiased=False)\nx_hat_t = (X_t - mu_t) / (var_t + eps).sqrt()\nout_t = g_t * x_hat_t + b_t\nout_t.backward(torch.tensor(dout, dtype=torch.float64))\n\nprint(f\u0027dx     max diff: {np.abs(dx_analytical - X_t.grad.numpy()).max():.2e}\u0027)\nprint(f\u0027dgamma max diff: {np.abs(dgamma_a - g_t.grad.numpy()).max():.2e}\u0027)\nprint(f\u0027dbeta  max diff: {np.abs(dbeta_a  - b_t.grad.numpy()).max():.2e}\u0027)"},{"type":"heading","level":2,"content":"Batch Size Effects on BN Quality"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(0)\n\ndef bn_noise_by_batch_size(batch_size, n_experiments=200, d=64):\n    \"\"\"Measure variance of BN normalised activations across batches.\"\"\"\n    bn = nn.BatchNorm1d(d)\n    bn.train()\n    norms = []\n    for _ in range(n_experiments):\n        x = torch.randn(batch_size, d) * 3 + 2\n        with torch.no_grad():\n            out = bn(x)\n        norms.append(out.std(dim=0).mean().item())\n    return float(np.mean(norms)), float(np.std(norms))\n\nprint(f\u0027{\"Batch Size\":\u003e12}  {\"Mean std\":\u003e10}  {\"Std of std\":\u003e12}  {\"BN Reliable\":\u003e12}\u0027)\nfor bs in [2, 4, 8, 16, 32, 64, 128, 256]:\n    mean_s, std_s = bn_noise_by_batch_size(bs)\n    reliable = std_s \u003c 0.05\n    print(f\u0027{bs:\u003e12}  {mean_s:\u003e10.4f}  {std_s:\u003e12.4f}  {str(reliable):\u003e12}\u0027)"},{"type":"heading","level":2,"content":"Normalisation Method Comparison"},{"type":"table","headers":["Method","Normalises Over","Batch Dependent?","Works for m=1?","Best For"],"rows":[["Batch Norm","Batch dimension (per feature)","Yes — uses batch μ,σ","No — σ=0, NaN","CNNs with large batches; supervised image models"],["Layer Norm","Feature dimension (per sample)","No — per-sample stats","Yes","Transformers, NLP, variable-length sequences"],["Instance Norm","Spatial dims per sample per channel","No","Yes","Style transfer, image generation (single-sample style)"],["Group Norm","Groups of channels per sample","No","Yes","Object detection, small-batch regimes (batch size 2–4)"]]},{"type":"heading","level":2,"content":"Placement: Pre-Activation vs Post-Activation BN"},{"type":"text","content":"The original BN paper (Ioffe \u0026 Szegedy 2015) places BN after the linear layer and before the activation: Linear → BN → ReLU. He et al. (2016) proposed pre-activation ordering for ResNets: BN → ReLU → Conv, which keeps the residual path clean (identity shortcut adds un-normalised values) and empirically improves training of very deep networks. For Transformers, Layer Norm is placed before the sub-layer (Pre-LN) rather than after (Post-LN as in the original paper) — Pre-LN improves gradient flow and training stability at large scale. The practical takeaway: when in doubt, use Post-activation BN for CNNs and Pre-LN for Transformers."},{"type":"heading","level":2,"content":"Benefits of Batch Normalisation"},{"type":"list","ordered":false,"items":["Higher learning rates: BN smooths the loss landscape, allowing 5–10× larger LR without diverging.","Reduced sensitivity to initialisation: poor init is partially corrected by normalisation each forward pass.","Mild regularisation: batch statistics introduce noise (each batch has different μ,σ) — acts like dropout.","Faster convergence: normalised activations prevent saturation of tanh/sigmoid; speeds up gradient flow.","Gradient conditioning: BN makes the effective Hessian better conditioned — more uniform curvature.","Replaces some need for careful init: He init + BN together are nearly foolproof for CNN training."]},{"type":"heading","level":2,"content":"Common Batch Norm Mistakes"},{"type":"list","ordered":false,"items":["Forgetting model.eval() — BN uses batch stats at inference; predictions are noisy and wrong.","Batch size = 1 at train time — variance is 0; output is NaN or all-gamma. Use group norm instead.","Freezing BN layers but not setting them to eval — running stats diverge from actual data distribution.","Double normalising — applying both BN and Layer Norm in the same block rarely helps and can hurt.","Forgetting to call model.train() after evaluation — BN stays in eval mode and ignores batch stats.","Using BN with very small batches (\u003c 8) — statistics are noisy; switch to Group Norm with G=32."]},{"type":"divider"}]"
---
# Batch Normalization — Running Stats, Train vs Eval, and Gradients

Batch Normalisation (BN) normalises the pre-activations of each layer to have zero mean and unit variance within a mini-batch, then re-scales with learnable parameters γ and β. It dramatically accelerates training by allowing higher learning rates, reduces sensitivity to initialisation, and provides mild regularisation through the noise in batch statistics. Understanding the difference between train mode (batch stats) and eval mode (running stats) is critical — confusing them is one of the most common bugs in deep learning.

## Batch Norm Forward Pass

For a mini-batch of m activations x ∈ ℝ^{m × d}: μ_B = (1/m)Σxᵢ ∈ ℝ^d, σ²_B = (1/m)Σ(xᵢ-μ_B)² ∈ ℝ^d, x̂ᵢ = (xᵢ-μ_B)/√(σ²_B+ε), yᵢ = γ⊙x̂ᵢ + β. ε is a small constant (typically 1e-5) for numerical stability. γ ∈ ℝ^d and β ∈ ℝ^d are learnable: γ starts at 1, β at 0. This allows the network to undo normalisation if it helps — BN is strictly more expressive than not having it, since γ=std, β=mean recovers the original distribution.

## Running Statistics and Train vs Eval

At training time, BN uses per-batch statistics μ_B and σ²_B. At inference time, using batch stats is problematic: (1) the batch may have a single sample (m=1, σ²=0); (2) batch statistics introduce randomness into deterministic inference. Solution: maintain exponential moving averages during training: μ_running ← (1-momentum)·μ_running + momentum·μ_B, and similarly for σ²_running. At eval time, use μ_running and σ²_running instead of batch stats. PyTorch's model.train() and model.eval() switch this behaviour — forgetting model.eval() before inference is a common and silent bug.

```python
import numpy as np

class BatchNorm1d:
    """Batch Normalization for 2D input (m, d) with train/eval modes."""
    def __init__(self, d, eps=1e-5, momentum=0.1):
        self.gamma = np.ones(d)
        self.beta  = np.zeros(d)
        self.eps   = eps
        self.momentum = momentum
        self.running_mean = np.zeros(d)
        self.running_var  = np.ones(d)
        self.training = True
        self._cache = None

    def __call__(self, x):
        if self.training:
            mu  = x.mean(axis=0)                      # (d,)
            var = x.var(axis=0)                        # (d,)
            x_hat = (x - mu) / np.sqrt(var + self.eps)
            # Update running statistics
            self.running_mean = ((1 - self.momentum) * self.running_mean
                                 + self.momentum * mu)
            self.running_var  = ((1 - self.momentum) * self.running_var
                                 + self.momentum * var)
            self._cache = (x, x_hat, mu, var)
        else:
            # Use running stats — deterministic inference
            x_hat = (x - self.running_mean) / np.sqrt(self.running_var + self.eps)
        return self.gamma * x_hat + self.beta

    def train(self): self.training = True
    def eval(self):  self.training = False

np.random.seed(0)
bn = BatchNorm1d(8)
X_train = np.random.randn(64, 8) * 3 + 5  # mean≈5, std≈3

# Simulate a few training steps
for i in range(20):
    batch = X_train[np.random.choice(64, 16, replace=False)]
    out = bn(batch)

print(f'After 20 train steps:')
print(f'  running_mean: {bn.running_mean[:4].round(3)}')
print(f'  running_var:  {bn.running_var[:4].round(3)}')

# Train mode on a single sample
bn.eval()
out_eval = bn(X_train[[0]])
print(f'Eval mode output (deterministic): {out_eval[0, :4].round(4)}')
```

## Critical: model.eval() Matters

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(0)
model = nn.Sequential(
    nn.Linear(16, 64),
    nn.BatchNorm1d(64),
    nn.ReLU(),
    nn.Linear(64, 4)
)

# Simulate training: update running stats
model.train()
for _ in range(100):
    xb = torch.randn(32, 16) * 5 + 3  # non-standard distribution
    _ = model(xb)

# Test point
x_test = torch.randn(1, 16) * 5 + 3

with torch.no_grad():
    # WRONG: model still in train mode
    model.train()
    out_train = model(x_test).numpy()

    # CORRECT: switch to eval mode
    model.eval()
    out_eval = model(x_test).numpy()

print('Output with model.train() (batch stats, stochastic):')
print(' ', out_train.round(4))
print('Output with model.eval() (running stats, deterministic):')
print(' ', out_eval.round(4))
print('Max difference:', np.abs(out_train - out_eval).max().round(4))
print('\nRunning mean of BN layer:', model[1].running_mean[:4].numpy().round(3))
```

> **Always Call model.eval() Before Inference**: Forgetting model.eval() causes BatchNorm to use the current mini-batch statistics instead of the learned running statistics. With m=1 at inference, variance is 0 and outputs can be NaN or wildly off. Dropout also remains active in train mode. Always call model.eval() before any inference, evaluation loop, or export — and model.train() before resuming training.

## Batch Norm Gradient Derivation

```python
import numpy as np
import torch
import torch.nn as nn

def bn_backward_analytical(dout, cache):
    """Analytical backward pass for batch norm."""
    x, x_hat, mu, var, gamma, eps = cache
    m, d = x.shape
    # Gradients of learnable params
    dgamma = (dout * x_hat).sum(axis=0)   # (d,)
    dbeta  = dout.sum(axis=0)              # (d,)
    # Gradient wrt x_hat
    dx_hat = dout * gamma                  # (m, d)
    # Gradient wrt variance
    std_inv = 1.0 / np.sqrt(var + eps)
    dvar = (dx_hat * (x - mu) * -0.5 * std_inv**3).sum(axis=0)
    # Gradient wrt mean
    dmu = (dx_hat * (-std_inv)).sum(axis=0) + dvar * (-2.0 / m) * (x - mu).sum(axis=0)
    # Gradient wrt x
    dx = (dx_hat * std_inv
          + dvar * 2.0 * (x - mu) / m
          + dmu / m)
    return dx, dgamma, dbeta

np.random.seed(1)
m, d = 32, 8
X_np = np.random.randn(m, d) * 2 + 1
gamma_np = np.random.rand(d) + 0.5
beta_np  = np.random.randn(d)
eps = 1e-5

mu  = X_np.mean(0); var = X_np.var(0)
x_hat = (X_np - mu) / np.sqrt(var + eps)
out   = gamma_np * x_hat + beta_np
dout  = np.random.randn(m, d)
cache = (X_np, x_hat, mu, var, gamma_np, eps)

dx_analytical, dgamma_a, dbeta_a = bn_backward_analytical(dout, cache)

# Compare with PyTorch autograd
X_t = torch.tensor(X_np, dtype=torch.float64, requires_grad=True)
g_t = torch.tensor(gamma_np, dtype=torch.float64, requires_grad=True)
b_t = torch.tensor(beta_np,  dtype=torch.float64, requires_grad=True)
mu_t = X_t.mean(0); var_t = X_t.var(0, unbiased=False)
x_hat_t = (X_t - mu_t) / (var_t + eps).sqrt()
out_t = g_t * x_hat_t + b_t
out_t.backward(torch.tensor(dout, dtype=torch.float64))

print(f'dx     max diff: {np.abs(dx_analytical - X_t.grad.numpy()).max():.2e}')
print(f'dgamma max diff: {np.abs(dgamma_a - g_t.grad.numpy()).max():.2e}')
print(f'dbeta  max diff: {np.abs(dbeta_a  - b_t.grad.numpy()).max():.2e}')
```

## Batch Size Effects on BN Quality

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(0)

def bn_noise_by_batch_size(batch_size, n_experiments=200, d=64):
    """Measure variance of BN normalised activations across batches."""
    bn = nn.BatchNorm1d(d)
    bn.train()
    norms = []
    for _ in range(n_experiments):
        x = torch.randn(batch_size, d) * 3 + 2
        with torch.no_grad():
            out = bn(x)
        norms.append(out.std(dim=0).mean().item())
    return float(np.mean(norms)), float(np.std(norms))

print(f'{"Batch Size":>12}  {"Mean std":>10}  {"Std of std":>12}  {"BN Reliable":>12}')
for bs in [2, 4, 8, 16, 32, 64, 128, 256]:
    mean_s, std_s = bn_noise_by_batch_size(bs)
    reliable = std_s < 0.05
    print(f'{bs:>12}  {mean_s:>10.4f}  {std_s:>12.4f}  {str(reliable):>12}')
```

## Normalisation Method Comparison

| Method | Normalises Over | Batch Dependent? | Works for m=1? | Best For |
| --- | --- | --- | --- | --- |
| Batch Norm | Batch dimension (per feature) | Yes — uses batch μ,σ | No — σ=0, NaN | CNNs with large batches; supervised image models |
| Layer Norm | Feature dimension (per sample) | No — per-sample stats | Yes | Transformers, NLP, variable-length sequences |
| Instance Norm | Spatial dims per sample per channel | No | Yes | Style transfer, image generation (single-sample style) |
| Group Norm | Groups of channels per sample | No | Yes | Object detection, small-batch regimes (batch size 2–4) |

## Placement: Pre-Activation vs Post-Activation BN

The original BN paper (Ioffe & Szegedy 2015) places BN after the linear layer and before the activation: Linear → BN → ReLU. He et al. (2016) proposed pre-activation ordering for ResNets: BN → ReLU → Conv, which keeps the residual path clean (identity shortcut adds un-normalised values) and empirically improves training of very deep networks. For Transformers, Layer Norm is placed before the sub-layer (Pre-LN) rather than after (Post-LN as in the original paper) — Pre-LN improves gradient flow and training stability at large scale. The practical takeaway: when in doubt, use Post-activation BN for CNNs and Pre-LN for Transformers.

## Benefits of Batch Normalisation

- Higher learning rates: BN smooths the loss landscape, allowing 5–10× larger LR without diverging.
- Reduced sensitivity to initialisation: poor init is partially corrected by normalisation each forward pass.
- Mild regularisation: batch statistics introduce noise (each batch has different μ,σ) — acts like dropout.
- Faster convergence: normalised activations prevent saturation of tanh/sigmoid; speeds up gradient flow.
- Gradient conditioning: BN makes the effective Hessian better conditioned — more uniform curvature.
- Replaces some need for careful init: He init + BN together are nearly foolproof for CNN training.

## Common Batch Norm Mistakes

- Forgetting model.eval() — BN uses batch stats at inference; predictions are noisy and wrong.
- Batch size = 1 at train time — variance is 0; output is NaN or all-gamma. Use group norm instead.
- Freezing BN layers but not setting them to eval — running stats diverge from actual data distribution.
- Double normalising — applying both BN and Layer Norm in the same block rarely helps and can hurt.
- Forgetting to call model.train() after evaluation — BN stays in eval mode and ignores batch stats.
- Using BN with very small batches (< 8) — statistics are noisy; switch to Group Norm with G=32.

---

