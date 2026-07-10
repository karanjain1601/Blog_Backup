---
title: "Transfer Learning — Feature Extraction vs Fine-Tuning Strategies"
slug: "transfer-learning-cnn"
description: "Transfer learning strategies for CNNs: feature extraction (frozen backbone) vs fine-tuning (unfrozen layers). Covers discriminative learning rates per layer group, progressive unfreezing, freezing BatchNorm statistics, and domain shift considerations for ImageNet-pretrained models."
tags: ["deep-learning", "cnns", "architectures"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Transfer learning is the practice of initializing a model with weights pretrained on a large dataset (typically ImageNet with 1.28M images and 1000 classes) and adapting it to a new task. Because early CNN layers learn universal low-level features (edges, textures, colors) and later layers learn increasingly task-specific features, pretrained weights provide a powerful starting point that dramatically reduces the data and compute required for the target task. The two primary transfer strategies — feature extraction and fine-tuning — differ in which layers are allowed to update during target training."},{"type":"heading","level":2,"content":"Feature Extraction — Frozen Backbone"},{"type":"text","content":"In feature extraction, all convolutional layers are frozen (requires_grad=False) and only the classification head is trained. The backbone acts as a fixed feature extractor: each image is mapped to a feature vector (e.g., 2048-dim for ResNet-50 after global avg pool), and a new linear classifier is trained on top of these frozen features. This is fast (only head params are optimized), memory-efficient (no gradients through the backbone), and works well when the target domain is visually similar to ImageNet. Feature extraction is the right choice when training data is very small (\u003c1000 examples) or when the target task is similar to ImageNet classification."},{"type":"heading","level":2,"content":"Fine-Tuning — Unfreezing Layers"},{"type":"text","content":"In fine-tuning, some or all pretrained layers are unfrozen and allowed to update during target training. The key hyperparameter is the learning rate: pretrained layers should use a much lower learning rate (1e-5 to 1e-4) than the new head (1e-3), to preserve the learned representations while allowing them to shift slightly toward the target domain. Fine-tuning provides higher accuracy than feature extraction on most tasks because the backbone can adapt its higher-level features to the target distribution. It requires more training data (typically \u003e5000 examples) and longer training to avoid overfitting."},{"type":"heading","level":2,"content":"When to Use Which Strategy"},{"type":"list","ordered":false,"items":["Very small dataset (\u003c1000 samples), similar domain (e.g., pets, flowers) -\u003e feature extraction only.","Small dataset (1000-10000), similar domain -\u003e fine-tune top 1-2 layers + head.","Medium dataset (10000+), similar domain -\u003e fine-tune all layers with small backbone LR.","Large dataset (100000+), any domain -\u003e fine-tune all layers or train from scratch.","Very different domain (e.g., medical imaging, satellite) -\u003e fine-tune all layers regardless of size.","Low compute budget -\u003e feature extraction (no backbone gradients, faster per step)."]},{"type":"callout","variant":"warning","title":"Always Freeze BatchNorm During Fine-Tuning","content":"BatchNorm layers maintain running statistics (mean and variance) estimated from training batches. When you call model.train() and fine-tune with small batches on a new domain, the running stats are updated to reflect the new distribution — destroying the statistics calibrated on ImageNet. Always call bn_module.eval() after model.train() to freeze the BN running stats. The affine parameters (gamma, beta) can still be updated. Forgetting this step often causes a significant accuracy drop, especially when the target batch size is small or the domain shift is large."},{"type":"heading","level":2,"content":"Discriminative Learning Rates"},{"type":"text","content":"Discriminative learning rates (Howard \u0026 Ruder, ULMFiT 2018) assign different learning rates to different layer groups: earlier layers (closer to the input) use lower learning rates, later layers use higher rates. The rationale: early layers contain more general, transferable features that should change little; later layers contain more task-specific features that need to adapt more. For ResNet-50, a typical schedule might be: layer1 LR = 1e-5, layer2 LR = 3e-5, layer3 LR = 1e-4, layer4 LR = 3e-4, fc LR = 1e-3 (a 10× step per group). This achieves better accuracy than a single LR for all layers."},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models\n\ndef build_feature_extractor(num_classes: int):\n    \"\"\"Freeze all backbone params; only train the new classification head.\"\"\"\n    model = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)\n    # Freeze all parameters\n    for param in model.parameters():\n        param.requires_grad = False\n    # Replace final fully-connected layer\n    model.fc = nn.Linear(model.fc.in_features, num_classes)\n    # fc is newly created so requires_grad=True by default\n    trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\n    total     = sum(p.numel() for p in model.parameters())\n    print(f\"Trainable: {trainable:,} / {total:,} ({100*trainable/total:.3f}%)\")\n    return model\n\nmodel = build_feature_extractor(num_classes=10)\noptimizer = torch.optim.Adam(\n    filter(lambda p: p.requires_grad, model.parameters()), lr=1e-3\n)\ncriterion = nn.CrossEntropyLoss()\nprint(f\"Optimizer params: {sum(p.numel() for g in optimizer.param_groups for p in g[\u0027params\u0027]):,}\")\nprint(\"Feature extraction: backbone is a fixed transform; only head params optimized\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models\n\ndef make_discriminative_groups(model, base_lr=1e-5, lr_mult=3.0):\n    \"\"\"\n    Discriminative LRs: earlier layers get lower LR to preserve pretrained features.\n    Each deeper layer group uses lr_mult x higher LR than the previous.\n    \"\"\"\n    groups = [\n        {\u0027params\u0027: model.layer1.parameters(), \u0027lr\u0027: base_lr},\n        {\u0027params\u0027: model.layer2.parameters(), \u0027lr\u0027: base_lr * lr_mult},\n        {\u0027params\u0027: model.layer3.parameters(), \u0027lr\u0027: base_lr * lr_mult**2},\n        {\u0027params\u0027: model.layer4.parameters(), \u0027lr\u0027: base_lr * lr_mult**3},\n        {\u0027params\u0027: model.fc.parameters(),     \u0027lr\u0027: base_lr * lr_mult**4},\n    ]\n    return groups\n\nmodel = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)\nmodel.fc = nn.Linear(model.fc.in_features, 10)\n\ngroups = make_discriminative_groups(model, base_lr=1e-5, lr_mult=3.0)\noptimizer = torch.optim.Adam(groups)\n\nnames = [\u0027layer1\u0027, \u0027layer2\u0027, \u0027layer3\u0027, \u0027layer4\u0027, \u0027fc\u0027]\nprint(\u0027Discriminative learning rates:\u0027)\nfor name, g in zip(names, groups):\n    n = sum(p.numel() for p in g[\u0027params\u0027])\n    print(f\"  {name:\u003c10}: lr={g[\u0027lr\u0027]:.1e}  ({n:,} params)\")\nprint(\u0027Earlier layers use lower LR -- pretrained features preserved more strongly\u0027)"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models\n\ndef set_requires_grad_from(model, layer_name: str):\n    \"\"\"Freeze all layers before layer_name; unfreeze from layer_name onward.\"\"\"\n    unfreezing = False\n    for name, param in model.named_parameters():\n        if layer_name in name:\n            unfreezing = True\n        param.requires_grad = unfreezing\n    n = sum(p.numel() for p in model.parameters() if p.requires_grad)\n    print(f\"  Unfrozen from \u0027{layer_name}\u0027: {n:,} trainable params\")\n\nmodel = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)\nmodel.fc = nn.Linear(model.fc.in_features, 10)\n\n# Epoch 1-5: head only (feature extraction warmup)\nfor p in model.parameters(): p.requires_grad = False\nfor p in model.fc.parameters(): p.requires_grad = True\nprint(\"Epoch 1-5 (head only):\")\nprint(f\"  Trainable: {sum(p.numel() for p in model.parameters() if p.requires_grad):,}\")\n\n# Epoch 6-10: unfreeze layer4 (deepest residual block)\nprint(\"Epoch 6-10:\")\nset_requires_grad_from(model, \u0027layer4\u0027)\n\n# Epoch 11-15: unfreeze layer3\nprint(\"Epoch 11-15:\")\nset_requires_grad_from(model, \u0027layer3\u0027)\n\n# Epoch 16+: full fine-tuning\nfor p in model.parameters(): p.requires_grad = True\nprint(\"Epoch 16+ (full):\")\nprint(f\"  Trainable: {sum(p.numel() for p in model.parameters() if p.requires_grad):,}\")"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torchvision import models\n\ndef freeze_bn_stats(model: nn.Module):\n    \"\"\"\n    Keep BN layers in eval mode to freeze running_mean/running_var.\n    Affine params (weight=gamma, bias=beta) remain trainable.\n    Call this AFTER model.train() in each training iteration.\n    \"\"\"\n    for module in model.modules():\n        if isinstance(module, nn.BatchNorm2d):\n            module.eval()                        # freeze running stats\n            module.weight.requires_grad = True   # gamma still adapts\n            module.bias.requires_grad   = True   # beta still adapts\n\nmodel = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)\nmodel.fc = nn.Linear(model.fc.in_features, 5)\n\nbn_count = sum(1 for m in model.modules() if isinstance(m, nn.BatchNorm2d))\nprint(f\"BN layers in ResNet-50: {bn_count}\")\n\n# Simulate training loop step\nmodel.train()        # sets all layers to training mode (BN stats update)\nfreeze_bn_stats(model)  # immediately freeze BN stats back to eval mode\n\nbn_frozen = sum(1 for m in model.modules()\n                if isinstance(m, nn.BatchNorm2d) and not m.training)\nprint(f\"After freeze_bn_stats: {bn_frozen}/{bn_count} BN layers in eval mode\")\nprint(\"BN running_mean/var preserved; gamma/beta still fine-tuned\")\nprint(\"Without this: ImageNet BN stats are destroyed by target distribution\")"},{"type":"heading","level":2,"content":"Domain Adaptation Considerations"},{"type":"text","content":"When the source domain (ImageNet) and target domain differ significantly — e.g., grayscale medical images, satellite imagery, microscopy — pretrained features are less transferable. In these cases: (1) fine-tune all layers with a small learning rate (1e-5) for the backbone and a larger rate (1e-4) for the head; (2) use longer training (more epochs) to allow the backbone to adapt; (3) consider domain-specific pretraining if available (e.g., RadImageNet for medical imaging, GeoAI models for satellite data); (4) batch normalization statistics should definitely be frozen initially and then optionally fine-tuned in later epochs. For extreme domain shifts (e.g., RGB to depth images), training from scratch with a good random initialization (e.g., Kaiming) may outperform transfer learning."},{"type":"heading","level":2,"content":"Transfer Strategy Reference"},{"type":"table","headers":["Strategy","Frozen Layers","Target Dataset Size","Domain Similarity","Training Speed","Typical Accuracy"],"rows":[["Feature extraction","All conv layers","Very small (\u003c1K)","High (similar to ImageNet)","Fastest","Moderate"],["Fine-tune top block","Layers 1–3","Small (1K–10K)","High","Fast","Good"],["Progressive unfreeze","Layer-by-layer from top","Medium (10K–100K)","Medium","Moderate","Very good"],["Full fine-tuning","None","Large (\u003e100K)","Any","Slowest","Best"],["Train from scratch","N/A (random init)","Very large (\u003e500K)","Low (very different)","Slowest","Best for extreme shift"]]},{"type":"heading","level":2,"content":"Practical Guidelines"},{"type":"text","content":"A reliable transfer learning workflow: (1) always start with feature extraction for a few epochs to stabilize the new head weights before unfreezing anything; (2) use cosine LR schedule rather than step decay — it pairs better with fine-tuning because it does not abruptly change the LR; (3) apply label smoothing (ε=0.1) and moderate weight decay (1e-4) to prevent overfitting on small target datasets; (4) monitor validation loss carefully — fine-tuning can overfit quickly when target data is small; (5) use mixed precision (torch.autocast) to fit larger batches, which stabilize BN statistics if you choose to unfreeze BN."},{"type":"list","ordered":false,"items":["Feature extraction: freeze backbone, train head only — fastest, works with \u003c1000 samples.","Fine-tuning: lower LR for backbone (1e-5), higher for head (1e-3) — better accuracy.","Progressive unfreezing: unfreeze top-\u003ebottom, one block per phase — most stable.","Discriminative LRs: earlier layers get exponentially lower LR (3x steps per group).","BatchNorm: always call bn.eval() after model.train() to preserve ImageNet stats.","Domain shift: extreme shift (medical, satellite) often requires full fine-tuning or domain-specific pretraining."]}]"
---
# Transfer Learning — Feature Extraction vs Fine-Tuning Strategies

Transfer learning is the practice of initializing a model with weights pretrained on a large dataset (typically ImageNet with 1.28M images and 1000 classes) and adapting it to a new task. Because early CNN layers learn universal low-level features (edges, textures, colors) and later layers learn increasingly task-specific features, pretrained weights provide a powerful starting point that dramatically reduces the data and compute required for the target task. The two primary transfer strategies — feature extraction and fine-tuning — differ in which layers are allowed to update during target training.

## Feature Extraction — Frozen Backbone

In feature extraction, all convolutional layers are frozen (requires_grad=False) and only the classification head is trained. The backbone acts as a fixed feature extractor: each image is mapped to a feature vector (e.g., 2048-dim for ResNet-50 after global avg pool), and a new linear classifier is trained on top of these frozen features. This is fast (only head params are optimized), memory-efficient (no gradients through the backbone), and works well when the target domain is visually similar to ImageNet. Feature extraction is the right choice when training data is very small (<1000 examples) or when the target task is similar to ImageNet classification.

## Fine-Tuning — Unfreezing Layers

In fine-tuning, some or all pretrained layers are unfrozen and allowed to update during target training. The key hyperparameter is the learning rate: pretrained layers should use a much lower learning rate (1e-5 to 1e-4) than the new head (1e-3), to preserve the learned representations while allowing them to shift slightly toward the target domain. Fine-tuning provides higher accuracy than feature extraction on most tasks because the backbone can adapt its higher-level features to the target distribution. It requires more training data (typically >5000 examples) and longer training to avoid overfitting.

## When to Use Which Strategy

- Very small dataset (<1000 samples), similar domain (e.g., pets, flowers) -> feature extraction only.
- Small dataset (1000-10000), similar domain -> fine-tune top 1-2 layers + head.
- Medium dataset (10000+), similar domain -> fine-tune all layers with small backbone LR.
- Large dataset (100000+), any domain -> fine-tune all layers or train from scratch.
- Very different domain (e.g., medical imaging, satellite) -> fine-tune all layers regardless of size.
- Low compute budget -> feature extraction (no backbone gradients, faster per step).

> **Always Freeze BatchNorm During Fine-Tuning**: BatchNorm layers maintain running statistics (mean and variance) estimated from training batches. When you call model.train() and fine-tune with small batches on a new domain, the running stats are updated to reflect the new distribution — destroying the statistics calibrated on ImageNet. Always call bn_module.eval() after model.train() to freeze the BN running stats. The affine parameters (gamma, beta) can still be updated. Forgetting this step often causes a significant accuracy drop, especially when the target batch size is small or the domain shift is large.

## Discriminative Learning Rates

Discriminative learning rates (Howard & Ruder, ULMFiT 2018) assign different learning rates to different layer groups: earlier layers (closer to the input) use lower learning rates, later layers use higher rates. The rationale: early layers contain more general, transferable features that should change little; later layers contain more task-specific features that need to adapt more. For ResNet-50, a typical schedule might be: layer1 LR = 1e-5, layer2 LR = 3e-5, layer3 LR = 1e-4, layer4 LR = 3e-4, fc LR = 1e-3 (a 10× step per group). This achieves better accuracy than a single LR for all layers.

## Code Examples

```python
import torch
import torch.nn as nn
from torchvision import models

def build_feature_extractor(num_classes: int):
    """Freeze all backbone params; only train the new classification head."""
    model = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)
    # Freeze all parameters
    for param in model.parameters():
        param.requires_grad = False
    # Replace final fully-connected layer
    model.fc = nn.Linear(model.fc.in_features, num_classes)
    # fc is newly created so requires_grad=True by default
    trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
    total     = sum(p.numel() for p in model.parameters())
    print(f"Trainable: {trainable:,} / {total:,} ({100*trainable/total:.3f}%)")
    return model

model = build_feature_extractor(num_classes=10)
optimizer = torch.optim.Adam(
    filter(lambda p: p.requires_grad, model.parameters()), lr=1e-3
)
criterion = nn.CrossEntropyLoss()
print(f"Optimizer params: {sum(p.numel() for g in optimizer.param_groups for p in g['params']):,}")
print("Feature extraction: backbone is a fixed transform; only head params optimized")
```

```python
import torch
import torch.nn as nn
from torchvision import models

def make_discriminative_groups(model, base_lr=1e-5, lr_mult=3.0):
    """
    Discriminative LRs: earlier layers get lower LR to preserve pretrained features.
    Each deeper layer group uses lr_mult x higher LR than the previous.
    """
    groups = [
        {'params': model.layer1.parameters(), 'lr': base_lr},
        {'params': model.layer2.parameters(), 'lr': base_lr * lr_mult},
        {'params': model.layer3.parameters(), 'lr': base_lr * lr_mult**2},
        {'params': model.layer4.parameters(), 'lr': base_lr * lr_mult**3},
        {'params': model.fc.parameters(),     'lr': base_lr * lr_mult**4},
    ]
    return groups

model = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)
model.fc = nn.Linear(model.fc.in_features, 10)

groups = make_discriminative_groups(model, base_lr=1e-5, lr_mult=3.0)
optimizer = torch.optim.Adam(groups)

names = ['layer1', 'layer2', 'layer3', 'layer4', 'fc']
print('Discriminative learning rates:')
for name, g in zip(names, groups):
    n = sum(p.numel() for p in g['params'])
    print(f"  {name:<10}: lr={g['lr']:.1e}  ({n:,} params)")
print('Earlier layers use lower LR -- pretrained features preserved more strongly')
```

```python
import torch
import torch.nn as nn
from torchvision import models

def set_requires_grad_from(model, layer_name: str):
    """Freeze all layers before layer_name; unfreeze from layer_name onward."""
    unfreezing = False
    for name, param in model.named_parameters():
        if layer_name in name:
            unfreezing = True
        param.requires_grad = unfreezing
    n = sum(p.numel() for p in model.parameters() if p.requires_grad)
    print(f"  Unfrozen from '{layer_name}': {n:,} trainable params")

model = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)
model.fc = nn.Linear(model.fc.in_features, 10)

# Epoch 1-5: head only (feature extraction warmup)
for p in model.parameters(): p.requires_grad = False
for p in model.fc.parameters(): p.requires_grad = True
print("Epoch 1-5 (head only):")
print(f"  Trainable: {sum(p.numel() for p in model.parameters() if p.requires_grad):,}")

# Epoch 6-10: unfreeze layer4 (deepest residual block)
print("Epoch 6-10:")
set_requires_grad_from(model, 'layer4')

# Epoch 11-15: unfreeze layer3
print("Epoch 11-15:")
set_requires_grad_from(model, 'layer3')

# Epoch 16+: full fine-tuning
for p in model.parameters(): p.requires_grad = True
print("Epoch 16+ (full):")
print(f"  Trainable: {sum(p.numel() for p in model.parameters() if p.requires_grad):,}")
```

```python
import torch
import torch.nn as nn
from torchvision import models

def freeze_bn_stats(model: nn.Module):
    """
    Keep BN layers in eval mode to freeze running_mean/running_var.
    Affine params (weight=gamma, bias=beta) remain trainable.
    Call this AFTER model.train() in each training iteration.
    """
    for module in model.modules():
        if isinstance(module, nn.BatchNorm2d):
            module.eval()                        # freeze running stats
            module.weight.requires_grad = True   # gamma still adapts
            module.bias.requires_grad   = True   # beta still adapts

model = models.resnet50(weights=models.ResNet50_Weights.IMAGENET1K_V1)
model.fc = nn.Linear(model.fc.in_features, 5)

bn_count = sum(1 for m in model.modules() if isinstance(m, nn.BatchNorm2d))
print(f"BN layers in ResNet-50: {bn_count}")

# Simulate training loop step
model.train()        # sets all layers to training mode (BN stats update)
freeze_bn_stats(model)  # immediately freeze BN stats back to eval mode

bn_frozen = sum(1 for m in model.modules()
                if isinstance(m, nn.BatchNorm2d) and not m.training)
print(f"After freeze_bn_stats: {bn_frozen}/{bn_count} BN layers in eval mode")
print("BN running_mean/var preserved; gamma/beta still fine-tuned")
print("Without this: ImageNet BN stats are destroyed by target distribution")
```

## Domain Adaptation Considerations

When the source domain (ImageNet) and target domain differ significantly — e.g., grayscale medical images, satellite imagery, microscopy — pretrained features are less transferable. In these cases: (1) fine-tune all layers with a small learning rate (1e-5) for the backbone and a larger rate (1e-4) for the head; (2) use longer training (more epochs) to allow the backbone to adapt; (3) consider domain-specific pretraining if available (e.g., RadImageNet for medical imaging, GeoAI models for satellite data); (4) batch normalization statistics should definitely be frozen initially and then optionally fine-tuned in later epochs. For extreme domain shifts (e.g., RGB to depth images), training from scratch with a good random initialization (e.g., Kaiming) may outperform transfer learning.

## Transfer Strategy Reference

| Strategy | Frozen Layers | Target Dataset Size | Domain Similarity | Training Speed | Typical Accuracy |
| --- | --- | --- | --- | --- | --- |
| Feature extraction | All conv layers | Very small (<1K) | High (similar to ImageNet) | Fastest | Moderate |
| Fine-tune top block | Layers 1–3 | Small (1K–10K) | High | Fast | Good |
| Progressive unfreeze | Layer-by-layer from top | Medium (10K–100K) | Medium | Moderate | Very good |
| Full fine-tuning | None | Large (>100K) | Any | Slowest | Best |
| Train from scratch | N/A (random init) | Very large (>500K) | Low (very different) | Slowest | Best for extreme shift |

## Practical Guidelines

A reliable transfer learning workflow: (1) always start with feature extraction for a few epochs to stabilize the new head weights before unfreezing anything; (2) use cosine LR schedule rather than step decay — it pairs better with fine-tuning because it does not abruptly change the LR; (3) apply label smoothing (ε=0.1) and moderate weight decay (1e-4) to prevent overfitting on small target datasets; (4) monitor validation loss carefully — fine-tuning can overfit quickly when target data is small; (5) use mixed precision (torch.autocast) to fit larger batches, which stabilize BN statistics if you choose to unfreeze BN.

- Feature extraction: freeze backbone, train head only — fastest, works with <1000 samples.
- Fine-tuning: lower LR for backbone (1e-5), higher for head (1e-3) — better accuracy.
- Progressive unfreezing: unfreeze top->bottom, one block per phase — most stable.
- Discriminative LRs: earlier layers get exponentially lower LR (3x steps per group).
- BatchNorm: always call bn.eval() after model.train() to preserve ImageNet stats.
- Domain shift: extreme shift (medical, satellite) often requires full fine-tuning or domain-specific pretraining.

