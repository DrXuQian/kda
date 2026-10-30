# Sources and included evidence

The PPU knowledge needed by this skill is stored in this KDA checkout. The
links below lead to maintained local Markdown, not personal repositories,
private memory files or globally installed skills. Selected operator findings
are incorporated into the relevant reference instead of copying entire project
manuals and release procedures.

Reviewed on 2026-10-30. Historical device observations retain their original
target and scope. The included explanations are not raw report archives or a
new device validation. Build and validate the requested kernel on its target.

## Included reference map

| ID | Material in this checkout | Evidence scope |
|---|---|---|
| S01 | [Architecture](architecture.md), [CUTLASS/actlize](cutlass-porting.md), [numerics](numerics.md), [quantization](quantization.md), [GEMM/MoE](gemm-moe.md) | Selected operator-history findings and corrections: physical ownership, storage formats, scheduling and port comparisons. |
| S02 | [PPU0010 instructions](architecture.md#cudaptx-compatibility-preserve-and-check), [resources](architecture.md#resources-and-evidence), [FlashAttention](flash-attention.md) | PPU1.0 PTX/copy and occupancy observations. Historical card values and wrapper behavior are scoped in the text. |
| S03 | [PPU1.7 differences](architecture.md#ppu17-seams), [Hopper API seams](cutlass-porting.md#hopper-integration-has-api-seams-too) | Vendor-backend source comparisons and integration lessons; native PPU1.7 support is not inferred from them. |
| S04 | [GDN contract and operand delivery](linear-attention.md), [profiling diagnosis](../../ppu-profiling/references/analysis.md) | PPU1.0 residual/WY numerical schedules, global versus register-produced inputs, and split-prepare traffic interpretation. |
| S05 | [FlashAttention](flash-attention.md), [CUTLASS/actlize](cutlass-porting.md) | Legacy AIU and Hopper-style PPU paths, online-softmax semantics, pipeline interfaces and execution limits. |
| S06 | [SageAttention](sage-attention.md), [numerical debugging](numerics.md) | INT8-QK/FP16-PV contract, C-to-A bridge validation and historical compiler-binding failure. These are porting lessons, not a claim that an upstream PPU implementation is supplied. |
| S07 | [Low-bit format audit](sage-attention.md#low-bit-experimental-targets) | PPU1.5/1.7 source/native boundaries; E2M1 scale encodings and target mismatch in the reviewed vendor archive. |
| S08 | [CuTe debugging](numerics.md), [cold GEMV](quantization.md#cold-weight-experiments), [PPU profiling](../../ppu-profiling/SKILL.md) | Reusable debugging and measurement guidance, with project budgets and release policy removed. Adapted material retains its stated license. |
| S09 | [KDA flow](../../../docs/agent-flow.md), [adaptation map](../../../docs/ppu-adaptation.md) | The upstream workflow and pinned NVIDIA knowledge/profiling collections; their sources and licenses are listed in the repository README and notices. |
| S10 | [ACU collection](../../ppu-profiling/references/collection.md), [metrics/rules](../../ppu-profiling/references/metrics.md), [Asys timeline](../../ppu-profiling/references/timeline.md) | SDK2.1.1 command and schema observations. ACU imports were exercised; Asys help/version was checked without a new device capture. |
| S11 | [Official actlize baseline and extension boundaries](cutlass-porting.md#official-actlize-baseline), [PPU traits](architecture.md) | Official source review at the revision below. Local extensions and historical fixes are distinguished from the official implementation. |
| S12 | [PPU memory hierarchy and Hopper comparison](memory-hierarchy.md), [ACU interpretation](../../ppu-profiling/references/metrics.md) | Adapted from the user-supplied `PPU架构与NVIDIA_SM对照.md`. Includes diagram-derived topology, interface annotations and unresolved units. The PPU model/generation is unspecified; this is not a ZW810 specification or a device measurement. NVIDIA comparisons use the official documentation linked in the local reference. |

## Official upstreams

Use official public projects as dependency and algorithm starting points.
Record the selected revision in the task workspace. Do not substitute a
personal fork to obtain an undocumented feature; implement any needed change
in the task's own code or a reviewable patch against the official baseline.

| Project | Official source | Role |
|---|---|---|
| actlize | [t-head/actlize at cace89d](https://github.com/t-head/actlize/tree/cace89de8cb1cfc9345535bdbc1fb5f403bfb01f) | PPU0010/0015 C++/CuTe dependency. This is the inspected `v1.0.0` branch revision, not a claim that every historical extension is included. |
| CUTLASS | [NVIDIA/cutlass](https://github.com/NVIDIA/cutlass) | NVIDIA algorithms, CuTe interfaces and original kernel implementations. |
| FlashAttention | [Dao-AILab/flash-attention](https://github.com/Dao-AILab/flash-attention) | Exact-attention algorithm and NVIDIA implementation reference. |
| SageAttention | [thu-ml/SageAttention](https://github.com/thu-ml/SageAttention) | Quantized-attention algorithm and NVIDIA implementation reference. |
| Flash Linear Attention | [fla-org/flash-linear-attention](https://github.com/fla-org/flash-linear-attention) | Linear-attention algorithms and reference implementations. |

The attention upstreams are reference implementations, not certified ZW810
backends. PPU migration knowledge is included locally in the pages above.
The SDK/runtime and target kernel source remain task dependencies; KDA does
not bundle vendor binaries, private backend archives or original profiler
reports. See [the ZW810 entry](../../../docs/zw810.md) for execution.
