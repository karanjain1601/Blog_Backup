---
title: "GGUF Format and llama.cpp Quantization"
slug: "gguf-format"
description: "The GGUF file format for portable LLM quantization and the quantization types Q2_K through Q8_0 used by llama.cpp for CPU and GPU inference."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"GGUF (GPT-Generated Unified Format) is the binary file format used by llama.cpp to store quantized large language models. Introduced in August 2023 as the successor to GGML, GGUF resolves the backwards-compatibility problems of its predecessor by embedding all model metadata — tokenizer vocabulary, hyperparameters, tensor names, and quantization type — directly in the file header. A single GGUF file is fully self-contained: you can load it on any platform supported by llama.cpp without separately downloading a config or tokenizer. This portability has made GGUF the dominant format for running quantized LLMs locally on consumer hardware."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"llama.cpp implements a family of quantization schemes ranging from 2-bit (Q2_K) to 8-bit (Q8_0), each trading model size and speed against perplexity degradation. The K-quant family (Q2_K, Q3_K_M, Q4_K_M, Q5_K_M, Q6_K) uses a two-level super-block structure and mixed-precision blocks to achieve better accuracy than the legacy integer quants at similar bit rates. The typical workflow is: (1) download or train a model in HuggingFace format; (2) convert to F16 GGUF using convert_hf_to_gguf.py; (3) quantize to a target type using the llama-quantize binary; (4) run inference with llama-cli or via the llama-cpp-python Python bindings."},{"type":"heading","level":2,"content":"GGUF File Structure"},{"type":"text","content":"A GGUF file starts with a fixed header: a 4-byte magic number (0x46554747, i.e. \u0027GGUF\u0027), a uint32 version field (currently 3), and counts of tensors and key-value metadata entries. The metadata section stores arbitrary typed key-value pairs — model architecture, context length, rope parameters, tokenizer vocabulary, special token IDs, and more. Tensors are listed in a tensor info section (name, shape, dtype, byte offset) before the actual tensor data, which is stored contiguously and aligned to 32 bytes. This alignment allows memory-mapping the file directly for zero-copy loading on supported systems."},{"type":"list","ordered":false,"items":["Magic: 0x46554747 (\u0027GGUF\u0027) — identifies the file as GGUF regardless of extension.","Version: uint32, currently 3 — GGUF v1/v2 files from 2023 require conversion for modern llama.cpp.","n_tensors / n_kv: counts used to parse the tensor info and metadata sections.","Metadata KV pairs: general.architecture, general.name, llama.context_length, tokenizer.ggml.model, tokenizer.ggml.tokens, tokenizer.ggml.scores.","Tensor data section: 32-byte aligned; amenable to mmap for fast load and partial GPU offload.","Quantization type stored per tensor: each tensor independently records its ggml_type enum value."]},{"type":"heading","level":2,"content":"Quantization Types: Q4_K_M and Friends"},{"type":"text","content":"The llama.cpp quantization type system distinguishes legacy quants (Q4_0, Q4_1, Q5_0, Q5_1, Q8_0) from the modern K-quants (Q2_K, Q3_K_M/S, Q4_K_M/S, Q5_K_M/S, Q6_K). Legacy quants use a flat block of 32 weights with a single scale and optional bias. K-quants group 256 weights into a super-block, within which 8 sub-blocks of 32 each carry their own scale; the super-block scales are stored at higher precision. This hierarchical structure captures local variation in weight magnitude better than a single global scale. The M/S suffixes (medium/small) in K-quants control which tensor layers get the higher-precision quantization treatment: M keeps attention and feed-forward output matrices at slightly higher quality."},{"type":"table","headers":["Quant Type","Bits/Weight","Size (7B)","PPL Increase vs F16","Use Case"],"rows":[["Q2_K","2.63","~2.7 GB","+5.0 – 8.0","Extreme compression, acceptable quality loss, very constrained RAM"],["Q3_K_M","3.35","~3.4 GB","+1.5 – 3.0","RAM-limited devices where Q4 does not fit; noticeable quality degradation"],["Q4_K_M","4.50","~4.6 GB","+0.1 – 0.2","Community default; best accuracy/size tradeoff for most 7B–13B models"],["Q5_K_M","5.50","~5.7 GB","+0.05 – 0.1","High quality; use when RAM permits and Q4_K_M PPL is measurably worse"],["Q6_K","6.56","~6.7 GB","+0.01 – 0.05","Near-lossless; justified only on very large models or sensitive tasks"],["Q8_0","8.50","~8.7 GB","~0.0","Reference quality for benchmarking; rarely needed over Q6_K in practice"],["F16","16.00","~14.0 GB","0.0 (baseline)","Full precision; GPU inference, fine-tuning starting point, conversion source"]]},{"type":"heading","level":2,"content":"K-Quants vs Legacy"},{"type":"text","content":"Legacy quants (Q4_0, Q5_0) use a simple block size of 32 with one float32 scale per block. K-quants use a super-block of 256 weights subdivided into 8 blocks of 32, with scales stored at 6-bit precision in the super-block header. The critical difference is that K-quants allow the quantization grid to adapt to local weight statistics within the super-block, rather than assuming a single scale works for all 256 weights. Empirically, Q4_K_M delivers 0.2–0.5 lower perplexity than Q4_0 on Llama-2 7B at nearly the same model size. For new GGUF files, legacy quants exist mainly for compatibility with older inference engines; the K-quant variants are strictly better and should be the default choice."},{"type":"heading","level":2,"content":"Conversion from HuggingFace"},{"type":"text","content":"Converting a HuggingFace checkpoint to GGUF is a two-step process. First, convert_hf_to_gguf.py (in the llama.cpp repo) reads the HuggingFace model directory and writes an F16 GGUF file — this is lossless. Second, the llama-quantize binary reads the F16 GGUF and writes a quantized GGUF to a target quant type. The quantize step is fast (minutes on CPU) and operates entirely on the GGUF file, so the original HuggingFace weights can be deleted after conversion."},{"type":"code","language":"python","content":"import subprocess\nimport os\nfrom pathlib import Path\n\ndef convert_and_quantize(\n    hf_model_dir: str,\n    output_dir: str,\n    quant_type: str = \"Q4_K_M\",\n    llama_cpp_dir: str = \"/opt/llama.cpp\"\n) -\u003e str:\n    \"\"\"Convert a HuggingFace model to GGUF and quantize to target type.\"\"\"\n    llama_path = Path(llama_cpp_dir)\n    out_path = Path(output_dir)\n    out_path.mkdir(parents=True, exist_ok=True)\n\n    # Step 1: HF -\u003e F16 GGUF (lossless)\n    f16_gguf = out_path / \"model-f16.gguf\"\n    convert_script = llama_path / \"convert_hf_to_gguf.py\"\n    print(f\"[1/2] Converting {hf_model_dir} -\u003e {f16_gguf}\")\n    result = subprocess.run(\n        [\"python3\", str(convert_script), hf_model_dir,\n         \"--outfile\", str(f16_gguf), \"--outtype\", \"f16\"],\n        capture_output=True, text=True, check=True\n    )\n    f16_size = f16_gguf.stat().st_size / 1e9\n    print(f\"    F16 GGUF: {f16_size:.2f} GB\")\n\n    # Step 2: F16 GGUF -\u003e quantized GGUF\n    quant_gguf = out_path / f\"model-{quant_type}.gguf\"\n    quantize_bin = llama_path / \"build\" / \"bin\" / \"llama-quantize\"\n    print(f\"[2/2] Quantizing to {quant_type} -\u003e {quant_gguf}\")\n    result = subprocess.run(\n        [str(quantize_bin), str(f16_gguf), str(quant_gguf), quant_type],\n        capture_output=True, text=True, check=True\n    )\n    q_size = quant_gguf.stat().st_size / 1e9\n    ratio = f16_size / q_size\n    print(f\"    Quantized: {q_size:.2f} GB  (compression {ratio:.1f}x)\")\n    return str(quant_gguf)\n\nif __name__ == \"__main__\":\n    out = convert_and_quantize(\"./mistral-7b-v0.1\", \"./gguf-out\", \"Q4_K_M\")\n    print(f\"Done: {out}\")"},{"type":"heading","level":2,"content":"Running with llama.cpp"},{"type":"text","content":"The llama-cpp-python package provides Python bindings for llama.cpp, enabling loading GGUF models directly in Python. The Llama class accepts the model path plus hardware parameters: n_gpu_layers controls how many transformer layers are offloaded to GPU (Metal on Apple Silicon, CUDA on NVIDIA). Setting n_gpu_layers=-1 offloads all layers. The n_ctx parameter sets the context window size. Generation returns token-by-token with optional streaming."},{"type":"code","language":"python","content":"import time\nfrom llama_cpp import Llama\n\ndef load_and_generate(\n    model_path: str,\n    prompt: str,\n    n_gpu_layers: int = 0,\n    n_ctx: int = 2048,\n    max_tokens: int = 128\n) -\u003e dict:\n    \"\"\"Load a GGUF model and run generation, reporting tokens/second.\"\"\"\n    print(f\"Loading {model_path} (n_gpu_layers={n_gpu_layers})...\")\n    llm = Llama(\n        model_path=model_path,\n        n_gpu_layers=n_gpu_layers,\n        n_ctx=n_ctx,\n        verbose=False\n    )\n    # Warmup pass\n    _ = llm(prompt, max_tokens=4, echo=False)\n\n    # Timed generation\n    t0 = time.perf_counter()\n    output = llm(prompt, max_tokens=max_tokens, echo=False, temperature=0.0)\n    elapsed = time.perf_counter() - t0\n\n    n_tokens = output[\"usage\"][\"completion_tokens\"]\n    tps = n_tokens / elapsed\n    text = output[\"choices\"][0][\"text\"]\n    print(f\"Generated {n_tokens} tokens in {elapsed:.2f}s ({tps:.1f} tok/s)\")\n    print(f\"Output: {text[:120]}...\")\n    return {\"tokens_per_second\": tps, \"text\": text}\n\nif __name__ == \"__main__\":\n    result = load_and_generate(\n        model_path=\"./gguf-out/model-Q4_K_M.gguf\",\n        prompt=\"Explain quantization in one paragraph:\",\n        n_gpu_layers=35\n    )\n    print(f\"Throughput: {result[\u0027tokens_per_second\u0027]:.1f} tok/s\")"},{"type":"code","language":"python","content":"import time\nimport math\nfrom llama_cpp import Llama\n\n# Benchmark multiple quant types — perplexity estimation via log-likelihood\nQUANT_TYPES = [\"Q2_K\", \"Q3_K_M\", \"Q4_K_M\", \"Q5_K_M\", \"Q8_0\"]\nMODEL_DIR = \"./gguf-out\"\n\nSAMPLE_TEXT = (\n    \"The transformer architecture relies on self-attention mechanisms \"\n    \"to capture long-range dependencies in sequences. Each attention head \"\n    \"independently learns to focus on different positions, and their outputs \"\n    \"are concatenated and projected back to the model dimension.\"\n)\n\nresults = []\nfor qtype in QUANT_TYPES:\n    model_path = f\"{MODEL_DIR}/model-{qtype}.gguf\"\n    try:\n        llm = Llama(model_path=model_path, n_ctx=512, verbose=False)\n        # Log-likelihood of sample text as PPL proxy\n        tokens = llm.tokenize(SAMPLE_TEXT.encode())\n        log_likelihood = llm.score(tokens, add_bos=True)\n        ppl_estimate = math.exp(-log_likelihood / max(len(tokens) - 1, 1))\n        # Measure generation speed\n        t0 = time.perf_counter()\n        _ = llm(SAMPLE_TEXT[:80], max_tokens=32, echo=False)\n        tps = 32 / (time.perf_counter() - t0)\n        results.append((qtype, ppl_estimate, tps))\n        print(f\"{qtype:\u003c12} PPL={ppl_estimate:6.2f}  {tps:6.1f} tok/s\")\n        del llm\n    except FileNotFoundError:\n        print(f\"{qtype:\u003c12} model not found at {model_path}\")\n\nprint(\"\\nSummary (sorted by PPL):\")\nfor qtype, ppl, tps in sorted(results, key=lambda x: x[1]):\n    print(f\"  {qtype}: PPL={ppl:.2f}, speed={tps:.1f} tok/s\")"},{"type":"code","language":"python","content":"import time\nfrom llama_cpp import Llama\n\ndef benchmark_gpu_offload(\n    model_path: str,\n    prompt: str = \"The capital of France is\",\n    max_tokens: int = 64\n):\n    \"\"\"Compare CPU-only, partial GPU, and full GPU offload throughput.\"\"\"\n    configs = [\n        {\"label\": \"CPU only\",      \"n_gpu_layers\": 0},\n        {\"label\": \"Partial GPU\",   \"n_gpu_layers\": 16},\n        {\"label\": \"Full GPU\",      \"n_gpu_layers\": -1},\n    ]\n    results = []\n    for cfg in configs:\n        llm = Llama(\n            model_path=model_path,\n            n_gpu_layers=cfg[\"n_gpu_layers\"],\n            n_ctx=512, verbose=False\n        )\n        # Warmup\n        _ = llm(prompt, max_tokens=4, echo=False)\n        t0 = time.perf_counter()\n        out = llm(prompt, max_tokens=max_tokens, echo=False, temperature=0.0)\n        elapsed = time.perf_counter() - t0\n        n_tok = out[\"usage\"][\"completion_tokens\"]\n        tps = n_tok / elapsed\n        results.append((cfg[\"label\"], cfg[\"n_gpu_layers\"], tps))\n        print(f\"{cfg[\u0027label\u0027]:\u003c14} layers={cfg[\u0027n_gpu_layers\u0027]:\u003e3}  {tps:6.1f} tok/s\")\n        del llm\n    best = max(results, key=lambda x: x[2])\n    print(f\"\\nBest: {best[0]} at {best[2]:.1f} tok/s\")\n    return results\n\nbenchmark_gpu_offload(\"./gguf-out/model-Q4_K_M.gguf\")"},{"type":"heading","level":2,"content":"Memory and Speed Tradeoffs"},{"type":"text","content":"The dominant factor in GGUF model performance is whether the entire model fits in GPU VRAM. When all layers are offloaded to GPU, inference runs at GPU memory bandwidth (typically 400–900 GB/s on modern consumer GPUs), delivering 50–150 tokens/second for a 7B model. When layers spill to CPU RAM, each layer transition incurs PCIe bandwidth overhead (typically 32–64 GB/s), dropping throughput substantially. On Apple Silicon, the unified memory architecture eliminates this distinction: Metal-backed llama.cpp runs GGUF models in unified RAM with GPU-like bandwidth. For CPU-only inference on x86, Q4_K_M is usually the fastest quant type because its 4.5-bit representation maximises the amount of model that fits in L3 cache relative to compute time."},{"type":"callout","variant":"tip","title":"Q4_K_M Community Default","content":"Q4_K_M is the community default for good reason: it hits the sweet spot of 4.5 bits per weight on average while keeping perplexity within 0.1–0.2 of FP16 for most models. Unless you are severely RAM-constrained (use Q3_K_M) or need near-lossless quality (use Q6_K), Q4_K_M is the right choice for 7B and 13B models."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["GGUF is self-contained: tokenizer, architecture metadata, and quantized tensors are all in one file — no separate config download.","Conversion is two steps: HF -\u003e F16 GGUF (convert_hf_to_gguf.py), then F16 GGUF -\u003e quantized GGUF (llama-quantize).","K-quants outperform legacy quants at the same bit rate; always prefer Q4_K_M over Q4_0 for new GGUF files.","Q4_K_M: 4.5 bits/weight, ~4.6 GB for 7B models, PPL within 0.1–0.2 of F16 — the community default.","Use n_gpu_layers=-1 in llama-cpp-python to offload all layers to GPU; partial offload is useful when VRAM is insufficient.","On Apple Silicon (Metal), llama.cpp uses unified memory — Q4_K_M 7B models run at 50–80 tok/s on M1/M2 without a discrete GPU.","Q8_0 is a lossless-quality reference quant; only justified for benchmarking or when GPU VRAM exceeds model size in F16.","Monitor RAM usage with n_ctx: a 7B Q4_K_M model uses ~4.6 GB for weights plus context KV cache (~0.5 GB per 2048 tokens at fp16)."]},{"type":"divider"}]"
---
# GGUF Format and llama.cpp Quantization

GGUF (GPT-Generated Unified Format) is the binary file format used by llama.cpp to store quantized large language models. Introduced in August 2023 as the successor to GGML, GGUF resolves the backwards-compatibility problems of its predecessor by embedding all model metadata — tokenizer vocabulary, hyperparameters, tensor names, and quantization type — directly in the file header. A single GGUF file is fully self-contained: you can load it on any platform supported by llama.cpp without separately downloading a config or tokenizer. This portability has made GGUF the dominant format for running quantized LLMs locally on consumer hardware.

## Overview

llama.cpp implements a family of quantization schemes ranging from 2-bit (Q2_K) to 8-bit (Q8_0), each trading model size and speed against perplexity degradation. The K-quant family (Q2_K, Q3_K_M, Q4_K_M, Q5_K_M, Q6_K) uses a two-level super-block structure and mixed-precision blocks to achieve better accuracy than the legacy integer quants at similar bit rates. The typical workflow is: (1) download or train a model in HuggingFace format; (2) convert to F16 GGUF using convert_hf_to_gguf.py; (3) quantize to a target type using the llama-quantize binary; (4) run inference with llama-cli or via the llama-cpp-python Python bindings.

## GGUF File Structure

A GGUF file starts with a fixed header: a 4-byte magic number (0x46554747, i.e. 'GGUF'), a uint32 version field (currently 3), and counts of tensors and key-value metadata entries. The metadata section stores arbitrary typed key-value pairs — model architecture, context length, rope parameters, tokenizer vocabulary, special token IDs, and more. Tensors are listed in a tensor info section (name, shape, dtype, byte offset) before the actual tensor data, which is stored contiguously and aligned to 32 bytes. This alignment allows memory-mapping the file directly for zero-copy loading on supported systems.

- Magic: 0x46554747 ('GGUF') — identifies the file as GGUF regardless of extension.
- Version: uint32, currently 3 — GGUF v1/v2 files from 2023 require conversion for modern llama.cpp.
- n_tensors / n_kv: counts used to parse the tensor info and metadata sections.
- Metadata KV pairs: general.architecture, general.name, llama.context_length, tokenizer.ggml.model, tokenizer.ggml.tokens, tokenizer.ggml.scores.
- Tensor data section: 32-byte aligned; amenable to mmap for fast load and partial GPU offload.
- Quantization type stored per tensor: each tensor independently records its ggml_type enum value.

## Quantization Types: Q4_K_M and Friends

The llama.cpp quantization type system distinguishes legacy quants (Q4_0, Q4_1, Q5_0, Q5_1, Q8_0) from the modern K-quants (Q2_K, Q3_K_M/S, Q4_K_M/S, Q5_K_M/S, Q6_K). Legacy quants use a flat block of 32 weights with a single scale and optional bias. K-quants group 256 weights into a super-block, within which 8 sub-blocks of 32 each carry their own scale; the super-block scales are stored at higher precision. This hierarchical structure captures local variation in weight magnitude better than a single global scale. The M/S suffixes (medium/small) in K-quants control which tensor layers get the higher-precision quantization treatment: M keeps attention and feed-forward output matrices at slightly higher quality.

| Quant Type | Bits/Weight | Size (7B) | PPL Increase vs F16 | Use Case |
| --- | --- | --- | --- | --- |
| Q2_K | 2.63 | ~2.7 GB | +5.0 – 8.0 | Extreme compression, acceptable quality loss, very constrained RAM |
| Q3_K_M | 3.35 | ~3.4 GB | +1.5 – 3.0 | RAM-limited devices where Q4 does not fit; noticeable quality degradation |
| Q4_K_M | 4.50 | ~4.6 GB | +0.1 – 0.2 | Community default; best accuracy/size tradeoff for most 7B–13B models |
| Q5_K_M | 5.50 | ~5.7 GB | +0.05 – 0.1 | High quality; use when RAM permits and Q4_K_M PPL is measurably worse |
| Q6_K | 6.56 | ~6.7 GB | +0.01 – 0.05 | Near-lossless; justified only on very large models or sensitive tasks |
| Q8_0 | 8.50 | ~8.7 GB | ~0.0 | Reference quality for benchmarking; rarely needed over Q6_K in practice |
| F16 | 16.00 | ~14.0 GB | 0.0 (baseline) | Full precision; GPU inference, fine-tuning starting point, conversion source |

## K-Quants vs Legacy

Legacy quants (Q4_0, Q5_0) use a simple block size of 32 with one float32 scale per block. K-quants use a super-block of 256 weights subdivided into 8 blocks of 32, with scales stored at 6-bit precision in the super-block header. The critical difference is that K-quants allow the quantization grid to adapt to local weight statistics within the super-block, rather than assuming a single scale works for all 256 weights. Empirically, Q4_K_M delivers 0.2–0.5 lower perplexity than Q4_0 on Llama-2 7B at nearly the same model size. For new GGUF files, legacy quants exist mainly for compatibility with older inference engines; the K-quant variants are strictly better and should be the default choice.

## Conversion from HuggingFace

Converting a HuggingFace checkpoint to GGUF is a two-step process. First, convert_hf_to_gguf.py (in the llama.cpp repo) reads the HuggingFace model directory and writes an F16 GGUF file — this is lossless. Second, the llama-quantize binary reads the F16 GGUF and writes a quantized GGUF to a target quant type. The quantize step is fast (minutes on CPU) and operates entirely on the GGUF file, so the original HuggingFace weights can be deleted after conversion.

```python
import subprocess
import os
from pathlib import Path

def convert_and_quantize(
    hf_model_dir: str,
    output_dir: str,
    quant_type: str = "Q4_K_M",
    llama_cpp_dir: str = "/opt/llama.cpp"
) -> str:
    """Convert a HuggingFace model to GGUF and quantize to target type."""
    llama_path = Path(llama_cpp_dir)
    out_path = Path(output_dir)
    out_path.mkdir(parents=True, exist_ok=True)

    # Step 1: HF -> F16 GGUF (lossless)
    f16_gguf = out_path / "model-f16.gguf"
    convert_script = llama_path / "convert_hf_to_gguf.py"
    print(f"[1/2] Converting {hf_model_dir} -> {f16_gguf}")
    result = subprocess.run(
        ["python3", str(convert_script), hf_model_dir,
         "--outfile", str(f16_gguf), "--outtype", "f16"],
        capture_output=True, text=True, check=True
    )
    f16_size = f16_gguf.stat().st_size / 1e9
    print(f"    F16 GGUF: {f16_size:.2f} GB")

    # Step 2: F16 GGUF -> quantized GGUF
    quant_gguf = out_path / f"model-{quant_type}.gguf"
    quantize_bin = llama_path / "build" / "bin" / "llama-quantize"
    print(f"[2/2] Quantizing to {quant_type} -> {quant_gguf}")
    result = subprocess.run(
        [str(quantize_bin), str(f16_gguf), str(quant_gguf), quant_type],
        capture_output=True, text=True, check=True
    )
    q_size = quant_gguf.stat().st_size / 1e9
    ratio = f16_size / q_size
    print(f"    Quantized: {q_size:.2f} GB  (compression {ratio:.1f}x)")
    return str(quant_gguf)

if __name__ == "__main__":
    out = convert_and_quantize("./mistral-7b-v0.1", "./gguf-out", "Q4_K_M")
    print(f"Done: {out}")
```

## Running with llama.cpp

The llama-cpp-python package provides Python bindings for llama.cpp, enabling loading GGUF models directly in Python. The Llama class accepts the model path plus hardware parameters: n_gpu_layers controls how many transformer layers are offloaded to GPU (Metal on Apple Silicon, CUDA on NVIDIA). Setting n_gpu_layers=-1 offloads all layers. The n_ctx parameter sets the context window size. Generation returns token-by-token with optional streaming.

```python
import time
from llama_cpp import Llama

def load_and_generate(
    model_path: str,
    prompt: str,
    n_gpu_layers: int = 0,
    n_ctx: int = 2048,
    max_tokens: int = 128
) -> dict:
    """Load a GGUF model and run generation, reporting tokens/second."""
    print(f"Loading {model_path} (n_gpu_layers={n_gpu_layers})...")
    llm = Llama(
        model_path=model_path,
        n_gpu_layers=n_gpu_layers,
        n_ctx=n_ctx,
        verbose=False
    )
    # Warmup pass
    _ = llm(prompt, max_tokens=4, echo=False)

    # Timed generation
    t0 = time.perf_counter()
    output = llm(prompt, max_tokens=max_tokens, echo=False, temperature=0.0)
    elapsed = time.perf_counter() - t0

    n_tokens = output["usage"]["completion_tokens"]
    tps = n_tokens / elapsed
    text = output["choices"][0]["text"]
    print(f"Generated {n_tokens} tokens in {elapsed:.2f}s ({tps:.1f} tok/s)")
    print(f"Output: {text[:120]}...")
    return {"tokens_per_second": tps, "text": text}

if __name__ == "__main__":
    result = load_and_generate(
        model_path="./gguf-out/model-Q4_K_M.gguf",
        prompt="Explain quantization in one paragraph:",
        n_gpu_layers=35
    )
    print(f"Throughput: {result['tokens_per_second']:.1f} tok/s")
```

```python
import time
import math
from llama_cpp import Llama

# Benchmark multiple quant types — perplexity estimation via log-likelihood
QUANT_TYPES = ["Q2_K", "Q3_K_M", "Q4_K_M", "Q5_K_M", "Q8_0"]
MODEL_DIR = "./gguf-out"

SAMPLE_TEXT = (
    "The transformer architecture relies on self-attention mechanisms "
    "to capture long-range dependencies in sequences. Each attention head "
    "independently learns to focus on different positions, and their outputs "
    "are concatenated and projected back to the model dimension."
)

results = []
for qtype in QUANT_TYPES:
    model_path = f"{MODEL_DIR}/model-{qtype}.gguf"
    try:
        llm = Llama(model_path=model_path, n_ctx=512, verbose=False)
        # Log-likelihood of sample text as PPL proxy
        tokens = llm.tokenize(SAMPLE_TEXT.encode())
        log_likelihood = llm.score(tokens, add_bos=True)
        ppl_estimate = math.exp(-log_likelihood / max(len(tokens) - 1, 1))
        # Measure generation speed
        t0 = time.perf_counter()
        _ = llm(SAMPLE_TEXT[:80], max_tokens=32, echo=False)
        tps = 32 / (time.perf_counter() - t0)
        results.append((qtype, ppl_estimate, tps))
        print(f"{qtype:<12} PPL={ppl_estimate:6.2f}  {tps:6.1f} tok/s")
        del llm
    except FileNotFoundError:
        print(f"{qtype:<12} model not found at {model_path}")

print("\nSummary (sorted by PPL):")
for qtype, ppl, tps in sorted(results, key=lambda x: x[1]):
    print(f"  {qtype}: PPL={ppl:.2f}, speed={tps:.1f} tok/s")
```

```python
import time
from llama_cpp import Llama

def benchmark_gpu_offload(
    model_path: str,
    prompt: str = "The capital of France is",
    max_tokens: int = 64
):
    """Compare CPU-only, partial GPU, and full GPU offload throughput."""
    configs = [
        {"label": "CPU only",      "n_gpu_layers": 0},
        {"label": "Partial GPU",   "n_gpu_layers": 16},
        {"label": "Full GPU",      "n_gpu_layers": -1},
    ]
    results = []
    for cfg in configs:
        llm = Llama(
            model_path=model_path,
            n_gpu_layers=cfg["n_gpu_layers"],
            n_ctx=512, verbose=False
        )
        # Warmup
        _ = llm(prompt, max_tokens=4, echo=False)
        t0 = time.perf_counter()
        out = llm(prompt, max_tokens=max_tokens, echo=False, temperature=0.0)
        elapsed = time.perf_counter() - t0
        n_tok = out["usage"]["completion_tokens"]
        tps = n_tok / elapsed
        results.append((cfg["label"], cfg["n_gpu_layers"], tps))
        print(f"{cfg['label']:<14} layers={cfg['n_gpu_layers']:>3}  {tps:6.1f} tok/s")
        del llm
    best = max(results, key=lambda x: x[2])
    print(f"\nBest: {best[0]} at {best[2]:.1f} tok/s")
    return results

benchmark_gpu_offload("./gguf-out/model-Q4_K_M.gguf")
```

## Memory and Speed Tradeoffs

The dominant factor in GGUF model performance is whether the entire model fits in GPU VRAM. When all layers are offloaded to GPU, inference runs at GPU memory bandwidth (typically 400–900 GB/s on modern consumer GPUs), delivering 50–150 tokens/second for a 7B model. When layers spill to CPU RAM, each layer transition incurs PCIe bandwidth overhead (typically 32–64 GB/s), dropping throughput substantially. On Apple Silicon, the unified memory architecture eliminates this distinction: Metal-backed llama.cpp runs GGUF models in unified RAM with GPU-like bandwidth. For CPU-only inference on x86, Q4_K_M is usually the fastest quant type because its 4.5-bit representation maximises the amount of model that fits in L3 cache relative to compute time.

> **Q4_K_M Community Default**: Q4_K_M is the community default for good reason: it hits the sweet spot of 4.5 bits per weight on average while keeping perplexity within 0.1–0.2 of FP16 for most models. Unless you are severely RAM-constrained (use Q3_K_M) or need near-lossless quality (use Q6_K), Q4_K_M is the right choice for 7B and 13B models.

## Key Takeaways

- GGUF is self-contained: tokenizer, architecture metadata, and quantized tensors are all in one file — no separate config download.
- Conversion is two steps: HF -> F16 GGUF (convert_hf_to_gguf.py), then F16 GGUF -> quantized GGUF (llama-quantize).
- K-quants outperform legacy quants at the same bit rate; always prefer Q4_K_M over Q4_0 for new GGUF files.
- Q4_K_M: 4.5 bits/weight, ~4.6 GB for 7B models, PPL within 0.1–0.2 of F16 — the community default.
- Use n_gpu_layers=-1 in llama-cpp-python to offload all layers to GPU; partial offload is useful when VRAM is insufficient.
- On Apple Silicon (Metal), llama.cpp uses unified memory — Q4_K_M 7B models run at 50–80 tok/s on M1/M2 without a discrete GPU.
- Q8_0 is a lossless-quality reference quant; only justified for benchmarking or when GPU VRAM exceeds model size in F16.
- Monitor RAM usage with n_ctx: a 7B Q4_K_M model uses ~4.6 GB for weights plus context KV cache (~0.5 GB per 2048 tokens at fp16).

---

