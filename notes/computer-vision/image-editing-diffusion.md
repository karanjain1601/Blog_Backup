---
title: "Image Editing with Diffusion Models: Inpainting, Instruct, and SDEdit"
slug: "image-editing-diffusion"
description: "Practical guide to the four main paradigms for diffusion-based image editing: SDEdit, InstructPix2Pix, masked inpainting, and attention manipulation."
tags: ["image-editing", "inpainting", "instructpix2pix", "sdedit", "diffusion"]
topic: "computer-vision"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Diffusion models are flexible image editors as well as generators. The core idea: perturb an existing image with noise (forward process), then denoise with a new conditioning signal (prompt, mask, or reference image). The degree of perturbation controls how much original content is preserved versus how freely the model can edit."},{"type":"text","content":"Four main paradigms dominate diffusion-based editing: SDEdit (add noise, denoise with new prompt), InstructPix2Pix (follow natural language edit instructions), masked inpainting (replace specific regions), and attention manipulation (swap cross-attention maps to preserve spatial layout). Each makes different tradeoffs between edit strength and structural preservation."},{"type":"callout","variant":"tip","content":"SDEdit strength parameter controls the edit magnitude: 0.3-0.5 for color/texture changes, 0.6-0.8 for structural edits. Above 0.8 and the output diverges from the original — use inpainting for precise region control."},{"type":"heading","level":2,"content":"SDEdit: Noise and Denoise"},{"type":"text","content":"SDEdit (Song et al., 2022) is the simplest editing approach: encode the source image to latents, add noise up to timestep t_strength (partial forward process), then denoise from t_strength to 0 with a new prompt. Higher strength means more noise, more freedom for edits, and less preservation of the original image structure."},{"type":"code","language":"python","content":"# SDEdit: partial noise then denoise with new prompt\ndef sdedit(pipe, image, prompt, strength=0.6, steps=50):\n    \"\"\"\n    strength: 0 = no edit, 1 = full regeneration.\n    Lower strength preserves more of the original.\n    \"\"\"\n    latent = pipe.vae.encode(image).latent_dist.sample()\n    latent = latent * pipe.vae.config.scaling_factor\n\n    t_start = int(strength * steps)\n    noise   = torch.randn_like(latent)\n    noisy   = pipe.scheduler.add_noise(\n        latent, noise, timesteps=torch.tensor([t_start]))\n\n    return pipe(prompt, latents=noisy,\n                num_inference_steps=steps,\n                strength=strength).images[0]"},{"type":"text","content":"SDEdit works well for global style changes (oil painting, sketch, watercolor), color shifts, and weather changes. It struggles with precise local edits because noise perturbs the entire image uniformly. For targeted edits to specific objects or regions, inpainting with an explicit mask is more appropriate and reliable."},{"type":"heading","level":2,"content":"Prompt-Based Editing (InstructPix2Pix)"},{"type":"text","content":"InstructPix2Pix (Brooks et al., 2023) trains a model to follow natural language editing instructions directly. Given an image and an instruction like \u0027turn the sky into a sunset\u0027, the model produces the edited result. Training data is synthesized using GPT-4 to generate instruction pairs and Stable Diffusion to produce before/after image pairs."},{"type":"text","content":"The architecture extends classifier-free guidance to two conditioning signals: the source image and the text instruction. This requires two guidance scales — s_T for text adherence and s_I for image preservation — giving independent control over how closely the model follows the instruction vs. preserving original content."},{"type":"code","language":"python","content":"# InstructPix2Pix double classifier-free guidance\ndef ip2p_cfg(unet, x_t, t, img_cond, txt_cond,\n            img_unc, txt_unc, s_text=7.5, s_img=1.5):\n    \"\"\"\n    s_text: higher = more instruction-following\n    s_img:  higher = closer to source image\n    \"\"\"\n    eps_full = unet(x_t, t, img_cond, txt_cond)\n    eps_img  = unet(x_t, t, img_cond, txt_unc)\n    eps_none = unet(x_t, t, img_unc,  txt_unc)\n\n    return (eps_none\n            + s_img  * (eps_img  - eps_none)\n            + s_text * (eps_full - eps_img))"},{"type":"heading","level":2,"content":"Inpainting with Masked Diffusion"},{"type":"text","content":"Inpainting fills a masked region while preserving the rest of the image exactly. At each denoising step, latents outside the mask are replaced with the noisy encoded original — ensuring unmasked content is pixel-perfect after decoding. Only the masked region is freely generated by the denoiser based on the prompt."},{"type":"code","language":"python","content":"# Masked inpainting: anchor unmasked region each step\ndef inpaint_step(scheduler, unet, x_t, t,\n                 original_latent, mask, prompt_embeds):\n    \"\"\"\n    mask: 1 = inpaint region, 0 = keep original pixels\n    \"\"\"\n    noise = torch.randn_like(original_latent)\n    noisy_orig = scheduler.add_noise(\n        original_latent, noise, timesteps=t)\n\n    # Blend: model output inside mask, noisy original outside\n    x_t = mask * x_t + (1 - mask) * noisy_orig\n\n    out = unet(x_t, t, encoder_hidden_states=prompt_embeds)\n    return scheduler.step(out.sample, t, x_t).prev_sample"},{"type":"text","content":"Inpainting has a seam problem: generated regions must blend seamlessly with unedited areas. Fine-tuned inpainting models (Stable Diffusion Inpainting) are trained with random masks so the model learns to produce plausible boundaries. Feathering masks with a Gaussian blur reduces visible seam artifacts in challenging cases."},{"type":"table","headers":["Method","Requires Mask?","Preserves Structure","Edits Semantics","Speed (steps)","Key Paper"],"rows":[["SDEdit","No","Partial (strength-dependent)","Yes","20-50","Song et al. 2022"],["InstructPix2Pix","No","High (via image CFG)","Yes (instruction-following)","50","Brooks et al. 2023"],["Stable Inpaint","Yes","Exact (unmasked region)","Yes (in mask only)","20-50","Rombach et al. 2022"],["Prompt-to-Prompt","No","High (attention injection)","Partial (word swaps)","50","Hertz et al. 2022"],["DiffEdit","Auto-generated","High","Yes (diff-based mask)","50","Couairon et al. 2022"]]},{"type":"heading","level":2,"content":"Attention-Based Editing"},{"type":"text","content":"Prompt-to-Prompt (Hertz et al., 2022) discovered that cross-attention maps in U-Net layers encode spatial layout — where each token attends in the image. By injecting cross-attention maps from a source generation into a target generation with a modified prompt, you can change semantics while preserving spatial structure without any explicit mask."},{"type":"code","language":"python","content":"# Prompt-to-Prompt: store source attention, inject into target\nattn_store = {}\n\ndef store_hook(name):\n    def _hook(module, inp, out):\n        attn_store[name] = out.detach()\n    return _hook\n\n# Step 1: generate with source prompt, collect maps\nfor name, layer in unet.named_modules():\n    if \u0027attn2\u0027 in name:  # cross-attention only\n        layer.register_forward_hook(store_hook(name))\nsource_maps = generate(source_prompt, unet)\n\n# Step 2: generate target, inject stored source maps\ndef inject_hook(name):\n    def _hook(module, inp, out):\n        return attn_store[name]  # replace with source\n    return _hook"},{"type":"text","content":"Attention injection works best for word swaps and attribute changes (dog to cat, red to blue). For structural changes, injection breaks because the new prompt genuinely requires a different layout. DiffEdit extends this by using the difference between source and target attention maps to automatically generate an edit mask — no manual masking required."},{"type":"text","content":"DDIM inversion is a prerequisite for high-fidelity editing in all these methods: instead of random noise, invert the source image through the reverse ODE to recover its approximate noise. Starting denoising from this inverted noise means the edited image naturally preserves more structure and detail from the original without explicit constraints."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Choose your editing paradigm based on the task: SDEdit for global style changes, InstructPix2Pix for instruction-following edits without masks, inpainting for precise region replacement, and Prompt-to-Prompt for layout-preserving semantic changes. Combining methods — inpainting a region with SDEdit blending at boundaries — often gives the best results."},{"type":"text","content":"The frontier is moving toward unified editing frameworks: models like FLUX-Fill, Adobe Firefly, and Google Imagen Editor train end-to-end on diverse editing tasks with task-specific conditioning. These outperform method-specific approaches by leveraging cross-task generalization and producing more coherent edits across diverse prompt types and image domains."}]"
---
# Image Editing with Diffusion Models: Inpainting, Instruct, and SDEdit

## Overview

Diffusion models are flexible image editors as well as generators. The core idea: perturb an existing image with noise (forward process), then denoise with a new conditioning signal (prompt, mask, or reference image). The degree of perturbation controls how much original content is preserved versus how freely the model can edit.

Four main paradigms dominate diffusion-based editing: SDEdit (add noise, denoise with new prompt), InstructPix2Pix (follow natural language edit instructions), masked inpainting (replace specific regions), and attention manipulation (swap cross-attention maps to preserve spatial layout). Each makes different tradeoffs between edit strength and structural preservation.

> **tip**: SDEdit strength parameter controls the edit magnitude: 0.3-0.5 for color/texture changes, 0.6-0.8 for structural edits. Above 0.8 and the output diverges from the original — use inpainting for precise region control.

## SDEdit: Noise and Denoise

SDEdit (Song et al., 2022) is the simplest editing approach: encode the source image to latents, add noise up to timestep t_strength (partial forward process), then denoise from t_strength to 0 with a new prompt. Higher strength means more noise, more freedom for edits, and less preservation of the original image structure.

```python
# SDEdit: partial noise then denoise with new prompt
def sdedit(pipe, image, prompt, strength=0.6, steps=50):
    """
    strength: 0 = no edit, 1 = full regeneration.
    Lower strength preserves more of the original.
    """
    latent = pipe.vae.encode(image).latent_dist.sample()
    latent = latent * pipe.vae.config.scaling_factor

    t_start = int(strength * steps)
    noise   = torch.randn_like(latent)
    noisy   = pipe.scheduler.add_noise(
        latent, noise, timesteps=torch.tensor([t_start]))

    return pipe(prompt, latents=noisy,
                num_inference_steps=steps,
                strength=strength).images[0]
```

SDEdit works well for global style changes (oil painting, sketch, watercolor), color shifts, and weather changes. It struggles with precise local edits because noise perturbs the entire image uniformly. For targeted edits to specific objects or regions, inpainting with an explicit mask is more appropriate and reliable.

## Prompt-Based Editing (InstructPix2Pix)

InstructPix2Pix (Brooks et al., 2023) trains a model to follow natural language editing instructions directly. Given an image and an instruction like 'turn the sky into a sunset', the model produces the edited result. Training data is synthesized using GPT-4 to generate instruction pairs and Stable Diffusion to produce before/after image pairs.

The architecture extends classifier-free guidance to two conditioning signals: the source image and the text instruction. This requires two guidance scales — s_T for text adherence and s_I for image preservation — giving independent control over how closely the model follows the instruction vs. preserving original content.

```python
# InstructPix2Pix double classifier-free guidance
def ip2p_cfg(unet, x_t, t, img_cond, txt_cond,
            img_unc, txt_unc, s_text=7.5, s_img=1.5):
    """
    s_text: higher = more instruction-following
    s_img:  higher = closer to source image
    """
    eps_full = unet(x_t, t, img_cond, txt_cond)
    eps_img  = unet(x_t, t, img_cond, txt_unc)
    eps_none = unet(x_t, t, img_unc,  txt_unc)

    return (eps_none
            + s_img  * (eps_img  - eps_none)
            + s_text * (eps_full - eps_img))
```

## Inpainting with Masked Diffusion

Inpainting fills a masked region while preserving the rest of the image exactly. At each denoising step, latents outside the mask are replaced with the noisy encoded original — ensuring unmasked content is pixel-perfect after decoding. Only the masked region is freely generated by the denoiser based on the prompt.

```python
# Masked inpainting: anchor unmasked region each step
def inpaint_step(scheduler, unet, x_t, t,
                 original_latent, mask, prompt_embeds):
    """
    mask: 1 = inpaint region, 0 = keep original pixels
    """
    noise = torch.randn_like(original_latent)
    noisy_orig = scheduler.add_noise(
        original_latent, noise, timesteps=t)

    # Blend: model output inside mask, noisy original outside
    x_t = mask * x_t + (1 - mask) * noisy_orig

    out = unet(x_t, t, encoder_hidden_states=prompt_embeds)
    return scheduler.step(out.sample, t, x_t).prev_sample
```

Inpainting has a seam problem: generated regions must blend seamlessly with unedited areas. Fine-tuned inpainting models (Stable Diffusion Inpainting) are trained with random masks so the model learns to produce plausible boundaries. Feathering masks with a Gaussian blur reduces visible seam artifacts in challenging cases.

| Method | Requires Mask? | Preserves Structure | Edits Semantics | Speed (steps) | Key Paper |
| --- | --- | --- | --- | --- | --- |
| SDEdit | No | Partial (strength-dependent) | Yes | 20-50 | Song et al. 2022 |
| InstructPix2Pix | No | High (via image CFG) | Yes (instruction-following) | 50 | Brooks et al. 2023 |
| Stable Inpaint | Yes | Exact (unmasked region) | Yes (in mask only) | 20-50 | Rombach et al. 2022 |
| Prompt-to-Prompt | No | High (attention injection) | Partial (word swaps) | 50 | Hertz et al. 2022 |
| DiffEdit | Auto-generated | High | Yes (diff-based mask) | 50 | Couairon et al. 2022 |

## Attention-Based Editing

Prompt-to-Prompt (Hertz et al., 2022) discovered that cross-attention maps in U-Net layers encode spatial layout — where each token attends in the image. By injecting cross-attention maps from a source generation into a target generation with a modified prompt, you can change semantics while preserving spatial structure without any explicit mask.

```python
# Prompt-to-Prompt: store source attention, inject into target
attn_store = {}

def store_hook(name):
    def _hook(module, inp, out):
        attn_store[name] = out.detach()
    return _hook

# Step 1: generate with source prompt, collect maps
for name, layer in unet.named_modules():
    if 'attn2' in name:  # cross-attention only
        layer.register_forward_hook(store_hook(name))
source_maps = generate(source_prompt, unet)

# Step 2: generate target, inject stored source maps
def inject_hook(name):
    def _hook(module, inp, out):
        return attn_store[name]  # replace with source
    return _hook
```

Attention injection works best for word swaps and attribute changes (dog to cat, red to blue). For structural changes, injection breaks because the new prompt genuinely requires a different layout. DiffEdit extends this by using the difference between source and target attention maps to automatically generate an edit mask — no manual masking required.

DDIM inversion is a prerequisite for high-fidelity editing in all these methods: instead of random noise, invert the source image through the reverse ODE to recover its approximate noise. Starting denoising from this inverted noise means the edited image naturally preserves more structure and detail from the original without explicit constraints.

## Key Takeaways

Choose your editing paradigm based on the task: SDEdit for global style changes, InstructPix2Pix for instruction-following edits without masks, inpainting for precise region replacement, and Prompt-to-Prompt for layout-preserving semantic changes. Combining methods — inpainting a region with SDEdit blending at boundaries — often gives the best results.

The frontier is moving toward unified editing frameworks: models like FLUX-Fill, Adobe Firefly, and Google Imagen Editor train end-to-end on diverse editing tasks with task-specific conditioning. These outperform method-specific approaches by leveraging cross-task generalization and producing more coherent edits across diverse prompt types and image domains.

