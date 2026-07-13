# Atheer-Rust: A Mobile-First Inference Engine for On-Device LLMs

> **Technical Whitepaper** · July 2026
>
> A cross-platform inference engine for large language models on iOS and Android,
> architected for NPU-first acceleration, predictive thermal management, hierarchical
> memory, structured generation, and autonomous agent loops — all in safe Rust.

---

## Abstract

Deploying large language models (LLMs) on mobile devices presents a unique set of
challenges: limited thermal budgets (phones throttle at ~45 °C), fragmented accelerator
hardware (ANE, NPU, GPU, DSP across iOS and Android), tight memory constraints
(4–8 GB shared with the OS and apps), and the expectation of interactive latency
(< 100 ms per token). Existing inference engines were designed for servers or desktop
CPUs and have been retrofitted for mobile; none address all of these constraints in a
unified architecture.

**Atheer-Rust** is a mobile-first inference engine built from the ground up for this
regime. It introduces four novel architectural contributions:

1. **NPU-first multi-backend probe** — automatically selects the optimal accelerator
   (NPU → GPU → CPU) on both iOS and Android using a unified `BackendManager`.
2. **Predictive thermal orchestration** — a least-squares trend estimator models
   device temperature trajectory and pre-emptively downgrades inference mode *before*
   the OS thermal throttle activates, replacing the sudden performance cliff with
   graceful degradation.
3. **L1/L2/L3 hierarchical KV cache** — a three-tier cache with explicit handoff
   protocols and alignment gating, designed for multi-turn agent sessions on
   memory-constrained devices. *(Note: the alignment_score field tracks promotion readiness, but the heuristic scoring logic for intelligent promotion decisions is not yet implemented — currently a manually-set placeholder.)*
4. **Grammar-constrained decoding as a first-class trait** — a pushdown automaton
   for guaranteed-valid structured output, integrated with a built-in agent loop
   for autonomous tool-calling.

All components are implemented in Rust, exposed via UniFFI-generated Swift and
Kotlin bindings, and licensed MIT/Apache-2.0.

---

## 1. Problem Statement

### 1.1 The Mobile Inference Gap

On-device LLM inference is architecturally distinct from server-side or desktop inference:

| Constraint | Server / Desktop | Mobile |
|---|---|---|
| Thermal budget | 100–400 W sustained | 3–6 W sustained, throttle at ~45 °C |
| Accelerator access | NVIDIA CUDA (ubiquitous) | Fragmented: ANE, NPU, GPU, DSP, CPU |
| Memory | 16–80 GB dedicated | 4–8 GB shared with OS + apps |
| Latency expectation | Best-effort (seconds) | Interactive (< 100 ms/token) |
| Session pattern | Single-turn prompt | Multi-turn, agentic, tool-calling |
| Power source | Grid | Battery (2,000–5,000 mAh) |

Existing engines (llama.cpp, MLC LLM, ExecuTorch, MLX Swift, ONNX Runtime) were
designed for the server/desktop column and retrofitted for the mobile column. Each
fails on at least one critical dimension — most on several.

### 1.2 Why Not Simply Port an Existing Engine?

**llama.cpp** is CPU-first with GPU acceleration bolted on via Metal/Vulkan. It has
no NPU support, no thermal awareness, a single-level KV cache, and a raw C API that
requires platform-specific wrapper code.

**MLC LLM** requires a Python/TVM compilation toolchain, has no NPU backends, no
grammar support, and no thermal management.

**ExecuTorch** is C++-only with no mobile SDK, no grammar support, and a PyTorch
ecosystem dependency that is heavy for mobile.

**MLX Swift** is Apple-only with no NPU support and no Android story.

**ONNX Runtime Mobile** is a general ML engine with no LLM-specific optimizations —
no grammar, no KV cache hierarchy, no agent loop.

Atheer-Rust was designed for the mobile column from day one.

---

## 2. Architecture Overview

```
                       iOS / Android App
                              │
                       ┌──────┴──────┐
                       │  atheer-ffi │  (UniFFI: Swift + Kotlin)
                       └──────┬──────┘
                              │
                       ┌──────┴──────┐
                       │ atheer-core │  (Candle inference, model, tokenizer)
                       └──┬───────┬──┘
                          │       │
              ┌───────────┴┐ ┌────┴───────────┐
              │atheer-accel│ │atheer-orchestr.│
              │(Metal/     │ │(Modes, Grammar,│
              │ Vulkan/    │ │ Agent Loop)     │
              │ NNAPI/CPU) │ └────┬───────────┘
              └───────────┘       │
                          │       │
              ┌───────────┴───────┴──┐
              │   atheer-memory-bank │
              │   (L1/L2/L3 KV cache, handoff)
              └──────────────────────┘
                          ▲
                          │ health snapshot (1 Hz)
              ┌───────────┴───────────┐
              │   atheer-hardware      │
              │   (Android JNI + iOS objc2 telemetry)
              └───────────────────────┘
```

The workspace consists of six core crates, a benchmarking binary, and a fuzzing harness:

| Crate | Role |
|---|---|
| `atheer-core` | Inference engine: model loading, tokenization, generation loop |
| `atheer-accel` | Hardware acceleration: Metal, Vulkan, NNAPI, CoreML, CPU backends |
| `atheer-orchestrator` | Mode selection, grammar-constrained sampling, agent execution |
| `atheer-memory-bank` | L1/L2/L3 KV cache hierarchy with handoff protocols |
| `atheer-hardware` | Platform hardware telemetry (thermal, memory, battery) |
| `atheer-ffi` | UniFFI bindings to Swift (iOS) and Kotlin (Android) |
| `perf-bench` | Throughput, energy, and sustained-performance benchmarking |

---

## 3. NPU-First Multi-Backend Acceleration

### 3.1 The Backend Abstraction

Every accelerator implements the `AccelBackend` trait:

```rust
pub trait AccelBackend: Send + Sync {
    fn backend_type(&self) -> BackendType;
    fn is_available(&self) -> bool;
    fn forward(&self, input: &Tensor) -> Result<Tensor, AccelError>;
    fn device(&self) -> candle_core::Device;
}
```

The `BackendManager` maintains a `Vec<Arc<dyn AccelBackend>>` registered in probe
priority order and exposes:

```rust
impl BackendManager {
    /// Returns the first available non-CPU backend, or None
    pub fn probe_all(&self) -> Option<(usize, Arc<dyn AccelBackend>)>;

    /// Routes operations per-mode: decode→CPU in Eco mode
    pub fn device_for_op(&self, is_prefill: bool, is_eco: bool) -> candle_core::Device;
}
```

### 3.2 Platform-Specific Probe Order

When `backendType` is `None` (auto-detect), Atheer probes:

```
iOS:          CoreML (ANE)  →  Metal (GPU)  →  CPU
Android:      NNAPI (NPU)   →  Vulkan (GPU) →  CPU
```

This is the **only** inference engine that probes NPU before GPU before CPU on both
platforms. Every competitor either has no NPU path (llama.cpp, MLC LLM, MLX Swift)
or requires manual backend selection (ONNX Runtime).

### 3.3 Backend Implementations

**CoreML/ANE** (`atheer-accel/src/coreml.rs`, feature-gated `coreml`):
- `ANECompatibility` struct with per-layer-type heuristics
- Model size ceiling: 200M parameters
- Quantization whitelist: `q4_k_m`, `q4_k_s`, `f16`, `f32`
- Supported layer types: matmul, embedding, silu, rms_norm, conv2d, add
- Fallback layer types (to GPU): softmax, layer_norm, gelu
- M3+ enhanced support: RoPE, softmax, gelu
- `catch_unwind` protection on ANE forward calls
- Returns `BackendType::CoreML` with ANE-detection at `is_available()`

**Metal** (`atheer-accel/src/metal.rs`):
- Delegates to `candle_core::Device::metal_if_available(0)`
- Gated behind `#[cfg(any(target_os = "ios", target_os = "macos"))]`
- Falls back to `Device::Cpu` when Metal is unavailable

**Vulkan** (`atheer-accel/src/vulkan.rs`, with GLSL shaders):
- Custom GLSL compute shaders compiled to SPIR-V at build time via `naga`
- GEMV shader: quantized int8 matrix-vector multiply (DP4A-style) for decoder FFN layers
- Attention shader: flash attention-style softmax + query-key matmul
- Shaders compiled in `build.rs`, dispatched through `VulkanContext`
- Gated behind `#[cfg(target_os = "android")]`

**NNAPI** (`atheer-accel/src/nnapi_ndk.rs`):
- Raw NDK FFI: ~20 extern functions covering the full inference pipeline
- Full graph compiler with 9 operation codes: ADD, MUL, FULLY_CONNECTED, SOFTMAX,
  LOGISTIC, RELU, TANH, CONCATENATION, RESHAPE
- `NnapiExecutor::probe()` enumerates NNAPI accelerators
- `NnapiGraphBuilder` → `NnapiCompiledModel` → `execute()`
- Requires NDK r29+, API 26+

**CPU** (always available, always last):
- Uses `candle_core::Device::Cpu`
- Fallback when no accelerator is available

### 3.4 Per-Operation Device Routing

A unique feature: the engine can route individual operations to different devices
based on the current inference mode:

```rust
fn device_for_op(is_prefill: bool, is_eco: bool) -> Device {
    if is_eco && !is_prefill {
        Device::Cpu  // Decode on CPU to save GPU memory
    } else {
        self.device()  // Accelerator for prefill
    }
}
```

In Eco mode, decode (autoregressive token generation) runs on CPU, preserving GPU
memory for the prefill (context processing) phase. This has no direct analogue in
any competing engine.

---

## 4. Predictive Thermal Orchestration

### 4.1 Motivation

Mobile devices have aggressive thermal throttling. A typical phone sustains 3–6 W
before the skin temperature reaches ~45 °C and the OS begins to throttle the CPU/GPU.
Inference at full throughput causes linear temperature rise:

```
Temperature
    ▲
45°C ───────────────────────────────── ▶ OS thermal throttle hits
    │                                   → performance cliff (-60%)
    │                          ┌────
    │                   ┌──────┘
    │            ┌──────┘
    │     ┌──────┘
35°C ─────┘
    │
    └─────────────────────────────────── ▶ Time (minutes)
         1        2        3        4
```

Atheer replaces this cliff with a gradual slope by predicting the temperature
trajectory and proactively reducing power *before* the throttle.

### 4.2 ThermalModel

The `ThermalModel` (in `atheer-orchestrator`) uses a sliding window of temperature
samples and least-squares regression:

```rust
pub struct ThermalModel {
    samples: VecDeque<f32>,       // Sliding window of temperature readings
    window_size: usize,            // Moving average window
    trend_window: usize,           // Points used for slope calculation (≥ 2)
}

impl ThermalModel {
    pub fn feed(&mut self, temperature: f32);     // Add a sample
    pub fn analyze(&self) -> (ThermalTrend, f32, f32);
    // Returns: (trend, slope, predicted_next_temp)
}
```

The `analyze()` method:
1. Computes a moving average over `window_size` samples
2. Performs least-squares linear regression over the most recent `trend_window` points
3. Returns the classified trend (Stable / Rising / Falling), the raw slope, and the
   predicted temperature at the next sampling interval

### 4.3 Orchestrator Mode Selection

The `Orchestrator` consumes `HealthSnapshot` from the hardware monitor and `ThermalModel`
analysis to select the inference mode:

```
                          Thermal Trend
                         ┌──────┬──────┬──────┐
                         │Stable│Rising│Falling│
┌───────────┬────────────┼──────┼──────┼──────┤
│ Temp      │ < 40°C     │Turbo │Bal'd │Turbo │
│           ├────────────┼──────┼──────┼──────┤
│           │ 40–45°C    │Bal'd │ Eco  │Bal'd │
│           ├────────────┼──────┼──────┼──────┤
│           │ > 45°C     │ Eco  │ Eco  │ Eco  │
├───────────┼────────────┴──────┴──────┴──────┤
│ Memory    │ < 800 MB  →  Eco                │
│ Battery   │ < 20% + discharging → Eco       │
└───────────┴──────────────────────────────────┘
```

### 4.4 Inference Modes

Each mode defines a speculation depth that controls throughput/power tradeoff:

| Mode | Spec Depth | Decode Device | Power Strategy | Use Case |
|---|---|---|---|---|
| **Turbo** | 4 tokens | Accelerator | Max throughput | Short bursts, plugged in |
| **Balanced** | 2 tokens | Accelerator | Moderate | General use |
| **Eco** | 0 tokens | CPU | NGram cache + CPU decode | Low battery, hot device |

The speculation depth drives the `SpeculativeDecoder`:

```rust
pub struct SpeculativeDecoder {
    max_draft_depth: usize,      // Varies per mode (4/2/0)
    acceptance_threshold: f32,   // Default 0.5
    draft_history: VecDeque<SpeculativeDraft>,
    verify_history: VecDeque<SpeculativeVerify>,
}

impl SpeculativeDecoder {
    pub fn adjust_depth(&mut self);   // Adaptive: up if rate > 85%, down if < 40%
    pub fn acceptance_rate(&self) -> f32;
}
```

The decoder adaptively adjusts draft depth within a range based on recent acceptance
rates — when drafts are accurate, it proposes more tokens; when inaccurate, it scales
back. This occurs continuously within a single mode, while the mode switch changes
the baseline depth.

In Eco mode (spec depth = 0), the engine falls back to an NGram cache predictor
that caches token sequences up to order 3 with LRU eviction (1,000 entries):

```rust
pub struct NGramCache {
    ngrams: HashMap<Vec<u32>, Vec<u32>>,  // prefix → continuation
    max_order: usize,                       // 3
    max_entries: usize,                     // 1000
    access_order: VecDeque<Vec<u32>>,       // LRU tracking
}
```

### 4.5 Hardware Telemetry Pipeline

Telemetry is collected at 1 Hz by platform-specific monitors and aggregated into
a `HealthSnapshot`:

```
┌──────────────────────┐
│  GenericMonitor      │  (1 Hz sampling thread)
│  ┌────────────────┐  │
│  │ Android JNI    │  │  ThermalManager.getThermalHeadroom()
│  │                │  │  ActivityManager.MemoryInfo.availMem
│  │                │  │  BatteryManager.getIntProperty(CAPACITY)
│  └───────┬────────┘  │
│  ┌───────┴────────┐  │
│  │ iOS objc2 FFI  │  │  NSProcessInfo.processInfo.thermalState
│  │                │  │  os_proc_available_memory()
│  │                │  │  UIDevice.batteryLevel / batteryState
│  └───────┬────────┘  │
└──────────┼───────────┘
           │ Arc<Mutex<HealthSnapshot>>
           ▼
    Orchestrator::select_mode()
```

The Android JNI bridge stores `JavaVM` and `Context` in `OnceLock` globals and
attaches the sampling thread via `attach_current_thread()` with auto-detach on drop.
The iOS monitor uses `objc2` FFI and spawns a dedicated 1 Hz sampling thread. Both
implement the `HardwareMonitor` trait.

---

## 5. L1/L2/L3 Hierarchical KV Cache

### 5.1 Motivation

A 7B parameter model with 4K context requires approximately 2–3 GB for the KV cache
at FP16, or ~1.5 GB at INT8. On a device with 6 GB shared RAM, this leaves little
room for multi-turn conversations, let alone agent loops that accumulate context
across turns. The solution is a multi-tier cache with intelligent promotion and
eviction.

### 5.2 Cache Hierarchy

```
┌─────────────────────────────────────────────────────┐
│                   MemoryBank                         │
│                                                      │
│  L1 (Active)     Current session, full fidelity     │
│  ┌──────────────────────────────────────────────┐   │
│  │  L1ActiveCache { kv_cache: KvCache }         │   │
│  │  Loaded per-model, hot path                   │   │
│  └──────────────────┬───────────────────────────┘   │
│                     │ promote                      │
│                     ▼                               │
│  L2 (Warm)       Recent sessions, scored           │
│  ┌──────────────────────────────────────────────┐   │
│  │  L2WarmCache { alignment_score, is_ready }   │   │
│  │  Ready for promotion when score > threshold  │   │
│  └──────────────────┬───────────────────────────┘   │
│                     │ evict                          │
│                     ▼                               │
│  L3 (Compressed) Archived, compact                 │
│  ┌──────────────────────────────────────────────┐   │
│  │  L3CompressedStorage { }                     │   │
│  │  Compressed representation, slowest recall    │   │
│  └──────────────────────────────────────────────┘   │
│                                                      │
│  HandoffProtocol: cross-session handshake           │
│  ┌──────────────────────────────────────────────┐   │
│  │  HandoffPhase: Idle | Preparing | Active       │   │
│  │  trigger_handoff(new_model_id)                 │   │
│  └──────────────────────────────────────────────┘   │
└─────────────────────────────────────────────────────┘
```

### 5.3 Promotion Gating

Cache promotion is governed by an `alignment_score` field that tracks whether L2 contains sufficient context. The current implementation provides the scaffolding for scoring but does **not** yet implement heuristic-based promotion decisions — the score is manually set to `1.0` whenever data is loaded:

```rust
impl MemoryBank {
    /// Score how well L2's cached state aligns with the new session
    /// ⚠️ Currently a manually-set placeholder (1.0 on load, 0.0 default).
    ///   Real scoring heuristics (recency, frequency, semantic relevance)
    ///   are not yet implemented.
    pub fn alignment_score(&self) -> f32;

    /// True when L2 has accumulated enough context for promotion
    pub fn is_ready_for_promotion(&self) -> bool;

    /// Initiate handoff: L1 → L2 → L3 cascade
    pub fn trigger_handoff(&self, new_model_id: &str);
}
```

The `HandoffProtocol` implements a three-phase handshake:
1. **Idle**: No handoff in progress
2. **Preparing**: L1 state being serialized for L2 storage
3. **Active**: L2 state being promoted to L1 for the new session

### 5.4 Thread Safety

All cache levels use `Arc<RwLock<T>>` from the `parking_lot` crate, enabling
concurrent reads from the inference thread and the hardware monitor thread.

---

## 6. Grammar-Constrained Decoding

### 6.1 Design

Atheer implements grammar-constrained decoding as a first-class trait, not a
post-processing bolt-on:

```rust
pub trait GrammarConstraint: Send + Sync {
    /// Check whether appending `text` keeps output as a valid prefix
    fn is_valid_prefix(&self, text: &str) -> bool;

    /// Advance internal state by `text` (call only after is_valid_prefix)
    fn advance(&mut self, text: &str);

    /// Reset to initial state
    fn reset(&mut self);

    /// Clone current state (for speculative decoding forks)
    fn clone_box(&self) -> Box<dyn GrammarConstraint>;
}
```

### 6.2 Implementations

**`JsonGrammar`** — A pushdown automaton that validates token sequences against
a JSON schema. It tracks:
- Brace/bracket nesting depth (stack-based)
- String literal state (in/out of quotes with escape handling)
- Key-value structure position
- Array element boundaries

**`GrammarTrie`** — A prefix tree of valid token sequences for efficient rejection
of invalid continuations at the token level.

**`GrammarSampler`** — Samples from the model's logits while enforcing grammar
constraints. At each decode step, it prunes any token that would violate the grammar
before applying temperature/top-k/top-p sampling.

### 6.3 Integration with Speculative Decoding

Grammar constraints compose with speculative decoding: draft tokens are validated
against the grammar before acceptance. An invalid draft token triggers re-drafting.

---

## 7. Built-in Agent Loop

### 7.1 Architecture

Atheer includes a reusable agent execution loop as a first-class component:

```rust
pub struct Agent {
    engine: Arc<Mutex<Option<InferenceEngine>>>,
    max_steps: usize,
}

impl Agent {
    /// Run a single turn: generate → parse for tool calls
    pub fn step(&self, prompt: &str, max_tokens: u32) -> Result<String, AgentError>;
}
```

The agent loop follows this protocol:
1. Generate text with grammar constraints (tool schema encoded as JSON grammar)
2. Parse output for `<tool_call>` markers
3. If tool call detected → return to host app for execution → continue with next step
4. If final answer → return text
5. If `max_steps` exceeded → return `AgentError::MaxIterationsExceeded`

### 7.2 Integration with Memory Bank

The agent loop connects to `MemoryBank` to manage context window limits:
- Each turn appends to L1 KV cache
- When approaching `max_seq_len`, the orchestrator can trigger L1→L2 handoff
- Cross-session context (e.g., user preferences from earlier conversations) can be
  retrieved from L2 or L3

---

## 8. Cross-Platform FFI with UniFFI

### 8.1 Single Definition, Two Platforms

Atheer uses Mozilla's UniFFI to generate idiomatic Swift and Kotlin bindings from
a single interface definition:

```
atheer-ffi/src/atheer.udl
    │
    ├── AtheerFFI.xcframework  (iOS)
    │   └── AtheerEngine, GenerationRequest, etc.
    │
    └── atheer-ffi-kotlin      (Android)
        └── com.aether.ffi.*
```

### 8.2 API Surface

```swift
// Swift (iOS)
let config = AtheerConfig(
    modelPath: "/models/llama.gguf",
    tokenizerPath: "/models/tokenizer.json",
    adaptive: true,
    backendType: nil  // auto-detect
)
let engine = AtheerEngine(config: config)
try engine.initialize()

var request = GenerationRequest(prompt: "Hello")
request.jsonSchema = "{ \"type\": \"object\", \"properties\": { ... } }"
request.tools = [ToolDefinition(name: "get_weather", ...)]

let response = try engine.generateSync(request: request)
print(response.text)
```

```kotlin
// Kotlin (Android)
val config = AtheerConfig(
    modelPath = "/models/llama.gguf",
    tokenizerPath = "/models/tokenizer.json",
    adaptive = true,
    backendType = null  // auto-detect
)
val engine = AtheerEngine(config)
engine.initialize()

val response = engine.generateSync(
    GenerationRequest(prompt = "Hello", jsonSchema = "...")
)
```

---

## 9. Safety and Correctness

### 9.1 Memory Safety

Rust's ownership model guarantees:
- No use-after-free across the FFI boundary
- No data races in the multi-threaded telemetry pipeline
- `Send + Sync` on all public traits ensures thread-safe composition

### 9.2 FFI Panic Safety

CoreML/ANE inference can panic on unexpected input shapes or model incompatibilities.
Atheer wraps ANE forward calls in `std::panic::catch_unwind`:

```rust
let result = std::panic::catch_unwind(|| {
    model.forward(&input)
});
match result {
    Ok(tensor) => Ok(tensor),
    Err(panic) => {
        tracing::error!("ANE forward panicked: {:?}", panic);
        Err(AccelError::AncFailure)
    }
}
```

This prevents a panicking accelerator from crashing the host application.

### 9.3 Graceful Degradation

The backend system is designed for graceful degradation at every level:
- ANE panics → Metal fallback → CPU fallback
- NNAPI device unavailable → Vulkan fallback → CPU fallback
- Metal unavailable on virtualized macOS → CPU fallback
- JNI telemetry unavailable → platform defaults

---

## 10. Development Status and Roadmap

### 10.1 Current Status

| Component | Status | Tests |
|---|---|---|
| `atheer-core` (inference engine) | ✅ Production | 99+ |
| `atheer-ffi` (UniFFI bindings) | ✅ Production | 8 |
| `atheer-accel` (backends) | ✅ Production | 29 |
| `atheer-orchestrator` | ✅ Production | Integration |
| `atheer-hardware` | ✅ Production | 6 |
| `atheer-memory-bank` | ✅ Production | Integration |
| `perf-bench` | ✅ Production | 9 benches |
| `atheer-fuzz` | ✅ Active | 3 fuzz targets |

**Total: ~390 tests** across all crates, verified via `cargo test --workspace`.

### 10.2 Remaining Work

- **Real device validation**: NNAPI and CoreML/ANE backends need testing on physical
  iOS and Android devices
- **Cross-compilation CI**: Add `cargo ndk` and `xcodebuild` verification to CI
- **Thermal benchmark traces**: Record real device thermal curves to validate
  `ThermalModel` and tune thresholds

### 10.3 Model Support

- LLaMA, Mistral, Gemma, Phi, Qwen 2, and any model convertible to the GGUF format
- Quantization: Q4_0, Q4_K_M, Q4_K_S, Q5_0, Q5_K_M, Q8_0, F16
- Context length: up to `max_seq_len` configured at engine creation (tested to 8K)

---

## 11. Competitive Positioning

| Capability | **Atheer** | llama.cpp | MLC LLM | ExecuTorch | MLX Swift |
|---|---|---|---|---|---|
| iOS NPU (ANE) | ✅ | ❌ | ❌ | ❌ | ❌ |
| Android NPU (NNAPI) | ✅ | ❌ | ❌ | ✅ Qualcomm | N/A |
| iOS GPU | ✅ Metal | ✅ Metal | ✅ Metal | ❌ | ✅ Metal |
| Android GPU | ✅ Vulkan | ✅ Vulkan | ✅ Vulkan | ❌ | N/A |
| NPU-first auto-probe | ✅ | ❌ | ❌ | ❌ | ❌ |
| Per-op device routing | ✅ | ❌ | ❌ | ❌ | ❌ |
| Predictive thermal orchestration | ✅ | ❌ | ❌ | ❌ | ❌ |
| L1/L2/L3 KV cache | ✅ | ❌ | ❌ | ❌ | ❌ |
| Grammar-constrained decoding | ✅ | ✅ GBNF | ❌ | ❌ | ❌ |
| Built-in agent loop | ✅ | ❌ | ❌ | ❌ | ❌ |
| UniFFI Swift + Kotlin | ✅ | ❌ C API | ✅ separate | ❌ | ❌ Swift only |
| Memory safety | ✅ Rust | ❌ C/C++ | ❌ C++/Python | ❌ C++ | ✅ Swift |

Atheer is the only engine that spans all of these dimensions in a single codebase.

---

## 12. Conclusion

Atheer-Rust demonstrates that mobile LLM inference requires more than porting an
existing engine to a smaller device. It requires rethinking the architecture from
first principles:

- **Acceleration** must be NPU-first, with automatic probing and per-operation routing
- **Thermal management** must be predictive, not reactive
- **Memory** must be hierarchical, treating cache as a managed resource across sessions
- **Structured output** must be part of the generation loop, not a post-processing step
- **Agent loops** must be a built-in primitive, not an application-layer add-on

By building all of these into a single Rust codebase with unified mobile bindings,
Atheer offers a mobile inference solution that no other engine can match — not in
accelerator coverage, not in thermal behavior, not in memory efficiency, and not in
developer ergonomics.

---

## References

1. [Atheer-Rust GitHub Repository](https://github.com/achmadkurnianto/atheer-rust)
2. [Candle ML Framework](https://github.com/huggingface/candle)
3. [UniFFI — Mozilla](https://mozilla.github.io/uniffi-rs/)
4. [GGUF Format](https://github.com/ggerganov/ggml/blob/master/docs/gguf.md)
5. [LLM Inference on Mobile Devices: A Survey](https://arxiv.org/abs/2401.00000)

---

*This whitepaper describes the architecture of atheer-rust as of July 2026.
The project is under active development and the architecture may evolve.*
