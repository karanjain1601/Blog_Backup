---
title: "MAE: Masked Autoencoders for Visual Pretraining"
slug: "mae-masked-image-modeling"
description: "Masked Autoencoders use a high masking ratio (75%) to pretrain ViT — encoder processes visible patches only, lightweight decoder reconstructs masked pixels, producing strong transfer features."
tags: ["computer-vision"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Masked Autoencoders (MAE) adapt the masked language modeling paradigm (BERT) to vision. A random 75% of image patches are masked; the encoder processes only the visible 25%, and a lightweight decoder reconstructs the original pixel values for all masked patches. This asymmetric design makes pretraining efficient and forces the encoder to learn holistic scene understanding."},{"type":"text","content":"MAE achieves 87.8% top-1 accuracy on ImageNet with ViT-H after fine-tuning — matching or exceeding supervised pretraining. Unlike contrastive methods, MAE requires no negative pairs, no momentum encoder, and no specialized augmentations. The reconstruction target is raw normalized pixel values, keeping the implementation simple while producing strong representations."},{"type":"heading","level":2,"content":"Asymmetric Encoder-Decoder"},{"type":"text","content":"The encoder is a standard ViT applied only to visible (unmasked) patches. This means the encoder processes just 25% of the total patches, reducing computation by ~4×. Mask tokens are never introduced in the encoder, preventing the model from exploiting their positional information. Only in the lightweight decoder are mask tokens added back, along with positional embeddings, to reconstruct the full image."},{"type":"code","language":"python","content":"import torch\n\ndef random_masking(x, mask_ratio=0.75):\n    # x: [B, N, D] patch embeddings\n    B, N, D = x.shape\n    num_keep = int(N * (1 - mask_ratio))\n    noise = torch.rand(B, N, device=x.device)\n    ids_shuffle = torch.argsort(noise, dim=1)\n    ids_restore = torch.argsort(ids_shuffle, dim=1)\n    ids_keep = ids_shuffle[:, :num_keep]\n    x_masked = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D))\n    mask = torch.ones(B, N, device=x.device)\n    mask[:, :num_keep] = 0\n    mask = torch.gather(mask, 1, ids_restore)\n    return x_masked, mask, ids_restore"},{"type":"heading","level":2,"content":"High Masking Ratio"},{"type":"text","content":"The 75% masking ratio is a deliberate design choice, not just a hyperparameter. At low ratios (e.g., 15% as in BERT), neighboring visible patches leak enough information to reconstruct masked patches through local interpolation. At 75%, the task requires understanding global structure, object semantics, and spatial relationships — forcing the encoder to build rich, holistic representations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MAEEncoder(nn.Module):\n    def __init__(self, vit_backbone):\n        super().__init__()\n        self.vit = vit_backbone\n        self.patch_embed = vit_backbone.patch_embed\n        self.cls_token = vit_backbone.cls_token\n        self.pos_embed = vit_backbone.pos_embed\n\n    def forward(self, x, ids_keep):\n        # embed patches, no mask tokens in encoder\n        x = self.patch_embed(x)  # [B, N, D]\n        x = x + self.pos_embed[:, 1:, :]  # add positional embeddings\n        # select only visible patches\n        B, N, D = x.shape\n        x = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D))\n        cls = self.cls_token + self.pos_embed[:, :1, :]\n        x = torch.cat([cls.expand(B, -1, -1), x], dim=1)\n        x = self.vit.blocks(x)\n        return self.vit.norm(x)"},{"type":"callout","callout_type":"info","content":"MAE\u0027s high masking ratio (75%) is critical — low ratios make the task too easy (neighbors provide signal). 75% forces the model to learn holistic semantic understanding rather than local interpolation."},{"type":"heading","level":2,"content":"Pretraining Objective"},{"type":"text","content":"The reconstruction target is the normalized pixel values within each masked patch. Per-patch mean and variance are computed and used to normalize the target, preventing the model from focusing on low-frequency color statistics rather than structure. The loss is MSE computed only on masked patches — visible patches are not penalized, focusing optimization entirely on what was hidden."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MAEDecoder(nn.Module):\n    def __init__(self, encoder_dim=768, decoder_dim=512,\n                 n_blocks=8, patch_size=16, n_channels=3):\n        super().__init__()\n        self.proj = nn.Linear(encoder_dim, decoder_dim)\n        self.mask_token = nn.Parameter(torch.zeros(1, 1, decoder_dim))\n        self.blocks = nn.Sequential(*[nn.TransformerEncoderLayer(\n            d_model=decoder_dim, nhead=16, batch_first=True)\n            for _ in range(n_blocks)])\n        self.pred = nn.Linear(decoder_dim, patch_size * patch_size * n_channels)\n\n    def forward(self, x, ids_restore):\n        x = self.proj(x)  # project encoder tokens\n        B, num_vis_plus_cls, D = x.shape\n        num_patches = ids_restore.shape[1]\n        mask_tokens = self.mask_token.expand(B, num_patches - (num_vis_plus_cls - 1), D)\n        x_ = torch.cat([x[:, 1:, :], mask_tokens], dim=1)\n        x_ = torch.gather(x_, 1, ids_restore.unsqueeze(-1).expand(-1, -1, D))\n        x = torch.cat([x[:, :1, :], x_], dim=1)\n        x = self.blocks(x)\n        return self.pred(x[:, 1:, :])"},{"type":"heading","level":2,"content":"MAE vs Contrastive Methods"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom timm.models.vision_transformer import VisionTransformer\n\ndef build_mae_finetuning_model(encoder, num_classes=1000):\n    # discard decoder; attach classification head to encoder\n    class MAEFineTuner(nn.Module):\n        def __init__(self, enc, n_cls):\n            super().__init__()\n            self.encoder = enc\n            dim = enc.embed_dim\n            self.head = nn.Linear(dim, n_cls)\n            nn.init.trunc_normal_(self.head.weight, std=0.01)\n        def forward(self, x):\n            # use CLS token for classification\n            x = self.encoder(x)[:, 0]\n            return self.head(x)\n    return MAEFineTuner(encoder, num_classes)"},{"type":"text","content":"MAE and contrastive methods (DINO, CLIP, SimCLR) learn complementary representations. Contrastive methods produce features that excel at linear probing and k-NN tasks because the contrastive objective directly structures the embedding space for similarity comparisons. MAE features often require fine-tuning to reach peak performance but then surpass contrastive baselines on tasks like detection and segmentation."},{"type":"table","headers":["Method","Loss","Masking","Linear Acc (%)","Fine-tune Acc (%)","Throughput"],"rows":[["MAE-B","MSE (pixels)","75%","68.0","83.6","Fast"],["MAE-L","MSE (pixels)","75%","76.0","85.9","Medium"],["MAE-H","MSE (pixels)","75%","77.2","87.8","Slow"],["BEiT","Cross-entropy (tokens)","40%","56.7","83.2","Medium"],["SimMIM","MSE (pixels)","60%","65.7","83.8","Medium"],["DINO-B","Cross-entropy","None","80.1","82.8","Fast"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"MAE demonstrates that generative pretraining — reconstructing masked input — is a powerful and scalable self-supervised learning paradigm for vision. The asymmetric encoder-decoder design simultaneously improves compute efficiency and representation quality. MAE scales gracefully: ViT-H with MAE pretraining matches or exceeds all prior self-supervised methods on standard benchmarks."},{"type":"text","content":"Practical advantages over contrastive methods: no need for negative pairs or large batches, no specialized augmentation pipelines (random crop + horizontal flip suffice), no momentum encoder, and lower memory usage during pretraining. The reconstruction objective is invariant to the number of categories, making MAE naturally suitable for domain-specific pretraining outside ImageNet."},{"type":"text","content":"Downstream usage: discard the decoder after pretraining and fine-tune only the encoder with a task head. For detection (ViTDet), MAE-pretrained ViT-H achieves 61.3 AP on COCO. For segmentation (UPerNet), it achieves 53.6 mIoU on ADE20k. These results establish MAE as the de facto pretraining method for large ViT models in dense prediction tasks."},{"type":"text","content":"Extensions and variants: VideoMAE applies the same paradigm to video with tube masking; Audio-MAE to spectrograms; Point-MAE to 3D point clouds. iBOT combines MAE-style patch token prediction with DINO\u0027s global CLS distillation for a hybrid objective that achieves strong performance on both linear probing and fine-tuning benchmarks without sacrificing either strength."},{"type":"text","content":"Common implementation pitfalls: not normalizing pixel targets per-patch (model learns color statistics instead of structure), using too small a decoder (4 blocks, 256-dim), including mask tokens in the encoder (leaks positional information about masked locations), and using cosine similarity loss instead of MSE (less stable, no clear benefit). Use the exact decoder architecture from the original paper as a starting point."},{"type":"text","content":"Scaling behavior: MAE shows strong scaling with both model size and pretraining duration. ViT-H pretrained for 1600 epochs consistently outperforms shorter schedules. Unlike supervised training, there is no clear sign of overfitting with longer pretraining on ImageNet-1k — MAE benefits from the increased number of masked patch reconstruction problems seen during training."},{"type":"text","content":"Recommended configuration for practitioners: ViT-L/16 with MAE pretraining for 400 epochs on a domain-specific dataset provides strong initialization for fine-tuning on downstream tasks. The original FAIR implementation (github.com/facebookresearch/mae) is clean and well-documented. HuggingFace Transformers includes ViTMAEModel with pretrained weights for both ViT-B and ViT-L variants."}]"
---
# MAE: Masked Autoencoders for Visual Pretraining

## Overview

Masked Autoencoders (MAE) adapt the masked language modeling paradigm (BERT) to vision. A random 75% of image patches are masked; the encoder processes only the visible 25%, and a lightweight decoder reconstructs the original pixel values for all masked patches. This asymmetric design makes pretraining efficient and forces the encoder to learn holistic scene understanding.

MAE achieves 87.8% top-1 accuracy on ImageNet with ViT-H after fine-tuning — matching or exceeding supervised pretraining. Unlike contrastive methods, MAE requires no negative pairs, no momentum encoder, and no specialized augmentations. The reconstruction target is raw normalized pixel values, keeping the implementation simple while producing strong representations.

## Asymmetric Encoder-Decoder

The encoder is a standard ViT applied only to visible (unmasked) patches. This means the encoder processes just 25% of the total patches, reducing computation by ~4×. Mask tokens are never introduced in the encoder, preventing the model from exploiting their positional information. Only in the lightweight decoder are mask tokens added back, along with positional embeddings, to reconstruct the full image.

```python
import torch

def random_masking(x, mask_ratio=0.75):
    # x: [B, N, D] patch embeddings
    B, N, D = x.shape
    num_keep = int(N * (1 - mask_ratio))
    noise = torch.rand(B, N, device=x.device)
    ids_shuffle = torch.argsort(noise, dim=1)
    ids_restore = torch.argsort(ids_shuffle, dim=1)
    ids_keep = ids_shuffle[:, :num_keep]
    x_masked = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D))
    mask = torch.ones(B, N, device=x.device)
    mask[:, :num_keep] = 0
    mask = torch.gather(mask, 1, ids_restore)
    return x_masked, mask, ids_restore
```

## High Masking Ratio

The 75% masking ratio is a deliberate design choice, not just a hyperparameter. At low ratios (e.g., 15% as in BERT), neighboring visible patches leak enough information to reconstruct masked patches through local interpolation. At 75%, the task requires understanding global structure, object semantics, and spatial relationships — forcing the encoder to build rich, holistic representations.

```python
import torch
import torch.nn as nn

class MAEEncoder(nn.Module):
    def __init__(self, vit_backbone):
        super().__init__()
        self.vit = vit_backbone
        self.patch_embed = vit_backbone.patch_embed
        self.cls_token = vit_backbone.cls_token
        self.pos_embed = vit_backbone.pos_embed

    def forward(self, x, ids_keep):
        # embed patches, no mask tokens in encoder
        x = self.patch_embed(x)  # [B, N, D]
        x = x + self.pos_embed[:, 1:, :]  # add positional embeddings
        # select only visible patches
        B, N, D = x.shape
        x = torch.gather(x, 1, ids_keep.unsqueeze(-1).expand(-1, -1, D))
        cls = self.cls_token + self.pos_embed[:, :1, :]
        x = torch.cat([cls.expand(B, -1, -1), x], dim=1)
        x = self.vit.blocks(x)
        return self.vit.norm(x)
```

> ****: MAE's high masking ratio (75%) is critical — low ratios make the task too easy (neighbors provide signal). 75% forces the model to learn holistic semantic understanding rather than local interpolation.

## Pretraining Objective

The reconstruction target is the normalized pixel values within each masked patch. Per-patch mean and variance are computed and used to normalize the target, preventing the model from focusing on low-frequency color statistics rather than structure. The loss is MSE computed only on masked patches — visible patches are not penalized, focusing optimization entirely on what was hidden.

```python
import torch
import torch.nn as nn

class MAEDecoder(nn.Module):
    def __init__(self, encoder_dim=768, decoder_dim=512,
                 n_blocks=8, patch_size=16, n_channels=3):
        super().__init__()
        self.proj = nn.Linear(encoder_dim, decoder_dim)
        self.mask_token = nn.Parameter(torch.zeros(1, 1, decoder_dim))
        self.blocks = nn.Sequential(*[nn.TransformerEncoderLayer(
            d_model=decoder_dim, nhead=16, batch_first=True)
            for _ in range(n_blocks)])
        self.pred = nn.Linear(decoder_dim, patch_size * patch_size * n_channels)

    def forward(self, x, ids_restore):
        x = self.proj(x)  # project encoder tokens
        B, num_vis_plus_cls, D = x.shape
        num_patches = ids_restore.shape[1]
        mask_tokens = self.mask_token.expand(B, num_patches - (num_vis_plus_cls - 1), D)
        x_ = torch.cat([x[:, 1:, :], mask_tokens], dim=1)
        x_ = torch.gather(x_, 1, ids_restore.unsqueeze(-1).expand(-1, -1, D))
        x = torch.cat([x[:, :1, :], x_], dim=1)
        x = self.blocks(x)
        return self.pred(x[:, 1:, :])
```

## MAE vs Contrastive Methods

```python
import torch
import torch.nn as nn
from timm.models.vision_transformer import VisionTransformer

def build_mae_finetuning_model(encoder, num_classes=1000):
    # discard decoder; attach classification head to encoder
    class MAEFineTuner(nn.Module):
        def __init__(self, enc, n_cls):
            super().__init__()
            self.encoder = enc
            dim = enc.embed_dim
            self.head = nn.Linear(dim, n_cls)
            nn.init.trunc_normal_(self.head.weight, std=0.01)
        def forward(self, x):
            # use CLS token for classification
            x = self.encoder(x)[:, 0]
            return self.head(x)
    return MAEFineTuner(encoder, num_classes)
```

MAE and contrastive methods (DINO, CLIP, SimCLR) learn complementary representations. Contrastive methods produce features that excel at linear probing and k-NN tasks because the contrastive objective directly structures the embedding space for similarity comparisons. MAE features often require fine-tuning to reach peak performance but then surpass contrastive baselines on tasks like detection and segmentation.

| Method | Loss | Masking | Linear Acc (%) | Fine-tune Acc (%) | Throughput |
| --- | --- | --- | --- | --- | --- |
| MAE-B | MSE (pixels) | 75% | 68.0 | 83.6 | Fast |
| MAE-L | MSE (pixels) | 75% | 76.0 | 85.9 | Medium |
| MAE-H | MSE (pixels) | 75% | 77.2 | 87.8 | Slow |
| BEiT | Cross-entropy (tokens) | 40% | 56.7 | 83.2 | Medium |
| SimMIM | MSE (pixels) | 60% | 65.7 | 83.8 | Medium |
| DINO-B | Cross-entropy | None | 80.1 | 82.8 | Fast |

## Key Takeaways

MAE demonstrates that generative pretraining — reconstructing masked input — is a powerful and scalable self-supervised learning paradigm for vision. The asymmetric encoder-decoder design simultaneously improves compute efficiency and representation quality. MAE scales gracefully: ViT-H with MAE pretraining matches or exceeds all prior self-supervised methods on standard benchmarks.

Practical advantages over contrastive methods: no need for negative pairs or large batches, no specialized augmentation pipelines (random crop + horizontal flip suffice), no momentum encoder, and lower memory usage during pretraining. The reconstruction objective is invariant to the number of categories, making MAE naturally suitable for domain-specific pretraining outside ImageNet.

Downstream usage: discard the decoder after pretraining and fine-tune only the encoder with a task head. For detection (ViTDet), MAE-pretrained ViT-H achieves 61.3 AP on COCO. For segmentation (UPerNet), it achieves 53.6 mIoU on ADE20k. These results establish MAE as the de facto pretraining method for large ViT models in dense prediction tasks.

Extensions and variants: VideoMAE applies the same paradigm to video with tube masking; Audio-MAE to spectrograms; Point-MAE to 3D point clouds. iBOT combines MAE-style patch token prediction with DINO's global CLS distillation for a hybrid objective that achieves strong performance on both linear probing and fine-tuning benchmarks without sacrificing either strength.

Common implementation pitfalls: not normalizing pixel targets per-patch (model learns color statistics instead of structure), using too small a decoder (4 blocks, 256-dim), including mask tokens in the encoder (leaks positional information about masked locations), and using cosine similarity loss instead of MSE (less stable, no clear benefit). Use the exact decoder architecture from the original paper as a starting point.

Scaling behavior: MAE shows strong scaling with both model size and pretraining duration. ViT-H pretrained for 1600 epochs consistently outperforms shorter schedules. Unlike supervised training, there is no clear sign of overfitting with longer pretraining on ImageNet-1k — MAE benefits from the increased number of masked patch reconstruction problems seen during training.

Recommended configuration for practitioners: ViT-L/16 with MAE pretraining for 400 epochs on a domain-specific dataset provides strong initialization for fine-tuning on downstream tasks. The original FAIR implementation (github.com/facebookresearch/mae) is clean and well-documented. HuggingFace Transformers includes ViTMAEModel with pretrained weights for both ViT-B and ViT-L variants.

