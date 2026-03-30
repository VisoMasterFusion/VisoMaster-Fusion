# Custom Kernels — faceparser_resnet34 (BiSeNet v1 Face Parser)

FP16 PyTorch reimplementation of `faceparser_resnet34.onnx`
(BiSeNet v1 with ResNet-34 backbone) with a single-capture CUDA graph.
Used as the **FaceParser** model in the application.

Model: **BiSeNet-v1 / ResNet-34**  `(1,3,512,512)f32 → (1,19,512,512)f32`
(fixed spatial dims at inference; 19-class face part segmentation)

---

## Benchmark Results

**Hardware:** NVIDIA GeForce RTX 4090 · PyTorch 2.8.0+cu129 · CUDA 12.9 · ORT 1.22.0
**Conditions:** 30 iterations, 5 warm-up, input 512×512

| Tier | Method | ms | vs ORT CUDA EP |
|------|--------|---:|:--------------:|
| 0    | ORT FP32 CUDA EP (baseline) | 4.05 ms | 1.00× |
| 0b   | ORT TensorRT EP FP32 | 3.28 ms | 1.23× |
| 1    | PyTorch FP32 | 3.40 ms | 1.19× |
| 2    | PyTorch FP16 | 3.07 ms | 1.32× |
| 2b   | PyTorch BF16 | 2.68 ms | 1.51× |
| **3** | **PT FP16 + CUDA graph** | **1.18 ms** | **3.44×** |
| **4** | **torch.compile (reduce-overhead) — `build_cuda_graph_runner(torch_compile=True)`** | **1.09 ms** | **4.01×** |

> **Application uses torch.compile reduce-overhead (Tier 4)** — **1.09 ms (4.01× vs ORT CUDA EP)**.
> Pass `torch_compile=True` to `build_cuda_graph_runner` (default in Custom provider).
> `torch.compile(default)` + manual CUDA graph fails on this model (same `current_seed` issue as yoloface_8n).
> Fixed by using `reduce-overhead` mode, which manages its own internal CUDA graphs.

**Accuracy (FP16 vs ORT FP32):** MAE = 9.91e-04, MaxAbsErr = 9.03e-03; Argmax pixel agreement = **99.91%**.

> **Note on accuracy baseline:** ORT CUDA EP runs some nodes on CPU due to
> asymmetric padding in the BiSeNet architecture, introducing rounding artefacts.
> PyTorch FP16 is the more numerically accurate reference.

### Speed-up Source

ResNet-34 + BiSeNet Context Path is a **pure Conv2d/ReLU/Sigmoid architecture**
(BatchNorm fully folded into Conv bias at ONNX export).  Speed-up comes from:

1. **FP16** — cuDNN dispatches Conv2d on FP16 weights to TensorCore GEMM
   kernels (~2× throughput vs FP32 on Ampere/Ada GPUs).
2. **CUDA graph** — eliminates Python/CUDA kernel-launch overhead across the
   full backbone; the 512×512 fixed input makes single-capture practical.
3. **torch.compile reduce-overhead** (Tier 4) — fuses ReLU/Conv sequences and
   captures its own internal CUDA graphs; achieves **1.09 ms (4.01×)** vs ORT.
   `mode="default"` + manual CUDA graph fails on Windows/sm_89 (`current_seed` issue).
   Fixed by using `reduce-overhead` mode, which bypasses the manual graph capture entirely.

---

## Architecture

Reverse-engineered from `model_assets/faceparser_resnet34.onnx`:

```
BiSeNet v1: ResNet-34 backbone + Context Path (ARM32/ARM16) + FFM + 3 output heads
Input: 512×512 RGB, float32, ImageNet-normalised
Output: (1, 19, 512, 512) class logits (primary head only at inference)
19 classes: background + 18 face parts (skin, hair, eyes, brows, nose, lips, etc.)
```

### ResNet-34 Backbone (BN folded into Conv bias)

```
Stem:    Conv(3→64, 7×7, s=2, p=3) + ReLU + MaxPool(3×3, s=2) → 64ch, 128×128

Layer 1: 3 × BasicBlock(64→64, s=1)         identity shortcut  → 64ch, 128×128
Layer 2: 1 × BasicBlock(64→128, s=2)        1×1 conv shortcut  → 128ch, 64×64  ← C3
         3 × BasicBlock(128→128, s=1)
Layer 3: 1 × BasicBlock(128→256, s=2)       1×1 conv shortcut  → 256ch, 32×32  ← C4
         5 × BasicBlock(256→256, s=1)
Layer 4: 1 × BasicBlock(256→512, s=2)       1×1 conv shortcut  → 512ch, 16×16  ← C5
         2 × BasicBlock(512→512, s=1)
```

**Strided BasicBlock shortcut**: `Conv1×1(in→out, s=2, bias=True)` (BN folded).

### Context Path

```
conv_avg:    GlobalAvgPool(C5) → Conv1×1(512→128) + ReLU → resize to C5 size (global ctx)

ARM32 (Attention Refinement Module at stride-32):
  conv_block: Conv3×3(512→128) + ReLU
  attention:  GlobalAvgPool → Conv1×1(128→128) → Sigmoid → channel-wise Mul
  out32 = arm32_feat * attn + global_ctx_resized
  conv_head32: resize(out32, ×2) → Conv3×3(128→128) + ReLU → 128ch, 32×32

ARM16 (Attention Refinement Module at stride-16):
  conv_block: Conv3×3(256→128) + ReLU
  attention:  GlobalAvgPool → Conv1×1(128→128) → Sigmoid → channel-wise Mul
  out16 = arm16_feat * attn + conv_head32
  conv_head16: resize(out16, ×2) → Conv3×3(128→128) + ReLU → 128ch, 64×64
```

### Feature Fusion Module (FFM)

```
Input: Concat(C3 [128ch], conv_head16 [128ch]) = 256ch, 64×64
  conv_block: Conv1×1(256→256) + ReLU
  SE attention:
    GlobalAvgPool → Conv1×1(256→64, no bias) + ReLU → Conv1×1(64→256, no bias) → Sigmoid
  ffm_out = conv_block_out + conv_block_out * SE_attn   (256ch, 64×64)
```

### Output Heads

```
conv_out   (primary): Conv3×3(256→256) + ReLU → Conv1×1(256→19) → Resize(8×) → 512×512
conv_out16 (aux):     Conv3×3(128→64)  + ReLU → Conv1×1(64→19)  → Resize(8×) → 512×512
conv_out32 (aux):     Conv3×3(128→64)  + ReLU → Conv1×1(64→19)  → Resize(16×)→ 512×512
```

Only `conv_out` is returned at inference time; the two auxiliary heads are
included solely for complete weight loading.

---

## Files

| File | Purpose |
|------|---------|
| `faceparser_resnet34_torch.py` | FP16 PyTorch BiSeNet/ResNet-34 + CUDA graph runner |
| `benchmark_faceparser.py` | 4-tier latency benchmark vs ORT baseline |
| `__init__.py` | Package marker |

---

## Application Integration

Select **"Custom"** in *Settings → General → Providers Priority*.

The `_faceparser_labels()` method in `face_masks.py` is then routed through
`FaceParserResnet34Torch` instead of the ONNX Runtime session:

```python
# Internal call path (face_masks.py):
from custom_kernels.faceparser_resnet34.faceparser_resnet34_torch import (
    FaceParserResnet34Torch, build_cuda_graph_runner,
)

model  = FaceParserResnet34Torch.from_onnx(onnx_path).cuda().eval()
runner = build_cuda_graph_runner(model)   # _CapturedGraph instance

# Per-call:
with torch.no_grad():
    logits = runner(x)           # (1,3,512,512) normalised → (1,19,512,512) float32
labels = logits.argmax(dim=1).squeeze(0)  # (512,512) long — 19 face classes
```

---

## Weight Loading

All **52 Conv2d** weights are loaded **positionally** by matching ONNX
topological Conv node order → PyTorch forward-execution order.

Most backbone weights use ONNX auto-generated names (`onnx::Conv_578` …
`onnx::Conv_717`).  A few neck/head weights have human-readable names
(`ffm.conv1.weight`, `conv_out.conv.weight`, etc.) but positional loading
handles both uniformly without needing a name-based mapping.

| Range | Module | Conv nodes |
|-------|--------|-----------|
| [0]   | Backbone stem | 1 |
| [1–6] | Layer 1 (×3 BasicBlock) | 6 |
| [7–15] | Layer 2 (×4 BasicBlock + downsample) | 9 |
| [16–28] | Layer 3 (×6 BasicBlock + downsample) | 13 |
| [29–35] | Layer 4 (×3 BasicBlock + downsample) | 7 |
| [36–45] | Context Path (conv_avg, ARM32/16, FFM) | 10 |
| [46–51] | Output heads (conv_out, conv_out16, conv_out32) | 6 |

Five Conv2d modules (`ffm.conv1`, `ffm.conv2`, `conv_out*.conv`) have
`bias=False` — positional loading skips bias for these automatically by
checking `onnx_node.input[2]`.
