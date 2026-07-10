---
title: "Backward Pass — Chain Rule and Gradient Derivation by Hand"
slug: "backward-pass-backpropagation"
description: "Derive gradients for linear layers, ReLU, sigmoid, and softmax+cross-entropy using the chain rule, verify with finite differences, implement a custom autograd Function, and understand vector-Jacobian products and why reverse-mode AD scales."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Backpropagation is the algorithm that computes gradients of the loss with respect to every parameter by applying the chain rule in reverse through the computational graph. Understanding it from first principles — deriving gradients by hand for each layer type — demystifies automatic differentiation and is essential for debugging gradient flow, implementing custom operations, and reasoning about training dynamics."},{"type":"heading","level":2,"content":"Chain Rule and Computational Graph Traversal"},{"type":"text","content":"For a composition f(g(x)), the chain rule gives df/dx = (df/dg)(dg/dx). In a neural network with loss L, the gradient flows backward: dL/dx = (dL/dy)(dy/dx) where y = f(x). In the computational graph, each node stores its local Jacobian dy/dx; backprop multiplies these Jacobians in reverse order from output to input. For a scalar loss and a vector x, dL/dx has the same shape as x — this is the vector-Jacobian product (VJP), the core operation in reverse-mode AD."},{"type":"heading","level":2,"content":"Gradient of a Linear Layer"},{"type":"text","content":"For z = Wx + b with loss L: the local Jacobian is ∂z/∂x = W. The gradient of W is dL/dW = (dL/dz)ᵀ x (outer product for a single sample) or dL/dW = (dL/dz)ᵀ X for a batch. The gradient of x is dL/dx = Wᵀ (dL/dz). The gradient of b is dL/db = sum of dL/dz over the batch dimension (because b broadcasts). Shape check: if dL/dz has shape (m, d_out) and W has shape (d_out, d_in), then dL/dW = (dL/dz)ᵀ @ X has shape (d_out, d_in) — matching W exactly."},{"type":"heading","level":2,"content":"Gradients of Activation Functions"},{"type":"text","content":"ReLU: a = max(0, z), so da/dz = 𝟙(z \u003e 0) — a binary mask. Gradient: dL/dz = dL/da ⊙ 𝟙(z \u003e 0). Sigmoid: σ(z) = 1/(1+e⁻ᶻ), derivative σ\u0027(z) = σ(z)(1-σ(z)) — elegantly expressed in terms of the output itself. Gradient: dL/dz = dL/da ⊙ a ⊙ (1-a). Softmax + cross-entropy: when combined, the gradient with respect to the logits z is remarkably clean: dL/dz = (1/m)(ŷ - y) where y is one-hot. This clean gradient is why cross-entropy and softmax are always used together."},{"type":"code","language":"python","content":"import numpy as np\n\n# ---- Forward pass ----\ndef relu(z):     return np.maximum(0, z)\ndef softmax(z):  e = np.exp(z - z.max(1, keepdims=True)); return e / e.sum(1, keepdims=True)\n\ndef forward(X, W1, b1, W2, b2):\n    z1 = X @ W1.T + b1\n    a1 = relu(z1)\n    z2 = a1 @ W2.T + b2\n    y_hat = softmax(z2)\n    return y_hat, dict(X=X, z1=z1, a1=a1, z2=z2, W1=W1, W2=W2, b1=b1, b2=b2)\n\ndef cross_entropy(y_hat, y):\n    m = y.shape[0]\n    return -np.log(y_hat[np.arange(m), y] + 1e-12).mean()\n\n# ---- Backward pass (manual chain rule) ----\ndef backward(y_hat, y_true, cache):\n    m = y_true.shape[0]\n    X, z1, a1 = cache[\u0027X\u0027], cache[\u0027z1\u0027], cache[\u0027a1\u0027]\n    W2 = cache[\u0027W2\u0027]\n    # Gradient of softmax + cross-entropy wrt logits z2\n    dz2 = y_hat.copy()\n    dz2[np.arange(m), y_true] -= 1\n    dz2 /= m                         # (m, d_out)\n    dW2 = dz2.T @ a1                 # (d_out, d_h)\n    db2 = dz2.sum(axis=0)            # (d_out,)\n    da1 = dz2 @ W2                   # (m, d_h)\n    dz1 = da1 * (z1 \u003e 0).astype(float)  # ReLU mask\n    dW1 = dz1.T @ X                  # (d_h, d_in)\n    db1 = dz1.sum(axis=0)            # (d_h,)\n    return dict(dW1=dW1, db1=db1, dW2=dW2, db2=db2)\n\nnp.random.seed(1)\nm, d_in, d_h, d_out = 16, 8, 12, 3\nX  = np.random.randn(m, d_in)\nW1 = np.random.randn(d_h, d_in) * 0.1\nb1 = np.zeros(d_h)\nW2 = np.random.randn(d_out, d_h) * 0.1\nb2 = np.zeros(d_out)\ny  = np.random.randint(0, d_out, m)\n\ny_hat, cache = forward(X, W1, b1, W2, b2)\nloss = cross_entropy(y_hat, y)\ngrads = backward(y_hat, y, cache)\nprint(f\u0027Loss: {loss:.4f}\u0027)\nfor k, v in grads.items():\n    print(f\u0027  d{k}: {v.shape}  norm={np.linalg.norm(v):.4f}\u0027)"},{"type":"heading","level":2,"content":"Gradient Checking via Finite Differences"},{"type":"code","language":"python","content":"import numpy as np\n\ndef numerical_gradient(loss_fn, param, eps=1e-5):\n    \"\"\"Compute numerical gradient of loss_fn wrt param using central differences.\"\"\"\n    grad = np.zeros_like(param)\n    it = np.nditer(param, flags=[\u0027multi_index\u0027])\n    while not it.finished:\n        idx = it.multi_index\n        orig = param[idx]\n        param[idx] = orig + eps\n        loss_plus = loss_fn()\n        param[idx] = orig - eps\n        loss_minus = loss_fn()\n        param[idx] = orig\n        grad[idx] = (loss_plus - loss_minus) / (2 * eps)\n        it.iternext()\n    return grad\n\n# Reuse X, W1, b1, W2, b2, y from previous cell\ndef loss_fn():\n    yh, _ = forward(X, W1, b1, W2, b2)\n    return cross_entropy(yh, y)\n\nyh, cache = forward(X, W1, b1, W2, b2)\ngrads = backward(yh, y, cache)\n\nngrad_W1 = numerical_gradient(loss_fn, W1)\nngrad_W2 = numerical_gradient(loss_fn, W2)\n\nrel_err_W1 = np.abs(grads[\u0027dW1\u0027] - ngrad_W1).max() / (np.abs(grads[\u0027dW1\u0027]).max() + 1e-8)\nrel_err_W2 = np.abs(grads[\u0027dW2\u0027] - ngrad_W2).max() / (np.abs(grads[\u0027dW2\u0027]).max() + 1e-8)\nprint(f\u0027Relative error dW1: {rel_err_W1:.2e}  (should be \u003c 1e-5)\u0027)\nprint(f\u0027Relative error dW2: {rel_err_W2:.2e}  (should be \u003c 1e-5)\u0027)\nprint(\u0027Gradient check\u0027, \u0027PASSED\u0027 if max(rel_err_W1, rel_err_W2) \u003c 1e-4 else \u0027FAILED\u0027)"},{"type":"heading","level":2,"content":"PyTorch Autograd Inspection"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(42)\nm, d_in, d_h, d_out = 16, 8, 12, 3\n\nmodel = nn.Sequential(\n    nn.Linear(d_in, d_h),\n    nn.ReLU(),\n    nn.Linear(d_h, d_out)\n)\nX_t = torch.randn(m, d_in)\ny_t = torch.randint(0, d_out, (m,))\n\n# Forward\nlogits = model(X_t)\nloss = nn.CrossEntropyLoss()(logits, y_t)\nprint(f\u0027Loss: {loss.item():.4f}\u0027)\n\n# Backward\nloss.backward()\n\n# Inspect gradients\nfor name, p in model.named_parameters():\n    print(f\u0027  {name}: grad.shape={tuple(p.grad.shape)}  \u0027\n          f\u0027grad.norm={p.grad.norm().item():.4f}\u0027)\n\n# Verify gradient of z2 = (y_hat - y) / m\nwith torch.no_grad():\n    y_hat = torch.softmax(logits, dim=1)\n    grad_logits = (y_hat.clone())\n    grad_logits[torch.arange(m), y_t] -= 1\n    grad_logits /= m\nprint(f\u0027\\nManual dL/dz2 norm: {grad_logits.norm().item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Custom Autograd Function"},{"type":"code","language":"python","content":"import torch\nfrom torch.autograd import Function\n\nclass LeakyReLUFunction(Function):\n    \"\"\"Custom autograd Function for Leaky ReLU with learnable slope.\"\"\"\n\n    @staticmethod\n    def forward(ctx, x, negative_slope=0.01):\n        ctx.save_for_backward(x)\n        ctx.negative_slope = negative_slope\n        return torch.where(x \u003e= 0, x, negative_slope * x)\n\n    @staticmethod\n    def backward(ctx, grad_output):\n        x, = ctx.saved_tensors\n        slope = ctx.negative_slope\n        # dL/dx = grad_output * (1 if x\u003e=0 else slope)\n        mask = (x \u003e= 0).float() + slope * (x \u003c 0).float()\n        grad_input = grad_output * mask\n        return grad_input, None  # None for negative_slope (not a tensor)\n\n# Test against PyTorch built-in\ntorch.manual_seed(0)\nx = torch.randn(4, 6, requires_grad=True)\nslope = 0.01\n\nout_custom = LeakyReLUFunction.apply(x, slope)\nout_custom.sum().backward()\ngrad_custom = x.grad.clone()\n\nx.grad = None\nout_builtin = torch.nn.functional.leaky_relu(x, slope)\nout_builtin.sum().backward()\ngrad_builtin = x.grad\n\ndiff = (grad_custom - grad_builtin).abs().max().item()\nprint(f\u0027Max grad difference (custom vs builtin): {diff:.2e}\u0027)\nprint(\u0027Custom autograd Function correct:\u0027, diff \u003c 1e-6)"},{"type":"callout","variant":"info","title":"Reverse-Mode AD is O(Forward Cost)","content":"For a scalar loss and n parameters, computing all gradients via reverse-mode AD costs O(forward pass) — not O(n × forward). This is because each backward operation computes a vector-Jacobian product (VJP) rather than the full Jacobian matrix. Forward-mode AD (computing Jacobian-vector products) would require one forward pass per parameter — O(n × forward). Reverse-mode is what makes training billion-parameter networks tractable."},{"type":"heading","level":2,"content":"Layer Gradient Summary"},{"type":"table","headers":["Layer","dL/dW formula","dL/dx formula","Computational Cost"],"rows":[["Linear z=Wx+b","dL/dz)ᵀ @ X  shape (d_out, d_in)","W.T @ dL/dz  shape (m, d_in)","O(m · d_in · d_out) — same as forward"],["ReLU a=max(0,z)","No weights","dL/da ⊙ 𝟙(z\u003e0) — elementwise mask","O(n) — cheap, just a multiply by 0/1"],["Sigmoid a=σ(z)","No weights","dL/da ⊙ a(1-a) — uses cached output","O(n) — two multiplies per element"],["Softmax+CE (combined)","No weights in softmax","(ŷ - y)/m — clean closed form","O(m · C) — just subtract one-hot"],["Batch Norm","dL/dγ = Σ dL/dy ⊙ x̂","Non-trivial — couples all batch samples","O(m · d) — harder than other layers"]]},{"type":"heading","level":2,"content":"Jacobians vs Gradients — VJPs in Practice"},{"type":"text","content":"For a vector-valued function y = f(x) with y ∈ ℝ^m and x ∈ ℝ^n, the full Jacobian J = ∂y/∂x ∈ ℝ^{m×n} is expensive to materialise for large m,n. Reverse-mode AD never forms J explicitly. Instead it computes the vector-Jacobian product (VJP): vᵀJ for a given row vector v (the upstream gradient). Each backward pass produces one VJP, which gives the gradient of a scalar L wrt x since dL/dx = (dL/dy)ᵀ J. For a scalar loss dL/dy is just a scalar times a vector, so the VJP collapses to the gradient. Forward-mode AD computes Jacobian-vector products Jv, which is useful for Hessian-vector products and second-order methods but requires one forward pass per input dimension."},{"type":"heading","level":2,"content":"Broadcasting in the Backward Pass"},{"type":"text","content":"When a tensor is broadcast in the forward pass (e.g., bias b ∈ ℝ^d added to Z ∈ ℝ^{m×d}), the backward pass must sum the upstream gradient over the broadcast dimensions. For the bias: dL/db = dL/dZ.sum(axis=0), because each element of b affected m output rows. Forgetting this sum is a common bug — it produces a dL/db of shape (m, d) rather than (d,) and silently corrupts updates. PyTorch handles this automatically; manual implementations must explicitly reduce over any dimensions added by broadcasting."},{"type":"list","ordered":false,"items":["Chain rule in computation graphs: multiply local Jacobians in reverse order from loss to input.","VJP (vector-Jacobian product) is the fundamental operation of reverse-mode AD — O(forward) for scalar loss.","ReLU backward: zero-out gradient where forward input was ≤ 0 — just a binary mask multiply.","Softmax + cross-entropy gradient simplifies to (ŷ - y)/m — always derive combined, never separate.","Broadcasting in forward: sum over corresponding dimensions in backward or shapes will not match.","Gradient checking: finite differences at eps=1e-5 with relative error \u003c 1e-4 confirms correctness."]},{"type":"divider"}]"
---
# Backward Pass — Chain Rule and Gradient Derivation by Hand

Backpropagation is the algorithm that computes gradients of the loss with respect to every parameter by applying the chain rule in reverse through the computational graph. Understanding it from first principles — deriving gradients by hand for each layer type — demystifies automatic differentiation and is essential for debugging gradient flow, implementing custom operations, and reasoning about training dynamics.

## Chain Rule and Computational Graph Traversal

For a composition f(g(x)), the chain rule gives df/dx = (df/dg)(dg/dx). In a neural network with loss L, the gradient flows backward: dL/dx = (dL/dy)(dy/dx) where y = f(x). In the computational graph, each node stores its local Jacobian dy/dx; backprop multiplies these Jacobians in reverse order from output to input. For a scalar loss and a vector x, dL/dx has the same shape as x — this is the vector-Jacobian product (VJP), the core operation in reverse-mode AD.

## Gradient of a Linear Layer

For z = Wx + b with loss L: the local Jacobian is ∂z/∂x = W. The gradient of W is dL/dW = (dL/dz)ᵀ x (outer product for a single sample) or dL/dW = (dL/dz)ᵀ X for a batch. The gradient of x is dL/dx = Wᵀ (dL/dz). The gradient of b is dL/db = sum of dL/dz over the batch dimension (because b broadcasts). Shape check: if dL/dz has shape (m, d_out) and W has shape (d_out, d_in), then dL/dW = (dL/dz)ᵀ @ X has shape (d_out, d_in) — matching W exactly.

## Gradients of Activation Functions

ReLU: a = max(0, z), so da/dz = 𝟙(z > 0) — a binary mask. Gradient: dL/dz = dL/da ⊙ 𝟙(z > 0). Sigmoid: σ(z) = 1/(1+e⁻ᶻ), derivative σ'(z) = σ(z)(1-σ(z)) — elegantly expressed in terms of the output itself. Gradient: dL/dz = dL/da ⊙ a ⊙ (1-a). Softmax + cross-entropy: when combined, the gradient with respect to the logits z is remarkably clean: dL/dz = (1/m)(ŷ - y) where y is one-hot. This clean gradient is why cross-entropy and softmax are always used together.

```python
import numpy as np

# ---- Forward pass ----
def relu(z):     return np.maximum(0, z)
def softmax(z):  e = np.exp(z - z.max(1, keepdims=True)); return e / e.sum(1, keepdims=True)

def forward(X, W1, b1, W2, b2):
    z1 = X @ W1.T + b1
    a1 = relu(z1)
    z2 = a1 @ W2.T + b2
    y_hat = softmax(z2)
    return y_hat, dict(X=X, z1=z1, a1=a1, z2=z2, W1=W1, W2=W2, b1=b1, b2=b2)

def cross_entropy(y_hat, y):
    m = y.shape[0]
    return -np.log(y_hat[np.arange(m), y] + 1e-12).mean()

# ---- Backward pass (manual chain rule) ----
def backward(y_hat, y_true, cache):
    m = y_true.shape[0]
    X, z1, a1 = cache['X'], cache['z1'], cache['a1']
    W2 = cache['W2']
    # Gradient of softmax + cross-entropy wrt logits z2
    dz2 = y_hat.copy()
    dz2[np.arange(m), y_true] -= 1
    dz2 /= m                         # (m, d_out)
    dW2 = dz2.T @ a1                 # (d_out, d_h)
    db2 = dz2.sum(axis=0)            # (d_out,)
    da1 = dz2 @ W2                   # (m, d_h)
    dz1 = da1 * (z1 > 0).astype(float)  # ReLU mask
    dW1 = dz1.T @ X                  # (d_h, d_in)
    db1 = dz1.sum(axis=0)            # (d_h,)
    return dict(dW1=dW1, db1=db1, dW2=dW2, db2=db2)

np.random.seed(1)
m, d_in, d_h, d_out = 16, 8, 12, 3
X  = np.random.randn(m, d_in)
W1 = np.random.randn(d_h, d_in) * 0.1
b1 = np.zeros(d_h)
W2 = np.random.randn(d_out, d_h) * 0.1
b2 = np.zeros(d_out)
y  = np.random.randint(0, d_out, m)

y_hat, cache = forward(X, W1, b1, W2, b2)
loss = cross_entropy(y_hat, y)
grads = backward(y_hat, y, cache)
print(f'Loss: {loss:.4f}')
for k, v in grads.items():
    print(f'  d{k}: {v.shape}  norm={np.linalg.norm(v):.4f}')
```

## Gradient Checking via Finite Differences

```python
import numpy as np

def numerical_gradient(loss_fn, param, eps=1e-5):
    """Compute numerical gradient of loss_fn wrt param using central differences."""
    grad = np.zeros_like(param)
    it = np.nditer(param, flags=['multi_index'])
    while not it.finished:
        idx = it.multi_index
        orig = param[idx]
        param[idx] = orig + eps
        loss_plus = loss_fn()
        param[idx] = orig - eps
        loss_minus = loss_fn()
        param[idx] = orig
        grad[idx] = (loss_plus - loss_minus) / (2 * eps)
        it.iternext()
    return grad

# Reuse X, W1, b1, W2, b2, y from previous cell
def loss_fn():
    yh, _ = forward(X, W1, b1, W2, b2)
    return cross_entropy(yh, y)

yh, cache = forward(X, W1, b1, W2, b2)
grads = backward(yh, y, cache)

ngrad_W1 = numerical_gradient(loss_fn, W1)
ngrad_W2 = numerical_gradient(loss_fn, W2)

rel_err_W1 = np.abs(grads['dW1'] - ngrad_W1).max() / (np.abs(grads['dW1']).max() + 1e-8)
rel_err_W2 = np.abs(grads['dW2'] - ngrad_W2).max() / (np.abs(grads['dW2']).max() + 1e-8)
print(f'Relative error dW1: {rel_err_W1:.2e}  (should be < 1e-5)')
print(f'Relative error dW2: {rel_err_W2:.2e}  (should be < 1e-5)')
print('Gradient check', 'PASSED' if max(rel_err_W1, rel_err_W2) < 1e-4 else 'FAILED')
```

## PyTorch Autograd Inspection

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(42)
m, d_in, d_h, d_out = 16, 8, 12, 3

model = nn.Sequential(
    nn.Linear(d_in, d_h),
    nn.ReLU(),
    nn.Linear(d_h, d_out)
)
X_t = torch.randn(m, d_in)
y_t = torch.randint(0, d_out, (m,))

# Forward
logits = model(X_t)
loss = nn.CrossEntropyLoss()(logits, y_t)
print(f'Loss: {loss.item():.4f}')

# Backward
loss.backward()

# Inspect gradients
for name, p in model.named_parameters():
    print(f'  {name}: grad.shape={tuple(p.grad.shape)}  '
          f'grad.norm={p.grad.norm().item():.4f}')

# Verify gradient of z2 = (y_hat - y) / m
with torch.no_grad():
    y_hat = torch.softmax(logits, dim=1)
    grad_logits = (y_hat.clone())
    grad_logits[torch.arange(m), y_t] -= 1
    grad_logits /= m
print(f'\nManual dL/dz2 norm: {grad_logits.norm().item():.4f}')
```

## Custom Autograd Function

```python
import torch
from torch.autograd import Function

class LeakyReLUFunction(Function):
    """Custom autograd Function for Leaky ReLU with learnable slope."""

    @staticmethod
    def forward(ctx, x, negative_slope=0.01):
        ctx.save_for_backward(x)
        ctx.negative_slope = negative_slope
        return torch.where(x >= 0, x, negative_slope * x)

    @staticmethod
    def backward(ctx, grad_output):
        x, = ctx.saved_tensors
        slope = ctx.negative_slope
        # dL/dx = grad_output * (1 if x>=0 else slope)
        mask = (x >= 0).float() + slope * (x < 0).float()
        grad_input = grad_output * mask
        return grad_input, None  # None for negative_slope (not a tensor)

# Test against PyTorch built-in
torch.manual_seed(0)
x = torch.randn(4, 6, requires_grad=True)
slope = 0.01

out_custom = LeakyReLUFunction.apply(x, slope)
out_custom.sum().backward()
grad_custom = x.grad.clone()

x.grad = None
out_builtin = torch.nn.functional.leaky_relu(x, slope)
out_builtin.sum().backward()
grad_builtin = x.grad

diff = (grad_custom - grad_builtin).abs().max().item()
print(f'Max grad difference (custom vs builtin): {diff:.2e}')
print('Custom autograd Function correct:', diff < 1e-6)
```

> **Reverse-Mode AD is O(Forward Cost)**: For a scalar loss and n parameters, computing all gradients via reverse-mode AD costs O(forward pass) — not O(n × forward). This is because each backward operation computes a vector-Jacobian product (VJP) rather than the full Jacobian matrix. Forward-mode AD (computing Jacobian-vector products) would require one forward pass per parameter — O(n × forward). Reverse-mode is what makes training billion-parameter networks tractable.

## Layer Gradient Summary

| Layer | dL/dW formula | dL/dx formula | Computational Cost |
| --- | --- | --- | --- |
| Linear z=Wx+b | dL/dz)ᵀ @ X  shape (d_out, d_in) | W.T @ dL/dz  shape (m, d_in) | O(m · d_in · d_out) — same as forward |
| ReLU a=max(0,z) | No weights | dL/da ⊙ 𝟙(z>0) — elementwise mask | O(n) — cheap, just a multiply by 0/1 |
| Sigmoid a=σ(z) | No weights | dL/da ⊙ a(1-a) — uses cached output | O(n) — two multiplies per element |
| Softmax+CE (combined) | No weights in softmax | (ŷ - y)/m — clean closed form | O(m · C) — just subtract one-hot |
| Batch Norm | dL/dγ = Σ dL/dy ⊙ x̂ | Non-trivial — couples all batch samples | O(m · d) — harder than other layers |

## Jacobians vs Gradients — VJPs in Practice

For a vector-valued function y = f(x) with y ∈ ℝ^m and x ∈ ℝ^n, the full Jacobian J = ∂y/∂x ∈ ℝ^{m×n} is expensive to materialise for large m,n. Reverse-mode AD never forms J explicitly. Instead it computes the vector-Jacobian product (VJP): vᵀJ for a given row vector v (the upstream gradient). Each backward pass produces one VJP, which gives the gradient of a scalar L wrt x since dL/dx = (dL/dy)ᵀ J. For a scalar loss dL/dy is just a scalar times a vector, so the VJP collapses to the gradient. Forward-mode AD computes Jacobian-vector products Jv, which is useful for Hessian-vector products and second-order methods but requires one forward pass per input dimension.

## Broadcasting in the Backward Pass

When a tensor is broadcast in the forward pass (e.g., bias b ∈ ℝ^d added to Z ∈ ℝ^{m×d}), the backward pass must sum the upstream gradient over the broadcast dimensions. For the bias: dL/db = dL/dZ.sum(axis=0), because each element of b affected m output rows. Forgetting this sum is a common bug — it produces a dL/db of shape (m, d) rather than (d,) and silently corrupts updates. PyTorch handles this automatically; manual implementations must explicitly reduce over any dimensions added by broadcasting.

- Chain rule in computation graphs: multiply local Jacobians in reverse order from loss to input.
- VJP (vector-Jacobian product) is the fundamental operation of reverse-mode AD — O(forward) for scalar loss.
- ReLU backward: zero-out gradient where forward input was ≤ 0 — just a binary mask multiply.
- Softmax + cross-entropy gradient simplifies to (ŷ - y)/m — always derive combined, never separate.
- Broadcasting in forward: sum over corresponding dimensions in backward or shapes will not match.
- Gradient checking: finite differences at eps=1e-5 with relative error < 1e-4 confirms correctness.

---

