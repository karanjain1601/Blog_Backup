---
title: "PyTorch — Autograd, Tensors, nn.Module, and DataLoader"
slug: "pytorch-fundamentals"
description: "PyTorch core primitives: tensor operations with autograd, building models with nn.Module, loading data with DataLoader, and writing a complete training loop."
tags: ["pytorch", "tools", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"PyTorch is the dominant deep learning framework for research and increasingly for production. Its core design — eager execution, dynamic graphs, Pythonic API — makes debugging natural and custom architectures straightforward. Understanding the four primitives (tensors, autograd, nn.Module, DataLoader) unlocks everything else."},{"type":"heading","level":2,"content":"Tensors and Data Types"},{"type":"text","content":"A torch.Tensor is an N-dimensional array backed by a contiguous block of memory, with a dtype (float32, float16, bfloat16, int64, bool), a device (cpu, cuda, mps), and optional autograd tracking via requires_grad. Operations on tensors with requires_grad=True are recorded into a computational graph."},{"type":"list","ordered":false,"items":["float32: default dtype for model weights — 32-bit IEEE 754, safe for most operations","float16: 16-bit reduced precision — faster on tensor cores, risks overflow (max ~65504)","bfloat16: 16-bit with same exponent range as float32 — preferred for training on A100/H100","Leaf tensors: tensors created by the user (not by operations) — only these accumulate .grad","Non-leaf tensors: outputs of operations — their .grad is not retained unless retain_grad() called","Device movement: tensor.to(\u0027cuda\u0027), tensor.cuda(), tensor.cpu() — always synchronous"]},{"type":"heading","level":2,"content":"Tensors and Autograd from Scratch"},{"type":"text","content":"The computational graph is built dynamically during the forward pass. Calling .backward() on a scalar traverses this graph in reverse, computing gradients via chain rule and accumulating them in .grad of each leaf tensor."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\n# Basic tensor with gradient tracking\nx = torch.tensor([[1.0, 2.0], [3.0, 4.0]], requires_grad=True)\nW = torch.tensor([[0.5, -0.5], [1.0, 0.3]], requires_grad=True)\n\n# Forward pass — builds computational graph\nz = x @ W          # matrix multiply\nloss = z.sum()     # scalar loss\n\n# Backward pass — traverses graph, fills .grad\nloss.backward()\nprint(\u0027x.grad:\u0027, x.grad)   # dl/dx\nprint(\u0027W.grad:\u0027, W.grad)   # dl/dW\n\n# Critical: zero gradients before next backward pass\n# (gradients accumulate by default — a common bug)\nx.grad.zero_()\nW.grad.zero_()\n\n# torch.no_grad() for inference — no graph, lower memory\nwith torch.no_grad():\n    z_inf = x @ W\n    print(\u0027Requires grad (inference):\u0027, z_inf.requires_grad)  # False\n\n# Detach a tensor from the graph (used in RL, GAN targets)\nz_detached = z.detach()\nprint(\u0027Detached requires grad:\u0027, z_detached.requires_grad)  # False"},{"type":"heading","level":2,"content":"Building Models with nn.Module"},{"type":"text","content":"nn.Module is the base class for all neural network layers and models. It tracks parameters automatically, supports device movement via .to(), and provides state_dict() for serialization. Every custom layer subclasses nn.Module and implements forward()."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass ResidualBlock(nn.Module):\n    def __init__(self, dim: int, dropout: float = 0.1):\n        super().__init__()\n        self.fc1    = nn.Linear(dim, dim * 2)\n        self.fc2    = nn.Linear(dim * 2, dim)\n        self.norm1  = nn.LayerNorm(dim)\n        self.norm2  = nn.LayerNorm(dim)\n        self.drop   = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        residual = x\n        x = self.norm1(x)\n        x = F.gelu(self.fc1(x))\n        x = self.drop(x)\n        x = self.fc2(x)\n        return self.norm2(x + residual)  # residual connection\n\nclass TabularMLP(nn.Module):\n    def __init__(self, n_in: int, n_out: int, depth: int = 3, width: int = 256):\n        super().__init__()\n        self.input_proj = nn.Linear(n_in, width)\n        self.blocks     = nn.ModuleList([ResidualBlock(width) for _ in range(depth)])\n        self.head       = nn.Linear(width, n_out)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        x = self.input_proj(x)\n        for block in self.blocks:\n            x = block(x)\n        return self.head(x)\n\nmodel = TabularMLP(n_in=20, n_out=2)\nprint(f\u0027Parameters: {sum(p.numel() for p in model.parameters()):,}\u0027)\nprint(model)"},{"type":"heading","level":2,"content":"Custom Dataset and DataLoader"},{"type":"text","content":"DataLoader wraps a Dataset, handles batching, shuffling, and parallel loading. Implementing __len__ and __getitem__ is all that is required for a custom Dataset. pin_memory=True and num_workers\u003e0 are key for GPU training throughput."},{"type":"code","language":"python","content":"import torch\nfrom torch.utils.data import Dataset, DataLoader\nimport numpy as np\nfrom sklearn.preprocessing import StandardScaler\n\nclass TabularDataset(Dataset):\n    def __init__(self, X: np.ndarray, y: np.ndarray, scaler=None, fit_scaler=False):\n        if scaler is None:\n            scaler = StandardScaler()\n        if fit_scaler:\n            X = scaler.fit_transform(X)\n        else:\n            X = scaler.transform(X)\n        self.X      = torch.FloatTensor(X)\n        self.y      = torch.LongTensor(y)\n        self.scaler = scaler\n\n    def __len__(self) -\u003e int:\n        return len(self.X)\n\n    def __getitem__(self, idx: int):\n        return self.X[idx], self.y[idx]\n\n# Usage\nfrom sklearn.datasets import make_classification\nX, y = make_classification(n_samples=5000, n_features=20, random_state=42)\n\ntrain_ds = TabularDataset(X[:4000], y[:4000], fit_scaler=True)\nval_ds   = TabularDataset(X[4000:], y[4000:], scaler=train_ds.scaler)\n\ntrain_loader = DataLoader(train_ds, batch_size=256, shuffle=True,\n                          num_workers=0, pin_memory=False)\nval_loader   = DataLoader(val_ds,   batch_size=512, shuffle=False)\n\nfor X_batch, y_batch in train_loader:\n    print(f\u0027Batch shape: {X_batch.shape}, dtype: {X_batch.dtype}\u0027)\n    break"},{"type":"heading","level":2,"content":"Complete Training Loop"},{"type":"text","content":"A production training loop includes: gradient zeroing before each forward pass, model.eval() for validation (disables dropout/BatchNorm), a learning rate scheduler, and early stopping based on validation loss."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.optim.lr_scheduler import CosineAnnealingLR\n\ndef train_epoch(model, loader, optimizer, criterion, device):\n    model.train()\n    total_loss, correct, total = 0.0, 0, 0\n    for X_batch, y_batch in loader:\n        X_batch, y_batch = X_batch.to(device), y_batch.to(device)\n        optimizer.zero_grad(set_to_none=True)  # memory-efficient zero_grad\n        logits = model(X_batch)\n        loss   = criterion(logits, y_batch)\n        loss.backward()\n        nn.utils.clip_grad_norm_(model.parameters(), max_norm=1.0)\n        optimizer.step()\n        total_loss += loss.item() * len(y_batch)\n        correct    += (logits.argmax(1) == y_batch).sum().item()\n        total      += len(y_batch)\n    return total_loss / total, correct / total\n\n@torch.no_grad()\ndef eval_epoch(model, loader, criterion, device):\n    model.eval()  # disables dropout and sets BN to eval mode\n    total_loss, correct, total = 0.0, 0, 0\n    for X_batch, y_batch in loader:\n        X_batch, y_batch = X_batch.to(device), y_batch.to(device)\n        logits = model(X_batch)\n        total_loss += criterion(logits, y_batch).item() * len(y_batch)\n        correct    += (logits.argmax(1) == y_batch).sum().item()\n        total      += len(y_batch)\n    return total_loss / total, correct / total"},{"type":"divider"},{"type":"heading","level":2,"content":"Key nn.Module Methods"},{"type":"table","headers":["Method","Purpose","Common Usage"],"rows":[["forward(x)","Define the computation","Called via model(x), not model.forward(x)"],["parameters()","Iterator over all trainable params","optimizer = Adam(model.parameters())"],["state_dict()","Ordered dict of all param tensors","torch.save(model.state_dict(), path)"],["load_state_dict(d)","Load saved weights","model.load_state_dict(torch.load(path))"],["to(device)","Move all params to device","model.to(\u0027cuda\u0027) or model.cuda()"],["train() / eval()","Set training vs inference mode","Affects Dropout and BatchNorm behavior"],["named_parameters()","Iterator over (name, param) pairs","Inspecting or freezing specific layers"]]},{"type":"callout","variant":"tip","title":"set_to_none=True in zero_grad","content":"Using optimizer.zero_grad(set_to_none=True) sets gradient tensors to None instead of zeroing them. This avoids allocating memory for gradients that will be immediately overwritten, saving 10-20% GPU memory in large models. It is the default in recent PyTorch versions."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["torch.Tensor = N-dim array with dtype, device, and optional autograd (requires_grad=True for leaf tensors)","autograd builds the computational graph on the forward pass; .backward() computes gradients via reverse-mode AD","nn.Module tracks parameters automatically — implement forward(), use ModuleList/ModuleDict for submodules","DataLoader handles batching, shuffling, and parallel loading — set pin_memory=True and num_workers\u003e0 for GPU","Training loop pattern: zero_grad → forward → loss → backward → clip_grad → step → scheduler.step"]}]"
---
# PyTorch — Autograd, Tensors, nn.Module, and DataLoader

PyTorch is the dominant deep learning framework for research and increasingly for production. Its core design — eager execution, dynamic graphs, Pythonic API — makes debugging natural and custom architectures straightforward. Understanding the four primitives (tensors, autograd, nn.Module, DataLoader) unlocks everything else.

## Tensors and Data Types

A torch.Tensor is an N-dimensional array backed by a contiguous block of memory, with a dtype (float32, float16, bfloat16, int64, bool), a device (cpu, cuda, mps), and optional autograd tracking via requires_grad. Operations on tensors with requires_grad=True are recorded into a computational graph.

- float32: default dtype for model weights — 32-bit IEEE 754, safe for most operations
- float16: 16-bit reduced precision — faster on tensor cores, risks overflow (max ~65504)
- bfloat16: 16-bit with same exponent range as float32 — preferred for training on A100/H100
- Leaf tensors: tensors created by the user (not by operations) — only these accumulate .grad
- Non-leaf tensors: outputs of operations — their .grad is not retained unless retain_grad() called
- Device movement: tensor.to('cuda'), tensor.cuda(), tensor.cpu() — always synchronous

## Tensors and Autograd from Scratch

The computational graph is built dynamically during the forward pass. Calling .backward() on a scalar traverses this graph in reverse, computing gradients via chain rule and accumulating them in .grad of each leaf tensor.

```python
import torch
import torch.nn as nn

# Basic tensor with gradient tracking
x = torch.tensor([[1.0, 2.0], [3.0, 4.0]], requires_grad=True)
W = torch.tensor([[0.5, -0.5], [1.0, 0.3]], requires_grad=True)

# Forward pass — builds computational graph
z = x @ W          # matrix multiply
loss = z.sum()     # scalar loss

# Backward pass — traverses graph, fills .grad
loss.backward()
print('x.grad:', x.grad)   # dl/dx
print('W.grad:', W.grad)   # dl/dW

# Critical: zero gradients before next backward pass
# (gradients accumulate by default — a common bug)
x.grad.zero_()
W.grad.zero_()

# torch.no_grad() for inference — no graph, lower memory
with torch.no_grad():
    z_inf = x @ W
    print('Requires grad (inference):', z_inf.requires_grad)  # False

# Detach a tensor from the graph (used in RL, GAN targets)
z_detached = z.detach()
print('Detached requires grad:', z_detached.requires_grad)  # False
```

## Building Models with nn.Module

nn.Module is the base class for all neural network layers and models. It tracks parameters automatically, supports device movement via .to(), and provides state_dict() for serialization. Every custom layer subclasses nn.Module and implements forward().

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class ResidualBlock(nn.Module):
    def __init__(self, dim: int, dropout: float = 0.1):
        super().__init__()
        self.fc1    = nn.Linear(dim, dim * 2)
        self.fc2    = nn.Linear(dim * 2, dim)
        self.norm1  = nn.LayerNorm(dim)
        self.norm2  = nn.LayerNorm(dim)
        self.drop   = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        residual = x
        x = self.norm1(x)
        x = F.gelu(self.fc1(x))
        x = self.drop(x)
        x = self.fc2(x)
        return self.norm2(x + residual)  # residual connection

class TabularMLP(nn.Module):
    def __init__(self, n_in: int, n_out: int, depth: int = 3, width: int = 256):
        super().__init__()
        self.input_proj = nn.Linear(n_in, width)
        self.blocks     = nn.ModuleList([ResidualBlock(width) for _ in range(depth)])
        self.head       = nn.Linear(width, n_out)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = self.input_proj(x)
        for block in self.blocks:
            x = block(x)
        return self.head(x)

model = TabularMLP(n_in=20, n_out=2)
print(f'Parameters: {sum(p.numel() for p in model.parameters()):,}')
print(model)
```

## Custom Dataset and DataLoader

DataLoader wraps a Dataset, handles batching, shuffling, and parallel loading. Implementing __len__ and __getitem__ is all that is required for a custom Dataset. pin_memory=True and num_workers>0 are key for GPU training throughput.

```python
import torch
from torch.utils.data import Dataset, DataLoader
import numpy as np
from sklearn.preprocessing import StandardScaler

class TabularDataset(Dataset):
    def __init__(self, X: np.ndarray, y: np.ndarray, scaler=None, fit_scaler=False):
        if scaler is None:
            scaler = StandardScaler()
        if fit_scaler:
            X = scaler.fit_transform(X)
        else:
            X = scaler.transform(X)
        self.X      = torch.FloatTensor(X)
        self.y      = torch.LongTensor(y)
        self.scaler = scaler

    def __len__(self) -> int:
        return len(self.X)

    def __getitem__(self, idx: int):
        return self.X[idx], self.y[idx]

# Usage
from sklearn.datasets import make_classification
X, y = make_classification(n_samples=5000, n_features=20, random_state=42)

train_ds = TabularDataset(X[:4000], y[:4000], fit_scaler=True)
val_ds   = TabularDataset(X[4000:], y[4000:], scaler=train_ds.scaler)

train_loader = DataLoader(train_ds, batch_size=256, shuffle=True,
                          num_workers=0, pin_memory=False)
val_loader   = DataLoader(val_ds,   batch_size=512, shuffle=False)

for X_batch, y_batch in train_loader:
    print(f'Batch shape: {X_batch.shape}, dtype: {X_batch.dtype}')
    break
```

## Complete Training Loop

A production training loop includes: gradient zeroing before each forward pass, model.eval() for validation (disables dropout/BatchNorm), a learning rate scheduler, and early stopping based on validation loss.

```python
import torch
import torch.nn as nn
from torch.optim.lr_scheduler import CosineAnnealingLR

def train_epoch(model, loader, optimizer, criterion, device):
    model.train()
    total_loss, correct, total = 0.0, 0, 0
    for X_batch, y_batch in loader:
        X_batch, y_batch = X_batch.to(device), y_batch.to(device)
        optimizer.zero_grad(set_to_none=True)  # memory-efficient zero_grad
        logits = model(X_batch)
        loss   = criterion(logits, y_batch)
        loss.backward()
        nn.utils.clip_grad_norm_(model.parameters(), max_norm=1.0)
        optimizer.step()
        total_loss += loss.item() * len(y_batch)
        correct    += (logits.argmax(1) == y_batch).sum().item()
        total      += len(y_batch)
    return total_loss / total, correct / total

@torch.no_grad()
def eval_epoch(model, loader, criterion, device):
    model.eval()  # disables dropout and sets BN to eval mode
    total_loss, correct, total = 0.0, 0, 0
    for X_batch, y_batch in loader:
        X_batch, y_batch = X_batch.to(device), y_batch.to(device)
        logits = model(X_batch)
        total_loss += criterion(logits, y_batch).item() * len(y_batch)
        correct    += (logits.argmax(1) == y_batch).sum().item()
        total      += len(y_batch)
    return total_loss / total, correct / total
```

---

## Key nn.Module Methods

| Method | Purpose | Common Usage |
| --- | --- | --- |
| forward(x) | Define the computation | Called via model(x), not model.forward(x) |
| parameters() | Iterator over all trainable params | optimizer = Adam(model.parameters()) |
| state_dict() | Ordered dict of all param tensors | torch.save(model.state_dict(), path) |
| load_state_dict(d) | Load saved weights | model.load_state_dict(torch.load(path)) |
| to(device) | Move all params to device | model.to('cuda') or model.cuda() |
| train() / eval() | Set training vs inference mode | Affects Dropout and BatchNorm behavior |
| named_parameters() | Iterator over (name, param) pairs | Inspecting or freezing specific layers |

> **set_to_none=True in zero_grad**: Using optimizer.zero_grad(set_to_none=True) sets gradient tensors to None instead of zeroing them. This avoids allocating memory for gradients that will be immediately overwritten, saving 10-20% GPU memory in large models. It is the default in recent PyTorch versions.

## Key Takeaways

- torch.Tensor = N-dim array with dtype, device, and optional autograd (requires_grad=True for leaf tensors)
- autograd builds the computational graph on the forward pass; .backward() computes gradients via reverse-mode AD
- nn.Module tracks parameters automatically — implement forward(), use ModuleList/ModuleDict for submodules
- DataLoader handles batching, shuffling, and parallel loading — set pin_memory=True and num_workers>0 for GPU
- Training loop pattern: zero_grad → forward → loss → backward → clip_grad → step → scheduler.step

