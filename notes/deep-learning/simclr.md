---
title: "SimCLR — Simple Contrastive Learning of Representations"
slug: "simclr"
description: "SimCLR (Chen et al. 2020) learns visual representations by maximizing agreement between two augmented views of the same image via the NT-Xent contrastive loss, a 2-layer MLP projection head, and large batch sizes that supply enough in-batch negatives."
tags: ["deep-learning", "self-supervised-learning", "contrastive-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"SimCLR (Simple Framework for Contrastive Learning of Visual Representations, Chen et al. 2020) showed that self-supervised contrastive learning could rival supervised ImageNet pre-training. The key insight is elegant: augment each image twice, encode both views with a shared ResNet, project the representations with a small MLP, and then train the encoder to maximise agreement between the two views while treating all other images in the batch as negatives. No labels required."},{"type":"heading","level":2,"content":"Contrastive Learning Framework"},{"type":"text","content":"For a mini-batch of N images, SimCLR generates 2N augmented views by applying two independent stochastic augmentation sequences to each image. The encoder f (a ResNet) maps each view xᵢ to a representation hᵢ = f(xᵢ). A two-layer MLP projection head g maps hᵢ to zᵢ = g(hᵢ), which is L2-normalised before the loss is computed. The contrastive loss is computed in the z-space; importantly, downstream tasks use hᵢ (the encoder output before projection), not zᵢ."},{"type":"heading","level":2,"content":"NT-Xent Loss"},{"type":"text","content":"The NT-Xent (Normalised Temperature-scaled Cross Entropy) loss for a positive pair (i, j) from the same image is: L_{i,j} = -log[ exp(sim(zᵢ,zⱼ)/τ) / Σ_{k≠i} exp(sim(zᵢ,zₖ)/τ) ] where sim(u,v) = uᵀv/(‖u‖‖v‖) is cosine similarity and τ is a temperature hyperparameter (default 0.07). The denominator sums over all 2(N-1) other views in the batch — both augmentations of other images — making them the negatives. The final loss is the mean over all 2N ordered pairs."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef nt_xent_loss(z1, z2, temperature=0.07):\n    \"\"\"NT-Xent loss for SimCLR.\n    z1, z2: (N, D) L2-normalised embeddings from two augmented views.\n    Returns scalar loss.\n    \"\"\"\n    N = z1.size(0)\n    # Concatenate representations: [z1_0, z1_1, ..., z2_0, z2_1, ...]\n    z = torch.cat([z1, z2], dim=0)          # (2N, D)\n    # Cosine similarity matrix for all pairs\n    sim = F.cosine_similarity(z.unsqueeze(1), z.unsqueeze(0), dim=2)  # (2N, 2N)\n    sim = sim / temperature\n    # Mask out self-similarity on the diagonal\n    mask_self = torch.eye(2 * N, dtype=torch.bool, device=z.device)\n    sim.masked_fill_(mask_self, float(\u0027-inf\u0027))\n    # Positive pairs: (i, i+N) and (i+N, i)\n    labels = torch.cat([torch.arange(N, 2*N), torch.arange(N)]).to(z.device)\n    loss = F.cross_entropy(sim, labels)\n    return loss\n\n# Quick sanity check\ntorch.manual_seed(42)\nz1 = F.normalize(torch.randn(32, 128), dim=1)\nz2 = F.normalize(torch.randn(32, 128), dim=1)\nprint(\u0027NT-Xent loss (random, should be ~log(63)):\u0027, nt_xent_loss(z1, z2).item())\n# Perfect agreement should give loss near zero\nz2_perfect = z1.clone()\nprint(\u0027NT-Xent loss (perfect agreement):\u0027, nt_xent_loss(z1, z2_perfect).item())"},{"type":"heading","level":2,"content":"Data Augmentation Pipeline"},{"type":"text","content":"The augmentation strategy is one of the most critical components of SimCLR. An ablation study in the paper showed that random cropping (resized crop) alone provides the most benefit, followed by color jitter. The intuition is that a crop forces the network to learn content rather than position or spatial layout. Color jitter prevents the network from using color statistics as a shortcut. Gaussian blur (applied with 50% probability) encourages robustness to frequency content."},{"type":"code","language":"python","content":"import torch\nfrom torchvision import transforms\n\nclass SimCLRAugmentation:\n    \"\"\"Two-view augmentation for SimCLR. Returns a pair (view1, view2) per image.\"\"\"\n    def __init__(self, image_size=224, s=1.0):\n        color_jitter = transforms.ColorJitter(\n            brightness=0.8 * s,\n            contrast=0.8 * s,\n            saturation=0.8 * s,\n            hue=0.2 * s\n        )\n        self.transform = transforms.Compose([\n            transforms.RandomResizedCrop(image_size, scale=(0.2, 1.0)),  # most important\n            transforms.RandomHorizontalFlip(p=0.5),\n            transforms.RandomApply([color_jitter], p=0.8),\n            transforms.RandomGrayscale(p=0.2),\n            transforms.RandomApply([transforms.GaussianBlur(kernel_size=23)], p=0.5),\n            transforms.ToTensor(),\n            transforms.Normalize(mean=[0.485, 0.456, 0.406],\n                                 std=[0.229, 0.224, 0.225]),\n        ])\n\n    def __call__(self, x):\n        return self.transform(x), self.transform(x)\n\n# Usage with DataLoader\n# dataset = ImageFolder(root, transform=SimCLRAugmentation(224))\n# Each batch gives: (view1_batch, view2_batch), labels\nprint(\u0027SimCLR augmentation pipeline defined.\u0027)\nprint(\u0027Key: RandomResizedCrop(scale=0.2-1.0) is the most important augmentation.\u0027)"},{"type":"heading","level":2,"content":"SimCLR Training Loop"},{"type":"text","content":"SimCLR requires no special architecture beyond a standard ResNet encoder and a small MLP projection head. The projection head (two linear layers with BatchNorm and ReLU) is only used during pre-training; it is discarded for downstream tasks. A large batch size (4096–8192) is critical because the number of in-batch negatives determines how informative the loss signal is. LARS optimiser is recommended at these batch sizes due to its layer-wise adaptive learning rate scaling."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torchvision.models as models\n\nclass SimCLR(nn.Module):\n    def __init__(self, backbone=\u0027resnet50\u0027, proj_dim=128):\n        super().__init__()\n        base = models.resnet50(weights=None)\n        self.encoder = nn.Sequential(*list(base.children())[:-1])  # remove fc\n        feat_dim = base.fc.in_features  # 2048 for ResNet-50\n        self.projector = nn.Sequential(\n            nn.Linear(feat_dim, feat_dim),\n            nn.BatchNorm1d(feat_dim),\n            nn.ReLU(inplace=True),\n            nn.Linear(feat_dim, proj_dim),\n        )\n\n    def forward(self, x1, x2):\n        h1 = self.encoder(x1).flatten(1)  # (N, 2048)\n        h2 = self.encoder(x2).flatten(1)\n        z1 = F.normalize(self.projector(h1), dim=1)  # (N, 128)\n        z2 = F.normalize(self.projector(h2), dim=1)\n        return z1, z2, h1, h2  # return h for downstream use\n\n# Training step (inside epoch loop)\ndef train_step(model, batch, optimizer, temperature=0.07):\n    (view1, view2), _ = batch\n    view1, view2 = view1.cuda(), view2.cuda()\n    z1, z2, _, _ = model(view1, view2)\n    loss = nt_xent_loss(z1, z2, temperature)\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    return loss.item()\n\nmodel = SimCLR().cuda()\nprint(\u0027Encoder output dim:\u0027, 2048)\nprint(\u0027Projector output dim:\u0027, 128)\nprint(\u0027Parameters:\u0027, sum(p.numel() for p in model.parameters()) // 1_000_000, \u0027M\u0027)"},{"type":"heading","level":2,"content":"Linear Evaluation Protocol"},{"type":"text","content":"To evaluate representation quality, SimCLR uses linear evaluation: freeze the pre-trained encoder and train a single linear classifier on top of the frozen representations. This isolates the representation quality from the linear head\u0027s capacity. A high linear evaluation accuracy indicates the encoder has learned semantically meaningful features. The encoder\u0027s output (before projection) is used; this is why the projection head must be discarded."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader\nfrom torchvision import datasets, transforms\n\ndef linear_evaluation(encoder, train_loader, val_loader, num_classes=1000,\n                       epochs=100, lr=0.1, device=\u0027cuda\u0027):\n    \"\"\"Freeze encoder, train and evaluate a linear classifier.\"\"\"\n    encoder.eval()\n    for p in encoder.parameters():\n        p.requires_grad_(False)\n\n    # Determine feature dimension from a dummy forward pass\n    with torch.no_grad():\n        dummy = torch.randn(2, 3, 224, 224).to(device)\n        feat_dim = encoder(dummy).flatten(1).size(1)\n\n    classifier = nn.Linear(feat_dim, num_classes).to(device)\n    optimizer = torch.optim.SGD(classifier.parameters(), lr=lr,\n                                momentum=0.9, weight_decay=0.0)\n    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)\n    criterion = nn.CrossEntropyLoss()\n\n    for epoch in range(epochs):\n        classifier.train()\n        for imgs, labels in train_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            with torch.no_grad():\n                feats = encoder(imgs).flatten(1)\n            logits = classifier(feats)\n            loss = criterion(logits, labels)\n            optimizer.zero_grad(); loss.backward(); optimizer.step()\n        scheduler.step()\n\n    # Validation accuracy\n    classifier.eval()\n    correct = total = 0\n    with torch.no_grad():\n        for imgs, labels in val_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            feats = encoder(imgs).flatten(1)\n            preds = classifier(feats).argmax(1)\n            correct += (preds == labels).sum().item()\n            total += labels.size(0)\n    return correct / total\n\nprint(\u0027Linear evaluation protocol: freeze encoder, train linear head only.\u0027)"},{"type":"callout","variant":"warning","title":"Projection Head Matters — Use Encoder Output Downstream","content":"A critical finding of SimCLR is that the projection head (g) improves contrastive learning but the representation before the projection head (h) is better for downstream tasks. The projection head collapses information that is useful for classification but not for contrastive loss. Always freeze the encoder and discard the projection head when performing linear evaluation or fine-tuning."},{"type":"heading","level":2,"content":"Temperature and Batch Size Sensitivity"},{"type":"text","content":"Temperature τ controls the concentration of the distribution. Low τ (e.g., 0.07) creates a sharper distribution, penalising hard negatives more. High τ treats negatives more uniformly. Batch size is a proxy for the number of negatives: at batch size N, there are 2(N-1) negatives per anchor. SimCLR needs 4096–8192 images per batch to accumulate enough negatives. This requires either many GPUs or gradient accumulation, making it expensive compared to queue-based methods."},{"type":"list","ordered":false,"items":["τ = 0.07 optimal across experiments — too low causes instability, too high degrades quality.","Batch size 4096 with LARS optimizer and cosine decay over 100–1000 epochs.","Random resized crop is the single most important augmentation (\u003e10% top-1 difference).","Color jitter + random grayscale prevents reliance on color statistics as a cheat code.","Removing Gaussian blur from the pipeline causes ~1–2% top-1 regression."]},{"type":"heading","level":2,"content":"SimCLR v2 and Extensions"},{"type":"text","content":"SimCLR v2 (Chen et al. 2020b) introduced three improvements: (1) a larger backbone (ResNet-152 with selective kernels), (2) a deeper projection head (3-layer MLP instead of 2-layer), and (3) semi-supervised learning with distillation — use the self-supervised model to generate pseudo-labels on unlabelled data and distil into a smaller student. These improvements pushed top-1 accuracy beyond 79% on ImageNet with only 1% of labels."},{"type":"table","headers":["Method","Batch Size","Negatives Needed","Projection Layers","Linear Eval Top-1"],"rows":[["SimCLR v1","4096","Yes (in-batch)","2-layer MLP","69.3%"],["SimCLR v2","4096","Yes (in-batch)","3-layer MLP","74.2%"],["BYOL","4096","No","2-layer MLP","74.3%"],["MoCo v3","4096","No (large batch ViT)","2-layer MLP","83.2% (ViT-B/16)"]]}]"
---
# SimCLR — Simple Contrastive Learning of Representations

SimCLR (Simple Framework for Contrastive Learning of Visual Representations, Chen et al. 2020) showed that self-supervised contrastive learning could rival supervised ImageNet pre-training. The key insight is elegant: augment each image twice, encode both views with a shared ResNet, project the representations with a small MLP, and then train the encoder to maximise agreement between the two views while treating all other images in the batch as negatives. No labels required.

## Contrastive Learning Framework

For a mini-batch of N images, SimCLR generates 2N augmented views by applying two independent stochastic augmentation sequences to each image. The encoder f (a ResNet) maps each view xᵢ to a representation hᵢ = f(xᵢ). A two-layer MLP projection head g maps hᵢ to zᵢ = g(hᵢ), which is L2-normalised before the loss is computed. The contrastive loss is computed in the z-space; importantly, downstream tasks use hᵢ (the encoder output before projection), not zᵢ.

## NT-Xent Loss

The NT-Xent (Normalised Temperature-scaled Cross Entropy) loss for a positive pair (i, j) from the same image is: L_{i,j} = -log[ exp(sim(zᵢ,zⱼ)/τ) / Σ_{k≠i} exp(sim(zᵢ,zₖ)/τ) ] where sim(u,v) = uᵀv/(‖u‖‖v‖) is cosine similarity and τ is a temperature hyperparameter (default 0.07). The denominator sums over all 2(N-1) other views in the batch — both augmentations of other images — making them the negatives. The final loss is the mean over all 2N ordered pairs.

```python
import torch
import torch.nn.functional as F

def nt_xent_loss(z1, z2, temperature=0.07):
    """NT-Xent loss for SimCLR.
    z1, z2: (N, D) L2-normalised embeddings from two augmented views.
    Returns scalar loss.
    """
    N = z1.size(0)
    # Concatenate representations: [z1_0, z1_1, ..., z2_0, z2_1, ...]
    z = torch.cat([z1, z2], dim=0)          # (2N, D)
    # Cosine similarity matrix for all pairs
    sim = F.cosine_similarity(z.unsqueeze(1), z.unsqueeze(0), dim=2)  # (2N, 2N)
    sim = sim / temperature
    # Mask out self-similarity on the diagonal
    mask_self = torch.eye(2 * N, dtype=torch.bool, device=z.device)
    sim.masked_fill_(mask_self, float('-inf'))
    # Positive pairs: (i, i+N) and (i+N, i)
    labels = torch.cat([torch.arange(N, 2*N), torch.arange(N)]).to(z.device)
    loss = F.cross_entropy(sim, labels)
    return loss

# Quick sanity check
torch.manual_seed(42)
z1 = F.normalize(torch.randn(32, 128), dim=1)
z2 = F.normalize(torch.randn(32, 128), dim=1)
print('NT-Xent loss (random, should be ~log(63)):', nt_xent_loss(z1, z2).item())
# Perfect agreement should give loss near zero
z2_perfect = z1.clone()
print('NT-Xent loss (perfect agreement):', nt_xent_loss(z1, z2_perfect).item())
```

## Data Augmentation Pipeline

The augmentation strategy is one of the most critical components of SimCLR. An ablation study in the paper showed that random cropping (resized crop) alone provides the most benefit, followed by color jitter. The intuition is that a crop forces the network to learn content rather than position or spatial layout. Color jitter prevents the network from using color statistics as a shortcut. Gaussian blur (applied with 50% probability) encourages robustness to frequency content.

```python
import torch
from torchvision import transforms

class SimCLRAugmentation:
    """Two-view augmentation for SimCLR. Returns a pair (view1, view2) per image."""
    def __init__(self, image_size=224, s=1.0):
        color_jitter = transforms.ColorJitter(
            brightness=0.8 * s,
            contrast=0.8 * s,
            saturation=0.8 * s,
            hue=0.2 * s
        )
        self.transform = transforms.Compose([
            transforms.RandomResizedCrop(image_size, scale=(0.2, 1.0)),  # most important
            transforms.RandomHorizontalFlip(p=0.5),
            transforms.RandomApply([color_jitter], p=0.8),
            transforms.RandomGrayscale(p=0.2),
            transforms.RandomApply([transforms.GaussianBlur(kernel_size=23)], p=0.5),
            transforms.ToTensor(),
            transforms.Normalize(mean=[0.485, 0.456, 0.406],
                                 std=[0.229, 0.224, 0.225]),
        ])

    def __call__(self, x):
        return self.transform(x), self.transform(x)

# Usage with DataLoader
# dataset = ImageFolder(root, transform=SimCLRAugmentation(224))
# Each batch gives: (view1_batch, view2_batch), labels
print('SimCLR augmentation pipeline defined.')
print('Key: RandomResizedCrop(scale=0.2-1.0) is the most important augmentation.')
```

## SimCLR Training Loop

SimCLR requires no special architecture beyond a standard ResNet encoder and a small MLP projection head. The projection head (two linear layers with BatchNorm and ReLU) is only used during pre-training; it is discarded for downstream tasks. A large batch size (4096–8192) is critical because the number of in-batch negatives determines how informative the loss signal is. LARS optimiser is recommended at these batch sizes due to its layer-wise adaptive learning rate scaling.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torchvision.models as models

class SimCLR(nn.Module):
    def __init__(self, backbone='resnet50', proj_dim=128):
        super().__init__()
        base = models.resnet50(weights=None)
        self.encoder = nn.Sequential(*list(base.children())[:-1])  # remove fc
        feat_dim = base.fc.in_features  # 2048 for ResNet-50
        self.projector = nn.Sequential(
            nn.Linear(feat_dim, feat_dim),
            nn.BatchNorm1d(feat_dim),
            nn.ReLU(inplace=True),
            nn.Linear(feat_dim, proj_dim),
        )

    def forward(self, x1, x2):
        h1 = self.encoder(x1).flatten(1)  # (N, 2048)
        h2 = self.encoder(x2).flatten(1)
        z1 = F.normalize(self.projector(h1), dim=1)  # (N, 128)
        z2 = F.normalize(self.projector(h2), dim=1)
        return z1, z2, h1, h2  # return h for downstream use

# Training step (inside epoch loop)
def train_step(model, batch, optimizer, temperature=0.07):
    (view1, view2), _ = batch
    view1, view2 = view1.cuda(), view2.cuda()
    z1, z2, _, _ = model(view1, view2)
    loss = nt_xent_loss(z1, z2, temperature)
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    return loss.item()

model = SimCLR().cuda()
print('Encoder output dim:', 2048)
print('Projector output dim:', 128)
print('Parameters:', sum(p.numel() for p in model.parameters()) // 1_000_000, 'M')
```

## Linear Evaluation Protocol

To evaluate representation quality, SimCLR uses linear evaluation: freeze the pre-trained encoder and train a single linear classifier on top of the frozen representations. This isolates the representation quality from the linear head's capacity. A high linear evaluation accuracy indicates the encoder has learned semantically meaningful features. The encoder's output (before projection) is used; this is why the projection head must be discarded.

```python
import torch
import torch.nn as nn
from torch.utils.data import DataLoader
from torchvision import datasets, transforms

def linear_evaluation(encoder, train_loader, val_loader, num_classes=1000,
                       epochs=100, lr=0.1, device='cuda'):
    """Freeze encoder, train and evaluate a linear classifier."""
    encoder.eval()
    for p in encoder.parameters():
        p.requires_grad_(False)

    # Determine feature dimension from a dummy forward pass
    with torch.no_grad():
        dummy = torch.randn(2, 3, 224, 224).to(device)
        feat_dim = encoder(dummy).flatten(1).size(1)

    classifier = nn.Linear(feat_dim, num_classes).to(device)
    optimizer = torch.optim.SGD(classifier.parameters(), lr=lr,
                                momentum=0.9, weight_decay=0.0)
    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)
    criterion = nn.CrossEntropyLoss()

    for epoch in range(epochs):
        classifier.train()
        for imgs, labels in train_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            with torch.no_grad():
                feats = encoder(imgs).flatten(1)
            logits = classifier(feats)
            loss = criterion(logits, labels)
            optimizer.zero_grad(); loss.backward(); optimizer.step()
        scheduler.step()

    # Validation accuracy
    classifier.eval()
    correct = total = 0
    with torch.no_grad():
        for imgs, labels in val_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            feats = encoder(imgs).flatten(1)
            preds = classifier(feats).argmax(1)
            correct += (preds == labels).sum().item()
            total += labels.size(0)
    return correct / total

print('Linear evaluation protocol: freeze encoder, train linear head only.')
```

> **Projection Head Matters — Use Encoder Output Downstream**: A critical finding of SimCLR is that the projection head (g) improves contrastive learning but the representation before the projection head (h) is better for downstream tasks. The projection head collapses information that is useful for classification but not for contrastive loss. Always freeze the encoder and discard the projection head when performing linear evaluation or fine-tuning.

## Temperature and Batch Size Sensitivity

Temperature τ controls the concentration of the distribution. Low τ (e.g., 0.07) creates a sharper distribution, penalising hard negatives more. High τ treats negatives more uniformly. Batch size is a proxy for the number of negatives: at batch size N, there are 2(N-1) negatives per anchor. SimCLR needs 4096–8192 images per batch to accumulate enough negatives. This requires either many GPUs or gradient accumulation, making it expensive compared to queue-based methods.

- τ = 0.07 optimal across experiments — too low causes instability, too high degrades quality.
- Batch size 4096 with LARS optimizer and cosine decay over 100–1000 epochs.
- Random resized crop is the single most important augmentation (>10% top-1 difference).
- Color jitter + random grayscale prevents reliance on color statistics as a cheat code.
- Removing Gaussian blur from the pipeline causes ~1–2% top-1 regression.

## SimCLR v2 and Extensions

SimCLR v2 (Chen et al. 2020b) introduced three improvements: (1) a larger backbone (ResNet-152 with selective kernels), (2) a deeper projection head (3-layer MLP instead of 2-layer), and (3) semi-supervised learning with distillation — use the self-supervised model to generate pseudo-labels on unlabelled data and distil into a smaller student. These improvements pushed top-1 accuracy beyond 79% on ImageNet with only 1% of labels.

| Method | Batch Size | Negatives Needed | Projection Layers | Linear Eval Top-1 |
| --- | --- | --- | --- | --- |
| SimCLR v1 | 4096 | Yes (in-batch) | 2-layer MLP | 69.3% |
| SimCLR v2 | 4096 | Yes (in-batch) | 3-layer MLP | 74.2% |
| BYOL | 4096 | No | 2-layer MLP | 74.3% |
| MoCo v3 | 4096 | No (large batch ViT) | 2-layer MLP | 83.2% (ViT-B/16) |

