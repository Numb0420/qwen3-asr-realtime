# Qwen3-ASR Realtime Server

> 当前支持的本地运行方式：`conda activate lingting` 后执行 `python run.py`。

Windows-local FastAPI server for [Qwen3-ASR](https://github.com/QwenLM/Qwen3-ASR)：ONNX Encoder (DirectML) + GGUF Decoder (Vulkan)。**只提供实时 WebSocket**，一次连接转一段音频。

## Features

### Speech-to-Text
- **Real-time WebSocket** — `WS /realtime/stream` accepts raw PCM for live transcription
- **One session, one utterance** — silence EOS, client `stop`, or 60s max → `final` then close
- **Multi-language** — auto-detects English, Chinese, Japanese, Cantonese, Hindi, Thai, and more

### Real-Time WebSocket
- **Backend endpoint (EOS)** — Silero VAD: silence ≥ `WS_EOS_SILENCE_MS` after speech ends the audio
- **Max 60 seconds** — accumulated 16 kHz PCM then `final` (`eos_reason=max_duration`) and disconnect
- **Client stop** — `{"action":"stop"}` also ends the session
- **Partials** — cumulative; client replaces, never appends. Final has **no `chars`**
- **Control commands** — `reset`, `config` (language, VAD), `stop`

### Performance
- **Priority scheduling** — WebSocket requests (priority 0) preempt HTTP uploads (priority 1) via min-heap queue
- **On-demand model loading** — model loads on first request, unloads after idle timeout (0 VRAM when idle)
- **Gateway + Worker mode** — proxy + subprocess split; killing worker reclaims all RAM/VRAM
- **Flash Attention 2** with graceful SDPA fallback
- **Pinned memory + CUDA stream** — async DMA pipeline for transfer/compute overlap

### Quantization & Acceleration (opt-in)
- **INT8 W8A8** via bitsandbytes (`QUANTIZE=int8`) — ~50% VRAM reduction
- **FP8** via torchao (`QUANTIZE=fp8`) — requires sm_89+ (Hopper/Ada Lovelace)
- **ONNX Runtime encoder** (`ONNX_ENCODER_PATH`) — ORT-accelerated encoder
- **TensorRT encoder** (`TRT_ENCODER_PATH`) — compiled TRT engine
- **CUDA Graphs warming** (`USE_CUDA_GRAPHS=true`) — kernel caching warmup passes
- **Speculative decoding** (`USE_SPECULATIVE=true`) — 0.6B draft + 1.7B verifier

### Observability
- **Structured logging** — loguru-based with configurable `LOG_LEVEL`
- **Request tracing** — `X-Request-ID` header propagated through gateway→worker→server
- **Atomic request logging** — every endpoint logs entry (params, size) and exit (duration, result)
- **Swagger UI** — interactive API docs at `/docs` with typed Pydantic schemas

## Quick Start

```bash
# Clone and start
git clone https://github.com/jaaacki/qwen3-asr.git
cd qwen3-asr
cp .env.example .env   # Adjust settings as needed
docker compose up -d

# Check health
curl http://localhost:8100/health

# Transcribe audio file
curl -X POST http://localhost:8100/v1/audio/transcriptions \
  -F "file=@audio.wav"

# Streaming transcription (SSE)
curl -X POST http://localhost:8100/v1/audio/transcriptions/stream \
  -F "file=@audio.wav" -N

# Generate subtitles
curl -X POST http://localhost:8100/v1/audio/subtitles \
  -F "file=@audio.wav" -F "mode=fast" -o subtitles.srt
```

For WebSocket real-time transcription, see [docs/WEBSOCKET_USAGE.md](docs/WEBSOCKET_USAGE.md).

## Requirements

- Docker with NVIDIA GPU support (`nvidia-docker2` or Docker 19.03+)
- NVIDIA GPU with CUDA 12.4 compatible driver
- ~4GB disk for model download (cached in `./models/`)
- ~3.5GB VRAM for ASR-1.7B model at runtime

## API Endpoints

### `GET /health`

Returns server status, model info, and GPU memory.

```json
{
  "status": "ok",
  "model_loaded": true,
  "model_id": "Qwen/Qwen3-ASR-1.7B",
  "cuda": true,
  "gpu_name": "NVIDIA GeForce RTX 4060",
  "gpu_allocated_mb": 3584,
  "gpu_reserved_mb": 3712
}
```

### `POST /v1/audio/transcriptions`

Transcribe an audio file. OpenAI-compatible.

| Parameter | Type | Default | Description |
|-----------|------|---------|-------------|
| `file` | file | required | Audio file (WAV, MP3, FLAC, OGG, AIFF, etc.) |
| `language` | string | `"auto"` | Language code (e.g. `en`, `zh`, `ja`) or `"auto"` |
| `return_timestamps` | bool | `false` | Include word-level timestamps |

```bash
curl -X POST http://localhost:8100/v1/audio/transcriptions \
  -F "file=@recording.wav" \
  -F "language=en" \
  -F "return_timestamps=true"
```

Response:
```json
{"text": "Hello world.", "language": "en"}
```

### `POST /v1/audio/transcriptions/stream`

Same parameters as transcription. Returns chunked SSE stream. Long audio (>5s) is split for progressive output.

```bash
curl -X POST http://localhost:8100/v1/audio/transcriptions/stream \
  -F "file=@recording.wav" -N
```

Each SSE event:
```
data: {"text": "Hello", "language": "en", "is_final": false, "chunk_index": 0}
data: {"text": "world.", "language": "en", "is_final": true, "chunk_index": 1}
data: {"done": true}
```

### `POST /v1/audio/subtitles`

Generate SRT subtitle file from audio.

| Parameter | Type | Default | Description |
|-----------|------|---------|-------------|
| `file` | file | required | Audio file |
| `language` | string | `"auto"` | Language code or `"auto"` |
| `mode` | string | `"accurate"` | `"accurate"` (ForcedAligner) or `"fast"` (heuristic) |
| `max_line_chars` | int | `42` | Maximum characters per subtitle line |

```bash
# Fast mode — no aligner needed, works on any GPU
curl -X POST http://localhost:8100/v1/audio/subtitles \
  -F "file=@recording.wav" \
  -F "mode=fast" \
  -o subtitles.srt

# Accurate mode — loads ForcedAligner (~5.8GB VRAM, needs >8GB GPU)
curl -X POST http://localhost:8100/v1/audio/subtitles \
  -F "file=@recording.wav" \
  -F "mode=accurate" \
  -o subtitles.srt
```

Output is standard `.srt` format:
```srt
1
00:00:00,000 --> 00:00:02,340
Hello, this is a test recording.

2
00:00:02,500 --> 00:00:05,120
The subtitles are generated automatically.
```

### `WS /realtime/stream`

Real-time WebSocket transcription. Accepts raw PCM 16-bit LE, 8 kHz or 16 kHz mono. Max 60 seconds.

| Query Parameter | Default | Description |
|-----------------|---------|-------------|
| `use_server_vad` | `true` | Enable server-side VAD (EOS on silence, skip leading silence) |

One connection = one utterance. End paths: silence EOS, `{"action":"stop"}`, or 60s cap. Final payload has `text` / `start` / `end` / `eos_reason`, no `chars`.

### `GET /docs`

Interactive Swagger UI with all endpoints and Pydantic request/response schemas.

## Configuration

All settings are configured via environment variables in `.env`. See [`.env.example`](.env.example) for a documented template.

### Core

| Variable | Default | Description |
|----------|---------|-------------|
| `PORT` | `8100` | Host port mapped to container port 8000 |
| `MODEL_ID` | `Qwen/Qwen3-ASR-1.7B` | HuggingFace model ID (`Qwen/Qwen3-ASR-0.6B` for speed) |
| `IDLE_TIMEOUT` | `120` | Seconds before unloading model from GPU (0 = keep loaded forever) |
| `REQUEST_TIMEOUT` | `300` | Max seconds per inference request |
| `LOG_LEVEL` | `INFO` | Log verbosity: `TRACE`, `DEBUG`, `INFO`, `WARNING`, `ERROR`, `CRITICAL` |

### WebSocket Streaming

| Variable | Default | Description |
|----------|---------|-------------|
| `WS_MAX_AUDIO_SECONDS` | `60` | Session PCM cap; then final + close (must be ≤ 60) |
| `WS_EOS_SILENCE_MS` | `600` | Backend endpoint: silence after speech before audio is considered ended |
| `WS_EARLY_SILENCE_MS` | `1000` | Longer silence required before ~0.8s of speech |
| `WS_PARTIAL_SECONDS` | `1.5` | Partial emit interval |
| `ASR_USE_SERVER_VAD` | `true` | Server-side VAD / EOS (overridable per-connection) |

### Subtitles

| Variable | Default | Description |
|----------|---------|-------------|
| `FORCED_ALIGNER_ID` | `Qwen/Qwen3-ForcedAligner-0.6B` | HuggingFace model for accurate mode alignment |
| `SUBTITLE_MAX_DURATION` | `7.0` | Max duration per subtitle block (seconds) |
| `SUBTITLE_PAUSE_THRESHOLD` | `0.5` | Pause duration that triggers subtitle break (seconds) |
| `SUBTITLE_MIN_DURATION` | `0.833` | Minimum subtitle display time (seconds) |
| `SUBTITLE_MIN_GAP` | `0.083` | Minimum gap between subtitles (seconds) |

### SSE Streaming

| Variable | Default | Description |
|----------|---------|-------------|
| `SSE_CHUNK_SECONDS` | `5` | Duration of each SSE chunk for long audio (seconds) |
| `SSE_OVERLAP_SECONDS` | `1` | Overlap between SSE chunks (seconds) |

### Performance & Quantization

| Variable | Default | Description |
|----------|---------|-------------|
| `QUANTIZE` | `""` | `int8` (bitsandbytes W8A8) or `fp8` (torchao, sm_89+) |
| `USE_CUDA_GRAPHS` | `false` | Extra warmup passes for CUDA kernel caching |
| `DUAL_MODEL` | `false` | Load 0.6B model for WebSocket partials alongside 1.7B |
| `FAST_MODEL_ID` | `Qwen/Qwen3-ASR-0.6B` | Model used for partials/draft in dual/speculative mode |
| `USE_SPECULATIVE` | `false` | Speculative decoding (0.6B draft + 1.7B verifier) |
| `ONNX_ENCODER_PATH` | `""` | Path to exported ONNX encoder |
| `TRT_ENCODER_PATH` | `""` | Path to compiled TensorRT engine |

### Infrastructure

| Variable | Default | Description |
|----------|---------|-------------|
| `GATEWAY_MODE` | `false` | Run as gateway proxy + worker subprocess (recommended for production) |
| `WORKER_HOST` | `127.0.0.1` | Worker host (used by gateway) |
| `WORKER_PORT` | `8001` | Worker port (used by gateway) |
| `NUMA_NODE` | `0` | NUMA node for CPU affinity (pins to GPU-collocated CPUs) |
| `USE_GRANIAN` | `false` | Use Granian (Rust-based ASGI) instead of uvicorn |

### Docker / CUDA

| Variable | Default | Description |
|----------|---------|-------------|
| `PYTORCH_CUDA_ALLOC_CONF` | `expandable_segments:True` | PyTorch CUDA memory allocator tuning |

## Supported Audio Formats

HTTP endpoints accept any format supported by libsndfile:
**WAV, FLAC, MP3, OGG, AIFF, CAF, AU, W64, RF64**, and more.

Not supported: MP4, AAC, M4A (soundfile limitation).

WebSocket accepts **raw PCM only**: 16-bit little-endian, 16kHz, mono.

## Project Structure

```
qwen3-asr/
├── compose.yaml          # Docker Compose configuration
├── Dockerfile            # Container build (all deps pinned)
├── .env.example          # Documented env var template
├── src/
│   ├── server.py         # FastAPI server — inference, WebSocket, SSE
│   ├── gateway.py        # Gateway proxy (GATEWAY_MODE=true)
│   ├── worker.py         # Inference worker subprocess
│   ├── subtitle.py       # Subtitle generation (aligner, segmentation, SRT)
│   ├── logger.py         # Loguru structured logging + uvicorn interception
│   ├── schemas.py        # Pydantic models for Swagger UI documentation
│   ├── config.py         # Config validation and extracted constants
│   ├── errors.py         # Standardized error response helper
│   ├── export_onnx.py    # Export encoder to ONNX Runtime
│   ├── build_trt.py      # Build TensorRT encoder engine
│   └── debug_audio.py    # Debug audio preprocessing locally
├── E2Etest/              # pytest E2E test suite
├── docs/
│   ├── WEBSOCKET_USAGE.md
│   └── GRANIAN_BENCHMARK.md
├── models/               # HuggingFace model cache (auto-populated)
├── CHANGELOG.md
├── ROADMAP.md
└── LEARNING_LOG.md
```

## License

Apache 2.0
