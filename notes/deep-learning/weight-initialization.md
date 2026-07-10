---
title: "Weight Initialization — Xavier/Glorot and Kaiming/He"
slug: "weight-initialization"
description: "Derive variance-preserving weight initialization from first principles, implement Xavier and He initialization, compare their gradient flow with tanh vs ReLU, and visualise activation and gradient norms across depth."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Weight initialisation is the starting point for all training dynamics. If weights are too large, activations and gradients explode; too small, they vanish. Both pathologies prevent learning in deep networks. Variance-preserving initialisation schemes — Xavier/Glorot for tanh/sigmoid and Kaiming/He for ReLU — are derived from the requirement that the variance of activations and gradients stay approximately constant as signals propagate through depth."},{"type":"heading","level":2,"content":"The Variance Propagation Problem"},{"type":"text","content":"For a linear layer z = Wx (ignoring bias, pre-activation), Var(zᵢ) = nᵢₙ · Var(W) · Var(x) if weights and inputs are i.i.d. and zero-mean. To keep Var(z) = Var(x) (variance preservation), we need Var(W) = 1/nᵢₙ — the LeCun initialisation. For the backward pass: Var(∂L/∂x) = nₒᵤₜ · Var(W) · Var(∂L/∂z), requiring Var(W) = 1/nₒᵤₜ. Xavier/Glorot compromises: Var(W) = 2/(nᵢₙ + nₒᵤₜ), maintaining signal in both directions for zero-mean symmetric activations like tanh."},{"type":"heading","level":2,"content":"Xavier/Glorot Initialisation"},{"type":"text","content":"For tanh and sigmoid activations: W ~ U(-√(6/(nᵢₙ + nₒᵤₜ)), +√(6/(nᵢₙ + nₒᵤₜ))) or equivalently W ~ N(0, 2/(nᵢₙ + nₒᵤₜ)). Derived by Glorot \u0026 Bengio (2010) assuming linear activations (tanh ≈ linear near origin) and requiring Var(forward signal) ≈ Var(backward signal). For sigmoid, the effective gradient at zero is 0.25, so a gain of 4 is applied: std = gain × √(2/(nᵢₙ + nₒᵤₜ))."},{"type":"heading","level":2,"content":"Kaiming/He Initialisation for ReLU"},{"type":"text","content":"ReLU zeros out half its inputs, halving the effective variance. He et al. (2015) account for this: Var(W) = 2/nᵢₙ so that after ReLU, the variance is preserved. In normal form: W ~ N(0, √(2/nᵢₙ)). For Leaky ReLU with slope α: Var(W) = 2/((1+α²)·nᵢₙ). The PyTorch function nn.init.kaiming_normal_ accepts a nonlinearity argument and computes the correct gain automatically. fan_in mode (default) preserves forward signal; fan_out mode preserves backward signal."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\ndef activation_variance_trace(init_std_fn, activation_fn, depth=20, width=512, m=256, seed=0):\n    \"\"\"Trace activation variance layer by layer with a given init and activation.\"\"\"\n    np.random.seed(seed)\n    x = np.random.randn(m, width)\n    variances = [x.var()]\n    for _ in range(depth):\n        n_in, n_out = width, width\n        std = init_std_fn(n_in, n_out)\n        W = np.random.randn(n_out, n_in) * std\n        b = np.zeros(n_out)\n        z = x @ W.T + b\n        x = activation_fn(z)\n        variances.append(x.var())\n    return variances\n\ndef relu(z): return np.maximum(0, z)\ndef tanh_fn(z): return np.tanh(z)\n\nxavier_std = lambda n_in, n_out: np.sqrt(2.0 / (n_in + n_out))\nhe_std     = lambda n_in, n_out: np.sqrt(2.0 / n_in)\nlecun_std  = lambda n_in, n_out: np.sqrt(1.0 / n_in)\nsmall_std  = lambda n_in, n_out: 0.01\n\nprint(\u0027Activation variance trace (depth=20, should stay near 1.0):\u0027)\nfor label, init_fn, act_fn in [\n    (\u0027Xavier+tanh\u0027, xavier_std, tanh_fn),\n    (\u0027He+ReLU\u0027,     he_std,     relu),\n    (\u0027LeCun+tanh\u0027,  lecun_std,  tanh_fn),\n    (\u0027small+ReLU\u0027,  small_std,  relu),\n]:\n    vars = activation_variance_trace(init_fn, act_fn)\n    print(f\u0027  {label:\u003e14}: layer0={vars[0]:.3f}  layer5={vars[5]:.3f}  \u0027\n          f\u0027layer10={vars[10]:.3f}  layer20={vars[-1]:.4f}\u0027)"},{"type":"heading","level":2,"content":"Xavier vs He — Gradient Flow Comparison"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef build_deep_net(depth, width, init_name, act_name):\n    layers = []\n    for i in range(depth):\n        lin = nn.Linear(width, width, bias=False)\n        if init_name == \u0027xavier\u0027:\n            nn.init.xavier_normal_(lin.weight)\n        elif init_name == \u0027he\u0027:\n            nn.init.kaiming_normal_(lin.weight, nonlinearity=\u0027relu\u0027)\n        elif init_name == \u0027small\u0027:\n            nn.init.normal_(lin.weight, 0, 0.01)\n        layers.append(lin)\n        act = nn.Tanh() if act_name == \u0027tanh\u0027 else nn.ReLU()\n        layers.append(act)\n    return nn.Sequential(*layers)\n\ntorch.manual_seed(42)\ndepth, width, m = 15, 128, 64\n\nfor init_name, act_name in [(\u0027xavier\u0027, \u0027tanh\u0027), (\u0027he\u0027, \u0027relu\u0027),\n                              (\u0027xavier\u0027, \u0027relu\u0027), (\u0027small\u0027, \u0027relu\u0027)]:\n    model = build_deep_net(depth, width, init_name, act_name)\n    x = torch.randn(m, width)\n    out = model(x)\n    out.sum().backward()\n    grad_norms = [mod.weight.grad.norm().item()\n                  for mod in model.modules()\n                  if isinstance(mod, nn.Linear) and mod.weight.grad is not None]\n    vanish = grad_norms[0] \u003c 1e-4\n    explode = grad_norms[-1] \u003e 1e3\n    print(f\u0027{init_name:\u003e8}+{act_name:\u003c5}: \u0027\n          f\u0027first_grad={grad_norms[0]:.2e}  last_grad={grad_norms[-1]:.2e}  \u0027\n          f\u0027vanishing={vanish}  exploding={explode}\u0027)"},{"type":"heading","level":2,"content":"PyTorch Initialisation API"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef apply_init(model, init_name):\n    for m in model.modules():\n        if isinstance(m, nn.Linear):\n            if init_name == \u0027xavier_uniform\u0027:\n                nn.init.xavier_uniform_(m.weight, gain=nn.init.calculate_gain(\u0027tanh\u0027))\n            elif init_name == \u0027xavier_normal\u0027:\n                nn.init.xavier_normal_(m.weight)\n            elif init_name == \u0027kaiming_uniform\u0027:\n                nn.init.kaiming_uniform_(m.weight, nonlinearity=\u0027relu\u0027)\n            elif init_name == \u0027kaiming_normal\u0027:\n                nn.init.kaiming_normal_(m.weight, nonlinearity=\u0027relu\u0027)\n            elif init_name == \u0027orthogonal\u0027:\n                nn.init.orthogonal_(m.weight)\n            nn.init.zeros_(m.bias)\n    return model\n\ntorch.manual_seed(0)\nfor init_name in [\u0027xavier_uniform\u0027, \u0027xavier_normal\u0027, \u0027kaiming_uniform\u0027,\n                   \u0027kaiming_normal\u0027, \u0027orthogonal\u0027]:\n    model = apply_init(nn.Sequential(\n        nn.Linear(128, 256), nn.ReLU(),\n        nn.Linear(256, 128), nn.ReLU(),\n        nn.Linear(128, 10)\n    ), init_name)\n    weights = [m.weight for m in model.modules() if isinstance(m, nn.Linear)]\n    stds = [w.std().item() for w in weights]\n    print(f\u0027{init_name:\u003e18}: layer stds = {[f\"{s:.4f}\" for s in stds]}\u0027)"},{"type":"callout","variant":"info","title":"Rule of Thumb for Choosing Initialisation","content":"Use He/Kaiming for ReLU and Leaky ReLU — it accounts for the 50% zeroing. Use Xavier/Glorot for tanh, sigmoid, and linear activations. Use LeCun for SELU (self-normalising networks). Use Orthogonal for RNNs to preserve gradient norms across time steps. Always initialise biases to zero unless there is a specific reason otherwise."},{"type":"heading","level":2,"content":"Gradient Norm Monitoring Across Layers"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef grad_norm_per_layer(init_name, depth=12, width=128, m=64, seed=0):\n    torch.manual_seed(seed)\n    layers = []\n    for _ in range(depth):\n        lin = nn.Linear(width, width, bias=True)\n        if init_name == \u0027he\u0027:\n            nn.init.kaiming_normal_(lin.weight, nonlinearity=\u0027relu\u0027)\n        elif init_name == \u0027xavier\u0027:\n            nn.init.xavier_normal_(lin.weight)\n        elif init_name == \u0027small\u0027:\n            nn.init.normal_(lin.weight, 0, 0.01)\n        nn.init.zeros_(lin.bias)\n        layers.extend([lin, nn.ReLU()])\n    model = nn.Sequential(*layers)\n    x = torch.randn(m, width)\n    out = model(x)\n    out.sum().backward()\n    norms = []\n    for mod in model.modules():\n        if isinstance(mod, nn.Linear) and mod.weight.grad is not None:\n            norms.append(mod.weight.grad.norm().item())\n    return norms\n\nfor init_name in [\u0027he\u0027, \u0027xavier\u0027, \u0027small\u0027]:\n    norms = grad_norm_per_layer(init_name)\n    print(f\u0027{init_name:\u003e8}: \u0027 + \u0027  \u0027.join(f\u0027L{i+1}={n:.3f}\u0027 for i, n in enumerate(norms)))"},{"type":"heading","level":2,"content":"Initialisation Method Reference"},{"type":"table","headers":["Method","Activation","Formula (std)","Variance Target","When to Use"],"rows":[["Xavier Uniform","tanh, sigmoid, linear","√(6/(n_in+n_out))","Var(forward)≈Var(backward)","Default for tanh/sigmoid networks"],["Xavier Normal","tanh, sigmoid, linear","√(2/(n_in+n_out))","Same as uniform (different dist)","Normal variant of Xavier — often interchangeable"],["He/Kaiming Normal","ReLU, Leaky ReLU","√(2/n_in)","Var preserved after ReLU zeroing","Default for ReLU networks — CNNs, MLPs"],["LeCun Normal","SELU","√(1/n_in)","Unit variance for self-normalising","Self-normalising networks with SELU activation"],["Orthogonal","Any (esp. RNNs)","Random orthogonal matrix","Preserves gradient norms over time","RNNs, sequence models, avoid vanishing over steps"]]},{"type":"heading","level":2,"content":"Orthogonal Initialisation for Recurrent Networks"},{"type":"text","content":"In recurrent networks, the weight matrix W_h is applied T times (once per timestep): hₜ = f(W_h hₜ₋₁ + W_x xₜ). If W_h has singular values \u003e 1, gradients explode; \u003c 1, they vanish. Orthogonal matrices have all singular values = 1, so ‖W_h^T‖ = 1 for all T — gradients neither explode nor vanish through the recurrence. In practice, orthogonal init (nn.init.orthogonal_) is the recommended starting point for RNNs and is used as the default in many LSTM implementations. It is also occasionally used in feedforward networks at large depth to stabilise signal propagation before training begins."},{"type":"heading","level":2,"content":"Practical Initialisation Checklist"},{"type":"list","ordered":false,"items":["ReLU hidden layers: nn.init.kaiming_normal_(w, nonlinearity=\u0027relu\u0027) — He init, fan_in mode.","Leaky ReLU: nn.init.kaiming_normal_(w, a=0.01, nonlinearity=\u0027leaky_relu\u0027).","Tanh/sigmoid: nn.init.xavier_normal_(w) or xavier_uniform_ with gain=nn.init.calculate_gain(\u0027tanh\u0027).","SELU: nn.init.kaiming_normal_(w, mode=\u0027fan_in\u0027) with std=1/√n_in (LeCun).","All biases: nn.init.zeros_(b) — always unless you have a specific reason otherwise.","RNN recurrent weights: nn.init.orthogonal_(w_h) to stabilise gradient norms over time.","Verify: monitor activation variance and gradient norms across layers in the first few batches."]},{"type":"divider"}]"
---
# Weight Initialization — Xavier/Glorot and Kaiming/He

Weight initialisation is the starting point for all training dynamics. If weights are too large, activations and gradients explode; too small, they vanish. Both pathologies prevent learning in deep networks. Variance-preserving initialisation schemes — Xavier/Glorot for tanh/sigmoid and Kaiming/He for ReLU — are derived from the requirement that the variance of activations and gradients stay approximately constant as signals propagate through depth.

## The Variance Propagation Problem

For a linear layer z = Wx (ignoring bias, pre-activation), Var(zᵢ) = nᵢₙ · Var(W) · Var(x) if weights and inputs are i.i.d. and zero-mean. To keep Var(z) = Var(x) (variance preservation), we need Var(W) = 1/nᵢₙ — the LeCun initialisation. For the backward pass: Var(∂L/∂x) = nₒᵤₜ · Var(W) · Var(∂L/∂z), requiring Var(W) = 1/nₒᵤₜ. Xavier/Glorot compromises: Var(W) = 2/(nᵢₙ + nₒᵤₜ), maintaining signal in both directions for zero-mean symmetric activations like tanh.

## Xavier/Glorot Initialisation

For tanh and sigmoid activations: W ~ U(-√(6/(nᵢₙ + nₒᵤₜ)), +√(6/(nᵢₙ + nₒᵤₜ))) or equivalently W ~ N(0, 2/(nᵢₙ + nₒᵤₜ)). Derived by Glorot & Bengio (2010) assuming linear activations (tanh ≈ linear near origin) and requiring Var(forward signal) ≈ Var(backward signal). For sigmoid, the effective gradient at zero is 0.25, so a gain of 4 is applied: std = gain × √(2/(nᵢₙ + nₒᵤₜ)).

## Kaiming/He Initialisation for ReLU

ReLU zeros out half its inputs, halving the effective variance. He et al. (2015) account for this: Var(W) = 2/nᵢₙ so that after ReLU, the variance is preserved. In normal form: W ~ N(0, √(2/nᵢₙ)). For Leaky ReLU with slope α: Var(W) = 2/((1+α²)·nᵢₙ). The PyTorch function nn.init.kaiming_normal_ accepts a nonlinearity argument and computes the correct gain automatically. fan_in mode (default) preserves forward signal; fan_out mode preserves backward signal.

```python
import numpy as np
import torch
import torch.nn as nn

def activation_variance_trace(init_std_fn, activation_fn, depth=20, width=512, m=256, seed=0):
    """Trace activation variance layer by layer with a given init and activation."""
    np.random.seed(seed)
    x = np.random.randn(m, width)
    variances = [x.var()]
    for _ in range(depth):
        n_in, n_out = width, width
        std = init_std_fn(n_in, n_out)
        W = np.random.randn(n_out, n_in) * std
        b = np.zeros(n_out)
        z = x @ W.T + b
        x = activation_fn(z)
        variances.append(x.var())
    return variances

def relu(z): return np.maximum(0, z)
def tanh_fn(z): return np.tanh(z)

xavier_std = lambda n_in, n_out: np.sqrt(2.0 / (n_in + n_out))
he_std     = lambda n_in, n_out: np.sqrt(2.0 / n_in)
lecun_std  = lambda n_in, n_out: np.sqrt(1.0 / n_in)
small_std  = lambda n_in, n_out: 0.01

print('Activation variance trace (depth=20, should stay near 1.0):')
for label, init_fn, act_fn in [
    ('Xavier+tanh', xavier_std, tanh_fn),
    ('He+ReLU',     he_std,     relu),
    ('LeCun+tanh',  lecun_std,  tanh_fn),
    ('small+ReLU',  small_std,  relu),
]:
    vars = activation_variance_trace(init_fn, act_fn)
    print(f'  {label:>14}: layer0={vars[0]:.3f}  layer5={vars[5]:.3f}  '
          f'layer10={vars[10]:.3f}  layer20={vars[-1]:.4f}')
```

## Xavier vs He — Gradient Flow Comparison

```python
import torch
import torch.nn as nn
import numpy as np

def build_deep_net(depth, width, init_name, act_name):
    layers = []
    for i in range(depth):
        lin = nn.Linear(width, width, bias=False)
        if init_name == 'xavier':
            nn.init.xavier_normal_(lin.weight)
        elif init_name == 'he':
            nn.init.kaiming_normal_(lin.weight, nonlinearity='relu')
        elif init_name == 'small':
            nn.init.normal_(lin.weight, 0, 0.01)
        layers.append(lin)
        act = nn.Tanh() if act_name == 'tanh' else nn.ReLU()
        layers.append(act)
    return nn.Sequential(*layers)

torch.manual_seed(42)
depth, width, m = 15, 128, 64

for init_name, act_name in [('xavier', 'tanh'), ('he', 'relu'),
                              ('xavier', 'relu'), ('small', 'relu')]:
    model = build_deep_net(depth, width, init_name, act_name)
    x = torch.randn(m, width)
    out = model(x)
    out.sum().backward()
    grad_norms = [mod.weight.grad.norm().item()
                  for mod in model.modules()
                  if isinstance(mod, nn.Linear) and mod.weight.grad is not None]
    vanish = grad_norms[0] < 1e-4
    explode = grad_norms[-1] > 1e3
    print(f'{init_name:>8}+{act_name:<5}: '
          f'first_grad={grad_norms[0]:.2e}  last_grad={grad_norms[-1]:.2e}  '
          f'vanishing={vanish}  exploding={explode}')
```

## PyTorch Initialisation API

```python
import torch
import torch.nn as nn
import numpy as np

def apply_init(model, init_name):
    for m in model.modules():
        if isinstance(m, nn.Linear):
            if init_name == 'xavier_uniform':
                nn.init.xavier_uniform_(m.weight, gain=nn.init.calculate_gain('tanh'))
            elif init_name == 'xavier_normal':
                nn.init.xavier_normal_(m.weight)
            elif init_name == 'kaiming_uniform':
                nn.init.kaiming_uniform_(m.weight, nonlinearity='relu')
            elif init_name == 'kaiming_normal':
                nn.init.kaiming_normal_(m.weight, nonlinearity='relu')
            elif init_name == 'orthogonal':
                nn.init.orthogonal_(m.weight)
            nn.init.zeros_(m.bias)
    return model

torch.manual_seed(0)
for init_name in ['xavier_uniform', 'xavier_normal', 'kaiming_uniform',
                   'kaiming_normal', 'orthogonal']:
    model = apply_init(nn.Sequential(
        nn.Linear(128, 256), nn.ReLU(),
        nn.Linear(256, 128), nn.ReLU(),
        nn.Linear(128, 10)
    ), init_name)
    weights = [m.weight for m in model.modules() if isinstance(m, nn.Linear)]
    stds = [w.std().item() for w in weights]
    print(f'{init_name:>18}: layer stds = {[f"{s:.4f}" for s in stds]}')
```

> **Rule of Thumb for Choosing Initialisation**: Use He/Kaiming for ReLU and Leaky ReLU — it accounts for the 50% zeroing. Use Xavier/Glorot for tanh, sigmoid, and linear activations. Use LeCun for SELU (self-normalising networks). Use Orthogonal for RNNs to preserve gradient norms across time steps. Always initialise biases to zero unless there is a specific reason otherwise.

## Gradient Norm Monitoring Across Layers

```python
import torch
import torch.nn as nn
import numpy as np

def grad_norm_per_layer(init_name, depth=12, width=128, m=64, seed=0):
    torch.manual_seed(seed)
    layers = []
    for _ in range(depth):
        lin = nn.Linear(width, width, bias=True)
        if init_name == 'he':
            nn.init.kaiming_normal_(lin.weight, nonlinearity='relu')
        elif init_name == 'xavier':
            nn.init.xavier_normal_(lin.weight)
        elif init_name == 'small':
            nn.init.normal_(lin.weight, 0, 0.01)
        nn.init.zeros_(lin.bias)
        layers.extend([lin, nn.ReLU()])
    model = nn.Sequential(*layers)
    x = torch.randn(m, width)
    out = model(x)
    out.sum().backward()
    norms = []
    for mod in model.modules():
        if isinstance(mod, nn.Linear) and mod.weight.grad is not None:
            norms.append(mod.weight.grad.norm().item())
    return norms

for init_name in ['he', 'xavier', 'small']:
    norms = grad_norm_per_layer(init_name)
    print(f'{init_name:>8}: ' + '  '.join(f'L{i+1}={n:.3f}' for i, n in enumerate(norms)))
```

## Initialisation Method Reference

| Method | Activation | Formula (std) | Variance Target | When to Use |
| --- | --- | --- | --- | --- |
| Xavier Uniform | tanh, sigmoid, linear | √(6/(n_in+n_out)) | Var(forward)≈Var(backward) | Default for tanh/sigmoid networks |
| Xavier Normal | tanh, sigmoid, linear | √(2/(n_in+n_out)) | Same as uniform (different dist) | Normal variant of Xavier — often interchangeable |
| He/Kaiming Normal | ReLU, Leaky ReLU | √(2/n_in) | Var preserved after ReLU zeroing | Default for ReLU networks — CNNs, MLPs |
| LeCun Normal | SELU | √(1/n_in) | Unit variance for self-normalising | Self-normalising networks with SELU activation |
| Orthogonal | Any (esp. RNNs) | Random orthogonal matrix | Preserves gradient norms over time | RNNs, sequence models, avoid vanishing over steps |

## Orthogonal Initialisation for Recurrent Networks

In recurrent networks, the weight matrix W_h is applied T times (once per timestep): hₜ = f(W_h hₜ₋₁ + W_x xₜ). If W_h has singular values > 1, gradients explode; < 1, they vanish. Orthogonal matrices have all singular values = 1, so ‖W_h^T‖ = 1 for all T — gradients neither explode nor vanish through the recurrence. In practice, orthogonal init (nn.init.orthogonal_) is the recommended starting point for RNNs and is used as the default in many LSTM implementations. It is also occasionally used in feedforward networks at large depth to stabilise signal propagation before training begins.

## Practical Initialisation Checklist

- ReLU hidden layers: nn.init.kaiming_normal_(w, nonlinearity='relu') — He init, fan_in mode.
- Leaky ReLU: nn.init.kaiming_normal_(w, a=0.01, nonlinearity='leaky_relu').
- Tanh/sigmoid: nn.init.xavier_normal_(w) or xavier_uniform_ with gain=nn.init.calculate_gain('tanh').
- SELU: nn.init.kaiming_normal_(w, mode='fan_in') with std=1/√n_in (LeCun).
- All biases: nn.init.zeros_(b) — always unless you have a specific reason otherwise.
- RNN recurrent weights: nn.init.orthogonal_(w_h) to stabilise gradient norms over time.
- Verify: monitor activation variance and gradient norms across layers in the first few batches.

---

