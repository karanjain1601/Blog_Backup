---
title: "PyTorch Internals — Strides, Contiguous Memory, and Dispatch"
slug: "pytorch-internals"
description: "Under the hood of PyTorch: tensor storage layout, strides, non-contiguous tensors, the dispatcher, custom autograd Functions, TorchScript, and torch.fx."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Most PyTorch users never need to think about tensor strides or the dispatcher — until performance degrades unexpectedly or a custom CUDA kernel must be integrated. Understanding how PyTorch stores tensors in memory, routes operations to backends, and traces computation graphs is essential for optimizing and extending the framework."},{"type":"heading","level":2,"content":"Tensor Storage: Strides and Contiguity"},{"type":"text","content":"A PyTorch tensor is not just data — it is a view into a contiguous memory block defined by: storage (raw memory), offset (start position), shape (size per dimension), and strides (step size in memory to advance one element along each dimension)."},{"type":"list","ordered":false,"items":["Contiguous tensor: strides[i] = product of shape[i+1:] — elements stored in row-major (C) order","After transpose: strides swap — the data is the same, but the view is different (non-contiguous)","After narrow/slice: strides unchanged, offset shifts — another non-contiguous view",".is_contiguous() returns True only if strides match the expected C-order layout",".contiguous() forces a copy to a new contiguous allocation — needed before operations that require contiguous input","view() requires contiguous input; reshape() uses view if possible, otherwise copies"]},{"type":"heading","level":2,"content":"Strides in Practice"},{"type":"text","content":"Understanding strides helps diagnose why certain operations are slow (non-contiguous memory access) and when reshape vs contiguous+view is needed."},{"type":"code","language":"python","content":"import torch\n\n# Contiguous tensor: shape (3, 4)\nx = torch.arange(12).reshape(3, 4)\nprint(f\u0027Shape:          {x.shape}\u0027)\nprint(f\u0027Strides:        {x.stride()}\u0027)   # (4, 1) — row-major\nprint(f\u0027Is contiguous:  {x.is_contiguous()}\u0027)\n\n# Transpose: same data, swapped strides\nx_t = x.T\nprint(f\u0027\\nTransposed strides: {x_t.stride()}\u0027)  # (1, 4) — non-contiguous\nprint(f\u0027Is contiguous:      {x_t.is_contiguous()}\u0027)\n\n# view() fails on non-contiguous tensor\ntry:\n    x_t.view(6, 2)\nexcept RuntimeError as e:\n    print(f\u0027\\nview() error: {e}\u0027)\n\n# contiguous() creates a copy with correct strides\nx_t_contig = x_t.contiguous()\nprint(f\u0027\\nAfter contiguous(), strides: {x_t_contig.stride()}\u0027)\nx_t_contig.view(6, 2)  # now works\n\n# reshape() = view if contiguous, else copy\nx_reshaped = x_t.reshape(6, 2)\nprint(f\u0027x_reshaped shares storage: {x_reshaped.storage().data_ptr() == x_t.storage().data_ptr()}\u0027)"},{"type":"heading","level":2,"content":"Custom Autograd Functions"},{"type":"text","content":"When a numerically stable or fused operation is needed that autograd cannot handle automatically, torch.autograd.Function lets you define both the forward computation and the exact backward (gradient) formula."},{"type":"code","language":"python","content":"import torch\nfrom torch.autograd import Function\n\nclass StableSigmoid(Function):\n    \"\"\"Numerically stable sigmoid with saved output for backward.\"\"\"\n\n    @staticmethod\n    def forward(ctx, x: torch.Tensor) -\u003e torch.Tensor:\n        # Numerically stable: use negative exponential for positive x\n        sig = torch.where(x \u003e= 0,\n                          1 / (1 + torch.exp(-x)),\n                          torch.exp(x) / (1 + torch.exp(x)))\n        ctx.save_for_backward(sig)  # save output for backward pass\n        return sig\n\n    @staticmethod\n    def backward(ctx, grad_output: torch.Tensor) -\u003e torch.Tensor:\n        sig, = ctx.saved_tensors\n        # d/dx sigmoid(x) = sigmoid(x) * (1 - sigmoid(x))\n        return grad_output * sig * (1 - sig)\n\n# Register as a callable function\nstable_sigmoid = StableSigmoid.apply\n\n# Test: compare with torch.sigmoid\nx = torch.randn(5, requires_grad=True)\nout_custom = stable_sigmoid(x)\nout_custom.sum().backward()\nprint(\u0027Custom gradient:\u0027, x.grad)\n\nx2 = x.detach().clone().requires_grad_(True)\ntorch.sigmoid(x2).sum().backward()\nprint(\u0027Torch gradient: \u0027, x2.grad)\nprint(\u0027Match:\u0027, torch.allclose(x.grad, x2.grad, atol=1e-6))"},{"type":"heading","level":2,"content":"TorchScript — Tracing vs Scripting"},{"type":"text","content":"TorchScript compiles Python code to a portable IR (intermediate representation) that can be serialized, optimized, and deployed without a Python interpreter — essential for mobile and C++ serving. Two modes: trace (records operations on a sample input) and script (analyzes Python source code statically)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass SimpleNet(nn.Module):\n    def __init__(self, dim: int):\n        super().__init__()\n        self.fc = nn.Linear(dim, dim)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        return torch.relu(self.fc(x))\n\nmodel = SimpleNet(64)\nmodel.eval()\n\n# Method 1: torch.jit.trace — records operations on a sample input\nsample = torch.randn(1, 64)\ntraced = torch.jit.trace(model, sample)\ntraced.save(\u0027model_traced.pt\u0027)  # portable serialized model\nprint(\u0027Traced output:\u0027, traced(sample).shape)\n\n# Method 2: torch.jit.script — analyzes Python AST, supports control flow\n@torch.jit.script\ndef conditional_op(x: torch.Tensor, flag: bool) -\u003e torch.Tensor:\n    if flag:  # control flow preserved in scripted IR\n        return torch.relu(x)\n    else:\n        return torch.sigmoid(x)\n\nprint(\u0027Script with flag=True: \u0027, conditional_op(torch.randn(3), True))\nprint(\u0027Script with flag=False:\u0027, conditional_op(torch.randn(3), False))\n\n# Load and run traced model in a new session (no model definition needed)\nloaded = torch.jit.load(\u0027model_traced.pt\u0027)\nprint(\u0027Loaded model output:\u0027, loaded(sample).shape)"},{"type":"heading","level":2,"content":"torch.fx — Graph Capture and Manipulation"},{"type":"text","content":"torch.fx captures the symbolic execution trace of a nn.Module as an explicit graph (FX IR). This graph can be inspected, transformed, and compiled — the foundation for torch.compile\u0027s Dynamo tracing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.fx as fx\n\nclass SmallNet(nn.Module):\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        x = torch.relu(x)\n        x = x * 2.0\n        return x.sum(dim=-1)\n\nmodel = SmallNet()\n\n# Capture the FX graph by symbolic tracing\ngraph_module = fx.symbolic_trace(model)\n\nprint(\u0027=== FX Graph Nodes ===\u0027)\nfor node in graph_module.graph.nodes:\n    print(f\u0027  {node.op:\u003c15} {node.name:\u003c20} target={node.target}\u0027)\n\n# Example transformation: replace relu with gelu\nfor node in graph_module.graph.nodes:\n    if node.op == \u0027call_function\u0027 and node.target == torch.relu:\n        node.target = torch.nn.functional.gelu\n        print(f\u0027\\nReplaced relu -\u003e gelu in node: {node.name}\u0027)\n\ngraph_module.recompile()  # regenerate Python code from modified graph\nx_test = torch.randn(4, 8)\nout = graph_module(x_test)\nprint(f\u0027Output after transformation: {out.shape}\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"Tensor Operations: Views vs Copies"},{"type":"table","headers":["Operation","Copies Data","Stride Change","Requires Contiguous","When to Use"],"rows":[["view(shape)","No — zero-copy","Yes (recomputed)","Yes","Reshape contiguous tensors efficiently"],["reshape(shape)","Only if needed","Yes","No (copies if needed)","General reshape — prefer over view"],["transpose(d0, d1)","No — zero-copy","Yes (swapped)","No","Swap two dimensions; check contiguity after"],["permute(dims)","No — zero-copy","Yes (reordered)","No","Arbitrary dimension reordering"],["contiguous()","Yes if needed","Reset to C-order","N/A","Before view() or kernel requiring contig input"]]},{"type":"callout","variant":"warning","title":"Non-Contiguous Tensors and Kernel Performance","content":"CUDA kernels assume contiguous memory for maximum throughput. Operating on a non-contiguous tensor (e.g., after transpose) forces PyTorch to either copy the tensor first or use a slower generic kernel. Profile with torch.profiler if you observe unexpected slowdowns — a single .contiguous() call before a compute-heavy operation often resolves it."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["Tensors are (storage, offset, shape, strides) — transpose and slice create non-contiguous views without copying",".contiguous() forces a copy to C-order memory — required before view() and many CUDA kernels","Custom autograd Functions: define forward + backward explicitly with ctx.save_for_backward","TorchScript trace records operations on a sample; script parses Python AST — script supports control flow, trace does not","torch.fx captures the execution graph as an editable IR — foundation for compile-time optimizations"]}]"
---
# PyTorch Internals — Strides, Contiguous Memory, and Dispatch

Most PyTorch users never need to think about tensor strides or the dispatcher — until performance degrades unexpectedly or a custom CUDA kernel must be integrated. Understanding how PyTorch stores tensors in memory, routes operations to backends, and traces computation graphs is essential for optimizing and extending the framework.

## Tensor Storage: Strides and Contiguity

A PyTorch tensor is not just data — it is a view into a contiguous memory block defined by: storage (raw memory), offset (start position), shape (size per dimension), and strides (step size in memory to advance one element along each dimension).

- Contiguous tensor: strides[i] = product of shape[i+1:] — elements stored in row-major (C) order
- After transpose: strides swap — the data is the same, but the view is different (non-contiguous)
- After narrow/slice: strides unchanged, offset shifts — another non-contiguous view
- .is_contiguous() returns True only if strides match the expected C-order layout
- .contiguous() forces a copy to a new contiguous allocation — needed before operations that require contiguous input
- view() requires contiguous input; reshape() uses view if possible, otherwise copies

## Strides in Practice

Understanding strides helps diagnose why certain operations are slow (non-contiguous memory access) and when reshape vs contiguous+view is needed.

```python
import torch

# Contiguous tensor: shape (3, 4)
x = torch.arange(12).reshape(3, 4)
print(f'Shape:          {x.shape}')
print(f'Strides:        {x.stride()}')   # (4, 1) — row-major
print(f'Is contiguous:  {x.is_contiguous()}')

# Transpose: same data, swapped strides
x_t = x.T
print(f'\nTransposed strides: {x_t.stride()}')  # (1, 4) — non-contiguous
print(f'Is contiguous:      {x_t.is_contiguous()}')

# view() fails on non-contiguous tensor
try:
    x_t.view(6, 2)
except RuntimeError as e:
    print(f'\nview() error: {e}')

# contiguous() creates a copy with correct strides
x_t_contig = x_t.contiguous()
print(f'\nAfter contiguous(), strides: {x_t_contig.stride()}')
x_t_contig.view(6, 2)  # now works

# reshape() = view if contiguous, else copy
x_reshaped = x_t.reshape(6, 2)
print(f'x_reshaped shares storage: {x_reshaped.storage().data_ptr() == x_t.storage().data_ptr()}')
```

## Custom Autograd Functions

When a numerically stable or fused operation is needed that autograd cannot handle automatically, torch.autograd.Function lets you define both the forward computation and the exact backward (gradient) formula.

```python
import torch
from torch.autograd import Function

class StableSigmoid(Function):
    """Numerically stable sigmoid with saved output for backward."""

    @staticmethod
    def forward(ctx, x: torch.Tensor) -> torch.Tensor:
        # Numerically stable: use negative exponential for positive x
        sig = torch.where(x >= 0,
                          1 / (1 + torch.exp(-x)),
                          torch.exp(x) / (1 + torch.exp(x)))
        ctx.save_for_backward(sig)  # save output for backward pass
        return sig

    @staticmethod
    def backward(ctx, grad_output: torch.Tensor) -> torch.Tensor:
        sig, = ctx.saved_tensors
        # d/dx sigmoid(x) = sigmoid(x) * (1 - sigmoid(x))
        return grad_output * sig * (1 - sig)

# Register as a callable function
stable_sigmoid = StableSigmoid.apply

# Test: compare with torch.sigmoid
x = torch.randn(5, requires_grad=True)
out_custom = stable_sigmoid(x)
out_custom.sum().backward()
print('Custom gradient:', x.grad)

x2 = x.detach().clone().requires_grad_(True)
torch.sigmoid(x2).sum().backward()
print('Torch gradient: ', x2.grad)
print('Match:', torch.allclose(x.grad, x2.grad, atol=1e-6))
```

## TorchScript — Tracing vs Scripting

TorchScript compiles Python code to a portable IR (intermediate representation) that can be serialized, optimized, and deployed without a Python interpreter — essential for mobile and C++ serving. Two modes: trace (records operations on a sample input) and script (analyzes Python source code statically).

```python
import torch
import torch.nn as nn

class SimpleNet(nn.Module):
    def __init__(self, dim: int):
        super().__init__()
        self.fc = nn.Linear(dim, dim)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return torch.relu(self.fc(x))

model = SimpleNet(64)
model.eval()

# Method 1: torch.jit.trace — records operations on a sample input
sample = torch.randn(1, 64)
traced = torch.jit.trace(model, sample)
traced.save('model_traced.pt')  # portable serialized model
print('Traced output:', traced(sample).shape)

# Method 2: torch.jit.script — analyzes Python AST, supports control flow
@torch.jit.script
def conditional_op(x: torch.Tensor, flag: bool) -> torch.Tensor:
    if flag:  # control flow preserved in scripted IR
        return torch.relu(x)
    else:
        return torch.sigmoid(x)

print('Script with flag=True: ', conditional_op(torch.randn(3), True))
print('Script with flag=False:', conditional_op(torch.randn(3), False))

# Load and run traced model in a new session (no model definition needed)
loaded = torch.jit.load('model_traced.pt')
print('Loaded model output:', loaded(sample).shape)
```

## torch.fx — Graph Capture and Manipulation

torch.fx captures the symbolic execution trace of a nn.Module as an explicit graph (FX IR). This graph can be inspected, transformed, and compiled — the foundation for torch.compile's Dynamo tracing.

```python
import torch
import torch.nn as nn
import torch.fx as fx

class SmallNet(nn.Module):
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = torch.relu(x)
        x = x * 2.0
        return x.sum(dim=-1)

model = SmallNet()

# Capture the FX graph by symbolic tracing
graph_module = fx.symbolic_trace(model)

print('=== FX Graph Nodes ===')
for node in graph_module.graph.nodes:
    print(f'  {node.op:<15} {node.name:<20} target={node.target}')

# Example transformation: replace relu with gelu
for node in graph_module.graph.nodes:
    if node.op == 'call_function' and node.target == torch.relu:
        node.target = torch.nn.functional.gelu
        print(f'\nReplaced relu -> gelu in node: {node.name}')

graph_module.recompile()  # regenerate Python code from modified graph
x_test = torch.randn(4, 8)
out = graph_module(x_test)
print(f'Output after transformation: {out.shape}')
```

---

## Tensor Operations: Views vs Copies

| Operation | Copies Data | Stride Change | Requires Contiguous | When to Use |
| --- | --- | --- | --- | --- |
| view(shape) | No — zero-copy | Yes (recomputed) | Yes | Reshape contiguous tensors efficiently |
| reshape(shape) | Only if needed | Yes | No (copies if needed) | General reshape — prefer over view |
| transpose(d0, d1) | No — zero-copy | Yes (swapped) | No | Swap two dimensions; check contiguity after |
| permute(dims) | No — zero-copy | Yes (reordered) | No | Arbitrary dimension reordering |
| contiguous() | Yes if needed | Reset to C-order | N/A | Before view() or kernel requiring contig input |

> **Non-Contiguous Tensors and Kernel Performance**: CUDA kernels assume contiguous memory for maximum throughput. Operating on a non-contiguous tensor (e.g., after transpose) forces PyTorch to either copy the tensor first or use a slower generic kernel. Profile with torch.profiler if you observe unexpected slowdowns — a single .contiguous() call before a compute-heavy operation often resolves it.

## Key Takeaways

- Tensors are (storage, offset, shape, strides) — transpose and slice create non-contiguous views without copying
- .contiguous() forces a copy to C-order memory — required before view() and many CUDA kernels
- Custom autograd Functions: define forward + backward explicitly with ctx.save_for_backward
- TorchScript trace records operations on a sample; script parses Python AST — script supports control flow, trace does not
- torch.fx captures the execution graph as an editable IR — foundation for compile-time optimizations

