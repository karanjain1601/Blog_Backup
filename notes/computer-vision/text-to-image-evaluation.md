---
title: "Evaluating Text-to-Image Models: FID, CLIP Score, and Human Eval"
slug: "text-to-image-evaluation"
description: "A practical guide to the metrics that matter for T2I models — what each measures, its failure modes, and how to combine them for reliable benchmarking."
tags: ["evaluation", "FID", "CLIP-score", "text-to-image", "metrics"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Evaluating text-to-image (T2I) models is uniquely difficult: outputs must simultaneously satisfy distributional realism (do images look like real photos?) and semantic alignment (does the image match the prompt?). No single metric captures both, so comprehensive evaluation requires a suite of complementary measures used together."},{"type":"text","content":"The field has evolved through three generations: distribution-based metrics (FID, IS), embedding alignment (CLIP Score), and learned preference models (PickScore, HPSv2, ImageReward). Human evaluation remains the gold standard but is expensive and hard to reproduce — modern benchmarks combine automated metrics with structured human preference studies."},{"type":"callout","variant":"warning","content":"FID measures distributional similarity using Inception-v3 features tuned on ImageNet — it can rate photorealistic but semantically wrong images highly. Always pair FID with a text-alignment metric (CLIP score) for T2I evaluation."},{"type":"heading","level":2,"content":"FID and Inception Score"},{"type":"text","content":"Frechet Inception Distance (FID) compares real and generated image distributions in Inception-v3 feature space, computing the Frechet distance between two multivariate Gaussians fit to each set. Lower is better. FID requires at least 10K samples for stable estimates — using fewer samples introduces high variance that can obscure real differences between models."},{"type":"code","language":"python","content":"# FID with torchmetrics\nfrom torchmetrics.image.fid import FrechetInceptionDistance\nimport torch\n\nfid = FrechetInceptionDistance(feature=2048).to(\u0027cuda\u0027)\n\n# Images must be uint8, range 0-255\nfid.update(real_imgs.to(\u0027cuda\u0027),  real=True)\nfid.update(fake_imgs.to(\u0027cuda\u0027),  real=False)\n\nscore = fid.compute()\nprint(f\"FID: {score:.2f}\")"},{"type":"text","content":"FID is sensitive to preprocessing: image resizing method (bicubic vs. bilinear), center crop vs. resize, and color normalization all affect scores by several points. Always report the exact preprocessing pipeline. Inception Score (IS) measures quality and diversity jointly but is blind to prompt alignment — avoid using IS as a primary metric for T2I evaluation."},{"type":"heading","level":2,"content":"CLIP Score and Alignment"},{"type":"text","content":"CLIP Score measures semantic alignment between generated images and their prompts by computing cosine similarity between CLIP image and text embeddings. Unlike FID, it requires no reference dataset — just the generated image and prompt. Higher is better; typical values range from 0.20-0.35 depending on the CLIP model variant and image domain."},{"type":"code","language":"python","content":"# CLIP Score for text-image alignment\nimport clip, torch\nimport torch.nn.functional as F\n\ndevice = \u0027cuda\u0027\nmodel, preprocess = clip.load(\"ViT-B/32\", device=device)\n\ndef clip_score(img_pil, prompt_str):\n    img = preprocess(img_pil).unsqueeze(0).to(device)\n    tok = clip.tokenize([prompt_str]).to(device)\n    with torch.no_grad():\n        i = model.encode_image(img)\n        t = model.encode_text(tok)\n    return F.cosine_similarity(i, t).item()"},{"type":"text","content":"CLIP Score has known failure modes: it uses a fixed vocabulary, struggles with spatial relationships (left/right, above/below), counts poorly, and misses fine-grained attributes. VQA-based alignment metrics (BLIP-VQA, LLaVA-score) offer complementary signal by answering structured yes/no questions derived from the prompt about the generated image."},{"type":"heading","level":2,"content":"Human Preference Studies"},{"type":"text","content":"Human evaluation via pairwise comparisons (A vs. B given prompt) is the most reliable method. Annotators judge quality, prompt adherence, and overall preference. ELO ratings aggregate pairwise wins into a global ranking. Artificial intelligence feedback (AIF) from LLM judges (GPT-4V, LLaVA) is now standard as a scalable, reproducible proxy."},{"type":"code","language":"python","content":"# LLM-as-judge winrate over N prompt-image pairs\nimport openai, base64\nfrom pathlib import Path\n\ndef llm_winrate(img_a, img_b, prompt, n_pairs=500):\n    wins = 0\n    for _ in range(n_pairs):\n        a64 = base64.b64encode(Path(img_a).read_bytes()).decode()\n        b64 = base64.b64encode(Path(img_b).read_bytes()).decode()\n        resp = openai.chat.completions.create(\n            model=\"gpt-4o\",\n            messages=[{\"role\":\"user\",\"content\":[\n                {\"type\":\"text\",\"text\":f\"Prompt: {prompt}\\nWhich image better matches? Reply A or B.\"},\n                {\"type\":\"image_url\",\"image_url\":{\"url\":f\"data:image/png;base64,{a64}\"}},\n                {\"type\":\"image_url\",\"image_url\":{\"url\":f\"data:image/png;base64,{b64}\"}}\n            ]}])\n        if resp.choices[0].message.content.strip().upper() == \u0027A\u0027: wins += 1\n    return wins / n_pairs"},{"type":"text","content":"Learned preference models (PickScore, HPSv2, ImageReward) are trained on large human preference datasets and predict preference scores directly from image + prompt. They correlate better with human judgment than FID or CLIP Score alone, and are orders of magnitude cheaper than running annotation studies. Use them for model selection during training."},{"type":"heading","level":2,"content":"Benchmark Datasets"},{"type":"text","content":"DrawBench (200 prompts), PartiPrompts (1600 prompts across 12 categories), and T2I-CompBench focus on compositional, spatial, and attribute-binding challenges where T2I models still struggle. COCO captions are the standard for FID measurement. GenAI-Bench tests complex multi-concept prompts with counting, negation, and attribute binding."},{"type":"table","headers":["Metric","Measures","Needs Reference?","Compute Cost","Correlation to Human"],"rows":[["FID","Distributional realism","Yes (real images)","High (50K samples)","Moderate"],["IS","Quality + diversity","No","Medium","Low"],["CLIP Score","Text-image alignment","No","Low","Moderate"],["DINO FD","Realism (ViT features)","Yes (real images)","High","Higher than FID"],["PickScore","Human preference","No","Low (inference only)","High"],["Human ELO","True preference","No","Very high (annotators)","Ground truth"]]},{"type":"code","language":"python","content":"# DINO-based realism via Maximum Mean Discrepancy\nimport torch\nfrom sklearn.metrics.pairwise import rbf_kernel\n\ndef compute_mmd(real_f, gen_f, gamma=1.0):\n    \"\"\"Avoids Inception bias — use DINOv2 features instead.\"\"\"\n    XX = rbf_kernel(real_f, real_f, gamma)\n    YY = rbf_kernel(gen_f,  gen_f,  gamma)\n    XY = rbf_kernel(real_f, gen_f,  gamma)\n    return XX.mean() + YY.mean() - 2 * XY.mean()\n\ndino = torch.hub.load(\u0027facebookresearch/dinov2\u0027, \u0027dinov2_vitb14\u0027)\nreal_f = extract_features(dino, real_images)\ngen_f  = extract_features(dino, generated_images)\nmmd = compute_mmd(real_f.numpy(), gen_f.numpy())"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"No single metric fully captures T2I quality. The recommended stack: FID on COCO (realism baseline), CLIP Score on benchmark prompts (alignment), PickScore or HPSv2 (human preference proxy), and a VQA-based metric for compositional reasoning. Report all four to give a complete, non-gameable picture of model quality."},{"type":"text","content":"Sample count matters enormously for FID stability. With 1K samples, FID variance is ±5-10 points; with 30K samples it drops to ±0.5. Use at least 10K generated images for published results. For CLIP Score, 5K prompt-image pairs is typically sufficient for stable estimates with less than 0.002 standard deviation."},{"type":"text","content":"The field is moving toward LLM-judge evaluation frameworks (LLaVA-eval, GPT-4V-eval) that assess nuanced attributes: counting, spatial relations, text rendering, and style fidelity. These will likely replace CLIP Score as the primary alignment metric as multimodal LLMs become more capable and cost-effective for evaluation pipelines."},{"type":"text","content":"Always evaluate on prompts outside your training distribution. Models tuned on specific prompt styles (short vs. detailed, LAION-style vs. professional photography) can show inflated scores on in-distribution benchmarks. Adversarial prompt sets (T2I-CompBench hard split, Winoground) are better discriminators of true generalization."}]"
---
# Evaluating Text-to-Image Models: FID, CLIP Score, and Human Eval

## Overview

Evaluating text-to-image (T2I) models is uniquely difficult: outputs must simultaneously satisfy distributional realism (do images look like real photos?) and semantic alignment (does the image match the prompt?). No single metric captures both, so comprehensive evaluation requires a suite of complementary measures used together.

The field has evolved through three generations: distribution-based metrics (FID, IS), embedding alignment (CLIP Score), and learned preference models (PickScore, HPSv2, ImageReward). Human evaluation remains the gold standard but is expensive and hard to reproduce — modern benchmarks combine automated metrics with structured human preference studies.

> **warning**: FID measures distributional similarity using Inception-v3 features tuned on ImageNet — it can rate photorealistic but semantically wrong images highly. Always pair FID with a text-alignment metric (CLIP score) for T2I evaluation.

## FID and Inception Score

Frechet Inception Distance (FID) compares real and generated image distributions in Inception-v3 feature space, computing the Frechet distance between two multivariate Gaussians fit to each set. Lower is better. FID requires at least 10K samples for stable estimates — using fewer samples introduces high variance that can obscure real differences between models.

```python
# FID with torchmetrics
from torchmetrics.image.fid import FrechetInceptionDistance
import torch

fid = FrechetInceptionDistance(feature=2048).to('cuda')

# Images must be uint8, range 0-255
fid.update(real_imgs.to('cuda'),  real=True)
fid.update(fake_imgs.to('cuda'),  real=False)

score = fid.compute()
print(f"FID: {score:.2f}")
```

FID is sensitive to preprocessing: image resizing method (bicubic vs. bilinear), center crop vs. resize, and color normalization all affect scores by several points. Always report the exact preprocessing pipeline. Inception Score (IS) measures quality and diversity jointly but is blind to prompt alignment — avoid using IS as a primary metric for T2I evaluation.

## CLIP Score and Alignment

CLIP Score measures semantic alignment between generated images and their prompts by computing cosine similarity between CLIP image and text embeddings. Unlike FID, it requires no reference dataset — just the generated image and prompt. Higher is better; typical values range from 0.20-0.35 depending on the CLIP model variant and image domain.

```python
# CLIP Score for text-image alignment
import clip, torch
import torch.nn.functional as F

device = 'cuda'
model, preprocess = clip.load("ViT-B/32", device=device)

def clip_score(img_pil, prompt_str):
    img = preprocess(img_pil).unsqueeze(0).to(device)
    tok = clip.tokenize([prompt_str]).to(device)
    with torch.no_grad():
        i = model.encode_image(img)
        t = model.encode_text(tok)
    return F.cosine_similarity(i, t).item()
```

CLIP Score has known failure modes: it uses a fixed vocabulary, struggles with spatial relationships (left/right, above/below), counts poorly, and misses fine-grained attributes. VQA-based alignment metrics (BLIP-VQA, LLaVA-score) offer complementary signal by answering structured yes/no questions derived from the prompt about the generated image.

## Human Preference Studies

Human evaluation via pairwise comparisons (A vs. B given prompt) is the most reliable method. Annotators judge quality, prompt adherence, and overall preference. ELO ratings aggregate pairwise wins into a global ranking. Artificial intelligence feedback (AIF) from LLM judges (GPT-4V, LLaVA) is now standard as a scalable, reproducible proxy.

```python
# LLM-as-judge winrate over N prompt-image pairs
import openai, base64
from pathlib import Path

def llm_winrate(img_a, img_b, prompt, n_pairs=500):
    wins = 0
    for _ in range(n_pairs):
        a64 = base64.b64encode(Path(img_a).read_bytes()).decode()
        b64 = base64.b64encode(Path(img_b).read_bytes()).decode()
        resp = openai.chat.completions.create(
            model="gpt-4o",
            messages=[{"role":"user","content":[
                {"type":"text","text":f"Prompt: {prompt}\nWhich image better matches? Reply A or B."},
                {"type":"image_url","image_url":{"url":f"data:image/png;base64,{a64}"}},
                {"type":"image_url","image_url":{"url":f"data:image/png;base64,{b64}"}}
            ]}])
        if resp.choices[0].message.content.strip().upper() == 'A': wins += 1
    return wins / n_pairs
```

Learned preference models (PickScore, HPSv2, ImageReward) are trained on large human preference datasets and predict preference scores directly from image + prompt. They correlate better with human judgment than FID or CLIP Score alone, and are orders of magnitude cheaper than running annotation studies. Use them for model selection during training.

## Benchmark Datasets

DrawBench (200 prompts), PartiPrompts (1600 prompts across 12 categories), and T2I-CompBench focus on compositional, spatial, and attribute-binding challenges where T2I models still struggle. COCO captions are the standard for FID measurement. GenAI-Bench tests complex multi-concept prompts with counting, negation, and attribute binding.

| Metric | Measures | Needs Reference? | Compute Cost | Correlation to Human |
| --- | --- | --- | --- | --- |
| FID | Distributional realism | Yes (real images) | High (50K samples) | Moderate |
| IS | Quality + diversity | No | Medium | Low |
| CLIP Score | Text-image alignment | No | Low | Moderate |
| DINO FD | Realism (ViT features) | Yes (real images) | High | Higher than FID |
| PickScore | Human preference | No | Low (inference only) | High |
| Human ELO | True preference | No | Very high (annotators) | Ground truth |

```python
# DINO-based realism via Maximum Mean Discrepancy
import torch
from sklearn.metrics.pairwise import rbf_kernel

def compute_mmd(real_f, gen_f, gamma=1.0):
    """Avoids Inception bias — use DINOv2 features instead."""
    XX = rbf_kernel(real_f, real_f, gamma)
    YY = rbf_kernel(gen_f,  gen_f,  gamma)
    XY = rbf_kernel(real_f, gen_f,  gamma)
    return XX.mean() + YY.mean() - 2 * XY.mean()

dino = torch.hub.load('facebookresearch/dinov2', 'dinov2_vitb14')
real_f = extract_features(dino, real_images)
gen_f  = extract_features(dino, generated_images)
mmd = compute_mmd(real_f.numpy(), gen_f.numpy())
```

## Key Takeaways

No single metric fully captures T2I quality. The recommended stack: FID on COCO (realism baseline), CLIP Score on benchmark prompts (alignment), PickScore or HPSv2 (human preference proxy), and a VQA-based metric for compositional reasoning. Report all four to give a complete, non-gameable picture of model quality.

Sample count matters enormously for FID stability. With 1K samples, FID variance is ±5-10 points; with 30K samples it drops to ±0.5. Use at least 10K generated images for published results. For CLIP Score, 5K prompt-image pairs is typically sufficient for stable estimates with less than 0.002 standard deviation.

The field is moving toward LLM-judge evaluation frameworks (LLaVA-eval, GPT-4V-eval) that assess nuanced attributes: counting, spatial relations, text rendering, and style fidelity. These will likely replace CLIP Score as the primary alignment metric as multimodal LLMs become more capable and cost-effective for evaluation pipelines.

Always evaluate on prompts outside your training distribution. Models tuned on specific prompt styles (short vs. detailed, LAION-style vs. professional photography) can show inflated scores on in-distribution benchmarks. Adversarial prompt sets (T2I-CompBench hard split, Winoground) are better discriminators of true generalization.

