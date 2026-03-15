# VLM Model Guide

This document covers vision-language models (VLMs) compatible with `dam describe`. It lists tested models, hardware requirements, quality notes, and setup instructions for each inference backend.

dam tries the **Ollama native API** (`/api/generate`) first, falling back to the **OpenAI-compatible** `/v1/chat/completions` endpoint. Both use base64-encoded images. Any server that implements either API works — Ollama, llama.cpp, vLLM, LM Studio, SGLang, or cloud providers.

---

## Quick Start

1. Install [Ollama](https://ollama.com) (or another backend — see [Backends](#backends) below).
2. Pull a model: `ollama pull qwen2.5vl:3b`
3. Test connectivity: `dam describe --check`
4. Describe assets: `dam describe "description:none" --apply --log`

To switch models, either set `[vlm] model` in `dam.toml` or pass `--model` on the command line.

---

## Tested Models

All timings measured on Apple M3 Pro (18 GB) with Ollama, using preview images (~800px). Your results will vary with hardware, image size, and model quantization.

### Recommended for Photography

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Qwen2.5-VL 3B** `qwen2.5vl:3b` | **3 GB** `\newline`{=latex} (2.0 GB) | 8--12s | **Default.** Best balance of speed, quality, and resource use. Very good quality. |
| **Qwen3-VL 8B** `qwen3-vl:8b` | **6 GB** `\newline`{=latex} (5.2 GB) | 15--20s | **Recommended upgrade.** Excellent quality, noticeably better descriptions. |
| **Qwen3-VL 4B** `qwen3-vl:4b` | **4 GB** `\newline`{=latex} (2.8 GB) | 10--15s | Good step up from Qwen2.5-VL 3B without much extra RAM. Very good quality. |
| **Qwen2.5-VL 7B** `qwen2.5vl:7b` | **6 GB** `\newline`{=latex} (4.7 GB) | 20--36s | Proven, widely tested. Excellent quality. |
| **Gemma 3 4B** `gemma3:4b` | **4 GB** `\newline`{=latex} (3.3 GB) | 10--15s | Strong reasoning, good at scene understanding. Very good quality. |

### Budget / Batch Processing

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Moondream 2B** `moondream` | **2 GB** `\newline`{=latex} (1.7 GB) | 3--5s | Fastest option. Good for bulk first passes before refining with a larger model. |
| **SmolVLM 2.2B** `smolvlm` | **2 GB** `\newline`{=latex} (1.5 GB) | 4--8s | HuggingFace, very compact. Similar niche to Moondream. |

### Large / High Quality

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Qwen3-VL 32B** `qwen3-vl:32b` | **24 GB** `\newline`{=latex} (20 GB) | 60--90s | Best quality via Ollama. Needs 32 GB+ system RAM. Outstanding quality. |
| **LLaVA 1.6 7B** `llava:7b` | **6 GB** `\newline`{=latex} (4.7 GB) | 15--25s | Well-established, wide compatibility. Good quality. |

### Qwen3.5 (Next Generation)

Qwen3.5 models use **early fusion** — vision and text are processed jointly from the earliest layers, giving better visual reasoning than the separate-encoder approach of older models. All Qwen3.5 models are natively multimodal (no separate "-VL" variant).

| Model | RAM `\newline`{=latex} Download | Backend | Notes |
|-------------------:|---------:|----------------:|:----------------------------------------------------------------------|
| **Qwen3.5 4B** | **4 GB** `\newline`{=latex} (3 GB) | llama.cpp, vLLM | Comparable to Qwen3-VL 8B in some benchmarks. Very good quality. |
| **Qwen3.5 9B** | **8 GB** `\newline`{=latex} (6 GB) | llama.cpp, vLLM | Best quality-per-GB. Strong upgrade path. Excellent quality. |
| **Qwen3.5 27B** | **20 GB** `\newline`{=latex} (16 GB) | llama.cpp, vLLM | Needs significant RAM; best local quality. Outstanding quality. |

**Ollama caveat (as of March 2026):** Ollama cannot handle Qwen3.5 vision — the model's `mmproj` vision files are not supported yet. Text-only works, but image input silently fails. Use llama.cpp or vLLM for Qwen3.5 multimodal. This will likely be resolved in a future Ollama release.

---

## Backends

### Ollama (Recommended)

The simplest setup. Ollama manages model downloads, quantization, and serves an OpenAI-compatible API.

**Install:** https://ollama.com

```bash
# Pull a model
ollama pull qwen2.5vl:3b

# The server starts automatically; default endpoint is http://localhost:11434
dam describe --check
```

```toml
# dam.toml
[vlm]
endpoint = "http://localhost:11434"
model = "qwen2.5vl:3b"
```

**Supported models:** All models with Ollama vision support — Qwen2.5-VL, Qwen3-VL, LLaVA, Moondream, Gemma 3, SmolVLM. Not Qwen3.5 (see caveat above).

**Concurrency:** Ollama handles one request at a time by default. For `concurrency > 1`, set `OLLAMA_NUM_PARALLEL` environment variable or increase `num_parallel` in Ollama's config.

### llama.cpp

Direct inference with GGUF model files. Supports Qwen3.5 multimodal via the `--mmproj` flag.

**Install:** https://github.com/ggerganov/llama.cpp

```bash
# Download model files (e.g. from HuggingFace)
# You need both the main model and the vision projector (mmproj) file

# Start the server with vision support
llama-server \
  -m Qwen3.5-9B-Q4_K_M.gguf \
  --mmproj mmproj-BF16.gguf \
  --host 0.0.0.0 \
  --port 8080
```

```toml
# dam.toml
[vlm]
endpoint = "http://localhost:8080"
model = "Qwen3.5-9B"
```

**Key points:**
- Vision requires the `--mmproj` flag with the separate vision projector file
- Quantized GGUF files (Q4_K_M, Q5_K_M) reduce RAM needs significantly
- No automatic model management — you download and manage files yourself
- Serves the OpenAI-compatible API at `/v1/chat/completions`

### vLLM

High-throughput inference server, best for GPU machines and batch processing. Supports Qwen3.5 natively.

**Install:** https://docs.vllm.ai

```bash
# Requires vLLM 0.17.0+ for Qwen3.5
pip install vllm

# Start the server
vllm serve Qwen/Qwen3.5-9B --host 0.0.0.0 --port 8000
```

```toml
# dam.toml
[vlm]
endpoint = "http://localhost:8000"
model = "Qwen/Qwen3.5-9B"
concurrency = 4   # vLLM handles parallel requests well
```

**Key points:**
- Best throughput for batch processing (set `concurrency` higher)
- GPU recommended (CUDA, ROCm); CPU inference is slow
- Automatic model download from HuggingFace
- Full OpenAI-compatible API

### LM Studio

Desktop application with a GUI for model management and a built-in server.

**Install:** https://lmstudio.ai

```toml
# dam.toml
[vlm]
endpoint = "http://localhost:1234"
model = "qwen2.5-vl-3b"   # Use the model name shown in LM Studio
```

### Cloud APIs

Any OpenAI-compatible cloud API works. Note that cloud APIs charge per request and dam does not set authentication headers — use a local proxy if your endpoint requires an API key.

```toml
# dam.toml — example with a self-hosted proxy that adds auth
[vlm]
endpoint = "https://api.openai.com"
model = "gpt-4o"
```

---

## Choosing a Model

### By Use Case

| Scenario | Recommended Model | Why |
|------------------------------|--------------------------|----------------------------------------|
| **Daily use, modest hardware** | Qwen2.5-VL 3B | Fast, 3 GB RAM, good quality |
| **Best quality via Ollama** | Qwen3-VL 8B | Excellent descriptions, reasonable speed |
| **Bulk first pass** | Moondream 2B | 3--5s per image, good-enough descriptions |
| **Best local quality** | Qwen3.5 9B (llama.cpp) | Early fusion, strong reasoning |
| **32 GB+ Mac or GPU server** | Qwen3-VL 32B or Qwen3.5 27B | Near-cloud quality |
| **Tag suggestions** | Qwen3-VL 8B | Structured output reliability |
| **Architectural / technical** | Gemma 3 4B or Qwen3-VL 8B | Good at detail and materials |
| **Multilingual descriptions** | Qwen3.5 (any size) | 201 languages |

### By Hardware

| System RAM | GPU VRAM | Suggested Models |
|-------------|----------|-------------------------------------------------------|
| 8 GB | — | Moondream 2B, SmolVLM 2.2B |
| 16 GB | — | Qwen2.5-VL 3B (default), Gemma 3 4B, Qwen3-VL 4B |
| 24--32 GB | — | Qwen3-VL 8B, Qwen2.5-VL 7B, Qwen3.5 9B |
| 32 GB+ | — | Qwen3-VL 32B, Qwen3.5 27B |
| — | 8 GB | Qwen3-VL 8B (FP16), Qwen3.5 9B (Q4) |
| — | 16 GB+ | Qwen3.5 27B (Q4), Qwen3-VL 32B (Q4) |

---

## Model Comparison

### Qwen Model Generations

| | Qwen2.5-VL | Qwen3-VL | Qwen3.5 |
|--------------------------|------------------------------|------------------------------|-------------------------------|
| **Architecture** | Late fusion (separate vision encoder) | Late fusion (improved encoder) | Early fusion (native multimodal) |
| **Vision quality** | Good | Very good | Best |
| **Document understanding** | Good | Better | Best (90.8 OmniDocBench) |
| **Context length** | 128K | 128K | 256K |
| **Languages** | ~29 | ~119 | 201 |
| **Ollama vision** | Yes | Yes | Not yet |
| **llama.cpp vision** | Yes | Yes | Yes (with mmproj) |

For most users, **Qwen3-VL via Ollama** is the practical sweet spot right now. When Ollama adds Qwen3.5 vision support, it will become the clear best choice.

### Description Quality (Subjective)

Based on describing the same set of 50 photographs (landscapes, portraits, architecture, street):

- **Moondream 2B**: Short, accurate, occasionally generic. Good at identifying subjects, weaker on mood/lighting.
- **Qwen2.5-VL 3B**: Solid all-rounder. Good detail, reasonable sentence structure. Occasionally repetitive across similar images.
- **Qwen3-VL 4B**: Noticeable step up in vocabulary and scene understanding over Qwen2.5-VL 3B.
- **Gemma 3 4B**: Strong on materials, textures, and spatial relationships. Slightly less natural prose.
- **Qwen3-VL 8B**: Rich, natural descriptions. Good at lighting, mood, composition. Rarely generic.
- **Qwen2.5-VL 7B**: Similar quality to Qwen3-VL 8B but slower.
- **Qwen3.5 9B**: Best visual reasoning. Catches subtle details (reflections, depth of field, lens characteristics). Needs llama.cpp or vLLM.

---

## Thinking Models

Some models (Qwen3-VL, Qwen3.5) support "extended thinking" — they wrap internal chain-of-thought reasoning in `<think>...</think>` tags before producing the actual answer. This can consume most of the `max_tokens` budget with reasoning text, leaving little room for the description itself.

dam handles this automatically:

- Sends `think: false` to disable extended thinking (works with Ollama's native API)
- Strips any `<think>...</think>` tags from the response as a fallback
- Tries the Ollama native API first (where `think: false` is honored), falling back to the OpenAI-compatible endpoint

No configuration is needed — thinking models work out of the box. If you see empty or truncated descriptions, try increasing `max_tokens` (default 500) to give the model more headroom.

---

## Tips

**Start small, upgrade later.** Run `dam describe` with Moondream for a quick first pass, then re-describe the best assets with a larger model using `--force`:

```bash
dam describe "description:none" --model moondream --apply --log
dam describe "rating:4+" --model qwen3-vl:8b --apply --force --log
```

**Use `--mode tags` for discovery.** VLM-suggested tags can surface patterns you haven't tagged manually:

```bash
dam describe --mode tags "date:2024-06" --apply --log
```

**Lower temperature for batch consistency.** When describing hundreds of images, `--temperature 0` gives more uniform output:

```bash
dam describe "type:image" --temperature 0 --apply --log
```

**Increase timeout for first load.** Ollama loads the model into memory on first request, which can take 30--60 seconds for larger models:

```bash
dam describe --model qwen3-vl:8b --timeout 300 --asset a1b2c3d4
```

**Use per-model config for multi-model workflows.** If you switch between models frequently, set per-model overrides so each model gets its optimal settings automatically:

```toml
[vlm]
model = "qwen2.5vl:3b"
max_image_edge = 512
timeout = 300

[vlm.model_config."qwen3-vl:8b"]
timeout = 300
num_ctx = 8192

[vlm.model_config."moondream:latest"]
max_tokens = 200
temperature = 0.1
```

Now `dam describe --model qwen3-vl:8b` automatically uses the longer timeout and larger context window, while `dam describe --model moondream:latest` uses lower temperature and fewer tokens. See [Configuration Reference — per-model config](08-configuration.md#per-model-configuration) for full details.

**Tune sampling parameters per model.** Some models benefit from non-default sampling. Use `--num-ctx`, `--top-p`, `--top-k`, and `--repeat-penalty` on the CLI, or set them in `dam.toml` (globally or per-model). A value of zero means "not set — use server default":

```bash
dam describe "rating:5" --model qwen3-vl:8b --num-ctx 8192 --top-p 0.9 --apply --log
```

**Use concurrency with capable servers.** If your server handles parallel requests (vLLM, GPU Ollama with `OLLAMA_NUM_PARALLEL`):

```toml
[vlm]
concurrency = 4
```

---

## See Also

- [Configuration Reference — \[vlm\] section](08-configuration.md#vlm-section) — all configuration options
- [dam describe](02-ingest-commands.md#dam-describe) — command reference
- [Ingesting Assets](../user-guide/03-ingest.md) — auto-describe during import
