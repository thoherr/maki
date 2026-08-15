# VLM Model Guide *(Pro)* {#vlm-model-guide}

This document covers vision-language models (VLMs) compatible with `maki describe`. It lists tested models, hardware requirements, quality notes, and setup instructions for each inference backend.

MAKI tries the **Ollama native API** (`/api/generate`) first, falling back to the **OpenAI-compatible** `/v1/chat/completions` endpoint. Both use base64-encoded images. Any server that implements either API works — Ollama, llama.cpp, vLLM, LM Studio, SGLang, or cloud providers.

> **Model swap is pure config.** Switching VLMs requires zero code changes. Pull the new model with your backend, change `[vlm] model` in `maki.toml` (or pass `--model` on the CLI), restart `maki serve` if it's running. MAKI knows nothing about which model is loaded — it sends a base64 image + prompt to an HTTP endpoint and accepts whatever JSON comes back.

---

## Quick Start

1. Install [Ollama](https://ollama.com) (or another backend — see [Backends](#backends) below).
2. Pull a model: `ollama pull qwen2.5vl:3b`
3. Test connectivity: `maki describe --check`
4. Describe assets: `maki describe "description:none" --apply --log`

To switch models, either set `[vlm] model` in `maki.toml` or pass `--model` on the command line.

---

## Should I Upgrade?

The answer is usually "stick with what works." The descriptions you're getting from your current model are good enough for *navigation* — that's the bar `maki describe` is trying to clear, not poet-grade prose. The clearest upgrade paths from popular defaults:

- `gemma3:4b` → `gemma4:e4b` — same effective compute, native multimodal (vs Gemma 3's bolt-on projector), 128K context, native system prompts. Similar latency on equivalent hardware.
- `qwen2.5vl:3b` → `qwen3.5:4b` — the current Qwen generation (natively multimodal, no separate `-VL`) at the same size class; or `qwen3.5:9b` for a clear quality jump. The `qwen3-vl` line (`qwen3-vl:4b`/`:8b`) is the well-trodden previous generation and still an excellent choice if you prefer it.
- `moondream` → `gemma4:e2b` — same speed bracket, much better visual reasoning.

Upgrading helps in specific cases:

- **Generic / repetitive descriptions on similar images.** A 3 B model often falls back to template language ("a beautiful landscape with mountains and a clear sky"). Stepping up to a 7–8 B model usually breaks the pattern.
- **Wrong subject identification.** If the model mistakes a horse for a dog, or a wedding for a concert, a larger model with stronger visual reasoning helps. Verify with a small A/B batch before committing.
- **OCR / text-in-image needs.** If you've been asking the model to read signage, license plates, or document scans, the Qwen-VL family (especially 7 B+) is significantly stronger here than Gemma 3.
- **Multilingual descriptions.** If you want descriptions in German, Japanese, etc., Qwen models cover 100+ languages out of the box; Gemma is English-centric.

Stay on your current model if:

- **Descriptions are useful for search and you don't read them word-by-word.** The marginal quality gain from 4 B → 8 B costs you ~2–3× the inference time on the same hardware.
- **You're batch-processing 1000+ images.** Doubling latency per image matters at scale.
- **Hardware is tight.** A 4 B model running comfortably in RAM beats an 8 B model swapping to disk by every metric.

### Testing a Candidate Model on Your Own Photos

The honest way to decide is a small A/B on photos *you* care about. The web UI's per-asset model selector and the CLI's `--model` flag make this trivial:

```bash
# 1. Pull the candidate model.
ollama pull qwen3-vl:8b

# 2. Add it to your maki.toml so it appears in the web UI's per-asset
#    Describe dropdown without disturbing your default.
#
# [vlm]
# model = "gemma3:4b"                # your current default stays
# models = ["gemma3:4b", "qwen3-vl:8b"]  # both available in the dropdown

# 3. Pick 20 representative assets, generate descriptions with each
#    model, compare side-by-side. `--force` overwrites the existing
#    description on each iteration so you can re-run.
maki describe "rating:5 date:2026-05" --model gemma3:4b --apply --force --log
maki describe "rating:5 date:2026-05" --model qwen3-vl:8b --apply --force --log
```

Or use the web UI: open an asset's detail page, click **Describe** with the model selector set to one candidate, then re-run with the other. The descriptions overwrite each other so you're always seeing the latest.

---

## Tested Models

All timings measured on Apple M3 Pro (18 GB) with Ollama, using preview images (~800px) at default Q4 quantization. Your results will vary with hardware, image size, and quantization. Verify model availability on your backend's library page (e.g. `ollama.com/library/<name>`) — model rosters move faster than these docs.

### Recommended for Photography

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Qwen2.5-VL 3B** `qwen2.5vl:3b` | **3 GB** `\newline`{=latex} (2.0 GB) | 8--12s | **Default.** Best balance of speed, quality, and resource use. Very good quality. |
| **Gemma 4 E4B** `gemma4:e4b` | **10 GB** `\newline`{=latex} (9.6 GB) | 10--15s | **Recommended upgrade from Gemma 3 4B.** Native multimodal, 128K context, native system prompts. |
| **Qwen3-VL 8B** `qwen3-vl:8b` | **6 GB** `\newline`{=latex} (5.2 GB) | 15--20s | Excellent quality, noticeably better than 2.5-VL. Previous-gen; see Qwen3.5/3.6 below for the current line. |
| **Qwen3-VL 4B** `qwen3-vl:4b` | **4 GB** `\newline`{=latex} (2.8 GB) | 10--15s | Good step up from Qwen2.5-VL 3B without much extra RAM. Very good quality. |
| **Qwen2.5-VL 7B** `qwen2.5vl:7b` | **6 GB** `\newline`{=latex} (4.7 GB) | 20--36s | Proven, widely tested. Excellent quality. |
| **Gemma 3 4B** `gemma3:4b` | **4 GB** `\newline`{=latex} (3.3 GB) | 10--15s | Strong reasoning, good at scene understanding. Very good quality. |

### Budget / Batch Processing

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Moondream 2B** `moondream` | **2 GB** `\newline`{=latex} (1.7 GB) | 3--5s | Fastest option. Good for bulk first passes before refining with a larger model. |
| **Gemma 4 E2B** `gemma4:e2b` | **8 GB** `\newline`{=latex} (7.2 GB) | 6--10s | Smaller Gemma 4 variant; faster than E4B while keeping the new generation's prompting + 128K context. |

SmolVLM was previously listed here; it has been removed from the Ollama
library (`ollama pull smolvlm` no longer resolves — only
community-namespaced re-uploads remain), and Moondream / Gemma 4 E2B
cover the same niche. Moondream 3 (a 9B-MoE preview with much stronger
visual reasoning) exists on HuggingFace but is not in the Ollama library
yet.

### Large / High Quality

| Model | RAM `\newline`{=latex} Download | Speed | Notes |
|-------------------:|---------:|--------:|:----------------------------------------------------------------------|
| **Qwen3-VL 32B** `qwen3-vl:32b` | **24 GB** `\newline`{=latex} (20 GB) | 60--90s | Best Qwen quality via Ollama. Needs 32 GB+ system RAM. Outstanding quality. |
| **Gemma 4 26B** `gemma4:26b` | **22 GB** `\newline`{=latex} (18 GB) | 50--80s | MoE architecture (25 B total / 3.8 B active); strong quality with moderate active-weight footprint. 256K context. |
| **Gemma 4 31B** `gemma4:31b` | **24 GB** `\newline`{=latex} (20 GB) | 70--100s | Largest dense Gemma 4; near-cloud quality on a workstation. 256K context. |
| **LLaVA 1.6 7B** `llava:7b` | **6 GB** `\newline`{=latex} (4.7 GB) | 15--25s | Well-established, wide compatibility. Good quality. |

### Qwen3.5 & Qwen3.6 (Current Native-Multimodal Generation)

The Qwen line moved on from the `-VL` split: **Qwen3.5** (shipped early
2026) and **Qwen3.6** (the newest) are natively multimodal across every
size — no separate "-VL" variant — and generally out-reason the Qwen-VL
models at similar parameter counts. These are the current mainstream
Qwen recommendation; `qwen3-vl` is the still-solid previous generation.

**Qwen3.5** — the everyday line, with the full size range on Ollama:

| Model | RAM `\newline`{=latex} Download | Notes |
|-------------------:|---------:|:----------------------------------------------------------------------|
| **Qwen3.5 2B** `qwen3.5:2b` | **3 GB** | Budget / batch; fast. |
| **Qwen3.5 4B** `qwen3.5:4b` | **4 GB** | **Recommended everyday upgrade from Qwen2.5-VL 3B** — same class, current architecture. |
| **Qwen3.5 9B** `qwen3.5:9b` | **8 GB** | Clear quality jump; the sweet spot when RAM allows. |
| **Qwen3.5 27B** `qwen3.5:27b` | **20 GB** | High quality on a workstation. |
| **Qwen3.5 35B** `qwen3.5:35b` | **24 GB** | Largest widely-available variant. |

**Qwen3.6** — the newest generation; on Ollama currently only the
larger sizes are published (`qwen3.6:27b` ~17 GB, `qwen3.6:35b`
~24 GB), so it's a "best local quality" option rather than an everyday
one until smaller variants land.

**Vision on Ollama — 3.5 yes, 3.6 not yet (as of August 2026):**
current Ollama releases handle the **Qwen3.5** vision path correctly
(only quite old versions silently dropped image input). **Qwen3.6**
image input is *not* wired up in Ollama yet — the library page shows an
"image input" badge and text generation works, but the separate vision
projector isn't loaded, so `maki describe` gets text-only behavior. For
Qwen3.6 vision use llama.cpp or LM Studio. Quick test either way:
describe an obviously distinctive image (e.g. a sunset over water) — a
generic answer that could fit any photo means vision isn't wired up.
Newer Qwen generations keep appearing (Ollama just added Qwen 3.8
support); run the same smoke test before adopting one for `describe`.

### Gemma 4 (Native Multimodal)

Google's Gemma 4 is natively multimodal — vision (and audio on the smaller variants) baked into the same model rather than glued on via a separate projector. Compared to Gemma 3: 128K context (vs 8K), native system-prompt support, configurable "thinking" modes, and a noticeable step up on coding / structured-output benchmarks. For photographic description specifically the practical wins are the longer context (room for richer prompts + multi-image comparisons in the future) and the native system-prompt slot (cleaner instruction-following than Gemma 3's in-content prompts).

| Variant | Tag | Effective Params | Modalities | Notes |
|--------:|----:|-----------------:|-----------:|:------|
| E2B | `gemma4:e2b` | 2.3 B (5.1 B w/ embeddings) | text + image + audio | Compact, fast. Smaller-than-Gemma-3-4B effective compute. |
| E4B | `gemma4:e4b` | 4.5 B (8 B w/ embeddings) | text + image + audio | **Direct upgrade path for `gemma3:4b` users.** Similar effective size, newer architecture, longer context. |
| 12B | `gemma4:12b` | 12 B | text + image | Mid-size dense; a step above E4B when RAM allows, below the 26B MoE. |
| 26B MoE | `gemma4:26b` | 25.2 B total / 3.8 B active | text + image | MoE — only ~3.8 B weights active per token, large total. Good quality / active-weight ratio. |
| 31B Dense | `gemma4:31b` | 30.7 B | text + image | Largest dense variant; best local Gemma 4 quality. |

**Vision-only requires the standard quant tags.** Variants tagged `-mlx-bf16`, `-mxfp8`, or `-nvfp4` are text-only optimisations for specific accelerators and silently drop image input. Stick with the default tags (`gemma4:e2b`, `gemma4:e4b`, `gemma4:26b`, `gemma4:31b`) — or the explicit `-it-q4_K_M` / `-it-q8_0` quants — for `maki describe`. A quick smoke test matches the Qwen3.5 case: describe a distinctive image and check whether the answer is plausibly visual.

Audio support on E2B / E4B is interesting but `maki describe` only sends images — the audio modality is unused.

---

## Backends

### Ollama (Recommended)

The simplest setup. Ollama manages model downloads, quantization, and serves an OpenAI-compatible API.

**Install:** https://ollama.com

```bash
# Pull a model
ollama pull qwen2.5vl:3b

# The server starts automatically; default endpoint is http://localhost:11434
maki describe --check
```

```toml
# maki.toml
[vlm]
endpoint = "http://localhost:11434"
model = "qwen2.5vl:3b"
```

**Supported models:** All models with Ollama vision support — Qwen2.5-VL, Qwen3-VL, Qwen3.5 (current Ollama releases), Gemma 3, Gemma 4 (text+image variants, see caveat above), LLaVA, Moondream. Qwen3.6 vision is not wired up in Ollama yet (text-only there; see above).

**Concurrency:** Ollama handles one request at a time by default. For `concurrency > 1`, set `OLLAMA_NUM_PARALLEL` environment variable or increase `num_parallel` in Ollama's config.

**Apple Silicon — MLX backend.** Recent Ollama releases (early 2026 onwards) bundle Apple's MLX framework as the default inference path on Apple Silicon, with measurable wins on per-token latency and energy use vs the GGUF/llama.cpp backend. Most models pick this up automatically when the relevant `*-mlx-*` quants are available; some have MLX-only text-mode tags (notably the Gemma 4 `-mlx-bf16` series) that silently drop image input — use the standard tags for `maki describe`. No MAKI config changes needed; the speedup is transparent on the HTTP API.

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
# maki.toml
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
# maki.toml
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
# maki.toml
[vlm]
endpoint = "http://localhost:1234"
model = "qwen2.5-vl-3b"   # Use the model name shown in LM Studio
```

### Cloud APIs

Any OpenAI-compatible cloud API works. Note that cloud APIs charge per request and maki does not set authentication headers — use a local proxy if your endpoint requires an API key.

```toml
# maki.toml — example with a self-hosted proxy that adds auth
[vlm]
endpoint = "https://api.openai.com"
model = "gpt-5.1-chat-latest"
```

(Older examples used `gpt-4o`; OpenAI retired that model in 2026 —
use a current GPT-5.x identifier.)

---

## Choosing a Model

### By Use Case

| Scenario | Recommended Model | Why |
|------------------------------|--------------------------|----------------------------------------|
| **Daily use, modest hardware** | Qwen2.5-VL 3B | Fast, 3 GB RAM, good quality |
| **Direct upgrade from Gemma 3** | Gemma 4 E4B | Native multimodal, 128K context, similar latency |
| **Best quality via Ollama** | Qwen3.5 9B, Qwen3-VL 8B, or Gemma 4 E4B | Excellent descriptions, reasonable speed |
| **Bulk first pass** | Moondream 2B or Gemma 4 E2B | 3--10s per image, good-enough descriptions |
| **Best local quality** | Gemma 4 31B or Qwen3.5 27B | Strongest reasoning at workstation RAM |
| **32 GB+ Mac or GPU server** | Qwen3-VL 32B / Gemma 4 31B / Qwen3.5 27B | Near-cloud quality |
| **Tag suggestions** | Qwen3-VL 8B or Gemma 4 E4B | Structured output reliability |
| **Architectural / technical** | Gemma 4 E4B or Qwen3-VL 8B | Good at detail and materials |
| **Multilingual descriptions** | Qwen3.5 (any size) | 201 languages |
| **Apple Silicon, low energy** | any Gemma 4 / Qwen variant on recent Ollama | MLX backend kicks in automatically |

### By Hardware

| System RAM | GPU VRAM | Suggested Models |
|-------------|----------|-------------------------------------------------------|
| 8 GB | — | Moondream 2B, Gemma 4 E2B |
| 16 GB | — | Qwen2.5-VL 3B (default), Gemma 3 4B, Qwen3-VL 4B, Gemma 4 E4B |
| 24--32 GB | — | Qwen3-VL 8B, Qwen2.5-VL 7B, Qwen3.5 9B, Gemma 4 26B |
| 32 GB+ | — | Qwen3-VL 32B, Qwen3.5 27B, Gemma 4 31B |
| — | 8 GB | Qwen3-VL 8B (FP16), Qwen3.5 9B (Q4), Gemma 4 E4B |
| — | 16 GB+ | Qwen3.5 27B (Q4), Qwen3-VL 32B (Q4), Gemma 4 31B |

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
| **Ollama vision** | Yes | Yes | Yes (current releases) |
| **llama.cpp vision** | Yes | Yes | Yes (with mmproj) |

For most users, **Qwen3.5 via Ollama** (`qwen3.5:4b` or `:9b`) is the practical sweet spot now that Ollama wires up its vision path; **Qwen3-VL** remains a well-tested fallback. Qwen3.6 vision is not available via Ollama yet (see above).

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

MAKI handles this automatically:

- Sends `think: false` to disable extended thinking (works with Ollama's native API)
- Strips any `<think>...</think>` tags from the response as a fallback
- Tries the Ollama native API first (where `think: false` is honored), falling back to the OpenAI-compatible endpoint

No configuration is needed — thinking models work out of the box. If you see empty or truncated descriptions, try increasing `max_tokens` (default 500) to give the model more headroom.

---

## Tips

**Start small, upgrade later.** Run `maki describe` with Moondream for a quick first pass, then re-describe the best assets with a larger model using `--force`:

```bash
maki describe "description:none" --model moondream --apply --log
maki describe "rating:4+" --model qwen3-vl:8b --apply --force --log
```

**Use `--mode tags` for discovery.** VLM-suggested tags can surface patterns you haven't tagged manually:

```bash
maki describe --mode tags "date:2024-06" --apply --log
```

**Lower temperature for batch consistency.** When describing hundreds of images, `--temperature 0` gives more uniform output:

```bash
maki describe "type:image" --temperature 0 --apply --log
```

**Increase timeout for first load.** Ollama loads the model into memory on first request, which can take 30--60 seconds for larger models:

```bash
maki describe --model qwen3-vl:8b --timeout 300 --asset a1b2c3d4
```

**Use per-model config for multi-model workflows.** If you switch between models frequently, set per-model overrides so each model gets its optimal settings automatically. Each `[vlm.model_config."name"]` section merges on top of the global `[vlm]` settings when that model runs, and CLI flags still win over both:

```toml
[vlm]
endpoint = "http://localhost:11434"
model = "qwen2.5vl:3b"                  # the default for plain `maki describe`
models = ["qwen2.5vl:3b", "qwen3-vl:8b", "moondream:latest"]  # web UI dropdown
max_image_edge = 512                    # global: resize before sending
timeout = 300                           # global: 5 min server-side

# Bigger model — needs more time to load + more context for richer prompts.
# Lower temperature because we want more deterministic output on careful runs.
[vlm.model_config."qwen3-vl:8b"]
timeout = 600                           # first-load can take 1-2 min on cold start
num_ctx = 8192                          # extended thinking benefits from headroom
temperature = 0.3                       # less creative, more grounded

# Fast bulk pass — short outputs, near-zero temperature for consistency,
# tiny image edge to maximise throughput.
[vlm.model_config."moondream:latest"]
max_tokens = 200
temperature = 0.1
max_image_edge = 384
```

Each override answers a specific question:

- `timeout`: how long the HTTP client waits for the server to respond. Larger models need more on cold start (Ollama loads weights into RAM the first time).
- `num_ctx`: the model's context window. Thinking models (Qwen3-VL, Qwen3.5) need 4 K+ for the `<think>…</think>` block plus the actual answer to fit.
- `temperature`: 0.0 = deterministic, 1.0 = creative. For batch-describing many photos consistently, low temperature reduces "look at this beautiful…" boilerplate.
- `max_image_edge`: longest-edge pixel cap before resize. Smaller = faster encode + faster model. 384–512 is plenty for caption-style descriptions; 768 if you're asking the model to OCR or count things.
- `max_tokens`: response length cap. Tiny for moondream-style one-liners; default 500 for richer captions.

See [Configuration Reference — per-model config](08-configuration.md#per-model-configuration) for the merge precedence rules and field-by-field reference.

**Tune sampling parameters per model.** Some models benefit from non-default sampling. Use `--num-ctx`, `--top-p`, `--top-k`, and `--repeat-penalty` on the CLI, or set them in `maki.toml` (globally or per-model). A value of zero means "not set — use server default":

```bash
maki describe "rating:5" --model qwen3-vl:8b --num-ctx 8192 --top-p 0.9 --apply --log
```

**Use concurrency with capable servers.** If your server handles parallel requests (vLLM, GPU Ollama with `OLLAMA_NUM_PARALLEL`):

```toml
[vlm]
concurrency = 4
```

---

## See Also

- [Configuration Reference — \[vlm\] section](08-configuration.md#vlm-section) — all configuration options
- [maki describe](02-ingest-commands.md#maki-describe) — command reference
- [Ingesting Assets](../user-guide/03-ingest.md) — auto-describe during import
