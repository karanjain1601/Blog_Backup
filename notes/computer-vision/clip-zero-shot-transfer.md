---
title: "CLIP Zero-Shot Transfer: Contrastive Image-Language Pretraining"
slug: "clip-zero-shot-transfer"
description: ""
tags: ["clip", "zero-shot", "contrastive-learning", "vision-language", "openai"]
topic: ""
status: ""
updated: ""
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"CLIP (Contrastive Language-Image Pretraining) is a model trained by OpenAI on 400 million image-text pairs scraped from the internet. Unlike supervised models trained on fixed label sets, CLIP learns a shared embedding space for images and text, enabling zero-shot transfer to arbitrary downstream tasks."},{"type":"text","content":"The key insight is natural language supervision: instead of predicting discrete labels, the model learns to associate images with free-form text descriptions. At inference time, class names are embedded as text and compared against image embeddings — no task-specific fine-tuning required."},{"type":"callout","variant":"info","content":"CLIP\u0027s zero-shot transfer works because it learns visual concepts from natural language supervision rather than fixed label sets. The key is the contrastive objective — it pushes matching pairs together and unmatched pairs apart in a shared embedding space."},{"type":"text","content":"CLIP uses two encoders: a Vision Transformer (ViT) or ResNet for images, and a Transformer for text. Both encoders project their inputs into a shared 512-dimensional embedding space. The training signal comes entirely from whether an image and text were originally paired."},{"type":"heading","level":2,"content":"Contrastive Pretraining Objective"},{"type":"text","content":"The contrastive loss operates on a batch of N image-text pairs. For each batch, CLIP computes an N×N similarity matrix between all image and text embeddings. The diagonal entries are positive pairs; all off-diagonal entries are negatives. The loss maximizes diagonal similarity while minimizing off-diagonal."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef clip_loss(image_features, text_features, temperature):\n    # Normalize embeddings\n    image_features = F.normalize(image_features, dim=-1)\n    text_features = F.normalize(text_features, dim=-1)\n    # Scaled cosine similarity\n    logits = image_features @ text_features.T * temperature\n    B = logits.shape[0]\n    labels = torch.arange(B, device=logits.device)\n    loss_i = F.cross_entropy(logits, labels)\n    loss_t = F.cross_entropy(logits.T, labels)\n    return (loss_i + loss_t) / 2"},{"type":"text","content":"The temperature parameter (learned, initialized to 0.07) scales the logits before softmax. A lower temperature makes the distribution peakier, which is important early in training. CLIP uses a symmetric loss: it classifies both images given texts, and texts given images, averaging both cross-entropy terms."},{"type":"heading","level":2,"content":"Zero-Shot Classification"},{"type":"text","content":"Zero-shot classification with CLIP requires no labeled examples. At inference time, class names are wrapped in a prompt template (e.g., \u0027a photo of a {class}\u0027), encoded by the text encoder, and compared to the image embedding. The class with the highest cosine similarity is the prediction."},{"type":"code","language":"python","content":"import clip\nimport torch\n\ndef zero_shot_classify(image, classes, model, preprocess, device):\n    templates = [\"a photo of a {}.\".format(c) for c in classes]\n    tokens = clip.tokenize(templates).to(device)\n    with torch.no_grad():\n        image_feat = model.encode_image(preprocess(image).unsqueeze(0).to(device))\n        text_feat = model.encode_text(tokens)\n        image_feat = image_feat / image_feat.norm(dim=-1, keepdim=True)\n        text_feat = text_feat / text_feat.norm(dim=-1, keepdim=True)\n        scores = (image_feat @ text_feat.T).squeeze(0)\n    return scores.argmax(-1).item()"},{"type":"text","content":"This approach transfers to any task expressible as a classification problem with named categories. CLIP achieves 76.2% zero-shot accuracy on ImageNet-1K with ViT-L/14@336px — matching supervised ResNet-50 performance from 2019, but without ever seeing ImageNet labels during training."},{"type":"heading","level":2,"content":"Linear Probe vs Zero-Shot"},{"type":"text","content":"Linear probing freezes the pretrained image encoder and trains only a linear classification head on labeled features. This requires labeled data but significantly outperforms zero-shot CLIP on most benchmarks. The comparison reveals how much task-specific information exists in CLIP\u0027s frozen features."},{"type":"code","language":"python","content":"import clip\nimport torch\nimport numpy as np\nfrom sklearn.linear_model import LogisticRegression\n\ndef linear_probe(train_loader, test_loader, model, device):\n    model.eval()\n    def extract(loader):\n        feats, labels = [], []\n        with torch.no_grad():\n            for imgs, lbls in loader:\n                f = model.encode_image(imgs.to(device))\n                feats.append(f.cpu().numpy())\n                labels.append(lbls.numpy())\n        return np.concatenate(feats), np.concatenate(labels)\n    X_train, y_train = extract(train_loader)\n    X_test, y_test = extract(test_loader)\n    clf = LogisticRegression(max_iter=1000).fit(X_train, y_train)\n    return clf.score(X_test, y_test)"},{"type":"text","content":"Linear probing with CLIP ViT-B/32 achieves 84.2% on ImageNet vs 63.2% zero-shot — a gap of 21 points. This gap narrows at larger model scales. On specialized datasets like EuroSAT (satellite imagery) and MNIST (handwritten digits), zero-shot underperforms significantly, revealing domain gaps in training data."},{"type":"table","headers":["Model","ViT Variant","Params (M)","IN-1K Zero-Shot %","IN-1K Linear Probe %","Training Data"],"rows":[["CLIP","ViT-B/32","151","63.2","84.2","400M WIT"],["CLIP","ViT-B/16","150","68.3","86.3","400M WIT"],["CLIP","ViT-L/14","428","75.5","87.8","400M WIT"],["CLIP","ViT-L/14@336px","428","76.2","88.3","400M WIT"],["OpenCLIP","ViT-H/14","986","78.0","89.3","LAION-2B"]]},{"type":"heading","level":2,"content":"Prompt Engineering"},{"type":"text","content":"The choice of text prompt significantly affects zero-shot accuracy. Using \u0027a photo of a {class}\u0027 outperforms using the raw class name by about 1.3% on ImageNet. More elaborate prompt ensembles — averaging embeddings across 80 diverse templates — yield an additional 3.5% improvement."},{"type":"code","language":"python","content":"imagenet_templates = [\n    \"a photo of a {}.\",\n    \"a blurry photo of a {}.\",\n    \"a black and white photo of a {}.\",\n    \"a low contrast photo of a {}.\",\n    \"a high contrast photo of a {}.\",\n    \"a bad photo of a {}.\",\n    \"a good photo of a {}.\",\n    \"a rendering of a {}.\",\n]\n\ndef ensemble_text_features(classes, model, templates, device):\n    with torch.no_grad():\n        class_feats = []\n        for cls in classes:\n            tokens = clip.tokenize([t.format(cls) for t in templates]).to(device)\n            feats = model.encode_text(tokens)\n            feats = feats / feats.norm(dim=-1, keepdim=True)\n            class_feats.append(feats.mean(0))\n    return torch.stack(class_feats)"},{"type":"text","content":"Context matters beyond just the class name. Prompts like \u0027a photo of a {class}, a type of pet\u0027 for fine-grained animal classification or \u0027a centered satellite photo of {}\u0027 for EuroSAT substantially improve accuracy. Domain-specific prompt engineering can close much of the gap to supervised baselines."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"CLIP demonstrated that web-scale image-text data, combined with a contrastive objective, produces powerful visual representations without task-specific supervision. The model\u0027s generality is its defining property: a single trained model transfers competitively across dozens of benchmarks."},{"type":"text","content":"Limitations remain: CLIP struggles with abstract reasoning, counting objects, and fine-grained spatial relationships. Its zero-shot performance on highly specialized domains (medical imaging, satellite imagery) lags supervised models. Prompt engineering requires domain expertise to bridge these gaps effectively."},{"type":"text","content":"CLIP became the de facto visual encoder backbone for subsequent multimodal models including DALL-E, Stable Diffusion, LLaVA, and BLIP-2. Its contrastive pretraining paradigm influenced the broader field of self-supervised and weakly supervised representation learning."}]"
---
# CLIP Zero-Shot Transfer: Contrastive Image-Language Pretraining

## Overview

CLIP (Contrastive Language-Image Pretraining) is a model trained by OpenAI on 400 million image-text pairs scraped from the internet. Unlike supervised models trained on fixed label sets, CLIP learns a shared embedding space for images and text, enabling zero-shot transfer to arbitrary downstream tasks.

The key insight is natural language supervision: instead of predicting discrete labels, the model learns to associate images with free-form text descriptions. At inference time, class names are embedded as text and compared against image embeddings — no task-specific fine-tuning required.

> **info**: CLIP's zero-shot transfer works because it learns visual concepts from natural language supervision rather than fixed label sets. The key is the contrastive objective — it pushes matching pairs together and unmatched pairs apart in a shared embedding space.

CLIP uses two encoders: a Vision Transformer (ViT) or ResNet for images, and a Transformer for text. Both encoders project their inputs into a shared 512-dimensional embedding space. The training signal comes entirely from whether an image and text were originally paired.

## Contrastive Pretraining Objective

The contrastive loss operates on a batch of N image-text pairs. For each batch, CLIP computes an N×N similarity matrix between all image and text embeddings. The diagonal entries are positive pairs; all off-diagonal entries are negatives. The loss maximizes diagonal similarity while minimizing off-diagonal.

```python
import torch
import torch.nn.functional as F

def clip_loss(image_features, text_features, temperature):
    # Normalize embeddings
    image_features = F.normalize(image_features, dim=-1)
    text_features = F.normalize(text_features, dim=-1)
    # Scaled cosine similarity
    logits = image_features @ text_features.T * temperature
    B = logits.shape[0]
    labels = torch.arange(B, device=logits.device)
    loss_i = F.cross_entropy(logits, labels)
    loss_t = F.cross_entropy(logits.T, labels)
    return (loss_i + loss_t) / 2
```

The temperature parameter (learned, initialized to 0.07) scales the logits before softmax. A lower temperature makes the distribution peakier, which is important early in training. CLIP uses a symmetric loss: it classifies both images given texts, and texts given images, averaging both cross-entropy terms.

## Zero-Shot Classification

Zero-shot classification with CLIP requires no labeled examples. At inference time, class names are wrapped in a prompt template (e.g., 'a photo of a {class}'), encoded by the text encoder, and compared to the image embedding. The class with the highest cosine similarity is the prediction.

```python
import clip
import torch

def zero_shot_classify(image, classes, model, preprocess, device):
    templates = ["a photo of a {}.".format(c) for c in classes]
    tokens = clip.tokenize(templates).to(device)
    with torch.no_grad():
        image_feat = model.encode_image(preprocess(image).unsqueeze(0).to(device))
        text_feat = model.encode_text(tokens)
        image_feat = image_feat / image_feat.norm(dim=-1, keepdim=True)
        text_feat = text_feat / text_feat.norm(dim=-1, keepdim=True)
        scores = (image_feat @ text_feat.T).squeeze(0)
    return scores.argmax(-1).item()
```

This approach transfers to any task expressible as a classification problem with named categories. CLIP achieves 76.2% zero-shot accuracy on ImageNet-1K with ViT-L/14@336px — matching supervised ResNet-50 performance from 2019, but without ever seeing ImageNet labels during training.

## Linear Probe vs Zero-Shot

Linear probing freezes the pretrained image encoder and trains only a linear classification head on labeled features. This requires labeled data but significantly outperforms zero-shot CLIP on most benchmarks. The comparison reveals how much task-specific information exists in CLIP's frozen features.

```python
import clip
import torch
import numpy as np
from sklearn.linear_model import LogisticRegression

def linear_probe(train_loader, test_loader, model, device):
    model.eval()
    def extract(loader):
        feats, labels = [], []
        with torch.no_grad():
            for imgs, lbls in loader:
                f = model.encode_image(imgs.to(device))
                feats.append(f.cpu().numpy())
                labels.append(lbls.numpy())
        return np.concatenate(feats), np.concatenate(labels)
    X_train, y_train = extract(train_loader)
    X_test, y_test = extract(test_loader)
    clf = LogisticRegression(max_iter=1000).fit(X_train, y_train)
    return clf.score(X_test, y_test)
```

Linear probing with CLIP ViT-B/32 achieves 84.2% on ImageNet vs 63.2% zero-shot — a gap of 21 points. This gap narrows at larger model scales. On specialized datasets like EuroSAT (satellite imagery) and MNIST (handwritten digits), zero-shot underperforms significantly, revealing domain gaps in training data.

| Model | ViT Variant | Params (M) | IN-1K Zero-Shot % | IN-1K Linear Probe % | Training Data |
| --- | --- | --- | --- | --- | --- |
| CLIP | ViT-B/32 | 151 | 63.2 | 84.2 | 400M WIT |
| CLIP | ViT-B/16 | 150 | 68.3 | 86.3 | 400M WIT |
| CLIP | ViT-L/14 | 428 | 75.5 | 87.8 | 400M WIT |
| CLIP | ViT-L/14@336px | 428 | 76.2 | 88.3 | 400M WIT |
| OpenCLIP | ViT-H/14 | 986 | 78.0 | 89.3 | LAION-2B |

## Prompt Engineering

The choice of text prompt significantly affects zero-shot accuracy. Using 'a photo of a {class}' outperforms using the raw class name by about 1.3% on ImageNet. More elaborate prompt ensembles — averaging embeddings across 80 diverse templates — yield an additional 3.5% improvement.

```python
imagenet_templates = [
    "a photo of a {}.",
    "a blurry photo of a {}.",
    "a black and white photo of a {}.",
    "a low contrast photo of a {}.",
    "a high contrast photo of a {}.",
    "a bad photo of a {}.",
    "a good photo of a {}.",
    "a rendering of a {}.",
]

def ensemble_text_features(classes, model, templates, device):
    with torch.no_grad():
        class_feats = []
        for cls in classes:
            tokens = clip.tokenize([t.format(cls) for t in templates]).to(device)
            feats = model.encode_text(tokens)
            feats = feats / feats.norm(dim=-1, keepdim=True)
            class_feats.append(feats.mean(0))
    return torch.stack(class_feats)
```

Context matters beyond just the class name. Prompts like 'a photo of a {class}, a type of pet' for fine-grained animal classification or 'a centered satellite photo of {}' for EuroSAT substantially improve accuracy. Domain-specific prompt engineering can close much of the gap to supervised baselines.

## Key Takeaways

CLIP demonstrated that web-scale image-text data, combined with a contrastive objective, produces powerful visual representations without task-specific supervision. The model's generality is its defining property: a single trained model transfers competitively across dozens of benchmarks.

Limitations remain: CLIP struggles with abstract reasoning, counting objects, and fine-grained spatial relationships. Its zero-shot performance on highly specialized domains (medical imaging, satellite imagery) lags supervised models. Prompt engineering requires domain expertise to bridge these gaps effectively.

CLIP became the de facto visual encoder backbone for subsequent multimodal models including DALL-E, Stable Diffusion, LLaVA, and BLIP-2. Its contrastive pretraining paradigm influenced the broader field of self-supervised and weakly supervised representation learning.

