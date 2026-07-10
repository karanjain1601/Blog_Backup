---
title: "BLIP-2: Q-Former Bridging Vision and Language Models"
slug: "blip2-qformer"
description: ""
tags: ["blip2", "qformer", "bootstrapping", "frozen-llm", "salesforce"]
topic: ""
status: ""
updated: ""
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"BLIP-2 (Bootstrapping Language-Image Pretraining) from Salesforce Research introduces the Q-Former, a lightweight transformer module that bridges a frozen image encoder and a frozen large language model. By keeping both pre-trained components frozen, BLIP-2 achieves state-of-the-art multimodal performance with minimal trainable parameters."},{"type":"text","content":"The central challenge BLIP-2 addresses is the modality gap: image encoder and LLM embedding spaces are learned independently and incompatible out of the box. The Q-Former solves this by learning to translate between them using only 188M trainable parameters, while the backbone encoders (billions of parameters) remain frozen."},{"type":"callout","variant":"info","content":"Q-Former is the core innovation: 32 learned queries distill the entire image into a compact visual representation that any frozen LLM can condition on. This decouples vision encoder upgrades from LLM upgrades — swap either independently."},{"type":"text","content":"BLIP-2 uses EVA-CLIP ViT-G/14 (1B params) as the visual encoder and either OPT or FlanT5 as the language model. Despite using frozen backbones, BLIP-2 FlanT5-XXL achieves 65.0% on VQAv2 and 45.9% on OK-VQA, outperforming Flamingo 80B with 54x fewer trainable parameters."},{"type":"heading","level":2,"content":"Q-Former Architecture"},{"type":"text","content":"The Q-Former is a BERT-based transformer with two attention pathways: self-attention between learned query tokens, and cross-attention from query tokens to frozen image patch features. The 32 query tokens (each 768-dimensional) are the only learned visual representations passed downstream to the LLM."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass QFormerLayer(nn.Module):\n    def __init__(self, d_model, n_heads, n_queries=32):\n        super().__init__()\n        self.query_tokens = nn.Parameter(torch.randn(1, n_queries, d_model))\n        self.self_attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)\n        self.cross_attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)\n        self.ffn = nn.Sequential(nn.Linear(d_model, 4*d_model),\n                                 nn.GELU(), nn.Linear(4*d_model, d_model))\n\n    def forward(self, image_features):\n        B = image_features.shape[0]\n        q = self.query_tokens.expand(B, -1, -1)\n        q, _ = self.self_attn(q, q, q)\n        q, _ = self.cross_attn(q, image_features, image_features)\n        return self.ffn(q) + q  # residual"},{"type":"text","content":"The 32 query tokens compress the entire image — which may have 256 or more patch tokens from ViT-G/14 — into a fixed-size representation. This compression is learned rather than hand-designed: the Q-Former training objectives teach it what visual information is relevant for language understanding."},{"type":"heading","level":2,"content":"Stage-1 Vision-Language Pretraining"},{"type":"text","content":"Stage-1 trains the Q-Former with three objectives simultaneously, using 129M image-text pairs. The image encoder is frozen; only Q-Former weights are updated. The three losses together teach the Q-Former to extract image features useful for matching, discriminating, and generating text descriptions."},{"type":"code","language":"python","content":"def qformer_stage1_losses(query_output, text_output, image_embeds, text_ids, model):\n    # 1. Image-Text Contrastive (ITC) — align [CLS] of query and text\n    q_feat = F.normalize(model.itc_query_proj(query_output[:, 0]), dim=-1)\n    t_feat = F.normalize(model.itc_text_proj(text_output[:, 0]), dim=-1)\n    sim_matrix = q_feat @ t_feat.T / model.temp\n    labels = torch.arange(sim_matrix.size(0), device=sim_matrix.device)\n    itc_loss = (F.cross_entropy(sim_matrix, labels) +\n                F.cross_entropy(sim_matrix.T, labels)) / 2\n    # 2. Image-Text Matching (ITM) — binary classification on fused features\n    itm_logits = model.itm_head(query_output)  # (B, 2)\n    itm_loss = F.cross_entropy(itm_logits, model.itm_labels)\n    # 3. Image-Grounded Text Generation (ITG) — causal LM on query+text\n    itg_loss = model.lm_head_loss(query_output, text_ids)\n    return itc_loss + itm_loss + itg_loss"},{"type":"text","content":"ITC aligns global image and text representations. ITM is a binary cross-entropy loss that teaches the Q-Former to distinguish genuine from mismatched image-text pairs. ITG is autoregressive text generation conditioned on query token outputs — it forces the query tokens to capture text-relevant visual information."},{"type":"heading","level":2,"content":"Stage-2 Language Model Connection"},{"type":"text","content":"Stage-2 connects the Q-Former output to a frozen LLM via a linear projection. The 32 query token outputs (768-dim) are projected to the LLM input dimension (e.g., 2048 for OPT-2.7B) and prepended to the text embedding sequence. The LLM generates text conditioned on this visual prefix."},{"type":"code","language":"python","content":"def blip2_generate(image, prompt_ids, model, max_new_tokens=50):\n    # Frozen CLIP encodes image\n    with torch.no_grad():\n        image_features = model.visual_encoder(image)  # (B, 257, 1408)\n    # Q-Former extracts 32 query tokens\n    query_output = model.qformer(image_features)    # (B, 32, 768)\n    # Project to LLM embedding space\n    visual_prefix = model.language_projection(query_output)  # (B, 32, D_llm)\n    # Get text embeddings and concatenate\n    text_embeds = model.language_model.get_input_embeddings()(prompt_ids)\n    inputs_embeds = torch.cat([visual_prefix, text_embeds], dim=1)\n    # Frozen LLM generates\n    with torch.no_grad():\n        outputs = model.language_model.generate(\n            inputs_embeds=inputs_embeds, max_new_tokens=max_new_tokens)\n    return outputs"},{"type":"text","content":"For generative LLMs (OPT), the visual prefix acts as a soft visual prompt and the LLM generates the full response autoregressively. For encoder-decoder LLMs (FlanT5), query tokens are passed to the encoder, and the decoder generates the answer. FlanT5-based variants generally score higher on knowledge-intensive VQA tasks."},{"type":"heading","level":2,"content":"Zero-Shot VQA"},{"type":"text","content":"BLIP-2 supports zero-shot VQA out of the box through its generative interface. The question is formatted as a prompt and concatenated after the visual prefix tokens. The frozen LLM generates a free-form answer conditioned on both the visual representation and the question text — no fine-tuning required."},{"type":"code","language":"python","content":"from transformers import Blip2Processor, Blip2ForConditionalGeneration\nfrom PIL import Image\nimport requests\nimport torch\n\nprocessor = Blip2Processor.from_pretrained(\"Salesforce/blip2-opt-2.7b\")\nmodel = Blip2ForConditionalGeneration.from_pretrained(\n    \"Salesforce/blip2-opt-2.7b\", torch_dtype=torch.float16, device_map=\"auto\")\n\nimage = Image.open(requests.get(\"https://example.com/img.jpg\", stream=True).raw)\nquestion = \"Question: How many people are in the image? Answer:\"\ninputs = processor(image, question, return_tensors=\"pt\").to(model.device, torch.float16)\ngenerated = model.generate(**inputs, max_new_tokens=30)\nprint(processor.decode(generated[0], skip_special_tokens=True))"},{"type":"text","content":"Zero-shot VQAv2 accuracy for BLIP-2 OPT-6.7B is 61.2%, compared to Flamingo-80B at 56.3% — achieved with a 54x smaller model. The gap comes from BLIP-2\u0027s staged pretraining: Q-Former stage-1 provides a strong visual representation before the LLM connection is even introduced."},{"type":"table","headers":["BLIP-2 Variant","LLM","Visual Encoder","VQAv2 %","OK-VQA %","Params Total"],"rows":[["BLIP-2 OPT-2.7B","OPT-2.7B","EVA-CLIP ViT-G","53.7","31.7","~3.4B"],["BLIP-2 OPT-6.7B","OPT-6.7B","EVA-CLIP ViT-G","61.2","36.4","~8.2B"],["BLIP-2 FlanT5-XL","FlanT5-XL (3B)","EVA-CLIP ViT-G","62.0","40.7","~4.1B"],["BLIP-2 FlanT5-XXL","FlanT5-XXL (11B)","EVA-CLIP ViT-G","65.0","45.9","~12.1B"],["InstructBLIP FlanT5-XXL","FlanT5-XXL (11B)","EVA-CLIP ViT-G","—","50.7","~12.1B"]]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"BLIP-2\u0027s Q-Former design solves a fundamental problem in multimodal learning: how to efficiently bridge pretrained unimodal models without catastrophic forgetting. By keeping both encoders frozen and training only the 188M-parameter bridge, BLIP-2 is compute-efficient and modular."},{"type":"text","content":"The two-stage pretraining curriculum is principled: stage-1 develops rich visual representations aligned to language, and stage-2 teaches the LLM to use them for generation. This separation prevents the LLM\u0027s strong language priors from overwhelming the visual signal during early training."},{"type":"text","content":"BLIP-2\u0027s limitations include fixed 32-query compression (may miss fine-grained details), no instruction-following capability in the base model (addressed by InstructBLIP), and reduced performance on tasks requiring spatial reasoning or counting. Subsequent work like InstructBLIP adds instruction tuning on top of the Q-Former framework."}]"
---
# BLIP-2: Q-Former Bridging Vision and Language Models

## Overview

BLIP-2 (Bootstrapping Language-Image Pretraining) from Salesforce Research introduces the Q-Former, a lightweight transformer module that bridges a frozen image encoder and a frozen large language model. By keeping both pre-trained components frozen, BLIP-2 achieves state-of-the-art multimodal performance with minimal trainable parameters.

The central challenge BLIP-2 addresses is the modality gap: image encoder and LLM embedding spaces are learned independently and incompatible out of the box. The Q-Former solves this by learning to translate between them using only 188M trainable parameters, while the backbone encoders (billions of parameters) remain frozen.

> **info**: Q-Former is the core innovation: 32 learned queries distill the entire image into a compact visual representation that any frozen LLM can condition on. This decouples vision encoder upgrades from LLM upgrades — swap either independently.

BLIP-2 uses EVA-CLIP ViT-G/14 (1B params) as the visual encoder and either OPT or FlanT5 as the language model. Despite using frozen backbones, BLIP-2 FlanT5-XXL achieves 65.0% on VQAv2 and 45.9% on OK-VQA, outperforming Flamingo 80B with 54x fewer trainable parameters.

## Q-Former Architecture

The Q-Former is a BERT-based transformer with two attention pathways: self-attention between learned query tokens, and cross-attention from query tokens to frozen image patch features. The 32 query tokens (each 768-dimensional) are the only learned visual representations passed downstream to the LLM.

```python
import torch
import torch.nn as nn

class QFormerLayer(nn.Module):
    def __init__(self, d_model, n_heads, n_queries=32):
        super().__init__()
        self.query_tokens = nn.Parameter(torch.randn(1, n_queries, d_model))
        self.self_attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)
        self.cross_attn = nn.MultiheadAttention(d_model, n_heads, batch_first=True)
        self.ffn = nn.Sequential(nn.Linear(d_model, 4*d_model),
                                 nn.GELU(), nn.Linear(4*d_model, d_model))

    def forward(self, image_features):
        B = image_features.shape[0]
        q = self.query_tokens.expand(B, -1, -1)
        q, _ = self.self_attn(q, q, q)
        q, _ = self.cross_attn(q, image_features, image_features)
        return self.ffn(q) + q  # residual
```

The 32 query tokens compress the entire image — which may have 256 or more patch tokens from ViT-G/14 — into a fixed-size representation. This compression is learned rather than hand-designed: the Q-Former training objectives teach it what visual information is relevant for language understanding.

## Stage-1 Vision-Language Pretraining

Stage-1 trains the Q-Former with three objectives simultaneously, using 129M image-text pairs. The image encoder is frozen; only Q-Former weights are updated. The three losses together teach the Q-Former to extract image features useful for matching, discriminating, and generating text descriptions.

```python
def qformer_stage1_losses(query_output, text_output, image_embeds, text_ids, model):
    # 1. Image-Text Contrastive (ITC) — align [CLS] of query and text
    q_feat = F.normalize(model.itc_query_proj(query_output[:, 0]), dim=-1)
    t_feat = F.normalize(model.itc_text_proj(text_output[:, 0]), dim=-1)
    sim_matrix = q_feat @ t_feat.T / model.temp
    labels = torch.arange(sim_matrix.size(0), device=sim_matrix.device)
    itc_loss = (F.cross_entropy(sim_matrix, labels) +
                F.cross_entropy(sim_matrix.T, labels)) / 2
    # 2. Image-Text Matching (ITM) — binary classification on fused features
    itm_logits = model.itm_head(query_output)  # (B, 2)
    itm_loss = F.cross_entropy(itm_logits, model.itm_labels)
    # 3. Image-Grounded Text Generation (ITG) — causal LM on query+text
    itg_loss = model.lm_head_loss(query_output, text_ids)
    return itc_loss + itm_loss + itg_loss
```

ITC aligns global image and text representations. ITM is a binary cross-entropy loss that teaches the Q-Former to distinguish genuine from mismatched image-text pairs. ITG is autoregressive text generation conditioned on query token outputs — it forces the query tokens to capture text-relevant visual information.

## Stage-2 Language Model Connection

Stage-2 connects the Q-Former output to a frozen LLM via a linear projection. The 32 query token outputs (768-dim) are projected to the LLM input dimension (e.g., 2048 for OPT-2.7B) and prepended to the text embedding sequence. The LLM generates text conditioned on this visual prefix.

```python
def blip2_generate(image, prompt_ids, model, max_new_tokens=50):
    # Frozen CLIP encodes image
    with torch.no_grad():
        image_features = model.visual_encoder(image)  # (B, 257, 1408)
    # Q-Former extracts 32 query tokens
    query_output = model.qformer(image_features)    # (B, 32, 768)
    # Project to LLM embedding space
    visual_prefix = model.language_projection(query_output)  # (B, 32, D_llm)
    # Get text embeddings and concatenate
    text_embeds = model.language_model.get_input_embeddings()(prompt_ids)
    inputs_embeds = torch.cat([visual_prefix, text_embeds], dim=1)
    # Frozen LLM generates
    with torch.no_grad():
        outputs = model.language_model.generate(
            inputs_embeds=inputs_embeds, max_new_tokens=max_new_tokens)
    return outputs
```

For generative LLMs (OPT), the visual prefix acts as a soft visual prompt and the LLM generates the full response autoregressively. For encoder-decoder LLMs (FlanT5), query tokens are passed to the encoder, and the decoder generates the answer. FlanT5-based variants generally score higher on knowledge-intensive VQA tasks.

## Zero-Shot VQA

BLIP-2 supports zero-shot VQA out of the box through its generative interface. The question is formatted as a prompt and concatenated after the visual prefix tokens. The frozen LLM generates a free-form answer conditioned on both the visual representation and the question text — no fine-tuning required.

```python
from transformers import Blip2Processor, Blip2ForConditionalGeneration
from PIL import Image
import requests
import torch

processor = Blip2Processor.from_pretrained("Salesforce/blip2-opt-2.7b")
model = Blip2ForConditionalGeneration.from_pretrained(
    "Salesforce/blip2-opt-2.7b", torch_dtype=torch.float16, device_map="auto")

image = Image.open(requests.get("https://example.com/img.jpg", stream=True).raw)
question = "Question: How many people are in the image? Answer:"
inputs = processor(image, question, return_tensors="pt").to(model.device, torch.float16)
generated = model.generate(**inputs, max_new_tokens=30)
print(processor.decode(generated[0], skip_special_tokens=True))
```

Zero-shot VQAv2 accuracy for BLIP-2 OPT-6.7B is 61.2%, compared to Flamingo-80B at 56.3% — achieved with a 54x smaller model. The gap comes from BLIP-2's staged pretraining: Q-Former stage-1 provides a strong visual representation before the LLM connection is even introduced.

| BLIP-2 Variant | LLM | Visual Encoder | VQAv2 % | OK-VQA % | Params Total |
| --- | --- | --- | --- | --- | --- |
| BLIP-2 OPT-2.7B | OPT-2.7B | EVA-CLIP ViT-G | 53.7 | 31.7 | ~3.4B |
| BLIP-2 OPT-6.7B | OPT-6.7B | EVA-CLIP ViT-G | 61.2 | 36.4 | ~8.2B |
| BLIP-2 FlanT5-XL | FlanT5-XL (3B) | EVA-CLIP ViT-G | 62.0 | 40.7 | ~4.1B |
| BLIP-2 FlanT5-XXL | FlanT5-XXL (11B) | EVA-CLIP ViT-G | 65.0 | 45.9 | ~12.1B |
| InstructBLIP FlanT5-XXL | FlanT5-XXL (11B) | EVA-CLIP ViT-G | — | 50.7 | ~12.1B |

## Key Takeaways

BLIP-2's Q-Former design solves a fundamental problem in multimodal learning: how to efficiently bridge pretrained unimodal models without catastrophic forgetting. By keeping both encoders frozen and training only the 188M-parameter bridge, BLIP-2 is compute-efficient and modular.

The two-stage pretraining curriculum is principled: stage-1 develops rich visual representations aligned to language, and stage-2 teaches the LLM to use them for generation. This separation prevents the LLM's strong language priors from overwhelming the visual signal during early training.

BLIP-2's limitations include fixed 32-query compression (may miss fine-grained details), no instruction-following capability in the base model (addressed by InstructBLIP), and reduced performance on tasks requiring spatial reasoning or counting. Subsequent work like InstructBLIP adds instruction tuning on top of the Q-Former framework.

