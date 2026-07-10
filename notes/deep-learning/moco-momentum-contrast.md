---
title: "MoCo — Momentum Contrast and Dynamic Queue"
slug: "moco-momentum-contrast"
description: "MoCo (He et al. 2020) achieves contrastive self-supervised learning without large batch sizes by maintaining a queue of consistent negative keys updated via an exponential moving average momentum encoder, decoupling the number of negatives from GPU memory."
tags: ["deep-learning", "self-supervised-learning", "contrastive-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"MoCo (Momentum Contrast, He et al. 2020) addresses the fundamental bottleneck of SimCLR: the requirement for enormous batch sizes to have enough negatives. MoCo decouples the number of negatives from the batch size by maintaining a dynamic queue of encoded keys from past mini-batches. A momentum encoder (updated by EMA, not gradient) ensures the keys in the queue remain consistent even as the model evolves during training."},{"type":"heading","level":2,"content":"Motivation — The Dictionary Perspective"},{"type":"text","content":"Contrastive learning can be viewed as training a dynamic dictionary look-up. Each encoded query q must match its positive key k₊ (from the same image, different augmentation) and be dissimilar from all negative keys K = {k₁, k₂, …, kK}. To make the loss informative, K must be large (tens of thousands). But computing gradients through K encodings per step is prohibitively expensive. MoCo stores keys in a FIFO queue and only encodes the current mini-batch\u0027s keys with gradient; old keys in the queue are reused without re-encoding."},{"type":"heading","level":2,"content":"Momentum Encoder — EMA Update"},{"type":"text","content":"The key encoder θ_k is not updated by gradient. Instead it tracks the query encoder θ_q via exponential moving average: θ_k ← m·θ_k + (1-m)·θ_q where m = 0.999 (very slow update). This ensures that the keys enqueued over the past few thousand steps were produced by an encoder that changed very slowly, so they are mutually consistent. If the key encoder were updated rapidly by gradient, older queue entries would be encoded by a very different model, making the negatives inconsistent and degrading the loss signal."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport copy\n\ndef build_momentum_encoder(query_encoder, momentum=0.999):\n    \"\"\"Create key encoder as EMA copy of query encoder.\"\"\"\n    key_encoder = copy.deepcopy(query_encoder)\n    # Key encoder not updated by gradient\n    for p in key_encoder.parameters():\n        p.requires_grad_(False)\n    return key_encoder\n\n@torch.no_grad()\ndef momentum_update(query_encoder, key_encoder, momentum=0.999):\n    \"\"\"EMA update: θ_k = m * θ_k + (1-m) * θ_q\"\"\"\n    for q_param, k_param in zip(query_encoder.parameters(),\n                                key_encoder.parameters()):\n        k_param.data = momentum * k_param.data + (1.0 - momentum) * q_param.data\n\n# Demo: show slow drift of key encoder\nimport torch.nn.functional as F\n\ntorch.manual_seed(0)\nq_enc = nn.Linear(64, 64)\nk_enc = build_momentum_encoder(q_enc)\n\n# Simulate one gradient step on query encoder\noptimizer = torch.optim.SGD(q_enc.parameters(), lr=0.1)\nloss = q_enc(torch.randn(8, 64)).mean()\nloss.backward()\noptimizer.step()\n\n# EMA update\nmomentum_update(q_enc, k_enc, momentum=0.999)\n\n# Measure drift\nwith torch.no_grad():\n    diff = sum((qp - kp).norm().item()\n               for qp, kp in zip(q_enc.parameters(), k_enc.parameters()))\nprint(f\u0027Parameter drift after 1 step (momentum=0.999): {diff:.6f}\u0027)"},{"type":"heading","level":2,"content":"Key Queue Management"},{"type":"text","content":"The queue stores K encoded keys (K = 65536 by default). After each mini-batch of size N, N new keys are enqueued and the oldest N keys are dequeued (FIFO). Importantly, keys are enqueued as-is from the key encoder output; they are not backpropagated through. The queue is stored on GPU as a fixed-size buffer. Because queue keys come from many past mini-batches (with the slowly-drifting key encoder), they are diverse and consistent — unlike SimCLR\u0027s in-batch negatives, which vary mini-batch to mini-batch."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\nclass MoCoQueue:\n    \"\"\"FIFO queue of encoded keys for MoCo.\"\"\"\n    def __init__(self, feat_dim=128, queue_size=65536, device=\u0027cuda\u0027):\n        self.queue_size = queue_size\n        # Initialise with random unit vectors\n        self.queue = F.normalize(\n            torch.randn(feat_dim, queue_size, device=device), dim=0\n        )\n        self.ptr = 0  # pointer to current write position\n\n    @torch.no_grad()\n    def enqueue_dequeue(self, keys):\n        \"\"\"Enqueue new keys and dequeue oldest. keys: (N, D) normalised.\"\"\"\n        N = keys.size(0)\n        assert self.queue_size % N == 0, \u0027queue_size must be divisible by batch size\u0027\n        # Write new keys at current pointer position\n        self.queue[:, self.ptr:self.ptr + N] = keys.T  # (D, N)\n        self.ptr = (self.ptr + N) % self.queue_size\n\n    def get_keys(self):\n        \"\"\"Return all keys in queue as (D, K) tensor.\"\"\"\n        return self.queue.clone().detach()\n\n# Demo\nqueue = MoCoQueue(feat_dim=128, queue_size=4096, device=\u0027cpu\u0027)\nprint(\u0027Queue shape:\u0027, queue.get_keys().shape)\nbatch_keys = F.normalize(torch.randn(64, 128), dim=1)\nqueue.enqueue_dequeue(batch_keys)\nprint(\u0027After enqueue (ptr should be 64):\u0027, queue.ptr)"},{"type":"heading","level":2,"content":"MoCo Training Loop and InfoNCE Loss"},{"type":"text","content":"The InfoNCE loss for MoCo: L = -log[ exp(q·k₊/τ) / (exp(q·k₊/τ) + Σᵢ exp(q·kᵢ/τ)) ] where q is the query embedding (from the query encoder with gradient), k₊ is the positive key (from the key encoder, no gradient), and {kᵢ} are the negative keys from the queue. The loss reduces to a K+1-way softmax classification where the positive pair is the correct class. The query encoder is updated by gradient; the key encoder is updated by EMA after each step; the positive key is enqueued."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torchvision.models as models\nimport copy\n\nclass MoCo(nn.Module):\n    def __init__(self, base_encoder, feat_dim=128, queue_size=65536,\n                 momentum=0.999, temperature=0.07):\n        super().__init__()\n        self.m = momentum\n        self.T = temperature\n        # Query encoder\n        self.encoder_q = base_encoder(weights=None)\n        self.encoder_q.fc = nn.Linear(self.encoder_q.fc.in_features, feat_dim)\n        # Key encoder (EMA copy)\n        self.encoder_k = copy.deepcopy(self.encoder_q)\n        for p in self.encoder_k.parameters():\n            p.requires_grad_(False)\n        # Queue\n        self.register_buffer(\u0027queue\u0027,\n            F.normalize(torch.randn(feat_dim, queue_size), dim=0))\n        self.register_buffer(\u0027queue_ptr\u0027, torch.zeros(1, dtype=torch.long))\n        self.queue_size = queue_size\n\n    @torch.no_grad()\n    def _momentum_update(self):\n        for q, k in zip(self.encoder_q.parameters(), self.encoder_k.parameters()):\n            k.data = self.m * k.data + (1 - self.m) * q.data\n\n    @torch.no_grad()\n    def _dequeue_enqueue(self, keys):\n        N = keys.size(0)\n        ptr = int(self.queue_ptr)\n        self.queue[:, ptr:ptr + N] = keys.T\n        self.queue_ptr[0] = (ptr + N) % self.queue_size\n\n    def forward(self, x_q, x_k):\n        q = F.normalize(self.encoder_q(x_q), dim=1)        # (N, C)\n        with torch.no_grad():\n            self._momentum_update()\n            k = F.normalize(self.encoder_k(x_k), dim=1)    # (N, C)\n        l_pos = (q * k).sum(dim=1, keepdim=True) / self.T  # (N, 1)\n        l_neg = (q @ self.queue.clone()) / self.T           # (N, K)\n        logits = torch.cat([l_pos, l_neg], dim=1)           # (N, 1+K)\n        labels = torch.zeros(logits.size(0), dtype=torch.long, device=q.device)\n        self._dequeue_enqueue(k)\n        return F.cross_entropy(logits, labels)\n\nprint(\u0027MoCo model defined. Positive is class 0 in (1+K)-way softmax.\u0027)"},{"type":"heading","level":2,"content":"MoCo v2 Improvements"},{"type":"text","content":"MoCo v2 (Chen et al. 2020) is a simple but impactful update: (1) replace the linear projection head with a 2-layer MLP (like SimCLR), and (2) adopt stronger augmentation (Gaussian blur + stronger color jitter). These two changes, without any other modification to the queue or momentum mechanism, brought MoCo within ~1% of SimCLR v1 using a batch size of just 256 — 16× smaller. This demonstrated that the MoCo framework was not the bottleneck; the missing ingredients were the MLP head and augmentation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torchvision.models as models\nfrom torchvision import transforms\n\ndef build_moco_v2_encoder(feat_dim=128):\n    \"\"\"ResNet-50 with 2-layer MLP projection head (MoCo v2).\"\"\"\n    base = models.resnet50(weights=None)\n    hidden_dim = base.fc.in_features  # 2048\n    base.fc = nn.Sequential(\n        nn.Linear(hidden_dim, hidden_dim),\n        nn.ReLU(inplace=True),\n        nn.Linear(hidden_dim, feat_dim),\n    )\n    return base\n\ndef moco_v2_augmentation(image_size=224):\n    \"\"\"Stronger augmentation matching SimCLR (MoCo v2).\"\"\"\n    return transforms.Compose([\n        transforms.RandomResizedCrop(image_size, scale=(0.2, 1.0)),\n        transforms.RandomApply([\n            transforms.ColorJitter(0.4, 0.4, 0.4, 0.1)\n        ], p=0.8),\n        transforms.RandomGrayscale(p=0.2),\n        transforms.RandomApply([\n            transforms.GaussianBlur(kernel_size=23)\n        ], p=0.5),\n        transforms.RandomHorizontalFlip(),\n        transforms.ToTensor(),\n        transforms.Normalize([0.485, 0.456, 0.406], [0.229, 0.224, 0.225]),\n    ])\n\nenc = build_moco_v2_encoder()\nparams = sum(p.numel() for p in enc.parameters()) // 1_000_000\nprint(f\u0027MoCo v2 encoder parameters: {params}M\u0027)\nprint(\u0027Key change: MLP head + Gaussian blur augmentation.\u0027)"},{"type":"callout","variant":"info","title":"Why Momentum = 0.999 Is Critical","content":"If momentum is too low (e.g. 0.9), the key encoder updates rapidly and older queue entries are encoded by a very different model, making the negatives inconsistent — the loss becomes noisy. If momentum is too high (close to 1), the key encoder barely learns from the query encoder, and convergence slows. Empirically m = 0.999 provides the best balance between key consistency and learning signal."},{"type":"heading","level":2,"content":"MoCo v3 and Vision Transformers"},{"type":"text","content":"MoCo v3 (Chen et al. 2021) adapts the framework to Vision Transformers (ViT). The queue is abandoned: with ViT-B and a batch size of 4096, sufficient negatives exist in-batch (like SimCLR). A stop-gradient is added on the key path (similar to BYOL). The projection head becomes a 3-layer MLP. MoCo v3 with ViT-B/16 achieves 83.2% top-1 on ImageNet linear eval — surpassing supervised ResNet-50 (76.1%) without any labels."},{"type":"list","ordered":false,"items":["v1: ResNet + queue(65536) + momentum encoder + linear projection + InfoNCE.","v2: v1 + MLP projection head + stronger augmentation — matches SimCLR at 256 batch.","v3: ViT backbone + no queue + stop-gradient on key path + 3-layer MLP head.","Momentum m = 0.999 (v1/v2), m = 0.99 (v3 with ViT — faster drift acceptable).","v3 training trick: freeze patch projection layer for first few epochs to stabilise ViT."]},{"type":"table","headers":["Version","Queue","Batch Size","Backbone","Augmentation","Linear Eval Top-1"],"rows":[["MoCo v1","65 536","256","ResNet-50","Standard","60.6%"],["MoCo v2","65 536","256","ResNet-50","SimCLR-style","71.1%"],["MoCo v3","None","4096","ViT-B/16","SimCLR-style","83.2%"],["SimCLR v1 (ref)","None","4096","ResNet-50","SimCLR-style","69.3%"]]},{"type":"heading","level":2,"content":"Results and Downstream Evaluation"},{"type":"text","content":"MoCo v1 achieves 60.6% top-1 linear evaluation on ImageNet with ResNet-50 — significantly below supervised (76.1%) but with zero labels. MoCo v2 closes the gap to 71.1% purely by adding MLP head and augmentation. For semi-supervised and fine-tuning tasks, MoCo representations transfer well: on PASCAL VOC detection, MoCo pre-training matches supervised pre-training within 0.5 AP. This demonstrates that queue-based contrastive learning produces broadly useful representations that transfer across tasks and domains without requiring the massive batch sizes of SimCLR."}]"
---
# MoCo — Momentum Contrast and Dynamic Queue

MoCo (Momentum Contrast, He et al. 2020) addresses the fundamental bottleneck of SimCLR: the requirement for enormous batch sizes to have enough negatives. MoCo decouples the number of negatives from the batch size by maintaining a dynamic queue of encoded keys from past mini-batches. A momentum encoder (updated by EMA, not gradient) ensures the keys in the queue remain consistent even as the model evolves during training.

## Motivation — The Dictionary Perspective

Contrastive learning can be viewed as training a dynamic dictionary look-up. Each encoded query q must match its positive key k₊ (from the same image, different augmentation) and be dissimilar from all negative keys K = {k₁, k₂, …, kK}. To make the loss informative, K must be large (tens of thousands). But computing gradients through K encodings per step is prohibitively expensive. MoCo stores keys in a FIFO queue and only encodes the current mini-batch's keys with gradient; old keys in the queue are reused without re-encoding.

## Momentum Encoder — EMA Update

The key encoder θ_k is not updated by gradient. Instead it tracks the query encoder θ_q via exponential moving average: θ_k ← m·θ_k + (1-m)·θ_q where m = 0.999 (very slow update). This ensures that the keys enqueued over the past few thousand steps were produced by an encoder that changed very slowly, so they are mutually consistent. If the key encoder were updated rapidly by gradient, older queue entries would be encoded by a very different model, making the negatives inconsistent and degrading the loss signal.

```python
import torch
import torch.nn as nn
import copy

def build_momentum_encoder(query_encoder, momentum=0.999):
    """Create key encoder as EMA copy of query encoder."""
    key_encoder = copy.deepcopy(query_encoder)
    # Key encoder not updated by gradient
    for p in key_encoder.parameters():
        p.requires_grad_(False)
    return key_encoder

@torch.no_grad()
def momentum_update(query_encoder, key_encoder, momentum=0.999):
    """EMA update: θ_k = m * θ_k + (1-m) * θ_q"""
    for q_param, k_param in zip(query_encoder.parameters(),
                                key_encoder.parameters()):
        k_param.data = momentum * k_param.data + (1.0 - momentum) * q_param.data

# Demo: show slow drift of key encoder
import torch.nn.functional as F

torch.manual_seed(0)
q_enc = nn.Linear(64, 64)
k_enc = build_momentum_encoder(q_enc)

# Simulate one gradient step on query encoder
optimizer = torch.optim.SGD(q_enc.parameters(), lr=0.1)
loss = q_enc(torch.randn(8, 64)).mean()
loss.backward()
optimizer.step()

# EMA update
momentum_update(q_enc, k_enc, momentum=0.999)

# Measure drift
with torch.no_grad():
    diff = sum((qp - kp).norm().item()
               for qp, kp in zip(q_enc.parameters(), k_enc.parameters()))
print(f'Parameter drift after 1 step (momentum=0.999): {diff:.6f}')
```

## Key Queue Management

The queue stores K encoded keys (K = 65536 by default). After each mini-batch of size N, N new keys are enqueued and the oldest N keys are dequeued (FIFO). Importantly, keys are enqueued as-is from the key encoder output; they are not backpropagated through. The queue is stored on GPU as a fixed-size buffer. Because queue keys come from many past mini-batches (with the slowly-drifting key encoder), they are diverse and consistent — unlike SimCLR's in-batch negatives, which vary mini-batch to mini-batch.

```python
import torch
import torch.nn.functional as F

class MoCoQueue:
    """FIFO queue of encoded keys for MoCo."""
    def __init__(self, feat_dim=128, queue_size=65536, device='cuda'):
        self.queue_size = queue_size
        # Initialise with random unit vectors
        self.queue = F.normalize(
            torch.randn(feat_dim, queue_size, device=device), dim=0
        )
        self.ptr = 0  # pointer to current write position

    @torch.no_grad()
    def enqueue_dequeue(self, keys):
        """Enqueue new keys and dequeue oldest. keys: (N, D) normalised."""
        N = keys.size(0)
        assert self.queue_size % N == 0, 'queue_size must be divisible by batch size'
        # Write new keys at current pointer position
        self.queue[:, self.ptr:self.ptr + N] = keys.T  # (D, N)
        self.ptr = (self.ptr + N) % self.queue_size

    def get_keys(self):
        """Return all keys in queue as (D, K) tensor."""
        return self.queue.clone().detach()

# Demo
queue = MoCoQueue(feat_dim=128, queue_size=4096, device='cpu')
print('Queue shape:', queue.get_keys().shape)
batch_keys = F.normalize(torch.randn(64, 128), dim=1)
queue.enqueue_dequeue(batch_keys)
print('After enqueue (ptr should be 64):', queue.ptr)
```

## MoCo Training Loop and InfoNCE Loss

The InfoNCE loss for MoCo: L = -log[ exp(q·k₊/τ) / (exp(q·k₊/τ) + Σᵢ exp(q·kᵢ/τ)) ] where q is the query embedding (from the query encoder with gradient), k₊ is the positive key (from the key encoder, no gradient), and {kᵢ} are the negative keys from the queue. The loss reduces to a K+1-way softmax classification where the positive pair is the correct class. The query encoder is updated by gradient; the key encoder is updated by EMA after each step; the positive key is enqueued.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torchvision.models as models
import copy

class MoCo(nn.Module):
    def __init__(self, base_encoder, feat_dim=128, queue_size=65536,
                 momentum=0.999, temperature=0.07):
        super().__init__()
        self.m = momentum
        self.T = temperature
        # Query encoder
        self.encoder_q = base_encoder(weights=None)
        self.encoder_q.fc = nn.Linear(self.encoder_q.fc.in_features, feat_dim)
        # Key encoder (EMA copy)
        self.encoder_k = copy.deepcopy(self.encoder_q)
        for p in self.encoder_k.parameters():
            p.requires_grad_(False)
        # Queue
        self.register_buffer('queue',
            F.normalize(torch.randn(feat_dim, queue_size), dim=0))
        self.register_buffer('queue_ptr', torch.zeros(1, dtype=torch.long))
        self.queue_size = queue_size

    @torch.no_grad()
    def _momentum_update(self):
        for q, k in zip(self.encoder_q.parameters(), self.encoder_k.parameters()):
            k.data = self.m * k.data + (1 - self.m) * q.data

    @torch.no_grad()
    def _dequeue_enqueue(self, keys):
        N = keys.size(0)
        ptr = int(self.queue_ptr)
        self.queue[:, ptr:ptr + N] = keys.T
        self.queue_ptr[0] = (ptr + N) % self.queue_size

    def forward(self, x_q, x_k):
        q = F.normalize(self.encoder_q(x_q), dim=1)        # (N, C)
        with torch.no_grad():
            self._momentum_update()
            k = F.normalize(self.encoder_k(x_k), dim=1)    # (N, C)
        l_pos = (q * k).sum(dim=1, keepdim=True) / self.T  # (N, 1)
        l_neg = (q @ self.queue.clone()) / self.T           # (N, K)
        logits = torch.cat([l_pos, l_neg], dim=1)           # (N, 1+K)
        labels = torch.zeros(logits.size(0), dtype=torch.long, device=q.device)
        self._dequeue_enqueue(k)
        return F.cross_entropy(logits, labels)

print('MoCo model defined. Positive is class 0 in (1+K)-way softmax.')
```

## MoCo v2 Improvements

MoCo v2 (Chen et al. 2020) is a simple but impactful update: (1) replace the linear projection head with a 2-layer MLP (like SimCLR), and (2) adopt stronger augmentation (Gaussian blur + stronger color jitter). These two changes, without any other modification to the queue or momentum mechanism, brought MoCo within ~1% of SimCLR v1 using a batch size of just 256 — 16× smaller. This demonstrated that the MoCo framework was not the bottleneck; the missing ingredients were the MLP head and augmentation.

```python
import torch
import torch.nn as nn
import torchvision.models as models
from torchvision import transforms

def build_moco_v2_encoder(feat_dim=128):
    """ResNet-50 with 2-layer MLP projection head (MoCo v2)."""
    base = models.resnet50(weights=None)
    hidden_dim = base.fc.in_features  # 2048
    base.fc = nn.Sequential(
        nn.Linear(hidden_dim, hidden_dim),
        nn.ReLU(inplace=True),
        nn.Linear(hidden_dim, feat_dim),
    )
    return base

def moco_v2_augmentation(image_size=224):
    """Stronger augmentation matching SimCLR (MoCo v2)."""
    return transforms.Compose([
        transforms.RandomResizedCrop(image_size, scale=(0.2, 1.0)),
        transforms.RandomApply([
            transforms.ColorJitter(0.4, 0.4, 0.4, 0.1)
        ], p=0.8),
        transforms.RandomGrayscale(p=0.2),
        transforms.RandomApply([
            transforms.GaussianBlur(kernel_size=23)
        ], p=0.5),
        transforms.RandomHorizontalFlip(),
        transforms.ToTensor(),
        transforms.Normalize([0.485, 0.456, 0.406], [0.229, 0.224, 0.225]),
    ])

enc = build_moco_v2_encoder()
params = sum(p.numel() for p in enc.parameters()) // 1_000_000
print(f'MoCo v2 encoder parameters: {params}M')
print('Key change: MLP head + Gaussian blur augmentation.')
```

> **Why Momentum = 0.999 Is Critical**: If momentum is too low (e.g. 0.9), the key encoder updates rapidly and older queue entries are encoded by a very different model, making the negatives inconsistent — the loss becomes noisy. If momentum is too high (close to 1), the key encoder barely learns from the query encoder, and convergence slows. Empirically m = 0.999 provides the best balance between key consistency and learning signal.

## MoCo v3 and Vision Transformers

MoCo v3 (Chen et al. 2021) adapts the framework to Vision Transformers (ViT). The queue is abandoned: with ViT-B and a batch size of 4096, sufficient negatives exist in-batch (like SimCLR). A stop-gradient is added on the key path (similar to BYOL). The projection head becomes a 3-layer MLP. MoCo v3 with ViT-B/16 achieves 83.2% top-1 on ImageNet linear eval — surpassing supervised ResNet-50 (76.1%) without any labels.

- v1: ResNet + queue(65536) + momentum encoder + linear projection + InfoNCE.
- v2: v1 + MLP projection head + stronger augmentation — matches SimCLR at 256 batch.
- v3: ViT backbone + no queue + stop-gradient on key path + 3-layer MLP head.
- Momentum m = 0.999 (v1/v2), m = 0.99 (v3 with ViT — faster drift acceptable).
- v3 training trick: freeze patch projection layer for first few epochs to stabilise ViT.

| Version | Queue | Batch Size | Backbone | Augmentation | Linear Eval Top-1 |
| --- | --- | --- | --- | --- | --- |
| MoCo v1 | 65 536 | 256 | ResNet-50 | Standard | 60.6% |
| MoCo v2 | 65 536 | 256 | ResNet-50 | SimCLR-style | 71.1% |
| MoCo v3 | None | 4096 | ViT-B/16 | SimCLR-style | 83.2% |
| SimCLR v1 (ref) | None | 4096 | ResNet-50 | SimCLR-style | 69.3% |

## Results and Downstream Evaluation

MoCo v1 achieves 60.6% top-1 linear evaluation on ImageNet with ResNet-50 — significantly below supervised (76.1%) but with zero labels. MoCo v2 closes the gap to 71.1% purely by adding MLP head and augmentation. For semi-supervised and fine-tuning tasks, MoCo representations transfer well: on PASCAL VOC detection, MoCo pre-training matches supervised pre-training within 0.5 AP. This demonstrates that queue-based contrastive learning produces broadly useful representations that transfer across tasks and domains without requiring the massive batch sizes of SimCLR.

