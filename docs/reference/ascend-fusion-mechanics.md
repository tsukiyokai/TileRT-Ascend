# Ascend-specific fusion mechanics — verbatim source dossier

Research dossier for the GLM-5.2-W4A8C8 megakernel effort on Ascend A3 (910-series, CANN 9.2.0).
Everything below is quoted verbatim from the cited source. Chinese text is left in Chinese.
Measured context this bears on: per-kernel-call launch floors on one die of
AI_VECTOR_CORE 0.70 us, AI_CORE 2.30 us, MIX_AIV 12.04 us, MIX_AIC 13.58 us;
~3008 kernels per decode round; 505 MIX_AIC calls per round (6.5 per layer); 11.5 ms launch floor.

---

## 1. Cross-core and cross-block synchronization primitives

### AscendC `kernel_operator_block_sync_intf.h` — the complete declared sync surface

https://raw.gitcode.com/cann/asc-devkit/raw/master/include/basic_api/kernel_operator_block_sync_intf.h
(also browsable at https://gitcode.com/cann/asc-devkit/blob/master/include/basic_api/kernel_operator_block_sync_intf.h)
Repo: `cann/asc-devkit` on GitCode, branch `master`. Copyright header says 2025, CANN Open Software License Agreement Version 2.0.

```cpp
/*!
 * \file kernel_operator_block_sync_intf.h
 * \brief
 */

#if defined(__NPU_COMPILER_INTERNAL_PURE_SIMT__)
#error "kernel_operator_block_sync_intf.h cannot be used with compile flag --enable-simt enabled."
#endif

#if !defined(__ASCENDC_INCLUDE_INTERNAL_HEADERS__)
#define __ASCENDC_INCLUDE_INTERNAL_HEADERS__
#define __UNDEF_ASCENDC_INCLUDE_INTERNAL_HEADERS_KERNEL_OPERATOR_BLOCK_SYNC_INTF_H__
#endif
#ifndef ASCENDC_MODULE_OPERATOR_BLOCK_SYNC_INTF_H
#define ASCENDC_MODULE_OPERATOR_BLOCK_SYNC_INTF_H

#include "../../impl/basic_api/kernel_macros.h"
#include "../../impl/basic_api/kernel_event.h"
#include "../../impl/basic_api/kernel_reg.h"
#include "kernel_tensor.h"
#include "../../impl/basic_api/kernel_tensor_base.h"
#include "../../impl/basic_api/utils/kernel_utils_mode.h"

#if defined(ASCENDC_CPU_DEBUG) && ASCENDC_CPU_DEBUG == 1
#include <cstdint>
#include "stub_def.h"
#include "stub_fun.h"
#endif

namespace AscendC {

template <HardEvent event>
__aicore__ inline void SetFlag(int32_t eventID);

template <HardEvent event>
__aicore__ inline void WaitFlag(int32_t eventID);

template <pipe_t pipe>
__aicore__ inline void PipeBarrier();

template <MemDsbT arg0>
__aicore__ inline void DataSyncBarrier();

/*
 * @ingroup：IBSet, IBWait
 * @brief：Set the flag bit of a core
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 * @param [in] blockIdx the idx number waiting for the core
 * @param [in] eventID Set and wait events
 */
template <bool isAIVOnly = true>
__aicore__ inline void IBSet(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);

template <bool isAIVOnly = true>
__aicore__ inline void IBWait(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);
/*
 * @ingroup：SyncALL
 * @brief：Set flag bits of all cores
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 */
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0);

#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 5162) || \
                              (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
__aicore__ inline void SyncAll();
#else
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll();
#endif

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId);

template <uint8_t modeId = 0, pipe_t pipe = PIPE_S>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId);

template <pipe_t src, pipe_t dst>
class TQueSync {
public:
    __aicore__ inline void SetFlag(TEventID id);
    __aicore__ inline void WaitFlag(TEventID id);
};

namespace BlockSync {
enum SyncScope {
    InterBlock,
};

template <SyncScope Scope = SyncScope::InterBlock>
__aicore__ inline void MakeBarrier(uint8_t groupID, uint16_t arriveNum);
} // namespace BlockSync

} // namespace AscendC
#if defined(__NPU_ARCH__)
#include "../../impl/basic_api/kernel_operator_block_sync_intf_impl.h"
#endif
#endif // KERNEL_BLOCK_SYNC_INTF_H
```

## Relevance
This is the exact API surface a megakernel must use to replace the 3008 host-side kernel launches with in-kernel
stage transitions. `CrossCoreSetFlag<modeId, pipe>(uint16_t flagId)` / `CrossCoreWaitFlag` is the AIC<->AIV handshake
that a MIX kernel performs internally — i.e. the thing our 13.58 us MIX_AIC floor is paying for once per launch
instead of once per stage. `SyncAll<isAIVOnly>()` with no workspace argument is the cheap intra-kernel grid barrier;
the `GlobalTensor<int32_t> gmWorkspace` overload is the GM-workspace-based variant. Note `BlockSync::MakeBarrier(groupID, arriveNum)`
— an arrive-count barrier, which is what a persistent multi-stage kernel wants rather than a full `SyncAll`.
`__NPU_ARCH__ == 2201` (our A3) takes the `#else` branch: no `SyncAllConfig` on A3, only the plain `SyncAll<bool>()`.

---

## 2. Architecture generations, `__NPU_ARCH__`, SocVersion mapping

### `asc-devkit` NPU architecture guide (`npu-arch-guide.md`)

https://raw.gitcode.com/cann/asc-devkit/raw/master/.agent/skills/asc-npu-arch/references/npu-arch-guide.md
Repo `cann/asc-devkit`, branch `master`. In-repo agent skill reference.

> # Ascend NPU 架构指南
>
> 本文档说明 Ascend NPU 的架构代际划分，以及在 `asc-devkit` 中进行 AscendC API 设计、实现和验证时需要关注的架构边界。
>
> ## 架构代际概述
>
> ### 核心概念
>
> | 概念 | 说明 |
> |-----|------|
> | **NpuArch** | 芯片架构号，定义指令集和微架构 |
> | **SocVersion** | 片上系统版本，软件命名标识 |
> | **__NPU_ARCH__** | Device 侧编译宏，四位数值，用于条件编译 |
>
> ### 架构代号别名
>
> | 代号 | 对应 SocVersion | 说明 |
> |-----|----------------|------|
> | **A2** | ASCEND910B | Ascend910B1~B4, Ascend910B2C |
> | **A3** | ASCEND910B (含 Ascend910_93) | 训练/推理芯片 |
> | **A5** | ASCEND950 | Ascend950DT / Ascend950PR |
>
> ### 关键细节
>
> - 一个 `NpuArch` 可以对应多个芯片型号或产品系列。
> - `Ascend910_93` 的 SocVersion 字符串在运行时映射到 `SocVersion::ASCEND910B`，NpuArch 同为 `DAV_2201`。
> - 源码中可能存在 `SocVersion::ASCEND910_93` 枚举值，但运行时字符串映射应以本地 `convertMap` 为准。
>
> ## 统一芯片调用名
>
> | 统一调用名 | __NPU_ARCH__ | SocVersion | 产品系列 / 常见芯片 | 说明 |
> |-----------|:------------:|------------|---------------------|------|
> | `ascend910` | 1001 | ASCEND910 | Atlas 训练系列 / Ascend910 | 初代训练架构 |
> | `ascend910b1` | 2201 | ASCEND910B | Atlas A2 / Ascend910B1~B4, Ascend910B2C | 与 A3 共用 2201 |
> | `ascend310p` | 2002 | ASCEND310P | Atlas 推理系列 / Ascend310P1, Ascend310P3 | 与 `ascend610` 共用 2002 |
> | `ascend610` | 2002 | ASCEND310P | Atlas 推理系列 / Ascend610 | 与 `ascend310p` 共用 2002 |
> | `ascend310b1` | 3002 | ASCEND310B | Atlas 200I/500 A2 / Ascend310B1~B4 | 推理架构 |
> | `ascend950pr_9599` | 3510 | ASCEND950 | Atlas A5 推理 / Ascend950PR | 当前 regbase / SIMT 主入口 |
>
> ## 完整映射表
>
> | 产品系列 | SocVersion | __NPU_ARCH__ | 芯片型号 | 说明 |
> |---------|-----------|:---:|---------|------|
> | Atlas A2 训练/推理 | ASCEND910B | 2201 | Ascend910B1~B4, Ascend910B2C | 主流训练芯片 |
> | Atlas A3 训练/推理 | ASCEND910B | 2201 | Ascend910_93 | 训练/推理芯片 |
> | Atlas A5 训练 | ASCEND950 | 3510 | Ascend950DT | Decode |
> | Atlas A5 推理 | ASCEND950 | 3510 | Ascend950PR | Prefill |
> | Atlas 训练系列 | ASCEND910 | 1001 | Ascend910 | 初代训练架构 |
> | Atlas 推理系列 | ASCEND310P | 2002 | Ascend310P1, Ascend310P3, Ascend610 | 推理芯片 |
> | Atlas 200I/500 A2 推理 | ASCEND310B | 3002 | Ascend310B1~B4 | 推理芯片 |
>
> ### 基础 dtype 大小与 32B 对齐
>
> | 数据类型 | sizeof | 32B 对齐元素数 | 说明 |
> |---------|--------|---------------|------|
> | `bool` | 1 字节 | 32 个元素 | 全 0 为 false，否则为 true |
> | `int8_t` | 1 字节 | 32 个元素 | INT8 |
> | `uint8_t` | 1 字节 | 32 个元素 | UINT8 |
> | `fp4x2_e2m1_t` | 1 字节 | 32 个元素 | 两个 FP4 E2M1 值打包 |
> | `fp4x2_e1m2_t` | 1 字节 | 32 个元素 | 两个 FP4 E1M2 值打包 |
> | `hifloat8_t` | 1 字节 | 32 个元素 | HiFloat8 |
> | `fp8_e5m2_t` | 1 字节 | 32 个元素 | FP8 E5M2 |
> | `fp8_e4m3fn_t` | 1 字节 | 32 个元素 | FP8 E4M3FN |
> | `fp8_e8m0_t` | 1 字节 | 32 个元素 | FP8 E8M0 |
> | `int4x2_t` | 1 字节 | 32 个元素 | 两个 4-bit 整数打包，单 lane 范围 `[-8, 7]` |
> | `half` | 2 字节 | 16 个元素 | FP16 |
> | `bfloat16_t` | 2 字节 | 16 个元素 | BF16 |
> | `int16_t` | 2 字节 | 16 个元素 | INT16 |
> | `uint16_t` | 2 字节 | 16 个元素 | UINT16 |
> | `float` | 4 字节 | 8 个元素 | FP32 |
> | `int32_t` | 4 字节 | 8 个元素 | INT32 |
> | `uint32_t` | 4 字节 | 8 个元素 | UINT32 |
> | `complex32` | 4 字节 | 8 个元素 | `AscendC::Complex<half>` |
> | `int64_t` | 8 字节 | 4 个元素 | INT64 |
> | `uint64_t` | 8 字节 | 4 个元素 | UINT64 |
> | `double` | 8 字节 | 4 个元素 | FP64 |
> | `complex64` | 8 字节 | 4 个元素 | `AscendC::Complex<float>` |
>
> 32B 对齐的通用约束为 `count * sizeof(T) % 32 == 0`。
>
> | 产品范围 | 文档声明的支持 dtype |
> |---------|----------------------|
> | Ascend 950PR&950DT系列产品 | `bool`, `int8_t`, `uint8_t`, `fp4x2_e2m1_t`, `fp4x2_e1m2_t`, `hifloat8_t`, `fp8_e5m2_t`, `fp8_e4m3fn_t`, `fp8_e8m0_t`, `int4x2_t`, `int16_t`, `uint16_t`, `half`, `bfloat16_t`, `int32_t`, `uint32_t`, `float`, `complex32`, `int64_t`, `uint64_t`, `double`, `complex64` |
> | Atlas A2 / A3 训练和推理系列 | `int8_t`, `uint8_t`, `int16_t`, `uint16_t`, `int32_t`, `uint32_t`, `int64_t`, `uint64_t`, `half`, `bfloat16_t`, `float`, `double` |
>
> | 简写 | 类型 |
> |-----|------|
> | `S4` | `int4b_t`，通常通过 `int4x2_t` 打包存储 |
> | `U8` / `S8` | `uint8_t` / `int8_t` |
> | `FP8_E4M3` | `fp8_e4m3fn_t` |
> | `HiF8` | `hifloat8_t` |
> | `FP16` / `BF16` / `FP32` | `half` / `bfloat16_t` / `float` |

## Relevance
Our A3 compiles with `__NPU_ARCH__ == 2201` (DAV_2201), shared with A2/910B. Every conditional-compilation branch
in AscendC that gates a feature on `3510` (A5) is unavailable to us — which rules out the `SyncAllConfig` SyncAll
overload and the regbase/SIMT programming model. Note also the A2/A3 dtype list does **not** include `fp8_*`,
`int4x2_t` or `hifloat8_t`: a W4A8 kernel on A3 must hand-pack int4 rather than use a native 4-bit dtype.

---

## 3. `TPipe` / `TQue` / `TBuf` / `LocalTensor` allocation and limits

### `asc-devkit` LocalTensor memory guide (`local-tensor-memory.md`)

https://raw.gitcode.com/cann/asc-devkit/raw/master/.agent/skills/asc-api-ut-gen/references/foundations/local-tensor-memory.md
Repo `cann/asc-devkit`, branch `master`.

> # LocalTensor 内存申请指南
>
> ## 1. 概述
>
> LocalTensor 是 AscendC 中用于表示片上内存（Unified Buffer、L1 等）的张量类型。获取 LocalTensor 需要先通过 `TPipe` 或 `TBufPool` 分配内存给 `TQue` 或 `TBuf`，再从中获取。
>
> ## 2. 内存分配方式
>
> ### 2.1 TPipe::InitBuffer（推荐）
>
> #### 为 TQue 分配内存
>
> ```cpp
> AscendC::TPipe pipe;
> AscendC::TQue<AscendC::TPosition::VECOUT, 2> que;
>
> // 分配 2 块内存，每块 128 字节
> // num=1 不开启 double buffer；num=2 开启 double buffer
> uint8_t num = 2;
> uint32_t len = 128;
> pipe.InitBuffer(que, num, len);
> ```
>
> #### 为 TBuf 分配内存
>
> ```cpp
> AscendC::TPipe pipe;
> AscendC::TBuf<AscendC::TPosition::VECCALC> tmpBuf;
>
> uint32_t len = 128;
> pipe.InitBuffer(tmpBuf, len);
> ```
>
> #### 自定义地址分配
>
> ```cpp
> AscendC::TPipe pipe;
> AscendC::TQue<AscendC::TPosition::VECOUT, 1> que;
>
> // 自定义内存地址信息：[起始地址, 长度]
> auto addr0 = Std::make_tuple(0, 1024);
> auto addr1 = Std::make_tuple(2048, 2048);
> auto addr2 = Std::make_tuple(8192, 4096);
> pipe.InitBuffer(que, addr0, addr1, addr2);
> ```
>
> ### 2.2 TBufPool::InitBuffer
>
> ```cpp
> // TBufPool 分配
> // bufIDSize 默认上限为 4，最大为 16
> TBufPool<TPosition::VECIN, 8> bufPool;  // 最多 8 个 Buffer
> bufPool.InitBuffer(que, num, len);
> bufPool.InitBuffer(buf, len);
> ```
>
> ## 3. 获取 LocalTensor
>
> ### 3.1 从 TQue 获取
>
> ```cpp
> // 申请 Tensor
> LocalTensor<T> tensor = que.AllocTensor<T>();
>
> // 使用后释放
> que.EnQue(tensor);  // 先入队
> que.DeQue<T>();     // 再出队使用
> que.FreeTensor(tensor);  // 最后释放
> ```
>
> ### 3.2 从 TBuf 获取
>
> ```cpp
> // 直接获取（无需手动释放）
> LocalTensor<uint8_t> tmpLocal = tmpBuf.Get<uint8_t>();
> ```
>
> ## 4. 重要约束
>
> ### 4.1 内存对齐
>
> | 约束项 | 说明 |
> |--------|------|
> | **32 字节对齐** | `len` 参数非 32Bytes 对齐时，会**自动向上补齐至 32Bytes** |
> | **元素对齐** | 确保 count * sizeof(T) 满足对齐要求 |
>
> ### 4.2 Buffer 数量限制
>
> | 限制类型 | 数量限制 |
> |----------|----------|
> | **TPipe 方式** | 一个 kernel 中所有 Buffer 数量之和**不能超过 64** |
> | **TBufPool 方式** | `bufIDSize` 默认上限为 4，最大为 16 |
>
> ### 4.3 Double Buffer
>
> ```cpp
> // num=1: 不开启 double buffer
> pipe.InitBuffer(que, 1, len);
>
> // num=2: 开启 double buffer，可提高流水线效率
> pipe.InitBuffer(que, 2, len);
> ```
>
> ## 5. 生命周期管理
>
> ### 5.2 重新分配
>
> ```cpp
> // 如需重新分配内存，需先调用 Reset
> pipe.Reset();
> pipe.InitBuffer(que, newNum, newLen);
> ```
>
> ## 6. TPosition 位置选择
>
> `TPosition` 决定了 LocalTensor 所在的物理存储位置：
>
> | 位置 | 适用场景 | 说明 |
> |------|----------|------|
> | **VECIN** | 矢量编程输入 | Vector Core 输入数据 |
> | **VECOUT** | 矢量编程输出 | Vector Core 输出数据 |
> | **VECCALC** | 矢量计算临时空间 | 用于临时变量，别名 LCM |
> | **A1/A2** | 矩阵编程 | A 矩阵 L1 缓冲区 |
> | **B1/B2** | 矩阵编程 | B 矩阵 L1 缓冲区 |
> | **C1/C2** | 矩阵编程 | C 矩阵 L1 缓冲区 |
> | **CO1/CO2** | 矩阵编程 | C 矩阵输出缓冲区 |

## Relevance
Hard ceiling for a megakernel: **all TQue/TBuf buffers in one kernel must total <= 64**. A fused multi-stage kernel
that gives each stage its own queues will hit this. `pipe.Reset()` plus re-`InitBuffer` is the documented way to
reuse UB across stages, and the custom-address `InitBuffer(que, addr0, addr1, ...)` overload lets us hand-place
stage buffers in UB instead of letting TPipe bump-allocate — the mechanism for keeping matmul -> vector -> matmul
resident on-chip without returning to HBM.

---

## 4. MIX core: what MIX_AIC / MIX_AIV actually mean, and `KERNEL_TASK_TYPE`

### CANN 9.0 (CANNCommunityEdition 900) — 设置Kernel类型 / Setting Kernel Type

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0218.html
English mirror: https://www.hiascend.com/doc_center/source/en/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0218.html
(The JS-gated viewer URL is https://www.hiascend.com/document/detail/en/canncommercial/latest/API/ascendcopapi/atlasascendc_api_07_0218.html — use the `doc_center/source` path to get raw HTML.)
Publisher: Huawei / Ascend, CANN Community Edition 9.0 API reference, parent topic 「Kernel Tiling」.

Applicability table (产品支持情况):

> | 产品 | 是否支持 |
> |---|---|
> | Atlas 350 加速卡 | √ |
> | Atlas A3 训练系列产品 / Atlas A3 推理系列产品 | √ |
> | Atlas A2 训练系列产品 / Atlas A2 推理系列产品 | √ |
> | Atlas 200I/500 A2 推理产品 | x |
> | Atlas 推理系列产品 AI Core | √ |
> | Atlas 推理系列产品 Vector Core | x |
> | Atlas 训练系列产品 | x |

功能说明 (Function Usage) — **this is the documented statement that kernel type exists specifically to cut launch cost**:

> 用于用户自定义设置kernel类型，控制算子执行时只启动该类型的核，避免启动不需要工作的核，缩短核启动开销。

> Customizes the kernel type. Only cores of this type are started during operator execution. This prevents unnecessary cores from being started and shortens the core startup overhead.

函数原型 (Prototype):

> 设置全局默认的kernel type，对所有的tiling key生效。
> 当前支持在自定义算子工程和Kernel直调工程中使用。
> ```
> KERNEL_TASK_TYPE_DEFAULT(value)
> ```
> 设置某一个具体的tiling key对应的kernel type。
> 当前仅支持在自定义算子工程中使用。
> ```
> KERNEL_TASK_TYPE(key, value)
> ```

> Sets the global default kernel type, which applies to all tiling keys.
> Currently, this function can be used in custom operator projects and kernel launch projects.
> Sets the kernel type corresponding to a specific tiling key.
> Currently, this function can be used only in custom operator projects.

参数说明:

> | 参数 | 输入/输出 | 说明 |
> |---|---|---|
> | key | 输入 | tiling key的key值，此参数是正数，表示某个核函数的分支。 |
> | value | 输入 | 设置的kernel类型，可选值范围，kernel类型具体说明请参考表2。不同硬件架构支持的参数取值不同，具体支持的参数取值请参考kernel type取值约束。 |

The enum, verbatim:

```cpp
enum KernelMetaType {
    KERNEL_TYPE_AIV_ONLY,
    KERNEL_TYPE_AIC_ONLY,
    KERNEL_TYPE_MIX_AIV_1_0,
    KERNEL_TYPE_MIX_AIC_1_0,
    KERNEL_TYPE_MIX_AIC_1_1,
    KERNEL_TYPE_MIX_AIC_1_2,
    KERNEL_TYPE_AICORE,
    KERNEL_TYPE_VECTORCORE,
    KERNEL_TYPE_MIX_AICORE,
    KERNEL_TYPE_MIX_VECTOR_CORE,
    KERNEL_TYPE_MAX
};
```

表2 kernel type取值说明 — verbatim, each value:

> | 参数 | 说明 |
> |---|---|
> | KERNEL_TYPE_AIV_ONLY | 算子执行时仅启动AI Core上的Vector核：比如用户在host侧设置numBlocks为10，则会启动10个Vector核。 |
> | KERNEL_TYPE_AIC_ONLY | 算子执行时仅启动AI Core上的Cube核：比如用户在host侧设置numBlocks为10，则会启动10个Cube核。 |
> | KERNEL_TYPE_MIX_AIV_1_0 | AIC、AIV混合场景下，使用了多核控制相关指令时，设置核函数的类型为MIX AIV:AIC 1:0（带有硬同步），算子执行时仅会启动AI Core上的Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Vector核。<br>硬同步的概念解释如下：当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用SyncAll()函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬同步是利用硬件自带的全核同步指令由硬件保证多核同步。 |
> | KERNEL_TYPE_MIX_AIC_1_0 | AIC、AIV混合场景下，使用了多核控制相关指令时，设置核函数的类型为MIX AIC:AIV 1:0（带有硬同步），算子执行时仅会启动AI Core上的Cube核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核。 |
> | KERNEL_TYPE_MIX_AIC_1_1 | AIC、AIV混合场景下，设置核函数的类型为MIX AIC:AIV 1:1，算子执行时会同时启动AI Core上的Cube核和Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核和10个Vector核。 |
> | KERNEL_TYPE_MIX_AIC_1_2 | AIC、AIV混合场景下，设置核函数的类型为MIX AIC:AIV 1:2，算子执行时会同时启动AI Core上的Cube核和Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核和20个Vector核。 |
> | KERNEL_TYPE_AICORE | 算子执行时仅会启动AI Core，比如用户在host侧设置numBlocks为5，则会启动5个AI Core。 |
> | KERNEL_TYPE_VECTORCORE | 该参数为预留参数，当前版本暂不支持。 |
> | KERNEL_TYPE_MIX_AICORE | 该参数为预留参数，当前版本暂不支持。 |
> | KERNEL_TYPE_MIX_VECTOR_CORE | 基于Ascend C开发的矢量计算相关的算子可以运行在Vector Core上，调用本接口传入该参数用于使能Vector Core。<br>使能Vector Core后，算子执行时会同时启动AI Core和Vector Core，用于并行计算。比如用户在host侧设置numBlocks为10，则会启动总数为10的AI Core和Vector Core。<br>需要注意的是，通过SetBlockDim设置核数时，需要大于AI Core的核数，否则不会启动VectorCore。 |

约束说明 — kernel type 取值约束, verbatim:

> Atlas 350 加速卡，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
>
> Atlas A3 训练系列产品 / Atlas A3 推理系列产品，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
>
> Atlas A2 训练系列产品 / Atlas A2 推理系列产品，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
>
> Atlas 推理系列产品，支持KERNEL_TYPE_AICORE、KERNEL_TYPE_MIX_VECTOR_CORE。
>
> KERNEL_TASK_TYPE优先级高于KERNEL_TASK_TYPE_DEFAULT，同时设置了全局kernel type和某一个tiling key的kernel type，该tiling key的kernel type以KERNEL_TASK_TYPE设置的为准。
>
> 没有设置全局默认kernel type的情况下，如果开发者只为其中的某几个tiling key设置kernel type，即部分tiling key没有设置kernel type，会导致算子kernel编译报错。
>
> 当设置具体的kernel task type时，用户的算子实现需要与kernel type相匹配。比如用户设置kernel type为KERNEL_TYPE_MIX_AIC_1_2，则算子内部实现应与核配比AIC:AIV为1:2相对应；若用户设置kernel type为KERNEL_TYPE_AIC_ONLY， 则算子内部实现应该为纯cube逻辑，不应该存在vector部分的逻辑。其他的kernel type类似。
>
> 当纯cube或者纯vec算子强制设定kernel type为MIX类型时，workspace的大小不能设置为0，需要设置一个大于0的值（比如16、32等）。
>
> 使用Tiling模板编程时，需要通过ASCENDC_TPL_KERNEL_TYPE_SEL设置Kernel类型即可，无需再通过该接口进行设置，本接口不生效。

调用示例 示例一：使能VectorCore样例 — verbatim:

```cpp
extern "C" __global__ __aicore__ void add_custom(__gm__ uint8_t *x, __gm__ uint8_t *y, __gm__ uint8_t *z, __gm__ uint8_t *workspace, __gm__ uint8_t *tiling)
{
    GET_TILING_DATA(tilingData, tiling);
    if (workspace == nullptr) {
        return;
    }
    KernelAdd op;
    op.Init(x, y, z, tilingData.numBlocks, tilingData.totalLength, tilingData.tileNum);
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_VECTOR_CORE); // 使能VectorCore
    if (TILING_KEY_IS(1)) {
        op.Process1();
    } else if (TILING_KEY_IS(2)) {
        op.Process2();
    }
    // ...
}
```

> 完成算子host侧Tiling开发时，设置的numBlocks代表的是AI Core和Vector Core的总数，比如用户在host侧设置numBlocks为10，则会启动总数为10的AI Core和Vector Core；为保证启动Vector Core，设置数值应大于AI Core的核数。您可以通过GetCoreNumAic接口获取AI Core的核数，GetCoreNumVector接口获取Vector Core的核数。

```cpp
// 配套的host侧tiling函数示例：
ge::graphStatus TilingFunc(gert::TilingContext* context)
{
    // 使能VectorCore，将numBlocks置为AI Core中vector核数 + Vector Core中的vector核数
    auto ascendcPlatform = platform_ascendc::PlatformAscendC(platformInfo);
    auto totalCoreNum = ascendcPlatform.GetCoreNumAiv();
    // ASCENDXXX请替换为实际的版本型号
    if (ascendcPlatform.GetSocVersion() == platform_ascendc::SocVersion::ASCENDXXX) {
       totalCoreNum = totalCoreNum + ascendcPlatform.GetCoreNumVector();
    }
    context->SetBlockDim(totalCoreNum);
}
```

示例二：设置某一个具体的tiling key对应的kernel type。如下代码为伪代码，不可直接运行。

```cpp
extern "C" __global__ __aicore__ void add_custom(__gm__ uint8_t *x, __gm__ uint8_t *y, __gm__ uint8_t *z, __gm__ uint8_t *workspace, __gm__ uint8_t *tiling)
{
    GET_TILING_DATA(tilingData, tiling);
    if (workspace == nullptr) {
        return;
    }
    KernelAdd op;
    op.Init(x, y, z, tilingData.numBlocks, tilingData.totalLength, tilingData.tileNum);
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIV_ONLY); // 设置默认的kernel类型为纯AIV类型
    if (TILING_KEY_IS(1)) {
        KERNEL_TASK_TYPE(1, KERNEL_TYPE_MIX_AIV_1_0); // 设置tiling key=1对应的kernel类型为MIX AIV 1:0
        op.Process1();
    } else if (TILING_KEY_IS(2)) {
        KERNEL_TASK_TYPE(2, KERNEL_TYPE_AIV_ONLY); // 设置tiling key=2对应的kernel类型为纯AIV类型
        op.Process2();
    }
    // ...
}
// 配套的host侧tiling函数示例：
ge::graphStatus TilingFunc(gert::TilingContext* context)
{
    // ...
    if (context->GetInputShape(0) > 10) {
        context->SetTilingKey(1);
    } else if (some condition) {
        context->SetTilingKey(2);
    }
}
```

## Relevance
Direct, documented explanation of our 12.04 us MIX_AIV / 13.58 us MIX_AIC vs 0.70 us AI_VECTOR_CORE floors.
`MIX_AIC_1_1` and `MIX_AIC_1_2` *start both Cube and Vector cores* on every launch — a `numBlocks=10` MIX_AIC_1_2 launch
boots 10 Cube cores and 20 Vector cores, i.e. 30 cores to bring up and tear down versus 10 for AIV_ONLY. The doc
states the purpose of this API in exactly our terms: 「避免启动不需要工作的核，缩短核启动开销」 ("shortens the core
startup overhead"). The named mechanisms behind the MIX penalty are (a) the AIC:AIV core-count multiplier, and
(b) 硬同步 — the hardware all-core sync instruction that MIX_AIV_1_0 / MIX_AIC_1_0 carry ("带有硬同步"). Note that
`MIX_AIV_1_0` and `MIX_AIC_1_0` start only one core class yet still cost MIX: the fee is the hard-sync capability,
not the extra cores. So 505 MIX_AIC calls/round at 13.58 us = 6.86 ms of our 11.6 ms TPOT, and the lever is to
retype stages to `AIV_ONLY` / `AIC_ONLY` where no cross-core sync is needed, or to collapse many MIX launches into one.
Also load-bearing for us: forcing a pure-cube or pure-vector operator to a MIX type requires `workspace != 0`
(「workspace的大小不能设置为0，需要设置一个大于0的值（比如16、32等）」).

---

### CrossCoreSetFlag (ISASI) — the AIC<->AIV handshake, modes 0/1/2/4, flagId range, deadlock constraint

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0273.html
JS-gated mirror: https://www.hiascend.com/document/detail/en/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0273.html
Publisher: Huawei / Ascend, CANN Community Edition 9.0, parent topic 「核间同步」 (inter-core synchronization).

产品支持情况:

> | 产品 | 是否支持 |
> |---|---|
> | Atlas 350 加速卡 | √ |
> | Atlas A3 训练系列产品 / Atlas A3 推理系列产品 | √ |
> | Atlas A2 训练系列产品 / Atlas A2 推理系列产品 | √ |
> | Atlas 200I/500 A2 推理产品 | x |
> | Atlas 推理系列产品 AI Core | x |
> | Atlas 推理系列产品 Vector Core | x |
> | Atlas 训练系列产品 | x |

功能说明, verbatim:

> 面向分离模式的核间同步控制接口。
>
> 该接口和CrossCoreWaitFlag接口配合使用。使用时需传入核间同步的标记ID(flagId)，每个ID对应一个用于控制同步的计数器。
>
> 同步控制分为以下几种模式，如图1所示：
>
> 模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。
>
> 模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。
>
> 模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后， 两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
>
> 模式4：AI Core内部，AIC与AIV之间的同步控制。AIV0与AIV1可单独触发AIC等待。比如，在AIC核执行CrossCoreSetFlag之后， AIV0上CrossCoreWaitFlag后续的指令才会继续执行；AIV0执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
>
> 其中，模式4仅支持Atlas 350 加速卡。

函数原型:

```cpp
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
```

表1 模板参数说明:

> | 参数名 | 描述 |
> |---|---|
> | modeId | 核间同步的模式，取值如下：<br>模式0：AI Core核间的同步控制。<br>模式1：AI Core内部，Vector核（AIV）之间的同步控制。<br>模式2：AI Core内部，Cube核（AIC）与Vector核（AIV）之间的同步控制。<br>模式4：AI Core内部，AIC与AIV之间的同步控制。AIV0与AIV1可单独触发AIC等待。 |
> | pipe | 设置这条指令所在的流水类型，流水类型可参考硬件流水类型。<br>特别地，PIPE_S流水类型仅Atlas 350 加速卡支持。 |

表2 参数说明 — flagId range:

> | 参数名 | 输入/输出 | 描述 |
> |---|---|---|
> | flagId | 输入 | 核间同步的标记。<br>Atlas A2 训练系列产品 / Atlas A2 推理系列产品，取值范围是0-10。<br>Atlas A3 训练系列产品 / Atlas A3 推理系列产品，取值范围是0-10。<br>Atlas 350 加速卡，取值范围如下：<br>AIV0发起的flagId 0-10的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-10的操作。<br>AIV1发起的flagId 0-10的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-26的操作。<br>AIC发起的flagId 0-10的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-10的操作。<br>AIC发起的flagId 16-26的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-10的操作。 |

约束说明, verbatim — the constraints that bind a megakernel:

> 使用该同步接口时，需要按照如下规则设置Kernel类型：
>
> 在纯Vector/Cube场景下，需设置Kernel类型为KERNEL_TYPE_MIX_AIV_1_0或KERNEL_TYPE_MIX_AIC_1_0。
>
> 对于Vector和Cube混合场景，需根据实际情况灵活配置Kernel类型。
>
> 因为Matmul高阶API内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则会有flagID冲突的风险。
>
> 同一flagId的计数器最多设置15次。
>
> 使用该接口模式0时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
>
> 多流并发场景（≥2条执行流）。
>
> ≥2个算子并发执行。
>
> 所有并发算子的核数总和超过物理核数。
>
> ≥2个并发算子使用了核间同步功能。
>
> 具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。
>
> Kernel直调场景下通过__schedmode__(mode)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式，具体请参考《基础数据结构和接口》。

调用示例 — verbatim:

```cpp
// 使用模式0的方式同步所有的AIV核
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(0x8);
    AscendC::CrossCoreWaitFlag(0x8);
}

// 使用模式1的方式同步当前AICore内的所有AIV子核
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreSetFlag<0x1, PIPE_MTE3>(0x8);
    AscendC::CrossCoreWaitFlag(0x8);
}

// 注意：如果调用高阶API,无需开发者处理AIC和AIV的同步
// 以Matmul为例：AIC侧做完Matmul计算后通知AIV进行后处理
if (g_coreType == AscendC::AIC) {
    // Matmul处理
    AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8);
}

// AIV侧等待AIC Set消息, 进行Vector后处理
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreWaitFlag(0x8);
    // Vector后处理
}
```

## Relevance
This is the in-kernel substitute for a host kernel launch between a cube stage and a vector stage, and the
constraints are hard limits on megakernel design: (1) only **flagId 0-10** on A3 — 11 distinct cross-core events
total; (2) **同一flagId的计数器最多设置15次** — a counter per flagId saturates at 15 Sets, so a persistent kernel
looping over 78 layers cannot reuse one flagId per layer without resetting; (3) the Matmul high-level API already
consumes flagIds internally, so hand-written `CrossCoreSetFlag` plus `Matmul` risks flagID collision — which
constrains whether we can use the `Matmul` high-level API inside a hand-synchronized megakernel; (4) mode 0
(all-AIC or all-AIV grid sync) wants batchmode (`__schedmode__(mode)` in kernel-direct-launch, or
`TilingContext::SetScheduleMode`) or the kernel can deadlock when total cores across concurrent streams exceed
physical cores — directly relevant because a megakernel occupying all cores on a die is exactly the batchmode case.
Also note `g_coreType == AscendC::AIC` / `AscendC::AIV` is the documented way one MIX kernel body branches between
the cube and vector halves — the mechanics of "one kernel runs on both AIC and AIV".

---

## 5. One kernel doing matmul -> vector op without returning to HBM: the Mix fusion operator pattern

### CANN 9.0 算子开发指南 — CV融合 / 算子实现 (Matmul+LeakyRelu)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/programug/Ascendcopdevg/atlas_ascendc_10_0050.html
Also published at https://www.hiascend.com/document/detail/zh/canncommercial/850/opdevg/Ascendcopdevg/atlas_ascendc_10_0050.html
and https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/82RC1/opdevg/Ascendcopdevg/atlas_ascendc_10_0050.html
Publisher: Huawei / Ascend, Ascend C 算子开发指南, parent topic 「CV融合」.

> 下文将以Matmul+LeakyRelu融合算子的实现为例，介绍Mix融合算子的设计和实现流程。该样例仅支持在 Atlas A2 训练系列产品 / Atlas A2 推理系列产品 上运行。

数据流分析, verbatim:

> 进行算子的数据流分析：数据流向为在Cube核上完成Matmul计算后将数据搬运至Vector核进行LeakyRelu计算。根据上述数据流并结合融合算子的编程范式，规划并行的流水任务。如下图所示：
>
> 将输入数据从Global Memory搬运到Cube核。
>
> 进行Matmul内部的计算，计算公式和计算示意图如下：
>
> 将Matmul的计算结果搬运到Vector核。
>
> 进行Vector矢量计算，该样例中进行LeakyReLU计算。
>
> 将输出结果搬运到Global Memory。
>
> 前三步的内容都封装在Matmul高阶API内，本样例中可以简化为3个stage。

Tiling 策略 — the UB constraint on the fused C tile, verbatim:

> 多核切分: 根据当前核数，对输入shape的M, K, N进行多核切分，得到单核内shape大小singleCoreM, singleCoreK, singleCoreN。
>
> 核内切分: 根据Local Memory的大小约束，对单核内的shape大小进一步切分，得到A、B、C矩阵参与一次矩阵乘指令的shape大小baseM, baseN, baseK。切分时需要注意：GetTensorC的结果如果放在LocalMemory（UB）上，需要注意，baseM * baseN的大小不能超出UB的限制。

Kernel-side code framework, verbatim:

```cpp
template<typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::Process(){
    uint32_t computeRound = 0;

    // 设置Matmul的输入（包括左矩阵、右矩阵、bias）
    matmulObj.SetTensorA(aGlobal);
    matmulObj.SetTensorB(bGlobal);
    matmulObj.SetBias(biasGlobal);
    // 调用matmul iterate获取一块[baseM, baseN]的计算结果
    while (matmulObj.template Iterate<true>())
    {
        MatmulCompute();
        LeakyReluCompute();
        CopyOut(computeRound);
        computeRound++;
    }
    matmulObj.End();
}
// kernel入口函数，mix场景，AIC:AIV=1:2
__global__ __mix__(1, 2) void matmul_leakyrelu_custom(GM_ADDR a, GM_ADDR b, GM_ADDR bias, GM_ADDR c,
                                                      __kfc_workspace__ GM_ADDR workspace, AscendC::tiling::TCubeTiling tiling)
{
    AscendC::TPipe pipe;
    MatmulLeakyKernel<half, half, float, float> matmulLeakyKernel;
    matmulLeakyKernel.Init(a, b, bias, c, workspace, tiling, &pipe);
    // Matmul对象初始化
    REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), matmulLeakyKernel.matmulObj, &matmulLeakyKernel.tiling);
    matmulLeakyKernel.Process(&pipe);
}
```

Matmul compute — `GetTensorC` is the cube->vector on-chip handoff, verbatim:

```cpp
template<typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::MatmulCompute(){
    reluOutLocal = reluOutQueue_.AllocTensor<cType>();
    // 调用GetTensorC将Matmul的计算结果搬运到Vector核。
    matmulObj.template GetTensorC<true>(reluOutLocal, false, true);
}
```

```cpp
// 调用LeakyRule接口进行计算
template<typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::LeakyReluCompute(){
    AscendC::LeakyRelu(reluOutLocal, reluOutLocal, (cType)alpha, tiling.baseM * tiling.baseN);
    reluOutQueue_.EnQue(reluOutLocal);
}
```

```cpp
// 将结果搬出到GM
template<typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::CopyOut(uint32_t count){
    reluOutQueue_.DeQue<cType>();
    const uint32_t roundM = tiling.singleCoreM / tiling.baseM;
    const uint32_t roundN = tiling.singleCoreN / tiling.baseN;
    uint32_t startOffset = (count % roundM * tiling.baseM * tiling.N + count / roundM * tiling.baseN);
    AscendC::DataCopyParams copyParam = {(uint16_t)tiling.baseM,
        (uint16_t)(tiling.baseN * sizeof(cType) / DEFAULT_C0_SIZE), 0,
        (uint16_t)((tiling.N - tiling.baseN) * sizeof(cType) / DEFAULT_C0_SIZE)};
    AscendC::DataCopy(cGlobal[startOffset], reluOutLocal, copyParam);
    reluOutQueue_.FreeTensor(reluOutLocal);
}
```

Host-side tiling, verbatim:

```cpp
auto ascendcPlatform = platform_ascendc::PlatformAscendC(context->GetPlatformInfo());
matmul_tiling::MultiCoreMatmulTiling cubeTiling(ascendcPlatform);
```

> 设置示例如下，其中TPosition::LCM是Unified Buffer上的逻辑位置，等同于TPosition::VECCALC，关于TPosition的详细内容请参考TPosition。

```cpp
cubeTiling.SetAType(matmul_tiling::TPosition::GM, matmul_tiling::CubeFormat::ND, matmul_tiling::DataType::DT_FLOAT16);
cubeTiling.SetBType(matmul_tiling::TPosition::GM, matmul_tiling::CubeFormat::ND, matmul_tiling::DataType::DT_FLOAT16);
cubeTiling.SetCType(matmul_tiling::TPosition::LCM, matmul_tiling::CubeFormat::ND, matmul_tiling::DataType::DT_FLOAT);
cubeTiling.SetBiasType(matmul_tiling::TPosition::GM, matmul_tiling::CubeFormat::ND, matmul_tiling::DataType::DT_FLOAT);
```

```cpp
cubeTiling.SetShape(M, N, K);
cubeTiling.SetOrgShape(M, N, K);
```

> 设置Matmul计算时可用的L1 Buffer/L0C Buffer/Unified Buffer空间大小，-1表示AI处理器对应Buffer的大小。
> ```cpp
> cubeTiling.SetBufferSpace(-1, -1, -1);
> ```

### 分离模式 vs 耦合模式 — WHY a MIX kernel costs what it costs

Verbatim, same page (this is the single most important paragraph for our launch-cost question):

> 特别的对于多核场景，需要通过SetDim接口设置Matmul计算所用的核数，MIX模式（包含矩阵计算和矢量计算）的设置规则如下：
>
> 分离模式：Matmul API都是从AIV侧发起的，调用Iterate计算时在AIV侧只会起到通知的作用，通知AIC去做矩阵计算，计算完成后AIC告知AIV计算完成。这个架构下，SetBlockDim设置为实际计算会用到的AI Core（AIC、AIV组合）的数量，SetDim设置为实际计算会用到的AIV的数量。例如，SetBlockDim时可以设置为20，启动20个AI Core（AIC AIV的组合），SetDim设置为40，表示按照40个AIV进行切分。
>
> 耦合模式：SetBlockDim加载的核数就是Matmul API实际计算会用到的核数，SetDim和SetBlockDim设置的值是一样的。

System workspace requirement, verbatim:

> Matmul高阶API内部实现时需要使用系统workspace，开发者需要：
>
> 在host侧Tiling实现时，设置总的workspace的数值大小（包含用户workspace和系统workspace），workspace空间由框架来申请并管理。系统workspace的空间大小通过GetLibApiWorkSpaceSize获取。

```cpp
size_t userWorkspaceSize = 0;
size_t systemWorkspaceSize = ascendcPlatform.GetLibApiWorkSpaceSize();
size_t *currentWorkspace = context->GetWorkspaceSizes(1);
currentWorkspace[0] = userWorkspaceSize + systemWorkspaceSize;
```

> 若算子工程不是自定义算子工程，也不是带有HAVE_WORKSPACE编译宏的Kernel直调算子工程，kernel侧需要在Matmul初始化前，通过SetSysWorkSpace设置系统workspace。

```cpp
// 使用Matmul时必须设置workspace空间
SetSysWorkspace(workspace);
if (GetSysWorkSpacePtr() == nullptr) {
    return;
}
```

### The low-level ("底层编码") route: hand-written AIC/AIV isolation and hand-written sync

Verbatim, same page — this is the documented escape hatch from the framework's KFC messaging:

> 上文介绍的实现方法，AIC侧和AIV侧的代码隔离和核间同步由框架来完成，开发者无需关心。除该方法外，开发者也可以选择底层编码的方式在分离模式下实现融合算子，这种方式将更加灵活。采用底层编码方式时，需要注意以下几点：
>
> 通过ASCEND_IS_AIV和ASCEND_IS_AIC实现AIV和AIC代码之间的隔离。
>
> 自行实现AIC核和AIV核之间的同步：比如Matmul + LeakyRelu算子样例中，需要确保在AIC完成矩阵计算后，AIV再进行LeakyRelu的计算。
>
> 使用高阶API Matmul时需要设置ASCENDC_CUBE_ONLY，表示仅在AIC侧调用Matmul API。
>
> 使用设置Kernel类型接口设置Kernel类型为KERNEL_TYPE_MIX_xxx，同时启用AIV核和AIC核。

```cpp
#define ASCENDC_CUBE_ONLY // 指定Matmul运行在AIC上
KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);  // 设置Kernel类型为KERNEL_TYPE_MIX_xxx
if ASCEND_IS_AIC {
    ...
    // AIC核进行Matmul计算
    // AIC核完成计算后，通过AscendC::CrossCoreSetFlag<modeId, pipe>(flagId)发送同步flag
}
if ASCEND_IS_AIV {
    ...
    // AIV核通过AscendC::CrossCoreWaitFlag(flagId)接收同步flag
    // AIV核进行LeakyRelu计算
}
```

> 完整样例请参考BareMix样例。

## Relevance
This is the template for the megakernel. Three things matter to our numbers.
(1) `__global__ __mix__(1, 2)` plus `__kfc_workspace__ GM_ADDR workspace` is the declaration form that produces a
MIX_AIC kernel — the 13.58 us class. "kfc" = kernel function call: in 分离模式 the Matmul API is *issued from the AIV
side*, and `Iterate` on AIV only sends a notification to AIC, which replies on completion. That request/reply channel
through GM workspace is a plausible named mechanism for the ~11 us gap between MIX_AIC (13.58 us) and AI_CORE (2.30 us).
(2) The `while (Iterate<true>()) { MatmulCompute(); LeakyReluCompute(); CopyOut(); }` loop with `GetTensorC<true>(reluOutLocal, ...)`
writing into a UB `LocalTensor` is the documented way to keep a matmul result on-chip and apply a vector op to it
without a round trip to HBM — exactly the fusion we need for the W4A8 dequant/activation chain.
(3) The 底层编码 route (`ASCENDC_CUBE_ONLY` + `ASCEND_IS_AIC`/`ASCEND_IS_AIV` + explicit `CrossCoreSetFlag`) is the
route that lets us keep the Matmul high-level API but drive the AIC/AIV handshake ourselves — which is what a
persistent multi-stage kernel requires, since the framework's per-`Iterate` KFC messaging is the per-call cost.
Note the constraint collision: section 4's CrossCoreSetFlag doc says mixing hand-written `CrossCoreSetFlag` with
the Matmul high-level API risks flagID conflicts, while this page tells us to do exactly that under `ASCENDC_CUBE_ONLY`.

---

## 6. SuperKernel — CANN's own kernel-binary fusion, and the mechanism behind it

### `cann/graph-autofusion` super_kernel README — 原理介绍 (the mechanism, verbatim)

https://gitcode.com/cann/graph-autofusion/blob/master/super_kernel/README.md
raw: https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/README.md
Repo: `cann/graph-autofusion` on GitCode (CANN open-source org), branch `master`. Copyright 2025 Huawei Technologies.

> # SuperKernel
>
> ## 原理介绍
>
>    SuperKernel 是一种面向网络图模型的调度优化技术。其核心思想是：基于网络图模型中算子的先验信息（如算子类型、前后序依赖关系等），结合即时编译（JIT）能力，将整个网络模型重新编译为单一算子，从而显著降低算子调度开销，并借助 ICache 预取、Early-Start、同步优化、子 Kernel 拆分等优化手段进一步提升性能。
>
> ***
>    SuperKernel 的设计初衷是将多个子算子融合成一个 SuperKernel，以节省 N-1 次算子调度开销。然而，为维持子算子间的执行顺序，通常需插入全核同步操作，这在一定程度上削弱了调度优化的收益。得益于编译阶段即可获取全部子算子的先验信息，SuperKernel 可在此基础上实施更多深层优化。
>
> 1. **ICache Preload 优化**
>
>    SuperKernel 融合全部算子后，其二进制体积较大。系统在加载算子时通常仅预取入口处指令，导致 SuperKernel 内部大量指令未被预加载至指令缓存（ICache），从而引发较高的 ICache Miss。为此，我们引入 ICache Preload 机制：在当前子算子开始执行前，预加载其后续子算子的代码段，从而有效减少后续算子执行时的 ICache Miss。
>
> 2. **Early-Start 优化**
>
>    在常规调度中，必须等待前序算子全部执行完成后，才能启动后续算子。然而，多数前序算子的末尾指令为 MTE 数据搬运指令，而后续算子的起始指令通常为与输入数据无关的初始化标量指令。由于这两类指令分属不同计算单元，具备并发执行的条件。Early-Start 技术在前序算子的搬运指令前插入 Set 同步点，在后续算子的初始化指令后插入 Wait 同步点，从而实现两个子算子的部分指令并发执行，提升整体执行效率。
>
> 3. **同步优化**
>
>    为保障执行顺序正确，SuperKernel 在各子算子调度之间会插入全核同步操作。对于 Kernel Type 为 Mix 1:2 的混合类型算子，完整的全核同步需等待所有 Aicore 的 Vector 核与 Cube 核均完成同步。SuperKernel 在编译时能够识别每个子算子的类型，因此可针对前后子算子的 Kernel Type 定制同步范围。例如，对于连续的 Vector 算子，仅需执行全 Vector 核同步即可。通过细粒度控制同步范围，可有效降低子算子间的同步开销。
>
> 4. **子 Kernel 拆分**
>
>    在多核系统中，当多个计算核心执行同一段代码时，会并发访问内存中的同一指令地址。这种对同一地址的并发访问会在共享的 L2 Cache 层面形成串行化访问队列，引发资源争用，削弱多核并行带来的性能增益。为解决该问题，SuperKernel 将子 Kernel 代码复制为多份副本，使不同核心能根据核 ID 映射到不同的物理地址执行。这一方法有效缓解了多核对同一指令地址的争用，显著提升算子执行效率。
>
>    此外，SuperKernel 还支持基于内存语义的 Notify 与 Wait 事件，以适配 Tiling 下沉与 Weight 预取等场景。Tiling 下沉算子指的是 Tiling 计算依赖前序算子的输出结果，为避免主机与设备间的频繁交互，将 Tiling 计算部署于 AICpu 执行的算子。若 SuperKernel 融合了该 Tiling 算子的前序算子，则需在前序算子执行完成后通过 Notify 事件通知 AICpu 启动 Tiling 计算；若融合了 Tiling 下沉算子本身，则需通过 Wait 事件等待 AICpu 完成 Tiling 计算后再执行 Device 侧计算。Weight 预取则借助 CMO 任务调用专用硬件单元 SDMA，将数据提前加载至 L2 Cache，以提升计算效率。SDMA 与 Aicore 之间的协作正是通过内存语义的 Notify/Wait 事件实现的。

Directory structure, verbatim:

```text
super_kernel/
├── docs                   # 文档介绍
├── examples               # 示例脚本或 Notebook，演示典型用法
├── include                # SuperKernel 对外头文件
├── kernel                 # 设备侧 Kernel 实现
├── scripts                # 脚本路径
├── src                    # SuperKernel 业务代码
│   ├── aot                # AOT 编译与优化实现
│   └── jit                # JIT 编译实现
├── tests                  # 测试工程目录
```

Supported products, from `super_kernel/examples/README.md`
(https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/examples/README.md):

> ## 环境依赖
>
> 支持如下产品型号：
>
> - Ascend 950PR/Ascend 950DT
> - Atlas A3 训练系列产品/Atlas A3 推理系列产品
> - Atlas A2 训练系列产品/Atlas A2 推理系列产品

> ```text
> examples/
> ├── run_example.sh                                   # 工程测试批量执行脚本
> ├── jit/
> │   ├── example01_super_kernel_base/                 # SuperKernel 基础功能
> │   ├── example02_super_kernel_profiling/            # SuperKernel profiling 对比
> │   └── example03_super_kernel_runtime_ascendc_only/ # AscendC + Runtime 极简样例
> └── aot/
>     ├── scripts/                                     # AOT 样例公共 Bash 函数
>     ├── example01_dual_stream/                       # 双流与 NPU Event 控制边
>     ├── example02_sk_options/                        # SuperKernel options
>     └── example03_kernel_pybind/                     # Pybind 自定义算子融合
> ```

The developer guide (https://raw.gitcode.com/cann/graph-autofusion/raw/master/docs/zh/super_kernel/developer_guide.md)
pins the default test SoC — note it is an A3 part:

> - `soc_version`（`fixtures/config.py`）：指定默认 SoC 信息，当前默认值为 `Ascend910_9391`；如需使用其他版本，可在场景内覆盖或增加新的 fixture。

## Relevance
This is the authoritative account of *why* kernel launch dominates and what the vendor does about it:
「将多个子算子融合成一个 SuperKernel，以节省 N-1 次算子调度开销」 — fuse N sub-operators, save N-1 dispatches.
That is our 3008-kernel / 11.5 ms problem stated by the vendor. Four mechanisms are named, and three bear directly
on our measurements:
- 同步优化 states the MIX cost explicitly: 「对于 Kernel Type 为 Mix 1:2 的混合类型算子，完整的全核同步需等待所有
  Aicore 的 Vector 核与 Cube 核均完成同步」 — a full all-core sync on a Mix 1:2 operator must wait for *both* the
  Vector and the Cube cores of every AI Core. That is the named reason MIX_AIC (13.58 us) costs ~6x AI_CORE (2.30 us)
  and ~19x AI_VECTOR_CORE (0.70 us). The fix SuperKernel applies is to narrow the sync scope per adjacent
  sub-operator kernel type (consecutive vector ops get a vector-only all-core sync).
- ICache Preload: a megakernel's binary is large and the hardware prefetches only the entry instructions, so naive
  fusion trades launch cost for ICache misses. We must plan for explicit code-segment preload.
- 子 Kernel 拆分: all cores executing the same instruction address serialize at the shared L2. SuperKernel replicates
  sub-kernel code so cores map to distinct physical addresses by core ID. A hand-written megakernel on 20+ cores
  will hit this L2 instruction-fetch serialization unless we replicate too.
- Early-Start: insert Set before the predecessor's trailing MTE instructions and Wait after the successor's
  input-independent scalar init, so two sub-operators' instructions overlap across pipes.

---

### SuperKernel public C API: `aclskOptimize`, `aclskScopeBegin/End`, `aclskScopeVerify`, full option enum

https://gitcode.com/cann/graph-autofusion/blob/master/super_kernel/include/super_kernel/super_kernel.h
raw: https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/include/super_kernel/super_kernel.h
Repo `cann/graph-autofusion`, branch `master`. Copyright (c) 2025 Huawei Technologies Co., Ltd.

```cpp
/*!
 * \file superkernel_opt_options.h
 * \brief
 */

#ifndef ACL_SUPERKERNEL_H
#define ACL_SUPERKERNEL_H

#include <cstdint>
#include <cstddef>
#include "acl/acl.h"

enum class aclskOptionType : uint32_t {
  PRELOAD_CODE = 0,
  SPLIT_MODE = 1,
  STREAM_FUSION = 2,
  DCCI_DISABLE_ON_KERNEL = 3,
  DEBUG_SYNC_ALL = 4,
  KERNEL_MAP = 5,
  AUTO_OP_PARALLEL = 7,
  DCCI_BEFORE_KERNEL_START = 8,
  DEBUG_OP_EXEC_TRACE = 9,
  DEBUG_CROSS_CORE_SYNC_CHECK = 10,
  OPT_EXTEND_OPTION = 11,
  DEBUG_EXTEND_OPTION = 12,
  DCCI_AFTER_KERNEL_END = 13,
  AGGRESSIVE_OPT_STRATEGIES = 14,
  UBUF_LOCK_IGNORE_KERNEL = 15,
  EARLY_START = 16,                // early start global option
  DEBUG_PER_OP_MAX_CORE_NUM = 17,  // debug: per op max core num limit
  SK_OPTION_MAX
};

enum class SkInnerOptionType : uint32_t { MIX_KERNEL_SPLIT = 0, SIMT_OP_SUPPORT = 1, SK_INNER_OPTION_MAX };

typedef struct aclskPreloadOption {
  uint32_t preloadMode;
} aclskPreloadOption;

typedef struct aclskSplitModeOption {
  uint32_t splitCnt;
} aclskSplitModeOption;

typedef struct aclskStreamFusionOption {
  uint32_t streamFusion;
} aclskStreamFusionOption;

typedef struct aclskDcciOption {
  char **kernelNames;
  size_t kernelCnt;
} aclskDcciOption;

typedef struct aclskDebugSyncAllOption {
  uint32_t debugSyncAll;
} aclskDebugSyncAllOption;

typedef struct aclskKernelMap {
  char *globalName;
  char *sknlNames[4];
} aclskKernelMap;

typedef struct aclskKernelMapOption {
  aclskKernelMap *kernelMaps;
  size_t numKernels;
} aclskKernelMapOption;

typedef struct aclskAutoOpParallelOption {
  uint32_t enableAutoOpParallel;
} aclskAutoOpParallelOption;

/**
 * aggressiveOpts carries aggressive fusion strategy switches:
 *  - eventBreakerBypass: reserved for event breaker policy
 *  - taskBreakerBypass: enable default-node bypass when set to 1
 *
 * aggressiveOpts.valueBreakerBypass is a bitmask-style value-memory wait policy:
 *  - ACLSK_VALUE_BREAKER_BYPASS_NONE (0b00): reject notify/wait pairing relation, keep wait unfusible
 *  - ACLSK_VALUE_BREAKER_BYPASS_PAIRED_WAIT (0b01): for paired notify+wait, existing rule must pass or SK exits
 *  - ACLSK_VALUE_BREAKER_BYPASS_UNPAIRED_WAIT (0b10): for waits without notify after rule check, allow wait fusion
 */
enum aclskValueBreakerBypassFlag : uint32_t {
  ACLSK_VALUE_BREAKER_BYPASS_NONE = 0b00U,
  ACLSK_VALUE_BREAKER_BYPASS_PAIRED_WAIT = 0b01U,
  ACLSK_VALUE_BREAKER_BYPASS_UNPAIRED_WAIT = 0b10U
};

typedef struct aclskAggressiveOptStrategies {
  uint32_t eventBreakerBypass;
  uint32_t valueBreakerBypass;
  uint32_t taskBreakerBypass;
} aclskAggressiveOptStrategies;

/**
 * Configure kernels that should ignore MIX kernel split by name pattern.
 */
typedef struct aclskUbufLockIgnoreKernelOption {
  uint32_t ubufLockIgnoreKernelCnt;
  char **ubufLockIgnoreKernel;
} aclskUbufLockIgnoreKernelOption;

enum aclskEarlyStartValue : uint32_t {
  ACLSK_EARLY_START_DISABLED = 0U,  // 默认值，表示不启用early start
  ACLSK_EARLY_START_ENABLED = 1U,   // 启用early start
};
typedef struct aclskEarlyStartOption {
  uint32_t enableEarlyStart;  // 0[default]: disable early start, 1: enable early start
} aclskEarlyStartOption;

typedef struct aclskDebugPerOpMaxCoreNumOption {
  uint32_t enableDebugPerOpMaxCoreNum;  // 0[default]: disable, 1: enable
} aclskDebugPerOpMaxCoreNumOption;

struct aclskOption {
  aclskOptionType optionType;
  union {
    aclskPreloadOption preload;
    aclskSplitModeOption splitMode;
    aclskStreamFusionOption streamFusion;
    aclskDcciOption disableKernelDcci;
    aclskDebugSyncAllOption debugSync;
    aclskKernelMapOption kernelMap;
    aclskAutoOpParallelOption autoOpParallel;
    aclskDcciOption dcciBeforeKernelStart;
    aclskDebugOpExecTraceOption debugOpExecTrace;
    aclskDebugCrossCoreSyncCheckOption debugCrossCoreSyncCheck;
    aclskExtendOption optExtend;
    aclskExtendOption debugExtend;
    aclskDcciOption dcciAfterKernelEnd;
    aclskAggressiveOptStrategies aggressiveOpts;
    aclskUbufLockIgnoreKernelOption ubufLockIgnoreKernel;
    aclskEarlyStartOption earlyStart;
    aclskDebugPerOpMaxCoreNumOption debugPerOpMaxCoreNum;
  };
};

typedef struct aclskOptions {
  aclskOption *options;
  size_t numOptions;
} aclskOptions;

typedef enum {
  ACLSK_SCOPE_VERIFY_NODE_WAIT = 0,
  ACLSK_SCOPE_VERIFY_NODE_NOTIFY = 1,
  ACLSK_SCOPE_VERIFY_NODE_COMPUTE = 2,
} aclskScopeVerifyNodeType;

typedef enum {
  ACLSK_SCOPE_VERIFY_KERNEL_NO_AICORE = 0,
  ACLSK_SCOPE_VERIFY_KERNEL_CUBE = 1,    // AI CUBE CORE
  ACLSK_SCOPE_VERIFY_KERNEL_VECTOR = 2,  // AI VECTOR CORE
  ACLSK_SCOPE_VERIFY_KERNEL_MIX = 3,
} aclskScopeVerifyKernelType;

typedef struct aclskScopeVerifyNodeInfo {
  int64_t taskId;
  int64_t streamId;
  int64_t eventId;
  int32_t scopeId;
  aclskScopeVerifyNodeType taskType;
  aclskScopeVerifyKernelType kernelType;
  uint32_t numBlocks;
  uint32_t taskRatio[2];
  int32_t scheMode;
  uint32_t flag;  // bit 0：是否动态，0表示静态，1表示动态；其余bit预留
  int32_t coreLimit[2];
  int32_t extendType;  // 当前必须是0
  void *extendInfo;    // 当前必须是nullptr
} aclskScopeVerifyNodeInfo;

typedef enum {
  ACLSK_SCOPE_VERIFY_SPLIT_BEFORE_NODE = 0,  // scope 在 current node 前断开（全核同步）
  ACLSK_SCOPE_VERIFY_SPLIT_EXCLUDE_NODE = 2,  // scope 在 current node 前断开，且current node不参与scope融合（死锁）
} aclskScopeVerifySplitType;

typedef enum {
  ACLSK_SCOPE_VERIFY_DEADLOCK_DETECTED = 0,
  ACLSK_SCOPE_VERIFY_SYNCALL_OP_DROP = 1,
} aclskScopeVerifySplitReason;

/**
 * @ingroup AscendCL
 * @brief Optimize model with super kernel
 *
 * @param model [IN]    Model handle to be optimized
 * @param options [IN]  Pointer to optimization options
 *
 * @retval ACL_ERROR_SUCCESS Optimization succeeded
 * @retval ACL_ERROR_INVALID_PARAM Invalid parameters
 * @retval ACL_ERROR_FAILURE Optimization failed
 *
 * @see aclskOptions
 */
ACL_FUNC_VISIBILITY aclError aclskOptimize(aclmdlRI model, aclskOptions *options);
ACL_FUNC_VISIBILITY aclError aclskScopeBegin(const char *scopeName, aclrtStream stream);
ACL_FUNC_VISIBILITY aclError aclskScopeEnd(const char *scopeName, aclrtStream stream);
/**
 * @ingroup AscendCL
 * @brief
 *
 * @param verifyGraph             传入的图
 * @param maxSplitResultCount     传入的splitResults数组的最大长度
 * @param splitResults            导致scope断开的node列表
 * @param realSplitResultCount    导致scope断开的node数量
 * @retval ACL_SUCCESS 接口调用成功
 * @retval ACL_ERROR_INVALID_PARAM 参数校验失败
 * @retval ACL_ERROR_FAILURE 接口调用失败
 */
ACL_FUNC_VISIBILITY aclError aclskScopeVerify(const aclskScopeVerifyGraphInfo *verifyGraph, size_t maxSplitResultCount,
                                              aclskScopeVerifySplitResult *splitResults, size_t *realSplitResultCount);
```

## Relevance
`aclskOptimize(aclmdlRI model, aclskOptions *options)` takes an `aclmdlRI` — the model runtime instance handle
produced by `aclmdlRICaptureBegin`/`aclmdlRICaptureEnd`. So SuperKernel is applied to an already-captured ACL graph,
i.e. the vendor path is "capture the 3008 launches, then fuse their binaries", not "write one kernel".
`aclskScopeBegin(scopeName, stream)` / `aclskScopeEnd` delimit the fusion range on a stream.
`aclskScopeVerify` returns the nodes that *break* a scope, with reasons `ACLSK_SCOPE_VERIFY_DEADLOCK_DETECTED` and
`ACLSK_SCOPE_VERIFY_SYNCALL_OP_DROP` — i.e. a node whose own `SyncAll` would be dropped, or that would deadlock,
forcibly splits the super kernel. `aclskScopeVerifyNodeInfo` carries `kernelType` (NO_AICORE / CUBE / VECTOR / MIX),
`numBlocks`, `taskRatio[2]` (the AIC:AIV ratio), `scheMode` and `coreLimit[2]` — the exact per-node metadata the
fuser uses to decide sync scope. `SkInnerOptionType::MIX_KERNEL_SPLIT` and `UBUF_LOCK_IGNORE_KERNEL`
("Configure kernels that should ignore MIX kernel split by name pattern") confirm MIX kernels are handled by
splitting, and that UB locking is what forces the split.
`EARLY_START`, `PRELOAD_CODE`, `SPLIT_MODE.splitCnt`, `DCCI_BEFORE_KERNEL_START` / `DCCI_AFTER_KERNEL_END` are the
knobs corresponding to the four mechanisms above. vllm-ascend passes exactly
`{"dcci_after_kernel_end": [".*"]}` (see next section), i.e. a DCCI (data cache clean-and-invalidate) after every
fused sub-kernel.

---

## 7. SuperKernel as wired up in vllm-ascend (including a GLM-5.2 A3 config)

### vllm-ascend `docs/source/user_guide/feature_guide/graph_mode.md` — Super Kernel optimization

https://github.com/vllm-project/vllm-ascend/blob/main/docs/source/user_guide/feature_guide/graph_mode.md
raw: https://raw.githubusercontent.com/vllm-project/vllm-ascend/main/docs/source/user_guide/feature_guide/graph_mode.md
Project: vllm-project/vllm-ascend, branch `main`, fetched 2026-10-20.

> ### Super Kernel optimization
>
> [Super Kernel](https://www.hiascend.com/document/detail/en/Pytorch/latest/devguide/TorchAir/docs/en/npugraph_ex/advanced/superkernel.md) is an **optional** operator-binary fusion optimization. Unlike source-level fusion, it works on compiled kernel binaries: eligible subgraphs are identified, their child kernels are combined into a larger kernel, and synchronization is inserted according to graph dependencies. Compared with launching operators individually, this can reduce task scheduling waits, launch overhead, and operator-head overhead.
>
> In vLLM Ascend, Super Kernel optimization is applied during ACLGraph capture. It depends on both static kernel and Npugraph_ex:
>
> ```text
> Super Kernel -> static kernel -> Npugraph_ex
> ```
>
> !!! note
>
>     Static kernel is disabled by default, so Super Kernel is also disabled under the default configuration. When `enable_static_kernel` is explicitly set to `true` and `enable_super_kernel` is omitted, Super Kernel follows static kernel and is enabled. Set `enable_super_kernel` explicitly to override this inherited behavior. Super Kernel cannot be enabled when static kernel is disabled.
>
>     Not every operator is eligible for Super Kernel fusion. An unsupported operator may split the fusion range, so the actual coverage and performance benefit depend on the model and operator sequence. Changing the Super Kernel setting also changes the static-kernel compilation configuration and may cause the static-kernel cache to be rebuilt.

```bash
vllm serve Qwen/Qwen2-7B-Instruct \
  --additional-config '{"ascend_compilation_config":{"enable_npugraph_ex":true, "enable_static_kernel":true}}'
```

> To use static kernel without Super Kernel:
>
> ```bash
> vllm serve Qwen/Qwen2-7B-Instruct \
>   --additional-config '{"ascend_compilation_config":{"enable_npugraph_ex":true, "enable_static_kernel":true, "enable_super_kernel":false}}'
> ```
>
> #### Verifying Super Kernel is active
>
> When Super Kernel optimization is applied during ACLGraph capture, vLLM Ascend emits:
>
> ```text
> Super kernel optimization is enabled for ACL graph capture.
> ```
>
> This message confirms that the optimization step was invoked. To verify the resulting fusion coverage and performance benefit, collect an **Ascend Profiling** trace and inspect `kernel_details.csv`. Compare the kernel/task entries and latency with Super Kernel disabled; the profiler also reports the launch core count for generated Super Kernels in the `Block Dim` field.

Static kernel compilation, verbatim:

> ### Static kernel compilation
>
> Static kernel compilation is an **optional** feature that pre-compiles operator binaries with fixed shapes at compile time, reducing runtime overhead for networks with static or near-static shapes. It is **disabled by default** and must be explicitly enabled.
>
> !!! note
>
>     Enabling static kernel triggers a compilation pass during the graph capture phase at service startup. This may add **several minutes to tens of minutes** to the startup time depending on the number of operators to compile and model complexity. Once completed, subsequent request processing is not affected.
>
> #### Verifying static kernel is active
>
> The recommended way to verify static kernel is in effect is through **Ascend Profiling**:
>
> 1. Collect a profiling trace of your running model using [Ascend PyTorch Profiler](...) (`torch_npu.profiler`).
> 2. Open the generated `op_statistic.csv` file.
> 3. Look for operators whose `op_type` or `name` column contains the keyword **`static_kernel`**. If such entries exist, static kernel compilation has taken effect for those operators.
>
> During the compilation phase, you will see a Python warning (visible by default):
>
> ```text
> Starting static kernel compilation, the build directory is <path>
> ```

Npugraph_ex, verbatim — the kernel-launch-reduction rationale:

> ## Using Npugraph_ex
>
> As introduced in the [RFC](https://github.com/vllm-project/vllm-ascend/issues/4715), Npugraph_ex is a compile-time FX graph optimization layer that works together with ACLGraph. It optimizes the model's FX graph before ACLGraph captures it at runtime. Its performance benefits mainly come from fusing multiple operators into single kernels (e.g., add + rms_norm → npu_add_rms_norm) to reduce kernel launch overhead.

> - Graph mode is currently available on both Model Runner V1/V2.
> - **ACLGraph** (capture/replay via `torch.npu.NPUGraph`) is the runtime graph execution mechanism used by the default graph path on Ascend.
> - **Npugraph_ex** is a compile-time FX graph optimization layer, enabled by default in FULL/FULL_DECODE_ONLY modes. It optimizes the graph before ACLGraph captures it.
> - **XliteGraph** is an optional graph path for selected model families and environments.
> - In context parallel scenarios, `cudagraph_mode="FULL"` is not sufficiently supported yet.

> | `cudagraph_mode` | Compile-time | Runtime | Npugraph_ex |
> |---|---|---|---|
> | FULL_AND_PIECEWISE | Piecewise compilation path | Mixed: PIECEWISE for mixed batches, FULL-capable for uniform decode batches | Disabled |
> | FULL / FULL_DECODE_ONLY | Npugraph_ex FX optimization | ACLGraph capture/replay | Enabled |
> | PIECEWISE | Fusion pass only | ACLGraph capture/replay | Disabled |
> | NONE | None | Eager execution | Disabled |

> Ascend sets `use_inductor=False` and selects its own compilation backend. That backend applies npugraph_ex optimizations or FX fusion passes according to the configuration.

Stream-resource exhaustion on capture, verbatim (relevant because a 3008-kernel graph is large):

> If ACL graph capture fails with the confirmed stream-resource signature in the error text, such as `207008` together with `Stream resources are insufficient` or `Insufficient_Stream_Resources`, vLLM Ascend will re-raise that capture failure with targeted mitigation guidance. In practice, the main levers are: upgrading to a newer HDK/CANN stack, reducing `cudagraph_capture_sizes`, lowering `max_cudagraph_capture_size`, or preferring `FULL` / `FULL_DECODE_ONLY` when the workload is mostly uniform decode.

### vllm-ascend source: how Super Kernel is actually invoked

https://github.com/vllm-project/vllm-ascend/blob/main/vllm_ascend/compilation/acl_graph.py
raw: https://raw.githubusercontent.com/vllm-project/vllm-ascend/main/vllm_ascend/compilation/acl_graph.py

```python
from ..utils import super_kernel_scope, use_updatable_graph, weak_ref_tensors
...
_STREAM_RESOURCE_ERROR_CODE = "207008"
_STREAM_RESOURCE_ERROR_MARKERS = (
    "insufficient_stream_resources",
    "stream resources are insufficient",
)
_OLD_HDK_CAPTURE_ERROR_MARKERS = ("alloc sq cq fail",)
...
        self.enable_super_kernel = get_ascend_config().ascend_compilation_config.enable_super_kernel
...
                forward_context.capturing = True
                try:
                    with torch.npu.graph(aclgraph, pool=self.graph_pool):
                        # `output` is managed by pytorch's aclgraph pool
                        with super_kernel_scope("full_model", self.enable_super_kernel):
                            output = self.runnable(*args, **kwargs)
...
            if self.enable_super_kernel:
                aclgraph.super_kernel_optimize(
                    optimize_options={
                        "dcci_after_kernel_end": [".*"],
                    },
                )
                logger.info_once("Super kernel optimization is enabled for ACL graph capture.")
```

https://github.com/vllm-project/vllm-ascend/blob/main/vllm_ascend/utils.py

```python
@contextmanager
def super_kernel_scope(scope: str, enabled: bool):
    if not enabled:
        yield
        return

    torch.npu.super_kernel_scope_begin(scope)
    try:
        yield
    finally:
        torch.npu.super_kernel_scope_end(scope)
```

### A real GLM-5.2-W8A8C8 A3 config that turns on static kernel + super kernel

https://github.com/vllm-project/vllm-ascend/blob/main/tests/e2e/cases/models/configs/GLM/GLM-5.2-W8A8C8-A3_128k-static-super-kernels.yaml
raw: https://raw.githubusercontent.com/vllm-project/vllm-ascend/main/tests/e2e/cases/models/configs/GLM/GLM-5.2-W8A8C8-A3_128k-static-super-kernels.yaml

```yaml
# Optional configuration based on PR #17871; intentionally not registered in weekly_config.yaml.
test_name: "multi-node-GLM-5.2-W8A8C8-MTP-A3_128k-static-super-kernels"
model: "Eco-Tech/GLM-5.2-w8a8c8"
num_nodes: 2
npu_per_node: 16
dp_load_balancing: internal
env_common: &env_common
  LOCAL_WORLD_SIZE: "16"
  HCCL_OP_EXPANSION_MODE: "AIV"
  OMP_PROC_BIND: "false"
  VLLM_USE_MODELSCOPE: "true"
  OMP_NUM_THREADS: "1"
  HCCL_BUFFSIZE: "400"
  PYTORCH_NPU_ALLOC_CONF: "expandable_segments:True"
  VLLM_ASCEND_ENABLE_FLASHCOMM1: "1"
  VLLM_ENGINE_READY_TIMEOUT_S: "3000"
  SERVER_PORT: 8077
```

The decisive line, verbatim:

```
      --compilation-config '{"cudagraph_mode": "FULL_DECODE_ONLY"}'
      --kv-cache-dtype int8
      --attention_config.indexer_kv_dtype int8
      --additional-config '{"enable_dsa_cp": true, "enable_balance_scheduling": true, "ascend_compilation_config": {"fuse_muls_add": true, "enable_npugraph_ex": true, "enable_static_kernel": true, "enable_super_kernel": true}, "multistream_overlap_shared_expert": true,"enable_fused_mc2":1,"enable_mlapo":true}'
      --speculative-config '{"num_speculative_tokens": 3, "method": "deepseek_mtp","enforce_eager":true}'
```

Benchmark entries attached to that config, verbatim:

```yaml
  perf_128k:
    case_type: performance
    dataset_path: vllm-ascend/GSM8K-in131072-bs500-prefix90-glm51
    request_conf: vllm_api_stream_chat
    dataset_conf: gsm8k/gsm8k_gen_0_shot_cot_str_perf
    num_prompts: 256
    max_out_len: 1024
    batch_size: 64
    request_rate: 0
    baseline: 733.1813
    threshold: 0.97
```

### `additional_config.md` as of v0.11.0 (for comparison — `enable_super_kernel` not yet in this table)

https://raw.githubusercontent.com/vllm-project/vllm-ascend/v0.11.0rc0/docs/source/user_guide/configuration/additional_config.md

> | Name                          | Type | Default | Description                                                                                   |
> |-------------------------------| ---- |------|-----------------------------------------------------------------------------------------------|
> | `torchair_graph_config`       | dict | `{}` | The config options for torchair graph mode                                                    |
> | `ascend_scheduler_config`     | dict | `{}` | The config options for ascend scheduler                                                       |
> | `refresh`                     | bool | `false` | Whether to refresh global ascend config content. This value is usually used by rlhf or ut/e2e test case.     |
> | `expert_map_path`             | str  | `None` | When using expert load balancing for the MOE model, an expert map path needs to be passed in. |
> | `enable_prefetch`     | bool | `False` | Whether to enable weight prefetch. |
> | `kv_cache_dtype`     | str | `None` | When using the kv cache quantization method, kv cache dtype needs to be set, currently only int8 is supported. |
> | `enable_shared_expert_dp`     | bool | `False` | When the shared expert in DP, it has better performance but consumes more memory. Currently only DeepSeek series models are supported to use. |
> | `lmhead_tensor_parallel_size` | int | `None` | The custom tensor parallel size of lmhead. |
> | `oproj_tensor_parallel_size` | int | `None` | The custom tensor parallel size of oproj. |
> | `multistream_overlap_shared_expert`| bool | `False` | Whether to enable multistream shared expert. This option only takes effects on moe models with shared experts. |

> **torchair_graph_config**
>
> | Name | Type | Default | Description |
> | ---- | ---- | ------- | ----------- |
> | `enabled` | bool | `False` | Whether to enable torchair graph mode. Currently only DeepSeek series models and PanguProMoE are supported to use torchair graph mode |
> | `mode` | str | `None` | When using reduce-overhead mode for torchair, mode needs to be set |
> | `enable_multistream_mla`| bool | `False` | Whether to put vector ops of MLA to another stream. This option only takes effects on models using MLA (e.g., DeepSeek). |
> | `enable_view_optimize` | bool | `True` | Whether to enable torchair view optimization |
> | `enable_frozen_parameter` | bool | `True` | Whether to fix the memory address of weights during inference to reduce the input address refresh time during graph execution. |
> | `use_cached_graph` | bool | `False` | Whether to use cached graph |
> | `graph_batch_sizes` | list[int] | `[]` | The batch size for torchair graph cache |
> | `graph_batch_sizes_init` | bool | `False` | Init graph batch size dynamically if `graph_batch_sizes` is empty |
> | `enable_kv_nz`| bool | `False` | Whether to enable kvcache NZ layout. This option only takes effects on models using MLA (e.g., DeepSeek). |

Earlier doc versions (v0.9.1 / v0.11.0 published docs) described the option as:

https://docs.vllm.ai/projects/ascend/en/v0.9.1/user_guide/configuration/additional_config.html

> `enable_super_kernel` | bool | `False` | Whether to enable super kernel

## Relevance
This is a working, vendor-maintained configuration for *our model family on our hardware* (GLM-5.2-W8A8C8, A3, 16 NPUs
per node) that enables exactly the launch-overhead attack we need. It establishes the dependency chain
`Super Kernel -> static kernel -> Npugraph_ex` and the three-flag incantation
`{"ascend_compilation_config": {"enable_npugraph_ex": true, "enable_static_kernel": true, "enable_super_kernel": true}}`
plus `--compilation-config '{"cudagraph_mode": "FULL_DECODE_ONLY"}'`. The quoted benefit is exactly our target:
"reduce task scheduling waits, launch overhead, and operator-head overhead". The actual API call is
`aclgraph.super_kernel_optimize(optimize_options={"dcci_after_kernel_end": [".*"]})` on a `torch.npu.NPUGraph`, plus
`torch.npu.super_kernel_scope_begin/end(scope)` around the forward. Two caveats stated by the vendor bear on our
3008-kernel count: (a) "An unsupported operator may split the fusion range" — coverage is sequence-dependent, so the
505 MIX_AIC calls may each be a potential split point; (b) `Block Dim` in `kernel_details.csv` reports the launch core
count for generated Super Kernels, which is how we would measure whether our MIX stages got fused or split.

---

## 8. Buffer capacities and AI Core architecture on 910B / A2 / A3 (`__NPU_ARCH__` 220x)

### `cann/catlass` `platform_info.h` — concrete default buffer sizes in vendor source

https://gitcode.com/cann/catlass/blob/master/examples/102_dynamic_optimized_matmul/include/platform_info.h
raw: https://raw.gitcode.com/cann/catlass/raw/master/examples/102_dynamic_optimized_matmul/include/platform_info.h
Repo `cann/catlass`, branch `master`. Copyright (c) 2025 Huawei Technologies Co., Ltd.

```cpp
#include "tiling/platform/platform_ascendc.h"

struct PlatformInfo {
    uint32_t coreNum{24};
    uint64_t ubSize{192 * 1024};
    uint64_t l1Size{512 * 1024};
    uint64_t l0ASize{64 * 1024};
    uint64_t l0BSize{64 * 1024};
    uint64_t l0CSize{128 * 1024};

    PlatformInfo()
    {
        coreNum = platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreNumAic();
        platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(
            platform_ascendc::CoreMemType::UB, ubSize);
        platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(
            platform_ascendc::CoreMemType::L1, l1Size);
        platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(
            platform_ascendc::CoreMemType::L0_A, l0ASize);
        platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(
            platform_ascendc::CoreMemType::L0_B, l0BSize);
        platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(
            platform_ascendc::CoreMemType::L0_C, l0CSize);
    }
};
```

Summarising the literal numbers in that struct: `coreNum = 24`, `UB = 192 KiB`, `L1 = 512 KiB`,
`L0A = 64 KiB`, `L0B = 64 KiB`, `L0C = 128 KiB`. The constructor immediately overwrites all of them from
`platform_ascendc::PlatformAscendCManager::GetInstance()->GetCoreMemSize(CoreMemType::{UB,L1,L0_A,L0_B,L0_C}, ...)`,
so these are documented-as-defaults, not a hard spec. `GetCoreNumAic()` is the AIC (cube) core count.

### CANN 9.0 算子开发指南 — 基本架构 (Basic Architecture)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/programug/Ascendcopdevg/atlas_ascendc_10_0008.html
English: https://www.hiascend.com/document/detail/en/canncommercial/850/opdevg/Ascendcopdevg/atlas_ascendc_10_0008.html
Publisher: Huawei / Ascend, parent topic 「硬件实现」.

> AI Core负责执行矩阵、矢量计算密集的任务，其包括以下组成部分：
>
> 计算单元：包括Cube（矩阵）计算单元、Vector（矢量）计算单元和Scalar（标量）计算单元。
>
> 存储单元：包括L1 Buffer、L0A Buffer、L0B Buffer、L0C Buffer、Unified Buffer、BiasTable Buffer、Fixpipe Buffer等专为高效计算设计的存储单元。
>
> 搬运单元：包括MTE1、MTE2、MTE3和FixPipe，用于数据在不同存储单元之间的高效传输。

关键概念和术语, verbatim:

> Core
>
> 拥有独立Scalar计算单元的计算核。Scalar计算单元是核内的调度单元，承担了核内的指令发射等功能。
>
> AI Core
>
> AI处理器的计算核，负责执行矩阵、矢量计算密集的任务。
>
> Cube Core
>
> 矩阵计算核，专注于矩阵计算。由Scalar调度单元、矩阵计算单元、搬运单元等组成，不包括矢量计算单元。
>
> Vector Core
>
> 矢量计算核，专注于矢量计算，由Scalar调度单元、矢量计算单元、搬运单元等组成，不包括矩阵计算单元。
>
> AIC
>
> 在AI Core分离模式下，一组Cube Core和Vector Core组合中的Cube Core。
>
> AIV
>
> 在AI Core分离模式下，一组Cube Core和Vector Core组合中的Vector Core。

AI Core 的工作模式 — 分离模式 vs 耦合模式, verbatim:

> 分离模式
>
> AI Core的一种工作模式，矩阵计算单元、矢量计算单元各自对应独立的Scalar调度单元，分离部署在Cube Core和Vector Core上。将Cube Core和Vector Core按照一定比例（1：N）进行组合，这样的组合视为一个AI Core，AI Core的核数以Cube Core为准。
>
> 耦合模式
>
> AI Core的一种工作模式，矩阵计算单元、矢量计算单元对应同一个Scalar调度单元，部署在一个AI Core上。
>
> Ascend C编程中，不同产品的工作模式如下：
>
> Atlas 推理系列产品：耦合模式
>
> Atlas 训练系列产品：耦合模式
>
> Atlas A2 训练系列产品 / Atlas A2 推理系列产品：分离模式
>
> Atlas A3 训练系列产品 / Atlas A3 推理系列产品：分离模式
>
> Atlas 350 加速卡：分离模式
>
> Atlas 200I/500 A2 推理产品：耦合模式

Cube / Vector / Scalar units, verbatim:

> Cube
>
> Cube计算单元负责执行矩阵运算，以float16数据类型为例，Cube每次执行可完成两个float16类型的16x16矩阵的乘法操作。如下图所示，高亮部分为Cube计算单元及其访问的存储单元，其中L0A存储左矩阵，L0B存储右矩阵，L0C存储矩阵乘的结果和中间结果。
>
> Vector
>
> Vector负责执行向量运算。向量计算单元执行向量指令，类似于传统的单指令多数据（Single Instruction Multiple Data，SIMD）指令，每个向量指令可以完成多个操作数的同一类型运算。向量计算单元可以快速完成两个float16类型的向量相加或者相乘。向量指令支持多次迭代执行，也支持对带有间隔的向量直接进行运算。
>
> 如下图所示，Vector所有计算的源数据以及目标数据都要求存储在Unified Buffer中，Vector指令的首地址和操作长度有对齐要求，通常要求32B对齐，具体对齐要求参考API的约束描述。
>
> Scalar
>
> Scalar负责各类型的标量数据运算和程序的流程控制。功能上可以看做一个小CPU，完成整个程序的循环控制、分支判断、Cube/Vector等指令的地址和参数计算以及基本的算术运算，并且可以通过在事件同步模块中插入同步符的方式来控制AI Core中其他执行单元的流水。相对于Host CPU，AI Core中的Scalar计算能力较弱，重点用于发射指令，所以在实际应用场景中应尽量减少Scalar计算，比如性能调优时尽量减少if/else等分支判断及变量运算。

ICache / DCache / L2 — exact figures as published, verbatim:

> 如下图所示：Scalar执行标量运算指令时，执行标准的ALU(Arithmetic Logic Unit)语句，ALU需要的代码段和数据段（栈空间）都来自于GM，ICache(Instruction Cache)用于缓存代码段，缓存大小与硬件规格相关，比如为16K或32K，以2K为单位加载；DCache(Data Cache)用于缓存数据段，大小也与硬件规格相关，比如为16K，以Cache Line（64Byte）为单位加载。考虑到核内访问效率最高，应尽量保证代码段和数据段被缓存在ICache和DCache，避免核外访问； 同时根据数据加载单位不同，编程时可以考虑单次加载数据大小，来提升加载效率。例如在DCache加载数据时，当数据内存首地址与Cache Line（64Byte）对齐时，加载效率最高。
>
> 硬件提供L2Cache用于缓存访问GM的数据（包括代码段、数据段），以此加快访问速度，提高访问效率。核外L2Cache以Cache Line为单位加载数据，根据硬件规格不同，Cache Line大小不同（128/256/512Byte等）。

存储单元 table, verbatim:

> | 存储单元 | 描述 |
> |---|---|
> | L1 Buffer | L1缓冲区，通用内部存储，是AI Core内比较大的一块数据中转区，可暂存Cube计算单元需要反复使用的一些数据从而减少从总线读写的次数。 |
> | L0A Buffer / L0B Buffer | Cube指令的输入。 |
> | L0C Buffer | Cube指令的输出，但进行累加计算的时候，也是输入的一部分。 |
> | Unified Buffer | 统一缓冲区，向量和标量计算的输入和输出。 |
> | BT Buffer | BiasTable Buffer，存放矩阵计算中的Bias。 |
> | FP Buffer | Fixpipe Buffer，存放量化参数、Relu参数等。 |

搬运单元 table, verbatim:

> | 搬运单元 | 描述 |
> |---|---|
> | MTE1 | 负责如下通路的数据搬运：<br>L1->L0A/L0B<br>L1->BT Buffer |
> | MTE2 | 负责如下通路的数据搬运：<br>GM->{L1, L0A/B}，在该通路下，基于分形大小搬运，搬运时满足Cache Line大小对齐，性能更优。<br>GM->UB，基于Cache Line大小搬运性能更优。 |
> | MTE3 | 负责如下通路的数据搬运：<br>UB -> GM |
> | FixPipe | 负责如下通路的数据搬运，搬运过程中可以完成随路数据格式/类型转换：<br>L0C->{GM/L1}<br>L1->FP Buffer |

> 不同类型的AI处理器，存储单元大小不同，开发者可通过GetCoreMemSize接口获取。
>
> 所有通过搬运单元读写GM的数据都缺省被缓存在L2Cache，以此加快访问速度，提高访问效率。

典型的数据流, verbatim:

> Vector计算典型的数据流如下：
>
> GM → UB → Vector → UB → GM
>
> Cube计算典型的数据流如下：
>
> GM →L1→L0A/L0B →Cube →L0C→FixPipe→GM
>
> GM →L1→L0A/L0B →Cube →L0C→FixPipe→L1

典型的指令流 — pipe parallelism and the two sync APIs, verbatim:

> 多条指令从系统内存通过总线接口进入到ICache(Instruction Cache)中，后续的指令执行过程，根据指令的类型，有两种可能：
>
> 如果指令是Scalar指令，指令会被Scalar单元直接执行。
>
> 其他指令会被Scalar单元调度到独立的分类序列（Vector指令序列、Cube指令序列、MTE1/MTE2/MTE3指令序列等），然后再被对应的执行单元执行。
>
> 同一个指令序列中的指令是按照进入指令序列的顺序执行的，不同指令序列之间可以并行执行，通过多个指令序列的并行执行可以提升整体执行效率。对于并行执行过程中可能出现的数据依赖，通过事件同步模块插入同步指令来控制流水线的同步，提供PipeBarrier、SetFlag/WaitFlag两种API，保证序列内部以及序列之间按照逻辑关系执行。
>
> PipeBarrier本身是一条指令，用于在序列内部约束执行顺序（虽然指令是顺序执行，但并不意味着后一条指令开始执行时前一条指令执行结束）。PipeBarrier指令可以保证前序指令中所有数据读写全部完成，后序指令才开始执行。
>
> SetFlag/WaitFlag为两条指令，在SetFlag/WaitFlag的指令中，可以指定一对指令序列的关系，表示两个序列之间完成一组"锁"机制，其作用方式为：
>
> SetFlag：当前序指令的所有读写操作都完成之后，当前指令开始执行，并将硬件中的对应标志位设置为1。
>
> WaitFlag：当执行到该指令时，如果发现对应标志位为0，该序列的后续指令将一直被阻塞；如果发现对应标志位为1，则将对应标志位设置为0，同时后续指令开始执行。

### CANN 9.0 架构规格 — NPU架构版本220x (this is A2 **and** A3)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/programug/Ascendcopdevg/atlas_ascendc_10_0011.html
Publisher: Huawei / Ascend, parent topic 「架构规格」.

> 本节介绍__NPU_ARCH__版本号为220x的硬件架构和其功能说明，其中220代表IP核编号，x表示同一个IP核的配置版本号。对应的产品型号为：
>
> Atlas A3 训练系列产品 / Atlas A3 推理系列产品
>
> Atlas A2 训练系列产品 / Atlas A2 推理系列产品

The decisive sentence for megakernel data flow, verbatim:

> 如下图所示，本架构中AI Core分为AIC和AIV两个独立的核，分别用于矩阵计算和向量计算。每个核都有自己的Scalar单元，能独立加载自己的代码段。AIV与AIC之间通过Global Memory进行数据传递。

> 本架构中，Cube计算单元和Vector计算单元分别部署在AIC核和AIV核上，每个核都有自己的Scalar单元，能独立加载自己的代码段。
>
> Vector计算单元
>
> Vector计算单元的数据来自于Unified Buffer，要求32字节对齐。
>
> Cube计算单元
>
> Cube计算单元可以访问的存储单元有L0A Buffer、L0B Buffer、L0C Buffer，其中L0A Buffer存储左矩阵，L0B Buffer存储右矩阵，L0C Buffer存储矩阵乘的结果和中间结果。

各存储单元的最小访问粒度（对齐要求）, verbatim:

> | 核 | 存储单元 | 对齐要求 |
> |---|---|---|
> | AIV | Unified Buffer | 32Byte对齐。 |
> | AIC | L1 Buffer | 32Byte对齐。 |
> | AIC | L0A Buffer | 512Byte对齐。 |
> | AIC | L0B Buffer | 512Byte对齐。 |
> | AIC | L0C Buffer | 64Byte对齐。 |
> | AIC | BiasTable Buffer | 64Byte对齐。 |
> | AIC | Fixpipe Buffer | 64Byte对齐。 |

> 各存储单元推荐使用的数据排布格式
>
> L0A Buffer、L0B Buffer和L0C Buffer推荐分别采用以下分形格式：
>
> L0A Buffer：FRACTAL_ZZ
>
> L0B Buffer：FRACTAL_ZN
>
> L0C Buffer：FRACTAL_NZ
>
> 这些格式针对矩阵乘法等计算密集型任务进行优化，可显著提升计算效率。
>
> L1 Buffer缓存推荐使用FRACTAL_NZ格式。当L1 Buffer采用NZ格式时，数据搬运到L0A/L0B Buffer（需分别转换为ZZ和ZN格式）时，可降低格式转换开销。
>
> Unified Buffer对数据格式没有要求。

> 当多个操作尝试同时访问Unified Buffer同一个bank或者bank group时，可能会发生bank冲突，包括读写冲突、写写冲突、读读冲突，这种冲突会导致访问排队，降低性能。可以通过优化bank分配的方式来提升读写性能，具体信息请参考避免Unified Buffer的bank冲突章节。

Fixpipe hardware acceleration on AIC — directly relevant to W4A8 dequant, verbatim:

> 支持Fixpipe硬件化加速
>
> Fixpipe是NPU将典型操作进行硬化的加速模块，位于AIC内部，配合Cube计算单元完成随路计算，主要功能如下：
>
> 量化反量化：包括S322FP16、S322S32、S322S4、S322S8、S322S16、FP322FP16、FP322BF16、FP322S8、FP322S4、FP322FP32。
>
> Relu功能，包括ReLu、PReLu和Leaky ReLu等典型的激活函数。
>
> 数据格式转换，包括：
>
> 通过Channel merge、Channel split可以实现分形大小的转换，保证输出到L1 Buffer/GM的分形满足诉求。
>
> NZ2ND数据格式转换。
>
> Channel merge（S8和U8数据类型）
>
> 对于转换为S8或U8的目标数据类型，分形矩阵通过硬件从16x16转换为16x32，如果输出通道数N是16的偶数倍，则N方向上每2个相邻的16x16分形矩阵将合并为1个16x32分形矩阵。如果N是16的奇数倍，则将通道1到通道（N–16）合并，最后16个通道保持未合并。
>
> Channel merge（S4和U4数据类型）
>
> 对于转换为S4或U4的目标数据类型，分形矩阵通过硬件从16x16转换为16x64，如果输出通道数N是64的倍数，则N方向上每4个相邻的16x16分形矩阵将合并为1个16x64分形矩阵。
>
> 在这种情况下，N的配置必须是64的倍数。
>
> FP32 Channel split：
>
> 对于目标类型为FP32，分形矩阵可以通过硬件从16x16转换为16x8，如果使能Channel split，则每个16x16分形矩阵将被分裂为2个16x8分形矩阵。

核内同步 — EventID discipline, verbatim:

> 上图中，ID1、ID2、ID3、ID4、ID5、ID6表示事件ID（EventID），每个EventID对应一块存储数据的搬运状态，确保数据操作的正确性和一致性。
>
> 需要注意以下几点：
>
> 建议通过AllocEventID或者FetchEventID接口获取EventID，以确保其合法性和有效性。
>
> EventID的数量有限，使用后应立即调用ReleaseEventID释放资源，避免EventID耗尽，影响系统正常运行。
>
> SetFlag和WaitFlag必须成对使用，且SetFlag和WaitFlag的参数必须完全一致（包括模板参数和事件ID）。如果不匹配，可能导致当前核的计算异常，或影响下一个核的算子执行，引发timeout问题。
>
> 例如，SetFlag<HardEvent::S_MTE3>(1)和SetFlag<HardEvent::MTE3_MTE1>(1)设置的不是同一个EventID，因为其模板参数不同。只有当模板参数和事件ID完全一致时，才表示同一个EventID。
>
> 不允许连续设置同一个EventID，因为这可能导致事件状态混乱或未被正确处理。
>
> 不建议手动插入 TEventID，不能手动插入6和7的TEventID，因为它们可能被系统预留或用于特殊用途。

核间同步 — the counter semantics, verbatim (this is more precise than the API reference page):

> CrossCoreSetFlag和CrossCoreWaitFlag接口配合使用。使用时需传入核间同步的标记ID(flagId)，即上图中的ID1，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。flagId取值范围是0-10。
>
> 需要注意以下几点：
>
> 成对使用
>
> CrossCoreSetFlag和CrossCoreWaitFlag必须成对使用，否则可能导致算子超时问题。
>
> 一致性要求
>
> CrossCoreSetFlag 的模板参数和flagId必须与CrossCoreWaitFlag完全一致，否则视为不同的flagId。例如，CrossCoreSetFlag<0x0, PIPE_MTE3>(0x8) 和 CrossCoreSetFlag<0x2, PIPE_FIX>(0x8) 设置的不是同一个flagId。
>
> 避免连续设置
>
> 不允许连续设置同一个flagId，以防止计数器状态混乱。
>
> 与高阶 API 的使用冲突
>
> Matmul高阶API内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则会有flagId冲突的风险。
>
> 计数器限制
>
> 同一flagId的计数器最多可以设置15次。
>
> 默认流水类型
>
> CrossCoreWaitFlag不需要显式设置指令所在的流水类型，默认使用PIPE_S。

Also from the same page, cross-card DataCopy on A2 and the example motivating cross-core sync:

> 支持跨卡数据搬运（Hccs物理链路）
>
> 在跨卡通信算子开发场景，DataCopy类接口支持跨卡数据搬运，在 Atlas A2 训练系列产品 / Atlas A2 推理系列产品 设备上，仅支持Hccs物理链路，不支持其他通路；开发者开发过程中，请关注涉及卡间通信的物理通路； 通过npu-smi info -t topo指令查询Hccs 物理通路。

> 例如，在AIC中将L0C的计算结果搬运到GM后，AIV需要将GM的数据搬运到UB。此时，可以使用CrossCoreSetFlag和CrossCoreWaitFlag命令，确保数据从L0C成功搬运到GM后，再从GM搬运到UB。

## Relevance
Three facts here constrain the megakernel more than anything else we found.
(1) On 220x (our A3) 「AIV与AIC之间通过Global Memory进行数据传递」 — the AIC and AIV halves of an AI Core exchange
data **through Global Memory**, not through a shared on-chip buffer. The cube result path is
`L0C -> FixPipe -> GM -> (MTE2) -> UB`. So "matmul -> vector -> matmul without returning to HBM" is only achievable
within one core class, or by relying on L2 to absorb the GM round trip. A fully HBM-free cube->vector->cube chain
on A3 is not available at the hardware level; the realistic goal is L2-resident, not UB-resident.
(2) 「每个核都有自己的Scalar单元，能独立加载自己的代码段」 — AIC and AIV each load their own code segment.
This is why a MIX kernel launch has to bring up two distinct code images, and it is the hardware basis for the
ICache-preload and sub-kernel-split problems SuperKernel addresses. ICache is only 「16K或32K，以2K为单位加载」 —
a megakernel's body will far exceed it, so instruction fetch becomes a first-order cost.
(3) The CrossCore counter is literally a saturating counter: Set increments, Wait decrements-if-nonzero, range
flagId 0-10, max 15 Sets per flagId, no two consecutive Sets of the same flagId, and `CrossCoreWaitFlag` defaults to
`PIPE_S`. A persistent kernel iterating layers must budget flag IDs and interleave Waits so no counter exceeds 15.
Buffer budget for tiling: UB 192 KiB, L1 512 KiB, L0A/L0B 64 KiB each, L0C 128 KiB, with L0A/L0B needing 512-byte
alignment and FRACTAL_ZZ/ZN/NZ layouts. Finally, `Fixpipe` on AIC does S32->S8/S4/FP16/BF16 requantization and
ReLU/PReLU/LeakyReLU in-line with the cube output — for W4A8 that means the dequant step can ride the cube pipeline
instead of costing a separate AIV kernel, which is a direct attack on our MIX call count.

---

## 9. `SyncAll`, `IBSet`/`IBWait` — grid barriers, hard vs soft sync

### SyncAll (CANN 9.0 API reference, 核间同步)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0204.html
Parent topic 「核间同步」, whose TOC (https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0268.html) is exactly:
`IBSet / IBWait / SyncAll / CrossCoreSetFlag(ISASI) / CrossCoreWaitFlag(ISASI) / InitDetermineComputeWorkspace / NotifyNextBlock / WaitPreBlock`.

产品支持情况 — note the two separate columns, 软同步原型 and 硬同步原型:

> | 产品 | 是否支持（软同步原型） | 是否支持（硬同步原型） |
> |---|---|---|
> | Atlas 350 加速卡 | √ | √ |
> | Atlas A3 训练系列产品 / Atlas A3 推理系列产品 | √ | √ |
> | Atlas A2 训练系列产品 / Atlas A2 推理系列产品 | √ | √ |
> | Atlas 200I/500 A2 推理产品 | x | x |
> | Atlas 推理系列产品 AI Core | √ | x |
> | Atlas 推理系列产品 Vector Core | x | x |
> | Atlas 训练系列产品 | √ | x |

功能说明, verbatim:

> 当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用该函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬件同步是利用硬件自带的全核同步指令由硬件保证多核同步，软件同步是使用软件算法模拟实现。

函数原型, verbatim:

```cpp
// 软同步
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll(const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0)

// 硬同步
template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
__aicore__ inline void SyncAll()
```

表1 模板参数说明, verbatim:

> | 参数名 | 描述 |
> |---|---|
> | isAIVOnly | 控制SyncAll作用于纯Vector算子或融合（Cube和Vector融合）算子。可选值：<br>true（默认值）：纯Vector算子的全核同步，仅执行Vector核的全核同步。<br>false：融合算子的全核同步，先分别完成Vector核和Cube核的全核同步，再执行两者之间的同步（软同步接口不支持此功能）。 |
> | config | 控制SyncAll函数的行为 ，在多个AI Core之间进行流水线同步时，指定哪些管道（pipe）用于触发和等待。<br>triggerPipe：指定哪个管道用于"发送触发信号"。<br>waitPipe：指定哪个管道用于"接收等待信号"。<br>默认为SyncAllConfig DEFAULT_SYNC_ALL_CONFIG= {PIPE_ALL, PIPE_ALL} ，使用全部管道来进行触发和等待行为。<br>该参数仅支持如下型号：<br>Atlas 350 加速卡 |

表2 参数说明, verbatim:

> | 参数名称 | 输入/输出 | 含义 |
> |---|---|---|
> | gmWorkspace | 输入 | gmWorkspace为用户定义的全局Global空间，作为所有核共用的缓存，用于保存每个核的状态标记，类型为GlobalTensor，支持的数据类型为int32_t。所需空间大小和使用注意项参见约束说明。硬同步接口不支持该参数。 |
> | ubWorkspace | 输入 | ubWorkspace为用户定义的局部Local空间，每个核单独自用，用于标记当前核的状态。类型为LocalTensor，支持的TPosition为VECIN/VECCALC/VECOUT，支持的数据类型为int32_t。所需空间大小参见约束说明。硬同步接口不支持该参数。 |
> | usedCores | 输入 | 指定多少个核之间的同步，传入数值不能超过算子调用时指定的逻辑numBlocks。此参数为默认参数，不传此参数表示全核软同步。仅在软同步接口中支持，硬同步接口不支持该参数。 |

约束说明, verbatim:

> gmWorkspace缓存申请的空间大小要求大于等于核数*32Bytes，并且缓存的值需要初始化为0。目前常见的有两种初始化方式：
>
> 通过在host侧进行初始化操作，确保传入该接口时，gmWorkspace缓存已经初始化为0；
>
> 在kernel侧初始化的时候对gmWorkspace缓存初始化，需要注意的是，每个核上都需要初始化全部的gmWorkspace缓存空间。
>
> ubWorkspace申请的空间大小要求大于等于核数*32Bytes。
>
> 使用该接口进行多核控制时，算子调用时指定的逻辑numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel"卡死"现象。
>
> 在分离模式下，建议使用硬同步接口而非软同步接口。软同步接口仅适用于纯Vector场景，且性能较低。使用硬同步接口时，需根据场景设置Kernel类型：
>
> 在纯Vector/Cube场景下，需设置Kernel类型为KERNEL_TYPE_MIX_AIV_1_0或KERNEL_TYPE_MIX_AIC_1_0。
>
> 对于Vector和Cube混合场景，需根据实际情况灵活配置Kernel类型。
>
> 使用该接口时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
>
> 多流并发场景（≥2条执行流）。
>
> ≥2个算子并发执行。
>
> 所有并发算子的核数总和超过物理核数。
>
> ≥2个并发算子使用了核间同步功能。
>
> Kernel直调场景下通过__schedmode__(mode)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式。

调用示例, verbatim:

```cpp
// syncGlobal为用户定义的全局Global空间，作为所有核共用的缓存，类型为GlobalTensor；workLocal为用户定义的局部Local空间，每个核单独自用，类型为LocalTensor
int srcDataSize = 256; // 参与计算的元素个数
int32_t blockNum = AscendC::GetBlockNum(); // 获取核总数
int32_t blockIdx = AscendC::GetBlockIdx(); // 获取当前工作的核ID
uint32_t perBlockSize = srcDataSize / blockNum; // 每个核平分处理相同个数
// 当前工作核计算后的数据先保存到外部工作空间，workGlobal为GlobalTensor，dstLocal为LocalTensor
AscendC::DataCopy(workGlobal[blockIdx * perBlockSize], dstLocal, perBlockSize);
// 等待所有核都完成计算
AscendC::SyncAll(syncGlobal, workLocal);
```

### IBSet / IBWait (point-to-point inter-block sync)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0202.html (IBSet)
https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0203.html (IBWait)

```cpp
__aicore__ inline void IBSet(const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx, int32_t eventID)
```

> | 参数名 | 输入/输出 | 描述 |
> |---|---|---|
> | gmWorkspace | 输出 | 外部存储核状态的公共缓存，类型为GlobalTensor。 |
> | ubWorkspace | 输入 | 存储当前核状态的公共缓存。类型为LocalTensor，支持的TPosition为VECIN/VECCALC/VECOUT。 |
> | blockIdx | 输入 | 表示等待核的idx号，取值范围：[0, 核数-1]。 |
> | eventID | 输入 | 用来控制当前核的set、wait事件。 |

约束说明, verbatim — the exact workspace sizing formula:

> gmWorkspace申请的空间最少要求为：核数 * 32Bytes * eventID_max + blockIdx_max * 32Bytes + 32Bytes。（eventID_max和blockIdx_max分别指eventID、blockIdx的最大值 ）；
>
> 注意：如果是AIVOnly模式，核数 = GetBlockNum()；如果是MIX模式，核数 = GetBlockNum() * 2；
>
> ubWorkspace申请的空间最少要求为：32Bytes；
>
> gmWorkspace缓存的值需要初始化为0。
>
> 使用该接口进行多核控制时，算子调用时指定的逻辑numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel"卡死"现象。

```cpp
// sync_gm为外部存储核状态的公共缓存，类型为GlobalTensor；sync_buf为存储当前核状态的公共缓存，类型为LocalTensor
int32_t blockIdx = AscendC::GetBlockIdx(); // 获取当前核
if (blockIdx == 1) { // 在核1设置IBWait，将阻塞指令执行直到核0操作完成
    AscendC::IBWait(sync_gm, sync_buf, 0, 0);
}
...
if (blockIdx == 0) { // 在核0设置IBSet，当核0的操作完成后再执行核1的指令
    AscendC::IBSet(sync_gm, sync_buf, 0, 0);
}
```

## Relevance
For a persistent megakernel on A3 (分离模式) the doc is explicit: use the **hard-sync** zero-argument
`SyncAll<isAIVOnly>()`, not the GM-workspace soft variant — 「在分离模式下，建议使用硬同步接口而非软同步接口。
软同步接口仅适用于纯Vector场景，且性能较低」. `isAIVOnly = false` is the fused-operator barrier and it costs three
barriers in sequence: vector all-core sync, then cube all-core sync, then a sync between the two. That tri-phase
barrier is the same thing SuperKernel's 同步优化 narrows, and it is the per-stage price of staying inside one MIX kernel.
The hard-sync prototype requires `KERNEL_TYPE_MIX_AIV_1_0` or `KERNEL_TYPE_MIX_AIC_1_0` even in a pure vector/cube
kernel — so a megakernel that uses `SyncAll` is forced into MIX typing, i.e. it cannot be an `AIV_ONLY` kernel.
The hard constraint 「逻辑numBlocks必须保证不大于实际运行该算子的AI处理器核数」 means a megakernel must be launched with
blockDim <= physical cores or it hangs; multi-round scheduling inserts a bad barrier. `SyncAllConfig{triggerPipe, waitPipe}`
would let us narrow the barrier to specific pipes but is **Atlas 350 only** — not available on A3.
`IBSet`/`IBWait` is the point-to-point alternative, cheap in flags but needing
`核数 * 32B * eventID_max + blockIdx_max * 32B + 32B` of GM, and note that in MIX mode 核数 = `GetBlockNum() * 2`.

---

## 10. `ICachePreLoad` — exact ICache sizes on A3, and the instruction-prefetch API a megakernel needs

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0276.html
Parent topic 「缓存控制」 (sibling: `DataCachePreload`).

> 功能说明
>
> 从指令所在DDR地址预加载指令到ICache中。

```cpp
__aicore__ inline void ICachePreLoad(const int64_t preFetchLen)
```

> | 参数名 | 输入/输出 | 描述 |
> |---|---|---|
> | preFetchLen | 输入 | 预取长度。<br>针对Atlas A2 训练系列产品/Atlas A2 推理系列产品：preFetchLen参数单位为2K Byte, 取值应小于ICache的大小/2K。AIC和AIV的ICache大小分别为32KB和16KB。<br>针对Atlas A3 训练系列产品/Atlas A3 推理系列产品：preFetchLen参数单位为2K Byte, 取值应小于ICache的大小/2K。AIC和AIV的ICache大小分别为32KB和16KB。<br>针对Atlas 推理系列产品AI Core：传入该参数无效，预取长度均为128Byte。<br>针对Atlas 350 加速卡：preFetchLen参数单位为2K Byte, 取值应小于ICache的大小/2K。AIC和AIV的ICache大小分别为32KB和16KB。 |

> 产品支持情况: Atlas 350 加速卡 √ / Atlas A3 训练系列产品/Atlas A3 推理系列产品 √ / Atlas A2 训练系列产品/Atlas A2 推理系列产品 √ / Atlas 200I/500 A2 推理产品 x / Atlas 推理系列产品AI Core √ / Atlas 推理系列产品Vector Core x / Atlas 训练系列产品 x

```cpp
int64_t preFetchLen = 2; // 预取指令长度
AscendC::ICachePreLoad(preFetchLen);
```

## Relevance
This is the primitive behind SuperKernel's ICache Preload mechanism, and it is available on A3. Exact figures:
**AIC ICache = 32 KB, AIV ICache = 16 KB**, prefetch granularity 2 KB, so `preFetchLen < 16` on AIC and `< 8` on AIV.
A megakernel that inlines 78 layers of stages will blow a 16 KB AIV ICache by orders of magnitude, so the design must
either (a) keep each stage's hot loop under ~16 KB and call `ICachePreLoad` ahead of the next stage, or (b) accept
instruction-fetch stalls from L2. This is the quantitative constraint that caps how much we can inline before
ICache misses eat the launch savings we are chasing — our 11.5 ms launch floor is only worth attacking if the fused
body does not reintroduce an equivalent fetch cost.

---

## 11. Matmul high-level API: `ASCENDC_CUBE_ONLY`, `MatmulType`, `TPosition::CO1`, `TPosition::TSCM`, `SetLocalWorkspace`

### CANN 9.0 API reference — Matmul使用说明

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0614.html
Parent topic 「Matmul Kernel侧接口」 (TOC id 0613), itself under 「矩阵计算」 (0612) under 「高阶API」.
The 0613 TOC lists, verbatim: `Matmul使用说明 / Matmul模板参数 / MatmulConfig / MatmulCallBackFunc / MatmulPolicy /
Matmul特性场景 / GetNormalConfig / GetMDLConfig / GetSpecialMDLConfig / GetIBShareNormConfig / GetBasicConfig /
GetMMConfig / REGIST_MATMUL_OBJ / Init / SetTensorA / SetTensorB / SetTensorScaleA / SetTensorScaleB / SetBias /
DisableBias / GetBatchTensorC / Iterate / GetTensorC / IterateAll / WaitIterateAll / IterateBatch /
WaitIterateBatch / IterateNBatch / End`.

The MIX-vs-pure-cube mode statement, verbatim — note the explicit performance claim:

> 默认为MIX模式（包含矩阵计算和矢量计算），该场景下通常不定义ASCENDC_CUBE_ONLY宏，如果在程序中使用了ASCENDC_CUBE_ONLY宏，则必须使用ASCEND_IS_AIC宏和ASCEND_IS_AIV宏将Cube计算和Vector计算隔离开。
>
> 纯Cube模式（只有矩阵计算）场景下，建议在代码中定义ASCENDC_CUBE_ONLY宏，避免额外的性能开销。

```cpp
// 纯cube模式（只有矩阵计算）场景下，需要设置该代码宏，并且必须在#include "lib/matmul_intf.h"之前设置
// #define ASCENDC_CUBE_ONLY
#include "lib/matmul_intf.h"
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, half> aType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, half> bType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, float> cType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, float> biasType;
AscendC::Matmul<aType, bType, cType, biasType> mm;
```

`MatmulType` definition, verbatim:

```cpp
template <AscendC::TPosition POSITION, CubeFormat FORMAT, typename TYPE, bool ISTRANS = false, LayoutMode LAYOUT = LayoutMode::NONE, bool IBSHARE = false, TPosition SRCPOS = TPosition::GM> struct MatmulType {
    constexpr static AscendC::TPosition pos = POSITION;
    constexpr static CubeFormat format = FORMAT;
    using T = TYPE;
    constexpr static bool isTrans = ISTRANS;
    constexpr static LayoutMode layout = LAYOUT;
    constexpr static bool ibShare = IBSHARE;
    constexpr static TPosition srcPos = SRCPOS;
};
```

POSITION, for A3 specifically, verbatim:

> 针对 Atlas A3 训练系列产品 / Atlas A3 推理系列产品：
>
> A矩阵可设置为TPosition::GM，TPosition::VECOUT，TPosition::TSCM
>
> B矩阵可设置为TPosition::GM，TPosition::VECOUT，TPosition::TSCM
>
> Bias可设置为TPosition::GM，TPosition::VECOUT
>
> C矩阵可设置为TPosition::GM，TPosition::VECIN, TPosition::CO1
>
> 注意，C矩阵设置为TPosition::CO1时，C矩阵的数据排布格式仅支持CubeFormat::NZ，C矩阵的数据类型仅支持float、int32_t。

> 注意，A矩阵、B矩阵或Bias矩阵设置为TPosition::VECOUT或TPosition::TSCM时，对应矩阵用于单核计算的数据必须全部在Unified Buffer或L1 Buffer上

FORMAT for A3, verbatim:

> A矩阵可设置为CubeFormat::ND，CubeFormat::NZ, CubeFormat::VECTOR
>
> B矩阵可设置为CubeFormat::ND，CubeFormat::NZ
>
> Bias可设置为CubeFormat::ND
>
> C矩阵可设置为CubeFormat::ND，CubeFormat::NZ，CubeFormat::ND_ALIGN

TYPE for A3, verbatim — note `int4b_t` is supported for A and B:

> 针对 Atlas A3 训练系列产品 / Atlas A3 推理系列产品：
>
> A矩阵可设置为half、float、bfloat16_t 、int8_t、int4b_t
>
> B矩阵可设置为half、float、bfloat16_t 、int8_t、int4b_t
>
> Bias可设置为half、float、int32_t
>
> C矩阵可设置为half、float、bfloat16_t、int32_t、int8_t

> 注意：除fp8_e4m3fn_t/fp8_e5m2_t两种数据类型、B矩阵为int8_t数据类型外，A矩阵和B矩阵数据类型需要一致，具体数据类型组合关系请参考表2。A矩阵和B矩阵为int4b_t数据类型时，矩阵内轴的数据个数必须为偶数。例如，A矩阵为int4b_t数据类型且不转置时，singleCoreK必须是偶数。关于int4b_t数据类型的使用样例请参考Int4类型输入的Matmul算子样例。关于B8位宽数据类型的样例请参考B8位宽数据类型的Matmul算子样例。

表2 Matmul输入输出数据类型的支持列表 (relevant rows, verbatim):

> | A矩阵 | B矩阵 | Bias | C矩阵 | 支持平台 |
> |---|---|---|---|---|
> | int8_t | int8_t | int32_t | int32_t/half | Atlas 350 加速卡 / Atlas A3 训练系列产品 / Atlas A3 推理系列产品 / Atlas A2 训练系列产品 / Atlas A2 推理系列产品 / Atlas 推理系列产品 AI Core / Atlas 200I/500 A2 推理产品 |
> | int4b_t | int4b_t | int32_t | int32_t/half | Atlas A3 训练系列产品 / Atlas A3 推理系列产品 / Atlas A2 训练系列产品 / Atlas A2 推理系列产品 |
> | half | half | float | float | ... |
> | bfloat16_t | bfloat16_t | float | float | ... |

L1 budget formula for the transpose case, verbatim:

> 注意，由于L1 Buffer上的矩阵数据有分形对齐的约束，A、B矩阵转置和不转置时所需的L1空间可能不相同，在开启支持矩阵转置功能时，必须保证按照Matmul Tiling参数申请的L1空间不超过L1 Buffer的规格，判断方式为(depthA1*Ceil(baseM/c0Size)*baseK + depthB1*Ceil(baseN/c0Size)*baseK) * db * sizeof(dtype) < L1Size，db表示L1是否开启double buffer，取值1（不开启double buffer）或2（开启double buffer）

IBSHARE (IntraBlock Share) — L1 reuse across Matmul objects, verbatim:

> IBSHARE
>
> 是否使能IBShare（IntraBlock Share）。IBShare的功能是能够复用L1 Buffer上相同的A矩阵或B矩阵数据，复用的矩阵必须在L1 Buffer上全载。A矩阵和B矩阵仅有一个使能IBShare的场景，与IBShare模板配合使用，具体参数设置详见表2。
>
> 注意，A矩阵和B矩阵同时使能IBShare的场景，表示L1 Buffer上的A矩阵和B矩阵同时复用，需要满足：
>
> 同一算子中其它Matmul对象的A矩阵和B矩阵也必须同时使能IBShare；
>
> Atlas A3 训练系列产品 / Atlas A3 推理系列产品，获取矩阵计算结果时，只支持调用IterateAll接口，且只支持输出到GlobalTensor，即计算结果放置于Global Memory的地址。

The three calling conventions, verbatim:

> 初始化操作。
> ```cpp
> REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, &tiling); // 初始化matmul对象，参数含义请参考REGIST_MATMUL_OBJ章节
> ```
> 设置左矩阵A、右矩阵B、Bias。
> ```cpp
> mm.SetTensorA(gm_a);    // 设置左矩阵A
> mm.SetTensorB(gm_b);    // 设置右矩阵B
> mm.SetBias(gm_bias);    // 设置Bias
> // Atlas 推理系列产品AI Core上需要额外调用SetLocalWorkspace接口设置计算所需的UB空间
> mm.SetLocalWorkspace(usedUbBufLen);
> ```
> 完成矩阵乘操作。用户可以选择以下三种调用方式之一。
>
> 调用Iterate完成单次迭代计算，叠加while循环完成单核全量数据的计算。Iterate方式，可以自行控制迭代次数，完成所需数据量的计算，方式比较灵活。
> ```cpp
> // API接口内部会进行循环结束条件判断处理
> while (mm.Iterate()) {
>     mm.GetTensorC(gm_c);
> }
> ```
> 调用IterateAll完成单核上所有数据的计算。IterateAll方式，无需循环迭代，使用比较简单。
> ```cpp
> mm.IterateAll(gm_c);
> ```
> 用户申请用于存放矩阵乘结果的逻辑位置CO1内存，调用一次或多次Iterate完成单次或多次迭代计算，在需要搬出计算结果时，调用Fixpipe接口完成CO1上计算结果的搬运，然后释放申请的CO1内存。该方式下，用户可以灵活控制计算和搬运的节奏，根据实际需要，一次计算对应一次结果的搬出，或者将多次计算结果缓存在CO1内存中，再一次性搬出计算结果。
>
> 在此种调用方式下，创建Matmul对象时，必须定义C矩阵的内存逻辑位置为TPosition::CO1、数据排布格式为CubeFormat::NZ、数据类型为float或int32_t。
>
> Atlas 350 加速卡暂不支持该方式。Atlas 推理系列产品 AI Core暂不支持该方式。Atlas 200I/500 A2 推理产品暂不支持该方式。

The CO1-resident pattern, verbatim — this is the on-chip accumulation route:

```cpp
// 定义C矩阵的类型信息
typedef AscendC::MatmulType<AscendC::TPosition::CO1, CubeFormat::NZ, float> cType;
// 创建Matmul对象
AscendC::Matmul<aType, bType, cType, biasType> mm;
// 用户提前申请CO1的内存l0cTensor
TQue<TPosition::CO1, 1> CO1_;
// 128 * 1024为申请的CO1内存大小
GetTPipePtr()->InitBuffer(CO1_, 1, 128 * 1024);
// L0cT为C矩阵的数据类型。
// A矩阵数据类型是int8_t或int4b_t时，C矩阵的数据类型是int32_t。
// A矩阵数据类型是half、float或bfloat16_t时，C矩阵的数据类型是float。
LocalTensor<L0cT> l0cTensor = CO1_.template AllocTensor<L0cT>();
// 将l0cTensor作为入参传入Iterate，矩阵乘结果输出到用户申请的l0cTensor上
mm.Iterate(false, l0cTensor);
// 调用Fixpipe接口将CO1上的计算结果搬运到GM
FixpipeParamsV220 params;
params.nSize = nSize;
params.mSize = mSize;
params.srcStride = srcStride;
params.dstStride = dstStride;
CO1_.EnQue(l0cTensor);
CO1_.template DeQue<L0cT>();
Fixpipe<cType, L0cT, CFG_ROW_MAJOR>(gm[dstOffset], l0cTensor, params);
//释放CO1内存
CO1_.FreeTensor(l0cTensor);
```

```cpp
mm.End();
```

## Relevance
This is the concrete toolkit for a W4A8 cube stage on A3.
- `int4b_t x int4b_t -> int32_t` is a supported A3 Matmul combination, with the constraint that the inner-axis
  element count must be even (「A矩阵为int4b_t数据类型且不转置时，singleCoreK必须是偶数」). So W4 weights can be
  consumed natively by the cube unit rather than unpacked by a separate AIV kernel — removing a whole class of
  per-layer AIV launches. (`int8_t x int8_t -> int32_t` covers the A8 activation side.)
- `TPosition::CO1` + `CubeFormat::NZ` + `Fixpipe` is the documented way to **keep the matmul accumulator in L0C
  across multiple `Iterate` calls** and flush once: 「将多次计算结果缓存在CO1内存中，再一次性搬出计算结果」.
  This is the real "don't return to HBM" mechanism for cube->cube chaining, and the 128 KiB `InitBuffer(CO1_, 1, 128 * 1024)`
  matches the L0C size in section 8. It is unsupported on Atlas 350 / Atlas inference / 200I, but supported on A3.
- `TPosition::TSCM` lets A/B come from L1 rather than GM (data must be fully resident), and `IBSHARE` lets several
  Matmul objects in the same kernel share one L1-resident A or B — directly useful for a megakernel reusing a weight
  tile across stages. Caveat for A3: with IBShare on both A and B, only `IterateAll` to a `GlobalTensor` is supported.
- `ASCENDC_CUBE_ONLY` is documented as the way to 「避免额外的性能开销」 for pure-cube use, and the cost it avoids is
  exactly the MIX-mode AIV-side controller that section 5 describes. Our 505 MIX_AIC calls/round at 13.58 us are the
  price of *not* having set it. `SetLocalWorkspace(usedUbBufLen)` is only required on Atlas inference AI Core, not A3.

---

## 12. Matmul static tiling / `MatmulApiStaticTiling` — the measured Scalar-overhead win

### Best practice: Matmul Constant Operator Performance Optimization (with numbers)

https://www.hiascend.com/doc_center/source/en/canncommercial/800/opdevg/ascendcbestP/atlas_ascendc_best_practices_10_10001.html
Also published at https://www.hiascend.com/document/detail/en/canncommercial/800/opdevg/ascendcbestP/atlas_ascendc_best_practices_10_10001.html
Publisher: Huawei / Ascend, CANN 8.0 operator development best practices. (Only the English rendering of this page
was reachable; the `zh` path returns AccessDenied.)

> ## Matmul Constant Operator Performance Optimization
>
> ### Case Study
>
> This case shows how to improve the operator performance by enabling Matmul static tiling when the Matmul high-level API is used for matrix multiplication computation. For details about Matmul static tiling, see Matmul Static Tiling.
>
> Matmul APIs involve a large number of Scalar computations during initialization and iteration. The Scalar computations during Matmul initialization affect the instruction head overhead, and the Scalar computations between Matmul iterations may block the MTE2 pipeline. The most variables involved in the Scalar computations during the two processes are the Tiling parameters singleCoreM/singleCoreN/singleCoreK and baseM/baseN/baseK. In the kernel implementation, if the variables obtained from the tiling parameters are replaced with constants and the related computations are moved forward to the compilation phase, the Scalar computation overhead can be reduced at run time.
>
> The operator specifications are as follows.
>
> | Input | Shape | Data type | Format |
> |---|---|---|---|
> | a | 32, 2048 | float16 | ND |
> | b | 2048, 32 | float16 | ND |
>
> For more examples of enabling Matmul static tiling, see matmul_api_constant.
>
> ### Obtaining Profile Data
>
> Use the msProf tool to obtain the profile data of the operator, focusing on the status of the Scalar pipeline.
>
> ### Analyzing Main Bottlenecks
>
> According to the preceding profile data, the ratio of Scalar time is high, implying that the performance bottleneck lies in the Scalar pipeline. Before performance optimization, the average time required for executing an operator for multiple times is 21.88 μs.
>
> ### Developing Optimization Solutions
>
> Enable Matmul static tiling. Specifically, when creating a Matmul object, use the constant template parameters. The procedure is as follows:
>
> When the GetMMConfig API is called to obtain the MatmulConfig template, set MatmulShapeParams to a constant value to obtain a customized MatmulConfig template with constant parameters.
>
> Call the GetMatmulApiTiling API to replace the tiling information with constants to obtain the constant template parameters, including the Matmul tiling information and MatmulConfig template.
>
> When creating a Matmul object, use the constant template parameters in step 2.
>
> Under these operator specifications, the optimal tiling obtained by the GetTiling API is achieved. The values of singleCoreM, singleCoreN, and singleCoreK are 32, 32, and 2048 respectively, and the values of baseM, baseN, and baseK are 32, 32, and 256 respectively. You only need to modify the part for creating the Matmul object in the original code. The details are as follows:

```cpp
constexpr static MatmulShapeParams shapeParams = {32, 32, 2048, 32, 32, 256};
constexpr static MatmulConfig MM_CFG = GetMMConfig<MatmulConfigMode::CONFIG_NORM>(shapeParams);
constexpr MatmulApiStaticTiling static MM_CFG_CONSTANT = GetMatmulApiTiling<A_TYPE, B_TYPE, C_TYPE, BIAS_TYPE>(mmConfig);
MatmulImpl<A_TYPE, B_TYPE, C_TYPE, BIAS_TYPE, MM_CFG_CONSTANT> mm;
```

> ### Verifying Optimization Benefits
>
> After the performance optimization, the average time required for executing an operator for multiple times is 17.728 μs, and the Scalar computation time is reduced by 44.4%.
>
> ### Summary
>
> If the shape information (singleCoreM/singleCoreN/singleCoreK and baseM/baseN/baseK) for a single Matmul computation in a single core is determined, you can enable Matmul static tiling to reduce the Scalar computation overhead and improve operator performance.

### `GetMatmulApiTiling` API reference (CANN 9.0, 中文)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0666.html
Parent topic 「Matmul Kernel侧接口」.

产品支持情况: `Atlas 350 加速卡 √ / Atlas A3 训练系列产品/Atlas A3 推理系列产品 √ / Atlas A2 训练系列产品/Atlas A2 推理系列产品 √ / Atlas 200I/500 A2 推理产品 x / Atlas 推理系列产品AI Core x / Atlas 推理系列产品Vector Core x / Atlas 训练系列产品 x`

功能说明, verbatim — note 部分常量化 vs 全量常量化:

> 本接口用于在编译期间获取常量化的Matmul Tiling参数。
>
> Matmul Tiling常量化功能为在编译期期间获取常量化的Matmul Tiling参数并进行算子编译，从而减少Scalar计算开销，提升算子整体性能。具体为，在获取Matmul模板时，可以确定MatmulConfig的singleCore Shape（MatmulConfig中的singleCoreM/singleCoreN/singleCoreK）和Base Shape（MatmulConfig中的basicM/basicN/basicK）参数，或者只确定Base Shape参数；通过指定获取模板的接口中的singleCore Shape和Base Shape参数，或者只指定Base Shape参数，获取自定义模板；然后调用本接口，得到常量化的Matmul Tiling参数。
>
> 当在调用获取MatmulConfig模板的接口时，只将(baseM, baseN, baseK)设置为常数值时，称为部分常量化，此时(singleCoreM, singleCoreN, singleCoreK)都保持默认值0，部分常量化场景在Kernel侧使用REGIST_MATMUL_OBJ初始化Matmul对象时，仍需要使用Tiling；将(baseM, baseN, baseK, singleCoreM, singleCoreN, singleCoreK)都设置为常数值时，称为全量常量化，这时可以在REGIST_MATMUL_OBJ的入参传递Tiling参数的位置，使用空指针替代。
>
> 经过上述部分常量化或全部常量化后，将得到带有常量化参数的MatmulConfig模板，然后使用本接口将Tiling参数常量化。本接口的返回值包含常量化的Matmul Tiling参数和MatmulConfig模板。

```cpp
template<class A_TYPE, class B_TYPE, class C_TYPE, class BIAS_TYPE>
__aicore__ constexpr MatmulApiStaticTiling GetMatmulApiTiling(const MatmulConfig& mmCFG, int32_t l1Size = Impl::L1_SIZE)
```

> | 参数名 | 输入/输出 | 描述 |
> |---|---|---|
> | mmCFG | 输入 | 获取的MatmulConfig模板。<br>对于Atlas 350 加速卡，支持常量化的为全部模板：Norm, IBShare, MDL模板。<br>对于Atlas A3 训练系列产品/Atlas A3 推理系列产品，支持常量化的模板有：Norm, MDL模板。<br>对于Atlas A2 训练系列产品/Atlas A2 推理系列产品，支持常量化的模板有：Norm, MDL模板。 |
> | l1Size | 输入 | 可用的L1大小，默认值L1_SIZE。 |

约束说明, verbatim:

> 入参mmCFG，在调用获取MatmulConfig模板的接口获取时，需要使用常数值指定(baseM, baseN, baseK)或者指定(baseM, baseN, baseK, singleCoreM, singleCoreN, singleCoreK)，并且指定的参数值需要和Tiling计算的值保持一致。
>
> Batch Matmul场景支持全量常量化，但不支持使用空指针替代REGIST_MATMUL_OBJ的入参Tiling。

调用示例, verbatim:

```cpp
//定义Matmul对象
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, half> aType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, half> bType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, float> cType;
typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, float> biasType;
// 这里CFG使用GetNormalConfig接口获取，并指定已知的singleshape信息和baseM,baseN,baseK，指定的数值跟运行时tiling保持一致
constexpr auto staticTiling = GetMatmulApiTiling<aType, bType, cType, biasType>(CFG, 524288); // 该示例L1 Buffer可用大小为512KB
AscendC::Matmul<aType, bType, cType, biasType, staticTiling > mm;
```

## Relevance
This is the one place in the vendor docs with a before/after number on the same axis we are measuring.
A tiny matmul (32x2048 x 2048x32) spends 21.88 us per call, of which the dominant term is **Scalar pipeline**, and
constantising the tiling drops it to 17.728 us with Scalar time down 44.4%. The named cost is 「instruction head
overhead」 during Matmul init plus Scalar work between iterations blocking MTE2. 21.88 us is the same order as our
13.58 us MIX_AIC floor, which supports reading our floor as Scalar/init-dominated rather than data-movement-dominated.
Concretely for us: at batch=1 decode the shapes are fixed, so 全量常量化 applies — set all six of
`(baseM, baseN, baseK, singleCoreM, singleCoreN, singleCoreK)` as compile-time constants and then
`REGIST_MATMUL_OBJ` can be passed a **null pointer** in place of the tiling argument, eliminating the runtime tiling
read entirely. On A3 only the `Norm` and `MDL` templates can be constantised (not `IBShare`), and
`l1Size` defaults to `Impl::L1_SIZE`, which the example states as 524288 = 512 KB — corroborating the L1 figure in
section 8.

---

## 13. ACL graph capture: `aclmdlRICaptureBegin` / `aclmdlRICaptureEnd` / `aclmdlRIExecuteAsync`

### CANN 9.0 应用软件开发指南 — 单流捕获 (Single-Stream Capture)

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/programug/acldevg/runtime_doc_dev_0030.html
English: https://www.hiascend.com/doc_center/source/en/CANNCommunityEdition/900/programug/acldevg/runtime_doc_dev_0030.html
Publisher: Huawei / Ascend, CANN Community Edition 9.0.

基本限制, verbatim:

> 捕获任务到模型中、再执行模型的场景下，存在如下基本限制：
>
> 在进入捕获状态前，Stream上的任务依然是立即执行的。
>
> 在Stream上捕获任务时，只会将任务下沉到Device上，并不会立即执行，因此，对Stream或Event的查询或同步均为非法操作。同样，对Device或Context的查询或同步也是非法的，因为Device和Context中包含了Stream的同步信息。捕获过程中，对Stream、Event、Device、Context的同步或查询，在任何捕获模式下都是非法的。
>
> 在捕获过程中，在ACL_MODEL_RI_CAPTURE_MODE_GLOBAL模式（全局禁止，所有线程都不可以调用非安全函数）下，调用内存同步操作类函数（例如aclrtMemset、aclrtMemcpy、aclrtMemcpy2d）是非法的，会校验报错导致捕获失败。若业务侧确定这些函数的执行不会影响任务捕获，此时，可以通过调用aclmdlRICaptureThreadExchangeMode接口切换当前线程的捕获模式为ACL_MODEL_RI_CAPTURE_MODE_RELAXED，解除调用限制。
>
> 在捕获过程中，下发配置类的任务，例如Profiling配置、Dump配置、溢出检测配置等，可能会返回报错或者对捕获模型不生效。
>
> 若捕获的异步内存复制任务涉及Host内存，则只支持使用acl接口（例如aclrtMallocHost）申请Host锁页内存，否则在捕获过程中将返回报错。
>
> 另外，在捕获过程中，对默认Stream的操作是非法的。
>
> 最后还需要注意的是，任务被捕获后，需要使用者保证模型中任务使用资源的有效性，直至模型被销毁后才能销毁相关资源。

The example's capture block, verbatim:

```cpp
    aclmdlRI modelRI;
    aclrtStream stream;
    aclrtCreateStream(&stream);
    // ========开始捕获任务========
    aclmdlRICaptureBegin(stream, ACL_MODEL_RI_CAPTURE_MODE_GLOBAL);
    // 异步拷贝，将算子self输入的数据从Host侧传到Device侧
    aclrtMemcpyAsync(self_d, size * sizeof(float), self_h, size * sizeof(float), ACL_MEMCPY_HOST_TO_DEVICE, stream);
    // 切换捕获模式为RELAXED，允许调用aclrtMemcpy函数
    aclmdlRICaptureMode mode = ACL_MODEL_RI_CAPTURE_MODE_RELAXED;
    aclmdlRICaptureThreadExchangeMode(&mode);
    // 同步拷贝，将算子other输入的数据从Host侧传到Device侧，仅执行一次
    aclrtMemcpy(other_d, size * sizeof(float), other_h, size * sizeof(float), ACL_MEMCPY_HOST_TO_DEVICE);
    // 将捕获模式切换回GLOBAL
    aclmdlRICaptureThreadExchangeMode(&mode);
    // 执行aclnnAdd算子
    aclnnAdd(workspaceAddr, workspaceSize, executor, stream);
    // 异步拷贝，将算子输出数据从Device侧传回Host侧
    aclrtMemcpyAsync(self_h, size * sizeof(float), out_d, size * sizeof(float), ACL_MEMCPY_DEVICE_TO_HOST, stream);
    // ========结束捕获任务========
    aclmdlRICaptureEnd(stream, &modelRI);
    // 打印模型信息，维测场景下使用
    const char *jsonPath = "./modelRI.json";
    aclmdlRIDebugJsonPrint(modelRI, jsonPath, 0);
    // 多次执行模型
    for (int i = 0; i < 8; i++) {
        aclmdlRIExecuteAsync(modelRI, stream);
        aclrtSynchronizeStream(stream);
```

Related API pages found in search (JS-gated viewer URLs; the doc_center raw equivalents follow the same path shape):
`aclmdlRICaptureBegin` / `aclmdlRICaptureEnd` —
https://www.hiascend.com/document/detail/en/canncommercial/850/API/appdevgapi/aclcppdevg_03_1849.html ,
https://www.hiascend.com/document/detail/en/canncommercial/850/API/appdevgapi/aclcppdevg_03_1782.html ;
「基于捕获模式构建模型运行实例」 (Building a Model Running Instance Based on the Capture Mode) —
https://www.hiascend.com/document/detail/en/canncommercial/850/appdevg/acldevg/aclcppdevg_000519.html ;
`aclrtLaunchKernelAttr` —
https://www.hiascend.com/doc_center/source/en/CANNCommunityEdition/900/API/runtimeapi/aclcppdevg_03_1815.html .

The task-group/update APIs for mutating a captured graph (named in the same volume) are
`aclmdlRICaptureTaskGrpBegin` / `aclmdlRICaptureTaskGrpEnd` and
`aclmdlRICaptureTaskUpdateBegin` / `aclmdlRICaptureTaskUpdateEnd`.

## Relevance
`aclmdlRI` is exactly the handle `aclskOptimize(aclmdlRI model, aclskOptions *options)` in section 6 consumes, so the
full vendor pipeline is: `aclmdlRICaptureBegin` -> issue the 3008 launches -> `aclmdlRICaptureEnd` -> `aclskOptimize`
-> `aclmdlRIExecuteAsync` per decode round. That means the launch cost we measure per kernel call is eliminated at
*replay* time without rewriting any kernel, and SuperKernel then additionally fuses the captured binaries.
`aclmdlRIDebugJsonPrint(modelRI, jsonPath, 0)` dumps the captured task list to JSON — a direct way to enumerate our
3008 tasks and their kernel types before attempting fusion. The constraint that matters for a batch=1 decode loop is
that captured task parameters are immutable unless wrapped in `aclmdlRICaptureTaskGrpBegin/End` and updated inside
`aclmdlRICaptureTaskUpdateBegin/End`.

---

## 14. Kernel launch model: `ACLRT_LAUNCH_KERNEL`, `<<<>>>`, and what `blockDim` means in separated architecture

### CANN 8.0 算子开发指南 — Kernel Launch Operator Development / Overview

https://www.hiascend.com/doc_center/source/en/canncommercial/800/opdevg/Ascendcopdevg/atlas_ascendc_10_0052.html
(TOC parent https://www.hiascend.com/doc_center/source/en/canncommercial/800/opdevg/Ascendcopdevg/atlas_ascendc_10_0051.html
lists: `Overview / Kernel Launch / pyBind Calling`.)

> ### Kernel Launch Method
>
> In the current version, obtaining user workspace is not supported.
>
> Use ACLRT_LAUNCH_KERNEL to call the API:
> ```
> ACLRT_LAUNCH_KERNEL(kernel_name)(blockDim, stream, argument list);
> ```
> kernel_name: name of the operator kernel function.
>
> blockDim: number of cores on which the kernel function will be executed. A logical ID, that is, block_idx, is allocated to each core that executes the kernel function, and block_idx can be obtained by calling GetBlockIdx during the kernel function implementation.
>
> stream, aclrtStream type. Streams preserve the order of a stack of asynchronous operations being executed on the device.
>
> argument list: list of arguments, which must be the same as the argument list of the kernel function.

```cpp
//If blockDim is set to 8, the add_custom kernel function is called on eight cores. Each core independently executes the kernel function in parallel. The parameter lists of the kernel function are x, y, and z.
ACLRT_LAUNCH_KERNEL(add_custom)(8, stream, x, y, z)
```

> ### Kernel Launch Symbol
>
> The kernel function can use the kernel launch symbol <<<...>>> to specify the execution configuration of the kernel function.
> ```
> kernel_name<<<blockDim, l2ctrl, stream>>>(argument list);
> ```
> blockDim specifies the number of cores on which a kernel function will be executed. A logical ID, that is, block_idx, is allocated to each core that executes the kernel function, and block_idx can be obtained by calling GetBlockIdx during the kernel function implementation.
>
> blockDim is a concept about logical cores, and its value range is [1, 65535]. To fully utilize hardware resources, set this parameter to the number of physical cores or a multiple of the number of physical cores. For the coupled architecture and separated architecture, the meaning and setting rules of blockDim during running are different. The details are as follows:
>
> Coupled architecture: Because the Vector and Cube Units are integrated, blockDim is used to start multiple AI Core instances, without differentiating Vector Units and Cube Units. The number of AI Cores can be obtained by calling GetCoreNumAiv or GetCoreNumAic.
>
> Separated architecture
>
> For operators that contain only Vector Units, blockDim is used to set the number of vector (AIV) instances to be started. For example, if an AI processor has 40 Vector cores, set blockDim to 40.
>
> For operators that contain only Cube Units, blockDim is used to set the number of cube (AIC) instances to be started. For example, if an AI processor has 20 Cube cores, set blockDim to 20.
>
> Operators for Vector/Cube fusion computing are started by groups of AIVs and AICs. blockDim is used to set the number of groups to be started. For example, if an AI processor has 40 Vector cores and 20 Cube cores, a group consists of two Vector cores and one Cube core. Set the number of groups to 20. In this case, 20 groups are started, including 40 Vector cores and 20 Cube cores. Note: In this scenario, the number of blockDim (logical cores) cannot exceed the number of physical cores (a physical core contains two Vector cores and one Cube core).
>
> The number of AIC and AIV cores can be obtained by calling GetCoreNumAic and GetCoreNumAiv, respectively.
>
> l2ctrl is a reserved parameter and can be ignored. This parameter is fixed at nullptr.

```cpp
//If blockDim is set to 8, the add_custom kernel function is called on eight cores. Each core independently executes the kernel function in parallel. The parameter lists of the kernel function are x, y, and z.
add_custom<<<8, nullptr, stream>>>(x, y, z);
```

> The kernel function is called asynchronously. After the kernel function is called, the control right is returned to the host immediately. You can call aclrtSynchronizeStream to force the host program to wait until all kernel functions are executed.

Compiler architecture flag, from `cann/asc-devkit` `examples/README.md`
(https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/README.md):

> | 产品型号 | npu-arch参数 |
> | ---- | ---- |
> | Ascend 950PR&950DT系列产品 | --npu-arch=dav-3510 |
> | Atlas A3系列产品<br>Atlas A2系列产品 | --npu-arch=dav-2201 |
> | Atlas推理系列产品AI Core | --npu-arch=dav-2002 |

## Relevance
`blockDim` for a MIX kernel counts **groups**, not cores: one group = 1 AIC + 2 AIV, and 「blockDim (logical cores)
cannot exceed the number of physical cores」. A MIX launch therefore boots 3x the core count of the blockDim value.
The vendor's own worked example — 40 Vector cores and 20 Cube cores, blockDim 20 — is the AIC:AIV = 1:2 ratio for a
910B-class die. Our A3 build must use `--npu-arch=dav-2201`.

---

## 15. CV fusion best practice with full A2/A3 profiling: `quant_group_matmul_high_performance`

This is the closest published analogue to our workload: per-token-quantized int8 grouped matmul with dequant +
activation + cast fused into one `__mix__` kernel, with three measured optimization stages on A2/A3 and 950PR.

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/quant_group_matmul_high_performance/README.md
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/quant_group_matmul_high_performance/README.md
Repo `cann/asc-devkit`, branch `master`.

> ## 概述
>
> 本样例实现了per-token量化的分组矩阵乘法（QuantGroupMatmul），展示CV融合时Vector bound场景下的性能调优方法。
>
> ## 本样例支持的产品及CANN软件版本
>
> | 产品 | CANN软件版本 |
> |------|-------------|
> | Ascend 950PR&950DT系列产品 | >= CANN 9.2.0 |
> | Atlas A3系列产品 | >= CANN 9.2.0 |
> | Atlas A2系列产品 | >= CANN 9.2.0 |

Operator spec, verbatim: `x [8192, 1024] int8 ND`, `weight [8, 1024, 8192] int8 NZ`, `group [8] int64 ND`,
`scale [8, 8192] float ND`, `perTokenScale [8192] float ND`, output `y [8192, 8192] float16 ND`,
kernel name `quant_group_matmul_custom`, invoked via `<<<>>>`.

Scenario matrix, verbatim:

> | 场景 | SCENARIO_NUM | __mix__模式 | PIPELINE_DEPTH | 说明 |
> |------|-------------|------------|----------------|------|
> | Scenario 0 | 0 | `__mix__(1, 1)` | 1 | 基准：单AIV，无流水重叠，Cube与Vector串行 |
> | Scenario 1 | 1 | `__mix__(1, 2)` | 1 | 双AIV，无流水重叠，多AIV分摊Vector任务 |
> | Scenario 2 | 2 | `__mix__(1, 2)` | 4 | 双AIV + 4级流水，Cube-Vector细粒度流水重叠 |

```cpp
constexpr uint32_t scenarioNum = SCENARIO_NUM;
// ...
constexpr uint32_t PIPELINE_DEPTH = (scenarioNum >= 2) ? 4 : 1;

template <...>
#if SCENARIO_NUM == 0
__global__ __mix__(1, 1)
#else
__global__ __mix__(1, 2)
#endif
void quant_group_matmul_custom(...)
```

Data-flow path, verbatim — note the cube result goes out to **GM workspace** and back in through MTE2:

```text
存储位置                        数据类型           流水

GM (x, weight)                   int8
  |                                               MTE2
L1                               int8
  |                                               MTE1
L0A / L0B                        int8
  |  Iterate                                     MMAD
L0C                              int32
  |                                               FIXPIPE
GM (workspace)                   int32
  |  DataCopyPad2D                                MTE2
UB vecInQueue                    int32
  |  AscendDequant (×scale)   int32 → float       VECTOR
UB dequantMiddleResult            float
  |  Mul (×perTokenScale)     float → float       VECTOR
UB mulsResultLocal                float
  |  FasterGelu               float → float       VECTOR
UB actResultLocal                 float
  |  Cast                     float → half        VECTOR
UB vecOutQueue                    half
  |  DataCopyPad2D                                MTE3
GM (y)                            half

注：scale[float] 和 perTokenScale[float] 通过 MTE2 独立搬入UB，
    分别参与 AscendDequant 和 Mul 步骤。
```

The AIC/AIV handshake, verbatim:

> 本样例采用`__mix__`核函数模式，AIC（Cube核）和AIV（Vector核）并行运行在同一个物理核上。AIC执行矩阵乘法，AIV执行反量化+激活+类型转换，两者通过`CrossCoreSetFlag`/`CrossCoreWaitFlag`实现同步：

```cpp
// AIC执行路径: MMCompute → Iterate循环 → SetFlag(SYNC_AIC_TO_AIV)
// AIV执行路径: 跳过MMCompute → VectorCompute → WaitFlag(SYNC_AIC_TO_AIV)
if ASCEND_IS_AIC {
    matmulObj.Iterate();    // Cube计算
    CrossCoreSetFlag<2, PIPE_FIX>(SYNC_AIC_TO_AIV);  // 通知Vector
}
if ASCEND_IS_AIV {
    CrossCoreWaitFlag<2>(SYNC_AIC_TO_AIV);  // 等待Cube完成
    // 处理数据...
    CrossCoreSetFlag<2, PIPE_MTE2>(SYNC_AIV_TO_AIC);
}
```

> Case 0中PIPELINE_DEPTH=1，workspace仅1个Slot（即 `CORE_NUM×BASE_M×BASE_N×sizeof(int32_t)` 大小的一段连续空间），Cube每次Iterate后必须等Vector处理完才能复用该Slot，Cube与Vector串行执行。

Tiling constantisation and UnitFlag, verbatim:

> **③ Tiling常量化**
>
> 所有Tiling参数通过`MatmulApiStaticTiling`在编译期确定，运行时无需Scalar动态计算，减少Scalar开销：
>
> ```cpp
> constexpr static auto CONSTANT_CFG = GetCustomConstantCFG();
> matmul::Matmul<A_TYPE, B_TYPE, C_TYPE, BIAS_TYPE, CONSTANT_CFG> matmulObj;
> ```
>
> **④ Matmul UnitFlag优化**
>
> 本样例通过`mmCFG.enUnitFlag = true`开启Matmul的UnitFlag优化，实现Cube计算与搬运的512B细粒度流水同步：
>
> ```cpp
> static constexpr MatmulShapeParams shapeParams = {SINGLE_M, SINGLE_N, K, BASE_M, BASE_N, BASE_K};
> MatmulConfig mmCFG = GetMMConfig<MatmulConfigMode::CONFIG_MDL>(shapeParams);
> mmCFG.enUnitFlag = true;  // 开启UnitFlag
> auto constantCFG = AscendC::GetMatmulApiTiling<A_TYPE, B_TYPE, C_TYPE, BIAS_TYPE>(mmCFG);
> ```
>
> 默认情况下，Cube的MMAD计算和FixPipe搬运是粗粒度同步的——必须等待整个`[BASE_M, BASE_N]`块的计算完成后，FixPipe才能开始搬出数据。开启UnitFlag后，MMAD和FixPipe实现细粒度（512B）流水并行：每当Cube完成一个512B数据结果的计算，FixPipe立即搬出该数据，Cube计算与结果写回流水重叠。

Double buffer sizing, verbatim — with the per-arch BASE_M:

```cpp
constexpr uint32_t BUFFER_NUM = 2; // UB队列Buffer数, 设为2开启double buffer

pipe->InitBuffer(scaleInQueue, BUFFER_NUM, BASE_N * sizeof(float));          // 2 × 1024B
pipe->InitBuffer(perTokenScaleInQueue, BUFFER_NUM, BASE_M * sizeof(float));   // DAV_2201(BASE_M=128): 2 × 512B；DAV_3510(BASE_M=256): 2 × 1024B
pipe->InitBuffer(vecInQueue, BUFFER_NUM, UB_CAL_SIZE * sizeof(int32_t));      // 2 × 24,576B
pipe->InitBuffer(vecOutQueue, BUFFER_NUM, UB_CAL_SIZE * sizeof(half));        // 2 × 12,288B
```

The dual-AIV task split, verbatim:

> `__mix__(1, 2)`模式下，每个物理核包含1个AIC和2个AIV。两个AIV通过`taskRation`轮询机制分摊Vector侧的offsetM迭代任务：
>
> ```cpp
> uint32_t taskRation = AscendC::GetTaskRation();  // __mix__(1,2)下为2
> if (taskRation != 0 && vecCount % taskRation != subBlockIdx) {
>     continue;  // 跳过不属于当前AIV的任务
> }
> ```
>
> 两个AIV共享同一个coreIdx，通过`subBlockIdx`（由`GetSubBlockIdx()`获取）区分身份。

The ring-slot workspace pipeline, verbatim:

> workspace是Cube和Vector之间的中转站，采用环形分槽设计。这里的 Slot 指由 `workSpaceOffset = BASE_N × BASE_M × (coreIdx + (cubeTaskIdx % PIPELINE_DEPTH) × CORE_NUM)` 定位的一段连续空间，单个 core 的 Slot 大小为 `BASE_M×BASE_N×sizeof(int32_t)`，每层 pipeline 的 Slot 总空间为 `CORE_NUM×BASE_M×BASE_N×sizeof(int32_t)`，`PIPELINE_DEPTH` 个 Slot 轮流使用，Cube 写入当前 Slot 的同时，Vector 可以处理之前 Slot 的数据
>
> - 当`cubeTaskIdx < PIPELINE_DEPTH`时，Cube无需等待，直接写入新Slot
> - 当`cubeTaskIdx >= PIPELINE_DEPTH`时，Cube需等待Vector释放对应Slot（`CrossCoreWaitFlag<2>(SYNC_AIV_TO_AIC)`）
> - 同步粒度为Iterate（=BASE_M×BASE_N），而非子块（=SINGLE_M×SINGLE_N）

```
时间 ──────────────────────────────────────────────────────────────>
Cube:  |─Iter0→Slot0─|─Iter1→Slot1─|─Iter2→Slot2─|─Iter3→Slot3─|─Iter4→Slot0─| ...
                      (Wait)                                     (Wait)
Vec:                 |─Slot0处理─|─Slot1处理─|─Slot2处理─|─Slot3处理─| ...
```

### Measured numbers — Atlas A2 training series (DAV_2201, same arch as our A3), verbatim

> | Scenario | Task Type | Task Duration(μs) | Block Num | Mix Block Num | aicore_time(μs) | aic_mac_time(μs) | aic_mac_ratio | aic_scalar_time(μs) | aic_scalar_ratio | aic_mte1_time(μs) | aic_mte1_ratio | aic_mte2_time(μs) | aic_mte2_ratio | aic_fixpipe_time(μs) | aic_fixpipe_ratio | aiv_time(μs) | aiv_vec_time(μs) | aiv_vec_ratio | aiv_scalar_time(μs) | aiv_scalar_ratio | aiv_mte2_time(μs) | aiv_mte2_ratio | aiv_mte3_time(μs) | aiv_mte3_ratio |
> |------|-----------|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|
> | Scenario 0 | MIX_AIC | 583.512 | 24 | 24 | 564.06 | 192.02 | 0.34 | 115.317 | 0.204 | 168.645 | 0.299 | 141.648 | 0.251 | 79.47 | 0.141 | 565.12 | 471.71 | 0.835 | 228.275 | 0.404 | 139.25 | 0.246 | 94.682 | 0.168 |
> | Scenario 1 | MIX_AIC | 353.887 | 24 | 48 | 344.01 | 192.612 | 0.56 | 143.518 | 0.417 | 170.031 | 0.494 | 160.396 | 0.466 | 107.662 | 0.313 | 345.22 | 235.871 | 0.683 | 122.424 | 0.355 | 107.715 | 0.312 | 56.494 | 0.164 |
> | Scenario 2 | MIX_AIC | 299.286 | 24 | 48 | 288.65 | 193.576 | 0.671 | 196.668 | 0.681 | 173.003 | 0.599 | 170.193 | 0.59 | 167.936 | 0.582 | 285.21 | 235.872 | 0.827 | 126.227 | 0.443 | 99.321 | 0.348 | 56.645 | 0.199 |

### Measured numbers — Ascend 950PR (DAV_3510), verbatim

> | Scenario | Task Type | Task Duration(μs) | Block Num | Mix Block Num | aicore_time(μs) | aic_mac_time(μs) | aic_mac_ratio | ... | aiv_vec_time(μs) | aiv_vec_ratio | ... |
> |---|---|---|---|---|---|---|---|---|---|---|---|
> | Scenario 0 | MIX_AIC | 282.717 | 32 | 32 | 281.84 | 167.952 | 0.596 | | 229.166 | 0.813 | |
> | Scenario 1 | MIX_AIC | 224.125 | 32 | 64 | 223.27 | 168.201 | 0.753 | | 112.441 | 0.504 | |
> | Scenario 2 | MIX_AIC | 204.129 | 32 | 64 | 203.26 | 180.347 | 0.887 | | 112.218 | 0.552 | |

性能分析总结, verbatim:

> 本样例固定shape为`M=8192, N=8192, K=1024`，分组只改变M轴调度方式，总Cube计算量仍为：
>
> Ops_cube = sum_{i=0}^{G-1} group_i × N × K = M × N × K
>
> 对于int8矩阵乘，Cube单cycle按`16 × 32 × 16`次乘加估算，理论Cube计算耗时为：
>
> T_cube = (M × N × K) / (16 × 32 × 16 × f × CORE_NUM)
>
> | 芯片 | CORE_NUM | 理论Cube耗时(μs) | aic_mac_time(μs) | aic_mac_ratio | aiv_vec_time(μs) | 达到理论峰值比例 | 瓶颈判断 |
> |------|----------|------------------|------------------|---------------|------------------|----------------|----------|
> | Atlas A2/A3（DAV_2201） | 24 | 188.93 | 193.576 | 0.671 | 235.872 | 97.60% | 仍偏Vector侧 |
> | Ascend 950PR（DAV_3510） | 32 | 158.88 | 180.347 | 0.887 | 112.218 | 88.10% | 不再是Vector侧 |
>
> Atlas A2/A3上表现不同：Scenario 2中`aiv_vec_time`为235.872μs，高于`aic_mac_time`的193.576μs，`aiv_vec_ratio`也达到0.827，说明Vector侧的反量化、per-token缩放、FasterGelu和Cast链路仍然占据较大比例，整体仍偏Vector侧瓶颈。与此同时，A2实测Cube计算耗时193.576μs已经接近理论Cube耗时188.93μs，达到理论峰值约97.60%，说明Cube矩阵乘本身已经较充分利用，继续优化端到端性能需要优先关注Vector侧计算链路和Cube-Vector同步开销。
>
> 虽然Atlas A2/A3最终仍偏Vector bound，但三级优化仍然有效：Scenario 1通过双AIV并行将Vector计算耗时从471.710μs降低到235.871μs，端到端耗时从583.512μs降低到353.887μs；Scenario 2在Vector计算耗时基本不变的情况下，通过4级workspace流水提升Cube和Vector的重叠度，将端到端耗时进一步降低到299.286μs，相比Scenario 0总耗时减少48.71%。

Profiling metric definitions, verbatim (useful for reading our own traces):

> | 指标 | 说明 |
> |---|---|
> | Task Duration(μs) | 整个任务执行的总时间，样例执行时间以该参数为准 |
> | Block Num | 使用的核数（Block 数量） |
> | aicore_time(μs) | AI Core 的平均执行时间 |
> | aic_mac_time(μs) | cube 类型指令（矩阵类运算指令）耗时 |
> | aic_mte1_time(μs) | mte1 类型指令（L1 -> L0A/L0B 搬运）耗时 |
> | aic_mte2_time(μs) | mte2 类型指令（GM -> L1 搬运）耗时 |
> | aic_fixpipe_time(μs) | fixpipe 类型指令（L0C -> GM/UB 搬运）耗时 |
> | aiv_time(μs) | Task 在 AI Vector Core 上的执行时间 |
> | aiv_vec_time(μs) | vec 类型指令（向量类运算指令）耗时 |
> | aiv_scalar_time(μs) | scalar 类型指令（标量类运算指令）耗时 |
> | aiv_mte2_time(μs) | mte2 类型指令（GM -> UB 搬运类指令）耗时 |
> | aiv_mte3_time(μs) | mte3 类型指令（UB -> GM 搬运类指令）耗时 |

### Sibling example that does the same for an activation chain

`matmul_gelu_high_performance` (same directory) —
https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/matmul_gelu_high_performance/README.md
Listed in the parent README as: 「[03_fusion_compute](./03_fusion_compute) | 融合计算相关的性能优化样例，介绍QuantGroupMatmul、Matmul+GELU等Cube-Vector融合算子的高性能实现。」
(Fetch of this README failed with a proxy 504 at the time of writing; see Gaps.)

### Sibling example: SSBuffer AIV/AIC message passing — **950PR/DT only, not A3**

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/ssbuf_aiv_aic_comm/README.md

> # SSBuffer AIV/AIC通信样例
>
> 本样例演示基础API场景下如何在同一个`__mix__(1, 2)`任务中使用SSBuffer实现AIV到AIC的消息通信。任务包含1个AIC和2个AIV，两个AIV分别通过独立的环形消息队列发送消息，AIC接收并检查消息，最后将结果写入GM，由Host侧逐条校验。
>
> | 产品 | CANN软件版本 |
> |------|-------------|
> | Ascend 950PR&950DT系列产品 | >= CANN 9.2.0 |
>
> 本样例固定使用`dav-3510`架构，仅支持NPU和仿真运行模式。
>
> ### SSBuffer空间布局
>
> - SSBuffer总容量为3KB，本样例使用前2KB。
> - AIV0使用`[0, 1024)`，包含8条128B消息。
> - AIV1使用`[1024, 2048)`，包含8条128B消息。
> - `[2048, 3072)`在本样例中不使用。
> - 两条消息队列互不重叠，每个AIV只写自己的消息队列。
>
> ### 1. 获取SSBuffer工作区
>
> 基础API通过`AscendC::GetSsbufBaseAddr()`获取SSBuffer基地址。返回值属于`__ssbuf__`地址空间，转换后的指针和后续消息指针都必须保留该地址空间限定，不能当作普通GM地址使用。
>
> ```cpp
> __aicore__ inline __ssbuf__ SsbufWorkspace* GetWorkspace()
> {
>     return reinterpret_cast<__ssbuf__ SsbufWorkspace*>(AscendC::GetSsbufBaseAddr());
> }
> ```
>
> ### 2. AIC初始化消息队列
>
> SSBuffer初始内容不保证为0，`AscendC::InitSocState()`也不会清空SSBuffer。AIC启动后遍历两个AIV的消息队列，清除全部消息头，再通过模式4核间同步分别通知AIV0和AIV1开始工作。
>
> ```cpp
> InitQueues(workspace);
> AscendC::CrossCoreSetFlag<4, PIPE_S>(GetAicFlagId(0, START_FLAG_ID));
> AscendC::CrossCoreSetFlag<4, PIPE_S>(GetAicFlagId(1, START_FLAG_ID));
> ```
>
> 模式4用于同一AI Core内AIC与单个AIV之间的同步。AIV0和AIV1都使用本地标记ID `0~15`，AIC侧使用`0~15`对应AIV0，使用`16~31`对应AIV1。`GetAicFlagId`按照`sender * 16 + aivFlagId`计算AIC侧标记ID。
>
> ## 使用约束
>
> - AIC和两个AIV必须在同一个`__mix__(1, 2)`任务中访问SSBuffer。
> - 自定义消息布局不能超过3KB，也不能与其他SSBuffer协议重叠。
> - 消息字段的写入顺序、`valid`位和消息头清理顺序不能随意调整。
> - 队列深度需要保持为2的幂，才能使用位与方式计算队列位置。
> - 跨核共享字段需要使用`volatile`，消息发布和空间复用需要使用配对的模式4核间同步通知。
> - AIV侧标记ID范围为`0~15`；AIC侧通过`0~15`和`16~31`分别与AIV0和AIV1配对。

## Relevance
This is the most directly transferable evidence we found.
- `CORE_NUM = 24` on DAV_2201 (A2/A3), 32 on DAV_3510. With `__mix__(1, 2)`, Block Num stays 24 but
  **Mix Block Num becomes 48** — the profiler column that reveals the core multiplier a MIX launch pays.
- The exact handshake we would write in a megakernel is published:
  `CrossCoreSetFlag<2, PIPE_FIX>(SYNC_AIC_TO_AIV)` on the cube side, `CrossCoreWaitFlag<2>(SYNC_AIC_TO_AIV)` then
  `CrossCoreSetFlag<2, PIPE_MTE2>(SYNC_AIV_TO_AIC)` on the vector side — mode 2, `PIPE_FIX` for the cube-complete
  signal and `PIPE_MTE2` for the slot-release signal.
- It confirms section 8's conclusion the hard way: even inside a single fused kernel, the cube result travels
  `L0C -> FIXPIPE -> GM (workspace) -> MTE2 -> UB`. There is no UB-resident cube->vector path on this architecture.
  The mitigation is a **ring of PIPELINE_DEPTH slots in GM workspace**, sized
  `CORE_NUM × BASE_M × BASE_N × sizeof(int32_t)` per level, with `workSpaceOffset = BASE_N × BASE_M × (coreIdx + (cubeTaskIdx % PIPELINE_DEPTH) × CORE_NUM)`.
  Depth 4 bought 8.92% over depth 1 on 950PR and 15.4% on A2.
- `mmCFG.enUnitFlag = true` gives 512-byte-granularity MMAD/FixPipe overlap instead of waiting for a whole
  `[BASE_M, BASE_N]` tile — a free lever we should check we have on.
- `AscendC::GetTaskRation()` returns 2 under `__mix__(1,2)`, and `GetSubBlockIdx()` identifies which AIV you are:
  the documented way to split vector work between the two AIVs of one group.
- On A2/A3 the workload stayed **Vector bound** (`aiv_vec_time` 235.872 us > `aic_mac_time` 193.576 us,
  `aiv_vec_ratio` 0.827) while cube hit 97.60% of theoretical peak. For our W4A8C8 decode the dequant/activation
  chain is the same shape, which argues the AIV side (not the cube side) is where a megakernel must economise on A3.
- `BASE_M = 128` on DAV_2201 vs 256 on DAV_3510 is the published per-arch base-tile difference.
- SSBuffer (`__ssbuf__`, `AscendC::GetSsbufBaseAddr()`, 3 KB, mode-4 cross-core sync, flag IDs 0-15 / 16-31) is a
  true on-chip AIV<->AIC mailbox — but it is **dav-3510 only**, so it is not available to us on A3. On A3 the
  mailbox must be GM workspace plus mode-2 `CrossCoreSetFlag`.

---

## 16. `matmul_gelu_high_performance` — the A3 cube->vector data path, proven, with L2 as the real fusion buffer

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/matmul_gelu_high_performance/README.md
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/01_simd_cpp_api/05_best_practices/03_fusion_compute/matmul_gelu_high_performance/README.md
Repo `cann/asc-devkit`, branch `master`. Kernel file `mmad_gelu.asc`, kernel name `mmad_vector_custom`.

> ## 概述
>
> 本样例基于静态Tensor编程范式，展示了Cube-Vector（CV）融合的实现方法，将Matmul矩阵乘法与GELU激活函数融合到同一AI Core中并行执行。AIC侧完成Matmul计算后通过Fixpipe将结果输出到GM或UB，AIV侧从GM或UB读取数据完成GELU向量计算。
>
> | 产品 | CANN软件版本 |
> | ------------------------------------------- | ------------- |
> | Ascend 950PR&950DT系列产品 | >= CANN 9.2.0 |
> | Atlas A3系列产品 | >= CANN 9.2.0 |
> | Atlas A2系列产品 | >= CANN 9.2.0 |

The two data paths, verbatim — **this is the definitive statement that A3 cannot do L0C -> UB**:

> 本样例提供两种CV融合场景：
>
> **Scenario 1：CV融合-GM中转（中级性能优化）**（A2/A3/Ascend 950PR均支持）
>
> ```
> GM ──(MTE2)──> L1 ──(MTE1)──> L0A/L0B ──(Cube)──> L0C ──(Fixpipe)──> GM ──(MTE2)──> UB ──(Gelu)──> UB ──(MTE3)──> GM
> ```
>
> **Scenario 2：CV融合-UB直通（高阶极限打磨）**（仅Ascend 950PR支持）
>
> Ascend 950PR新增L0C->UB的通路，A2/A3不支持，芯片能力增强，因此在Ascend 950PR架构中可以不经过GM直接将矩阵乘结果输出到UB进行GELU计算
>
> ```
> GM ──(MTE2)──> L1 ──(MTE1)──> L0A/L0B ──(Cube)──> L0C ──(Fixpipe)──> UB ──(Gelu)──> UB ──(MTE3)──> GM
> ```

Kernel entry and AIC/AIV split, verbatim:

> 本样例使用 `__global__ __mix__(1, 2)` 声明核函数，表示每个逻辑核由1个AIC和2个AIV组成。AIC侧负责Matmul计算，AIV侧负责GELU向量计算，两者在同一AI Core内按(baseM × baseN)块粒度流水并行。

```cpp
__global__ __mix__(1, 2) void mmad_vector_custom(__gm__ uint8_t* xMatrix, __gm__ uint8_t* yMatrix, __gm__ uint8_t* zMatrix)
{
    AscendC::InitSocState();
    KernelMmadVector<...> op;
    op.Init(xMatrix, yMatrix, zMatrix);
    op.Process();
    AscendC::PipeBarrier<PIPE_ALL>();
}
```

```cpp
if ASCEND_IS_AIC {
    // AIC侧：Buffer分配 + 计算循环 + Fixpipe搬出
    ProcessLoopAic(...);
}
if ASCEND_IS_AIV {
    // AIV侧：GELU向量计算 + 搬出至GM
    ProcessLoopAiv();
}
```

Cross-core notification, verbatim:

> AIC侧每完成一个 (baseM × baseN)大小子块的Fixpipe输出后，通过 `CrossCoreSetFlag` 通知AIV侧数据已就绪；AIV侧通过 `CrossCoreWaitFlag` 等待该信号，然后开始GELU计算：

```cpp
// AIC侧 CopyOutAic():
AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8);  // 通知AIV数据就绪

// AIV侧 GeluFromGM() / GeluFromUB():
AscendC::CrossCoreWaitFlag<0x2>(0x8);  // 等待AIC侧Fixpipe完成
```

BlockIdx semantics under `__mix__(1,2)`, verbatim:

> `__mix__(1,2)` 模式下，`GetBlockIdx()` 在AIC侧和AIV侧各自独立编号：AIC侧返回0~numAICores-1，AIV侧返回0~numAIVCores-1。由于每个逻辑核对应2个AIV，AIV侧需要将 `GetBlockIdx() / 2` 映射回逻辑核ID，从而与AIC侧使用相同的多核切分策略：

```cpp
uint32_t logicCoreId;
if ASCEND_IS_AIC {
    logicCoreId = AscendC::GetBlockIdx();
} else {
    logicCoreId = AscendC::GetBlockIdx() / 2;  // __mix__(1,2): 每个逻辑核对应2个AIV
}
uint32_t mIterIdx = logicCoreId % mIter;
uint32_t nIterIdx = logicCoreId / mIter;
```

> `__mix__(1,2)` 模式下每个逻辑核有2个AIV，Fixpipe输出到GM的M行数据按M/2行拆分给两个AIV处理。每个AIV通过 `GetSubBlockIdx() % 2` 获取自己的子块索引，独立完成各自M/2行的GELU计算

> 本样例的Matmul部分采用与Matmul基础API最佳实践样例相同的优化手段（L1/L0双缓冲、大包搬运、细粒度流水同步、UnitFlag等），GELU部分在Ascend 950PR架构上采用RegBase方式，在A2/A3架构上采用MemBase方式。

### Measured numbers (msOpProf, median of 5; M=K=N=8192, fp16 in, fp32 out)

> 以下数据基于msOpProf工具测量，取5次中位数。矩阵规格M=8192, K=8192, N=8192，输入数据类型float16，输出数据类型float32。
>
> ##### Atlas A2训练系列芯片
>
> - singleCoreM=2048, singleCoreN=1536，24核
>
> | Scenario | Task Type | Task Duration(μs) | Block Num | Mix Block Num | aicore_time(μs) | aic_mac_time(μs) | aic_mac_ratio | aic_scalar_time(μs) | aic_mte1_time(μs) | aic_mte2_time(μs) | aic_fixpipe_time(μs) | aiv_time(μs) | aiv_vec_time(μs) | aiv_vec_ratio | aiv_scalar_time(μs) | aiv_mte2_time(μs) | aiv_mte3_time(μs) |
> |---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|
> | Gelu计算 | AI_VECTOR_CORE | 369.827 | 48 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 0 | 358.91 | 236.506 | 0.659 | 8.293 | 316.672 | 150.033 |
> | Matmul计算 | AI_CORE | 4227.605 | 24 | 0 | 3760.55 | 3083.197 | 0.82 | 338.636 | 2516.081 | 3685.713 | 193.704 | 0 | 0 | 0 | 0 | 0 | 0 |
> | Scenario 1 | MIX_AIC | 4236.944 | 24 | 48 | 3770.16 | 3083.235 | 0.818 | 531.971 | 2520.852 | 3687.839 | 193.933 | 3773.6 | 174.327 | 0.046 | 2.016 | 90.315 | 66.373 |
>
> ##### Ascend 950PR芯片
>
> - singleCoreM=2048, singleCoreN=1024，32核
>
> | Scenario | Task Type | Task Duration(μs) | Block Num | Mix Block Num | aicore_time(μs) | aic_mac_time(μs) | aic_mac_ratio | aiv_vec_time(μs) | aiv_mte2_time(μs) | aiv_mte3_time(μs) |
> |---|---|---|---|---|---|---|---|---|---|---|
> | Gelu计算(RegBase) | AI_VECTOR_CORE | 348.868 | 64 | 0 | 0 | 0 | 0 | 66.277 | 320.543 | 314.547 |
> | Matmul计算 | AI_CORE | 2601.311 | 32 | 0 | 2600.55 | 2593.264 | 0.997 | 0 | 0 | 0 |
> | Scenario 1 | MIX_AIC | 2606.91 | 32 | 64 | 2605.9 | 2597.856 | 0.997 | 59.897 | 57.145 | 50.516 |

性能数据解读, verbatim:

> 以Ascend 950PR芯片数据为例：
>
> - 单独Gelu任务耗时348.868μs，单独Matmul任务耗时2601.311μs
> - Scenario 1融合后总耗时2606.91μs，与Matmul单独执行时间基本一致
>
> 这表明采用CV融合方式编写时，AIV的Vector计算时间基本被AIC的Cube计算时间完全覆盖。由于Cube和Vector可以并行执行，整体任务执行时间不是简单的C+V叠加，而是基本等于Cube计算时间（即Matmul时间），实现了高效的流水并行。

The L2 insight, verbatim — **this is the mechanism that makes GM-transit fusion acceptable on A3**:

> **MTE2时间显著减少的原因：**
>
> 对比数据可以发现：
>
> - 单独Gelu计算的aiv_mte2_time为320.543μs
> - Scenario 1中aiv_mte2_time仅为57.145μs，减少约82.2%
>
> 原因分析：虽然Scenario 1中AIV也需要从GM将数据读取到UB，但AIC的Fixpipe将Matmul计算结果写入GM后，数据会被缓存在L2 Cache中。当AIV发起MTE2操作从GM读取数据时，由于数据已在L2 Cache中命中，实际是从L2 Cache读取而非从GM读取，因此MTE2时间显著减少。这也是CV融合场景下的一个隐式性能优化点。

> Fixpipe L0C → UB（通过 `dualDstCtl=0b01` 开启双目标模式，按M维度拆分给2个AIV）

> - Scenario 2融合后总耗时2573.584μs，相比Scenario 1的2606.91μs进一步减少约33μs
> - Scenario 2中aiv_mte2_time仅为0.005μs，相比Scenario 1的57.145μs几乎降为零

Profiling command, verbatim:

> 流水图基于msOpProf工具上板获取，获取命令：`msopprof --aic-metrics=PipeTimeline ./demo`

> ```
>       ├──MemoryL0.csv               # L0A，L0B，和L0C读写带宽速率
> ```

## Relevance
Settles the central architectural question for our megakernel. On A3 there is **no L0C -> UB path** — that is a
950PR addition ("Ascend 950PR新增L0C->UB的通路，A2/A3不支持"), reached via `dualDstCtl=0b01`. The only fusion path
available to us is `L0C -> Fixpipe -> GM -> MTE2 -> UB`. But the measured cost of that round trip is small, because
the Fixpipe write lands in L2 and the AIV's MTE2 hits L2 rather than HBM: `aiv_mte2_time` fell from 320.543 us
standalone to 57.145 us fused, **-82.2%**. So "don't return to HBM" is achievable as "don't miss L2", and
tile sizes must be chosen so the `BASE_M x BASE_N` staging area stays L2-resident.
The headline result: fusing a 348.868 us GELU into a 2601.311 us Matmul produced a 2606.91 us MIX kernel — the
vector work became free, hidden entirely under cube time. On A2 the same experiment: 369.827 us Gelu +
4227.605 us Matmul -> 4236.944 us fused (+9.3 us). Note on A2 the fused kernel's `aic_scalar_time` rose from
338.636 to 531.971 us (+57%) — the MIX mode's Scalar cost is visible and measurable, which is consistent with our
MIX_AIC launch floor being Scalar/handshake bound.
Also note the `Task Type` column is exactly the taxonomy we measured: `AI_VECTOR_CORE`, `AI_CORE`, `MIX_AIC` —
with `Block Num` / `Mix Block Num` showing 24/0, 24/0, 24/48 respectively on A2. `msopprof --aic-metrics=PipeTimeline`
is the command that produces the pipe timeline, and `MemoryL0.csv` gives L0A/L0B/L0C bandwidth.

---

## 17. `npugraph_ex` RFC — the vendor's stated plan for kernel-launch reduction in vllm-ascend

https://github.com/vllm-project/vllm-ascend/issues/4715
Title: `[RFC]: npugraph_ex backend`. Author: ChenCangtao. Created 2025-12-04T11:59:51Z.

> ### Motivation.
>
> In order to achieve better performance when using aclgraph, we introduced the npugraph_ex backend, which is a simple, easy-to-boundary, and accuracy-concern-free fullgraph aclgraph acceleration solution.
>
> This is an overview of our npugraph_ex, all optimization capabilities are performed after AOT autograd
>
> Using the npugraph_ex backend allows for more NPU-friendly optimizations on fx graphs, and node fusion in fx graphs is easy to extend.
>
> ### Proposed Change.
>
> We propose introducing the npugraph_ex backend, which is based on the vllm Adaptor dispatch mechanism.
>
> - All the work of npugraph_ex is based on fx.graph to enhance the experience of aclgraph
> - Use the API in torch_npu to：
>     -  Match known computational subgraphs that can be fused
>     -  Replace them with fused kernels implemented in .torch_npu
>
> Optimize before executing the model, so that when the model does a dummy run, it's already running the optimized graph.
>
> #### Design Overview
>
> 1. Leverage vLLM’s Existing VllmBackend Path
> - We keep the original VllmBackend execution flow in place.
> - We use the npugraph_ex backend by implementing and introducing AscendAdaptor for NPU-friendly graph optimization and compilation. At the same time, a new configuration item was added in additional_config to control whether to use the npugraph_ex backend.
>
> 2.  Custom Fusion Pass Implementation
> This capability is entirely provided by torch_npu. Two main steps of work are needed
> - Implement a target operator matching method
> - Declare fused operators and parameter passing before and after fusion
> We provided an example for custom operator fusion. [norm quant fusion pass demo](https://github.com/vllm-project/vllm-ascend/blob/main/vllm_ascend/compilation/npugraph_ex_passes/graphex_norm_quant_fusion_pass.py)

> 1. How to use it by config?
> ```
> additional_config={
>             "npugraph_ex_config": {
>                 "enable": True
>             }
>         }
> ```

> - **The specific implementation of npugraph_ex and its related wiki：** https://gitcode.com/Ascend/torchair/wiki

> ### The current progress of this RFC
> These PRs have been merged：
> - [#4700](https://github.com/vllm-project/vllm-ascend/pull/4700#issue-3693332280)
> - [#5120](https://github.com/vllm-project/vllm-ascend/pull/5120#issue-3737544253)
> - [#5491](https://github.com/vllm-project/vllm-ascend/pull/5491#issue-3767394993)
> - [#5569](https://github.com/vllm-project/vllm-ascend/pull/5569#issue-3778701756)
>
> These PRs are waiting to be merged：
> - [#5775](https://github.com/vllm-project/vllm-ascend/pull/5775#issue-3799594997)
> - [#5721](https://github.com/vllm-project/vllm-ascend/pull/5721#issue-3791830255)
>
> After #5775 is merged, npugraph_ex can run with the default configuration, and support for more features will require waiting for the upcoming versions of torch_npu and CANN.

> ### Fature Plan
> We have submitted the basic code [[Feature] Support npuhraph_ex backend](https://github.com/vllm-project/vllm-ascend/pull/4700)
> We plan and hope that in the future this backend can become the default optimization for aclgraph.
> These optimization measures will also be included in our plan：
> 1. Memory reuse optimization
> 2. Kernel Performance Optimization
> 3. Redundant kernel optimization processing
>
> These features are also in our plan, but they require users to modify their scripts：
> 1. Support muti-stream
> 2. Support for the Dynamo cache in torch.compile
> 3. Supports weight prefetching
> 4. Weight proprietary format optimization — pre-convert the cube operator's weights to NZ format

## Relevance
Confirms the vendor's two-layer attack on launch count: FX-level node fusion (npugraph_ex) feeding ACLGraph capture,
with SuperKernel on top at binary level. The named fusion target in the shipped demo is **norm + quant** —
`graphex_norm_quant_fusion_pass.py` — which is the same pattern as our W4A8C8 RMSNorm+quant per layer. Also note
item 4 of the future plan: pre-converting cube weights to NZ format, which matches the `CubeFormat::NZ` /
`FRACTAL_ZN` recommendations in sections 8 and 11.

---

## 18. FFTS+ (Flexible Task Scheduling Plus) — the task-scheduling layer that classifies MIX_AIC / MIX_AIV

### `cann/ge` FFTS+ ops kernel builder

https://gitcode.com/cann/ge/blob/master/compiler/engines/ffts_engine/task_builder/fftsplus_ops_kernel_builder.cc
raw: https://raw.gitcode.com/cann/ge/raw/master/compiler/engines/ffts_engine/task_builder/fftsplus_ops_kernel_builder.cc
Repo `cann/ge`, branch `master`. Copyright (c) 2025 Huawei Technologies Co., Ltd.
(GitHub mirror of the same tree: https://github.com/hicann/ge)

The complete FFTS+ context-type taxonomy, verbatim:

```cpp
const std::string kFFTSPlusCoreName = "ffts_plus";
const uint64_t max_preload_context_num = 1000;
constexpr uint32_t kUInt8Max = 255;

const std::unordered_set<uint32_t> SUPPORT_CTX_PATH_TYPE{RT_CTX_TYPE_AICORE, RT_CTX_TYPE_AIV, RT_CTX_TYPE_MIX_AIC,
                                                         RT_CTX_TYPE_MIX_AIV};

static const std::unordered_map<rtFftsPlusContextType_t, std::string> kCtxTypeStrMap = {
    {RT_CTX_TYPE_AICORE, "aicore"},
    {RT_CTX_TYPE_AIV, "aiv"},
    {RT_CTX_TYPE_NOTIFY_WAIT, "notify_wait"},
    {RT_CTX_TYPE_NOTIFY_RECORD, "notify_record"},
    {RT_CTX_TYPE_WRITE_VALUE, "write_value"},
    {RT_CTX_TYPE_MIX_AIC, "mix_aic"},
    {RT_CTX_TYPE_MIX_AIV, "mix_aiv"},
    {RT_CTX_TYPE_SDMA, "sdma"},
    {RT_CTX_TYPE_FLUSH_DATA, "flush_data"},
    {RT_CTX_TYPE_INVALIDATE_DATA, "invalidate_data"},
    {RT_CTX_TYPE_WRITEBACK_DATA, "writeback_data"},
    {RT_CTX_TYPE_AICPU, "aicpu"},
    {RT_CTX_TYPE_COND_SWITCH, "cond_switch"},
    {RT_CTX_TYPE_CASE_SWITCH, "case_switch"},
    {RT_CTX_TYPE_AT_START, "at_start"},
    {RT_CTX_TYPE_AT_END, "at_end"},
    {RT_CTX_TYPE_LABEL, "label"},
    {RT_CTX_TYPE_PERSISTENT_CACHE, "persistent_cache"},
    {RT_CTX_TYPE_DSA, "dsa"}};

REGISTER_OPS_KERNEL_BUILDER(kFFTSPlusCoreName, FFTSPlusOpsKernelBuilder);
```

Subgraph SQE generation — the prefetch and preload knobs, verbatim:

```cpp
Status FFTSPlusOpsKernelBuilder::GenSubGraphSqeDef(domi::TaskDef &task_def, const uint64_t &ready_context_num,
                                                   const ge::ComputeGraph &sgt_graph) const {
  ...
  uint64_t preload_context_num;
  if (ready_context_num > max_preload_context_num) {
    preload_context_num = max_preload_context_num;
  } else {
    preload_context_num = ready_context_num;
  }

  ffts_plus_sqe->set_ready_context_num(ready_context_num);
  ffts_plus_sqe->set_preload_context_num(preload_context_num);
  ffts_plus_sqe->set_total_context_num(gen_ctx_size);
  ffts_plus_sqe->set_prefetch_ost_num(Configuration::Instance().GetPrefetchOstNum());
  ffts_plus_sqe->set_cmaint_ost_num(Configuration::Instance().GetCmaintOstNum());
  ffts_plus_sqe->set_aic_prefetch_lower(Configuration::Instance().GetAicPrefetchLower());
  ffts_plus_sqe->set_aic_prefetch_upper(Configuration::Instance().GetAicPrefetchUpper());
  ffts_plus_sqe->set_aiv_prefetch_lower(Configuration::Instance().GetAivPrefetchLower());
  ffts_plus_sqe->set_aiv_prefetch_upper(Configuration::Instance().GetAivPrefetchUpper());
  ffts_plus_sqe->set_data_split_unit(Configuration::Instance().GetDataSplitUnit());
  return SUCCESS;
}

const std::unordered_set<std::string> FFTS_NO_NEED_GEN_TASK_OP_TYPE = {"Data",  "NetOutput", "Variable",
                                                                       "Const", "Constant",  "PhonyConcat"};
const std::unordered_set<std::string> FFTS_CONTROL_OP_V2_TYPE = {"If", "While", "Case"};
```

Context dependency bookkeeping (dispatch on type), verbatim:

```cpp
Status FFTSPlusOpsKernelBuilder::SetSingleCtxPolicyPri(uint32_t type, domi::FftsPlusCtxDef *ffts_plus_ctx_def,
                                                       FftsPlusContextPath &ctx_path) const {
  switch (type) {
    case RT_CTX_TYPE_AICORE:
    case RT_CTX_TYPE_AIV:
      return FFTSPlusTaskBuilder::set_policy_pri(ctx_path.ctx_id, ctx_path.policy_pri,
                                                 ffts_plus_ctx_def->mutable_aic_aiv_ctx());
    case RT_CTX_TYPE_MIX_AIC:
    case RT_CTX_TYPE_MIX_AIV:
      return FFTSPlusTaskBuilder::set_policy_pri(ctx_path.ctx_id, ctx_path.policy_pri,
                                                 ffts_plus_ctx_def->mutable_mix_aic_aiv_ctx());
    default:
      // other type ctx no need to process
      return SUCCESS;
  }
```

```cpp
      "Ctx_path content: ctx_id:%u, type:%u, pre_cnt:%u, policy_pri:%hu, max_pre_index:%d,"
      "pre_list size:%zu, cmo_list size:%zu, label_list size:%zu, succ_list size:%zu.",
```

### FFTS+ task protobuf — AIC/AIV vs MIX_AIC/AIV context fields

https://github.com/hicann/ge/blob/master/graph_metadef/proto/task.proto
raw: https://raw.githubusercontent.com/hicann/ge/master/graph_metadef/proto/task.proto

```protobuf
    uint32 ready_context_num = 5;
    uint32 preload_context_num = 6;

    uint32 prefetch_ost_num = 7;
    uint32 cmaint_ost_num = 8;

    uint32 aic_prefetch_lower = 9;
    uint32 aic_prefetch_upper = 10;
    uint32 aiv_prefetch_lower = 11;
    uint32 aiv_prefetch_upper = 12;

    uint32 data_split_unit = 13;
}

message StarsSqeHeaderDef {
    uint32 l1_lock = 1;
    uint32 l1_unlock = 2;
    uint32 block_dim = 3;
}

// ffts plus context
message FftsPlusCtxDef {
    enum OpType {
        NORMAL = 0;
        ATOMIC = 1;
    }
    uint32 op_index = 1;
    string uniq_ctx_name = 2;
    uint32 context_type = 3;
    uint32 context_id = 4;
    OpType op_type = 5;

    FftsPlusAicAivCtxDef aic_aiv_ctx = 6;
    FftsPlusMixAicAivCtxDef mix_aic_aiv_ctx = 7;
    FftsPlusSdmaCtxDef sdma_ctx = 8;
    FftsPlusNotifyCtxDef notify_ctx = 9;
    FftsPlusWriteValueCtxDef write_value_ctx = 10;
    FftsPlusAicpuCtxDef aicpu_ctx = 11;
    FftsPlusDataCtxDef data_ctx = 12;
    FftsPlusAtStartCtxDef at_start_ctx = 13;
    FftsPlusAtEndCtxDef at_end_ctx = 14;
    FftsPlusLabelCtxDef label_ctx = 15;
    FftsPlusCaseSwitchCtxDef case_switch_ctx = 16;
    FftsPlusCaseDefaultCtxDef case_default_ctx = 17;
    FftsPlusCondSwitchCtxDef cond_switch_ctx = 18;
    FftsPlusCachePersistCtxDef cache_persist_ctx = 19;
    FftsPlusDsaCtxDef dsa_ctx = 20;
}

// aic/aiv context
message FftsPlusAicAivCtxDef {
    uint32 successor_num = 1;
    uint32 aten = 2;
    uint32 prefetch_config = 3;
    uint32 pred_cnt_init = 4;
    uint32 pred_cnt = 5;
    repeated uint32 successor_list = 6; // 16 bits, len = 26

    uint32 schem = 7;
    uint32 atm = 8;
    uint32 prefetch_enable_bitmap = 9;
    uint32 prefetch_once_bitmap = 10;

    uint32 pmg = 11;
    uint32 ns = 12;
    uint32 part_id = 13;
    uint32 qos = 14;

    uint32 thread_id = 15;
    uint32 thread_dim = 16;

    uint32 non_tail_block_dim = 17;
    uint32 tail_block_dim = 18;

    uint32 task_param_ptr_offset = 19;
    uint32 save_task_addr = 20;
    repeated uint64 task_addr = 21;
    repeated uint64 task_addr_offset = 22;
    uint32 input_output_count = 23;

    repeated string kernel_name = 24;

    repeated uint32 src_slot = 25;  // len = 4, context ID for source data which is out of subgraph
    uint32 policy_pri = 26;
    uint32 thread_window_size = 27;
}

// mix aic/aiv context
message FftsPlusMixAicAivCtxDef {
    uint32 successor_num = 1;
    uint32 aten = 2;
    uint32 prefetch_config = 3;
    uint32 pred_cnt_init = 4;
    uint32 pred_cnt = 5;
    repeated uint32 successor_list = 6; // len = 26

    uint32 schem = 7;
    uint32 atm = 8;
    uint32 prefetch_enable_bitmap = 9;
    uint32 prefetch_once_bitmap = 10;

    uint32 pmg = 11;
    uint32 ns = 12;
    uint32 part_id = 13;
    uint32 qos = 14;

    uint32 non_tail_block_ratio_n = 15;
    uint32 tail_block_ratio_n = 16;

    uint32 thread_id = 17;
    uint32 thread_dim = 18;

    uint32 non_tail_block_dim = 19;
    uint32 tail_block_dim = 20;

    uint32 aic_task_param_ptr_offset = 21;
    uint32 aiv_task_param_ptr_offset = 22;

    repeated string kernel_name = 23;

    repeated uint64 task_addr = 24;
    repeated uint64 task_addr_offset = 25;
    uint32 input_output_count = 26;
    uint32 save_task_addr = 27;
    repeated uint32 src_slot = 28;  // len = 4, context ID for source data which is out of subgraph
    uint32 policy_pri = 29;
    uint32 thread_window_size = 30;
    string args_format = 31;
}
```

Related sources found but not fully read (see Gaps):
`compiler/engines/ffts_engine/task_builder/mixl2_ctx/mix_l2_task_builder.cc`,
`compiler/engines/ffts_engine/task_builder/thread_ctx/mix_aic_aiv_dynamic_task_builder.cc`,
`runtime/v2/engine/ffts_plus/converter/ffts_plus_proto_transfer.h`, all in the `hicann/ge` / `cann/ge` tree.
Also `runtime/v1/hybrid/node_executor/node_executor.cc` maps the FFTS+ kernel name to an RTS executor type.

## Relevance
FFTS+ is the scheduling layer where our `MIX_AIC` / `MIX_AIV` / `AI_CORE` / `AI_VECTOR_CORE` task-type labels come
from: `RT_CTX_TYPE_AICORE`, `RT_CTX_TYPE_AIV`, `RT_CTX_TYPE_MIX_AIC`, `RT_CTX_TYPE_MIX_AIV` are literally the four
context types that participate in dependency paths (`SUPPORT_CTX_PATH_TYPE`). The structural difference between
`FftsPlusAicAivCtxDef` and `FftsPlusMixAicAivCtxDef` explains the MIX launch surcharge concretely:
a MIX context carries **two separate task-parameter pointers** (`aic_task_param_ptr_offset` and
`aiv_task_param_ptr_offset`) plus `non_tail_block_ratio_n` / `tail_block_ratio_n` (the AIC:AIV ratio), where a plain
AIC/AIV context has a single `task_param_ptr_offset` and no ratio field. So one MIX dispatch sets up two kernel
argument blocks and a ratio, against one block for a pure kernel. The SQE-level levers that exist but are
compile-configured rather than user-visible are `preload_context_num` (capped at `max_preload_context_num = 1000`),
`prefetch_ost_num`, `cmaint_ost_num`, and the four `aic/aiv_prefetch_lower/upper` bounds — i.e. FFTS+ already
preloads up to 1000 contexts ahead, which is why a captured graph replays far cheaper than 3008 individual
host launches.

---

## 19. SuperKernel at the AscendC level: `SK_BIND`, `__sk__`, Early-Start, and the exact adaptation constraints

Source repo: `hicann/asc-devkit` on GitHub (the `cann/asc-devkit` doc tree), branch `master`.

### 原理介绍 (principles.md)

https://github.com/hicann/asc-devkit/blob/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/principles.md
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/principles.md

> # 原理介绍
>
> ## 概述
>
> SuperKernel是一种算子的二进制融合技术。与源码融合不同，它聚焦于核函数（Kernel）的二进制调度方案优化，在已编译的二进制代码基础上，将多个子核函数（Kernel）融合创建出一个超级核函数（Kernel）（简称SuperKernel），由该SuperKernel以子函数调用的方式整合多个核函数（Kernel），从而优化计算任务、提升性能和资源利用率。
>
> 与单算子下发相比，SuperKernel技术能够减少Task调度的等待时间和调度开销，同时利用Task间隙资源进一步优化算子头开销，提升推理性能。
>
> 开启SuperKernel融合优化后，系统会自动识别图内可被融合的算子，并生成SuperKernel进行计算。同时框架提供标定SuperKernel范围的能力，支持用户根据实际业务需求对融合范围内的算子进行标记和优化配置。
>
> >[!NOTE]说明
> >SuperKernel适用于如下型号：
> > - Atlas A3系列产品
> > - Atlas A2系列产品
> > - Ascend 950PR&950DT系列产品，该型号下SuperKernel特性是试验特性，在后续版本中会调整或改进，不保证后续兼容性，请开发者在使用过程中关注后续版本更新。
>
> ## 性能收益来源
>
> 相对于单算子下发，SuperKernel主要通过以下方式带来性能收益：
>
> - **减少核函数（Kernel）启动开销**：原本需要多次启动的子核函数（Kernel），被统一通过一次SuperKernel启动完成，减少了任务调度开销。
> - **减少Task调度等待时间**：避免了多个独立Task之间的调度间隙。
> - **算子间流水并行**：通过SuperKernel内提供的任务间同步接口（SetNextTaskStart、WaitPreTaskEnd），可以让子核函数（Kernel）之间的部分指令实现并行执行，进一步压缩端到端耗时。
>
> ## 支持的开启方式
>
> 当前SuperKernel特性通过PyTorch图模式开启，主要有如下两种方式：
>
> | 开启方式 | 说明 |
> | --- | --- |
> | npugraph_ex后端 | 在`torch.compile`的`options`中传入`super_kernel_optimize=True`开启SuperKernel融合；如需控制融合范围，可通过`torch.npu.super_kernel_scope_begin/end`进行标定。具体请参考[SuperKernel功能](https://gitcode.com/Ascend/torchair/blob/master/docs/zh/npugraph_ex/advanced/superkernel.md)。 |
> | GE图模式 | 通过`torchair.scope.super_kernel`作用域标定融合范围，配合TorchAir的CompilerConfig开启。具体请参考[图内标定SuperKernel范围](https://gitcode.com/Ascend/torchair/blob/master/docs/zh/ascend_ir/features/advanced/super_kernel_scope.md)。 |
>
> ## 算子适配说明
>
> CANN包发布的主流模型常用算子已支持SuperKernel融合。用户自定义的Ascend C算子如需支持SuperKernel，需要满足一定适配条件

### 算子适配说明 (operator_adaptation.md) — the fusion-eligibility constraints

https://github.com/hicann/asc-devkit/blob/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/operator_adaptation.md
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/operator_adaptation.md

> 自定义算子要支持融合进SuperKernel，开发流程上与普通算子并无显著差异，但需要遵循以下一系列**特定约束**。这些约束与具体的开启方式（npugraph_ex后端或GE图模式）无关，大部分约束与算子启动核数（block num）以及SuperKernel启动核数之间的关系相关，需要开发者在算子设计阶段就予以关注。
>
> >[!NOTE]说明
> >SuperKernel启动核数为其中所有子核函数（Kernel）的最大启动核数。例如，SuperKernel包含算子a（启动核数为4）和算子b（启动核数为2），则SuperKernel启动核数为4。
>
> ## 全核同步约束
>
> 自定义算子若进行全核同步，需注意该子核函数（Kernel）启动的核数需要与SuperKernel的核数一致，通常需要启动当前硬件满核。若子核函数（Kernel）启动的核数少于SuperKernel的核数，全核同步会等待所有核完成，导致卡住超时。
>
> ## MIX 1:1算子核数比例约束
>
> 若自定义算子的核函数（Kernel）类型设置为`KERNEL_TYPE_MIX_AIC_1_1`，因为SuperKernel会根据启动核数等信息调整SuperKernel的启动比例，此时需特别注意该算子也可以适应SuperKernel的1:2启动比例，确保AIC与AIV之间的硬同步操作正确执行。比如：
>
> - 算子内部使用了AIC与AIV之间的硬同步接口（CrossCoreSetFlag和CrossCoreWaitFlag），不要单独指定某些AIV核调用硬同步接口，要使所有AIV核均调用硬同步接口，防止因为硬同步数量不匹配而导致卡死超时。
> - 使用Matmul高阶API时，算子逻辑应保证仅有一个AIV0核调用Matmul接口，防止启动两个AIV核之后出现AIV1核消息无法接收导致卡死超时。
>
> ## 标量读写与Cache一致性
>
> 在开发自定义算子时，开发者必须确保所有对GM的标量读写操作都按需正确插入DataCacheCleanAndInvalid指令。
>
> - 在单算子编译场景下，毕昇编译器自动在算子末尾添加DataCacheCleanAndInvalid指令，刷新整个DCache（数据缓存）。
> - 在SuperKernel中，子核函数（Kernel）被当作普通函数处理，编译器不会自动插入该指令来确保数据缓存一致性，开发者需要自行保证，避免因容错机制改变而导致错误。
>
> 出于性能考虑，SuperKernel场景下Cache刷新机制如下：
>
> - 如果开发者调用GlobalTensor的`GetValue`和`SetValue`接口对GM进行标量读写，在GE入图及npugraph_ex后端aclnn调用场景，SuperKernel编译时会自动在两个接口内部插入DataCacheCleanAndInvalid指令刷新单个Cache Line，保证一定的数据缓存一致性。不会在子核函数（Kernel）调用前后插入DataCacheCleanAndInvalid。
> - 如果开发者通过GlobalTensor的`()`运算符接口来获取值（读值时会插入DataCacheCleanAndInvalid指令刷新单个Cache Line保证数据缓存一致性），但通过该接口直接改写了GlobalTensor对应位置的值时，则不会自动插入DataCacheCleanAndInvalid指令，开发者需要自行保证数据缓存一致性。例如：
>
>     ```c++
>     AscendC::GlobalTensor<float> xGm;
>     xGm.SetGlobalBuffer((__gm__ float *)(addr), length); // addr为GM地址，length为对应GM长度
>     xGm(0) = (float)(1.0); // 在获取值时，SuperKernel能够保证自动刷新cache line，但是写值时，相当于普通变量直接赋值，SuperKernel无法插入DataCacheCleanAndInvalid，需要用户保证数据缓存的一致性。
>     ```
>
> 对于频繁调用`GetValue`和`SetValue`的算子，建议使用`dcci_before_kernel_start`、`dcci_after_kernel_end`关闭指定算子内`GetValue`/`SetValue`中自动插入的缓存刷新指令，而改为算子调用前后插入整个DCache刷新，避免性能劣化。
>
> ## 核数获取接口约束
>
> 在GE入图及npugraph_ex后端aclnn调用场景，子核函数（Kernel）中调用GetBlockNum接口获取核数时，无论是否融合SuperKernel，获取的核数保持不变，不受SuperKernel启动核数的影响。
>
> 在SuperKernel场景下，如下Ascend C API在算子编译过程中适配了SuperKernel，子算子需要严格按照Ascend C提供的API进行编程，从而无需感知是否开启SuperKernel。例如在获取核数和索引时，**不能调用`block_idx`、`block_num`等底层变量和相关API**，必须使用下表中的Ascend C API：
>
> | API列表 | 功能描述 |
> | --- | --- |
> | AscendC::GetBlockIdx() | 获取当前核的index |
> | AscendC::GetBlockNum() | 获取当前任务配置的核数 |
>
> ## TPipe析构约束
>
> 针对Atlas A2系列产品、Atlas A3系列产品，在GE入图及npugraph_ex后端aclnn调用场景，子算子TPipe对象析构（TPipe::Destroy）接口内部的`AscendC::PipeBarrier<PIPE_ALL>()`指令会被去除，如果算子内部使用了多个TPipe对象或手动调用Destroy函数时开发者需自行保障TPipe对象间流水的同步。
>
> ```c++
> // 场景一：两个TPipe对象通过作用域析构，需在第一个析构后插入PipeAll
> {
>     AscendC::TPipe pipe1;
>     AscendC::TQue<AscendC::TPosition::VECOUT, 2> que1;
>     uint8_t num1 = 2;
>     uint32_t len1 = 128;
>     pipe1.InitBuffer(que1, num1, len1);
>     // ... 使用pipe1进行算子计算 ...
> } // pipe1析构，但Destroy中的PipeBarrier已被去除
>
> // 必须手动插入PipeAll，保证pipe1流水完成后再使用pipe2
> AscendC::PipeBarrier<AscendC::PIPE_ALL>();
> ```
>
> ## 性能优化建议
>
> - **任务间同步**
>
>     开发者在进行核函数（Kernel）侧编程时，可以通过调用SetNextTaskStart和WaitPreTaskEnd两个任务间接口，进一步提升性能。
>
>     - 调用`SetNextTaskStart`后的指令可以和后续其他的子核函数（Kernel）实现并行，提升整体性能。SuperKernel按序调用子核函数（Kernel），为保证子核函数（Kernel）之间数据互不干扰，会在子核函数（Kernel）间插入算子间同步进行保序，子核函数（Kernel）N-1调用该接口后，之后的指令会和后续子核函数（Kernel）N实现并行。
>     - 调用`WaitPreTaskEnd`前的指令可以和前序其他的子核函数（Kernel）实现并行，提升整体性能。
>
> - **二进制复用优化**
>
>     在GE入图Tiling下沉场景下，可以通过`--op_relocatable_kernel_binary`编译选项，开启二进制复用优化，提升编译性能
>
> ## 核函数（Kernel）直调算子的额外适配
>
> 对于使用`<<<>>>`方式开发的Ascend C算子，目前仅支持在npugraph_ex后端融合进SuperKernel。此类算子除需遵循上述通用约束外，还需要在算子核函数（Kernel）入口侧增加SuperKernel入口函数。

### `SK_BIND` — binding a kernel to SK sub-functions (A2/A3 supported, 950 NOT)

https://github.com/hicann/asc-devkit/blob/master/docs/zh/api/Utils-API/SuperKernel/SK_BIND.md
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/Utils-API/SuperKernel/SK_BIND.md

> ## 产品支持情况
>
> - Ascend 950PR&950DT系列产品：不支持
> - Atlas A3系列产品：支持
> - Atlas A2系列产品：支持
> - Atlas 200I/500 A2推理产品：不支持
> - Atlas推理系列产品AI Core：不支持
> - Atlas推理系列产品Vector Core：不支持
> - Atlas训练系列产品：不支持
> - Kirin X90处理器系列产品：不支持
> - Kirin 9030处理器系列产品：不支持
>
> ## 功能说明
>
> 本接口为算子SuperKernel场景提供绑定原核函数（Kernel）和SK子函数的能力。
>
> ## 函数原型
>
> ```cpp
> #define SK_BIND(GF, cap, SK0,...)
> ```
>
> ## 参数说明
>
> | 参数名 | 输入/输出 | 描述 |
> | --- | --- | --- |
> | GF | 输入 | 核函数（Kernel）签名。 |
> | cap | 输入 | `uint64_t`类型，用于标记当前算子的SuperKernel特性。SuperKernel框架根据这些信息调整相应的同步和融合策略。各bit位可按位或组合：<br>&bull; 1：early start wait flag，表示算子内使用了WaitPreTaskEnd接口。<br>&bull; 2：early start set flag，表示算子内使用了SetNextTaskStart接口。<br>&bull; 4：disable_dcci，表示当前算子需要SuperKernel框架关闭调用前后的DCCI ALL指令。<br>&bull; 8：disable_batchmode_check，表示跳过当前算子的`__schedmode__`检查，使该算子可继续参与SuperKernel融合。<br>例如，同时配置early start wait flag和early start set flag时，cap取值为3。 <br>&bull; 16：blockdim_scale_up, 表示算子已自行支持核数向上扩展。融合后，SuperKernel会按自身的核数启动该算子；算子需要自行保证在实际启动核数大于其原始核数时仍能正确执行。|
> | SK0 | 输入 | SK子函数签名。 |
> | ... | 输入 | SK1~SK3。可选，可提供额外的SK子函数签名。SuperKernel可以为不同核指定不同的SK子函数缓解同地址访问开销。|
>
> ## 约束说明
>
> -   一个核函数（Kernel）最多绑定四个SK子函数。
> -   核函数（Kernel）直调算子目前仅支持在npugraph_ex后端进入SuperKernel，不支持GE图模式。

```cpp
#include "kernel_operator.h"

// 原普通核函数（Kernel）保留（用于非SuperKernel场景）
__global__ __vector__ void add_custom(GM_ADDR x, GM_ADDR y, GM_ADDR z, uint32_t totalLength)
{
    KernelAdd op;
    op.Init(x, y, z, totalLength);
    op.Process();
}

// 规则3：定义参数结构体（根据原global函数的实际参数定义）
struct AddCustomArgs {
   GM_ADDR x;                      // 对应add_custom的第一个参数
   GM_ADDR y;                      // 对应add_custom的第二个参数
   GM_ADDR z;                      // 对应add_custom的第三个参数
   uint32_t totalLength;           // 对应add_custom的第四个参数
};
// 定义一个带模板参数的SK子函数
// 模板参数仅用于实例化出不同的符号，不影响函数逻辑
template<uint32_t splitNum>
__sk__ __vector__ void add_custom_sk(const AddCustomArgs *args, sk::SkSystemArgs *sysArgs/* 可选添加sysArgs参数 */)
{
    // 从结构体中获取参数
    GM_ADDR x = args->x;
    GM_ADDR y = args->y;
    GM_ADDR z = args->z;
    uint32_t totalLength = args->totalLength;
    // 规则5：逻辑与global函数一致
    KernelAdd op;
    op.Init(x, y, z, totalLength);
    op.Process();
}
// 规则6：使用SK_BIND绑定
// 通过指定模板参数实例化出4个不同的符号
// cap取值4表示配置disable_dcci
SK_BIND(add_custom, 4, add_custom_sk<0>, add_custom_sk<1>, add_custom_sk<2>, add_custom_sk<3>);
```

### Early-Start APIs: `SetNextTaskStart` / `WaitPreTaskEnd` — **effective on A3, no-op on A2**

https://github.com/hicann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_task_sync/SetNextTaskStart.md
https://github.com/hicann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_task_sync/WaitPreTaskEnd.md

> > [!NOTE]说明
> >本接口为试验接口，在后续版本中可能会调整或改进，不保证后续兼容性。
>
> ## 产品支持情况
>
> - Ascend 950PR&950DT系列产品：支持，该接口生效
> - Atlas A3系列产品：支持，该接口生效
> - Atlas A2系列产品：支持，仅保证编译兼容，实际功能不生效。
> - Atlas 200I/500 A2推理产品：支持，仅保证编译兼容，实际功能不生效。
> - Atlas推理系列产品AI Core：支持，仅保证编译兼容，实际功能不生效。
> - Atlas推理系列产品Vector Core：支持，仅保证编译兼容，实际功能不生效。
> - Atlas训练系列产品：支持，仅保证编译兼容，实际功能不生效。
>
> ## 功能说明
>
> 头文件路径为：`"basic_api/kernel_operator_common_intf.h"`。
>
> 算子层面支持SuperKernel特性Early-Start能力的接口，调用后在TorchAir层面：1.GE图模式下进行默认启用; 2.npugraph_ex后端通过early_start选项进行控制启用。
>
> **开发者需要自行保证调用此接口后的指令不会与后序算子互相干扰而导致精度问题，推荐在整个算子最后一条搬运指令后调用此接口。**

```cpp
// Ascend 950PR&950DT / Atlas A3 / Atlas A2 / Atlas 200I/500 A2 / Kirin X90 / Kirin 9030
template<pipe_t AIV_PIPE = PIPE_MTE3, pipe_t AIC_PIPE = PIPE_FIX, bool FORCE = false>
__aicore__ inline void SetNextTaskStart()

// Atlas 推理系列产品 AI Core / Vector Core / Atlas 训练系列产品
template<pipe_t AIV_PIPE = PIPE_MTE3, pipe_t AIC_PIPE = PIPE_MTE3, bool FORCE = false>
__aicore__ inline void SetNextTaskStart()
```

```cpp
template<bool FORCE = false>
__aicore__ inline void WaitPreTaskEnd()
```

> | 参数名 | 描述 |
> | --- | --- |
> | AIV_PIPE | SetNextTaskStart之后运行的指令，如果位于AIV上的AIV_PIPE流水，可以与后序算子并行。AIV_PIPE的取值范围为PIPE_MTE2、PIPE_MTE3、PIPE_S、PIPE_V。 |
> | AIC_PIPE | SetNextTaskStart之后运行的指令，如果位于AIC上的AIC_PIPE流水，可以与后序算子并行。AIC_PIPE的取值范围为PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX、PIPE_M。 |
> | FORCE | 离线编译时是否强制启用Early-Start能力，不影响在线编译。<br>false：离线编译时不强制启用Early-Start能力；<br>true：离线编译时启用Early-Start能力，适用于无在线编译流程的算子（如<<<>>>开发的算子）。 |

> ## 约束说明
>
> - 该接口适用于TorchAir图模式开发场景，且需在启用SuperKernel特性后方可生效。
> - 在算子运行过程中，需要保证此接口在每个核上都被调用，且每个核上仅被调用一次。
> - 若子核函数（Kernel）某个TilingKey分支调用了此接口，则开发者需要保证当前算子可能会运行的所有TilingKey均调用了此接口，否则会出现因同步指令数量不匹配而卡住的现象。
> - 本接口内部实现会占用核间同步flagId，若与CrossCoreSetFlag/CrossCoreWaitFlag同时使用需注意避免flagId冲突

```cpp
AscendC::DataCopy(dstGlobal, dstLocal, TOTAL_LENGTH);
// 在最后一条搬运指令后调用，使之后的指令可与后续子核函数（Kernel）并行执行。
AscendC::SetNextTaskStart();
```

> 完整样例请参考TaskSync样例：`examples/01_simd_cpp_api/03_basic_api/05_sync_control/task_sync`

### `SetScheduleMode` — the batchmode setter

https://www.hiascend.com/doc_center/source/zh/canncommercial/81RC1/apiref/basicdataapi/atlasopapi_07_00248.html
(also https://www.hiascend.com/doc_center/source/zh/canncommercial/80RC2/apiref/opdevgapi/atlasophostapi_07_0072.html)

> SetScheduleMode
>
> 函数功能: 设置算子在NPU上执行时的调度模式。
>
> 函数原型
>
> ```
> ge::graphStatus SetScheduleMode(const uint32_t schedule_mode)
> ```
>
> | 参数 | 输入/输出 | 说明 |
> |---|---|---|
> | schedule_mode | 输入 | 0：普通模式，默认情况下为普通模式。<br>1：batchmode模式，核间同步算子需要设置该模式。 |

```cpp
ge::graphStatus TilingForAdd(TilingContext *context) {
  uint32_t batch_mode = 1U;
  auto ret = context->SetScheduleMode(batch_mode);
  GE_ASSERT_SUCCESS(ret);
  ...
}
```

## Relevance
This is the highest-value operational material in the dossier, because it is the vendor's own answer to our exact
problem on our exact chip, and it changes two of my earlier readings.
- `SK_BIND` is **supported on A2/A3 and NOT on 950PR**, so the kernel-direct-launch (`<<<>>>`) path into SuperKernel
  is available to us. The mechanics: keep the original `__global__` kernel, define an args struct, write a
  `__sk__`-qualified sub-function taking `(const Args*, sk::SkSystemArgs*)`, and `SK_BIND(kernel, cap, sk0, sk1, sk2, sk3)`.
  Up to **four** SK sub-functions per kernel, and the reason for four is explicitly 「SuperKernel可以为不同核指定不同的
  SK子函数缓解同地址访问开销」 — the L2 instruction-address contention from section 6's 子Kernel拆分.
- `cap` bits are the exact fusion-policy switches: 1 = uses `WaitPreTaskEnd`, 2 = uses `SetNextTaskStart`,
  4 = `disable_dcci`, 8 = `disable_batchmode_check` (skip the `__schedmode__` check so the operator can still fuse),
  16 = `blockdim_scale_up` (operator tolerates being launched with more cores than it was written for).
- Early-Start (`SetNextTaskStart` / `WaitPreTaskEnd`) **is effective on A3 and a compile-only no-op on A2**. That is
  an A3-specific lever we have and A2 users do not. Defaults are `AIV_PIPE = PIPE_MTE3`, `AIC_PIPE = PIPE_FIX`, and
  `FORCE = true` is required for `<<<>>>`-developed operators because they have no online-compile step.
- Three constraints will bite a megakernel directly: (a) SuperKernel's launch core count is the **max** over its
  sub-kernels, and any sub-kernel doing a full-core sync must be launched with the same core count or it hangs —
  「通常需要启动当前硬件满核」; (b) a `KERNEL_TYPE_MIX_AIC_1_1` operator must also work at the 1:2 ratio SuperKernel may
  impose, every AIV must call the hard-sync API, and with the Matmul high-level API only AIV0 may call Matmul;
  (c) inside a SuperKernel sub-kernel the compiler no longer emits the trailing `DataCacheCleanAndInvalid`, and
  `TPipe::Destroy`'s internal `PipeBarrier<PIPE_ALL>()` is **removed** on A2/A3 — so multi-`TPipe` kernels must insert
  `AscendC::PipeBarrier<AscendC::PIPE_ALL>()` by hand. Also `block_idx` / `block_num` raw variables are forbidden;
  only `AscendC::GetBlockIdx()` / `GetBlockNum()` are SuperKernel-aware.
- `dcci_before_kernel_start` / `dcci_after_kernel_end` are the per-operator options that trade per-`GetValue`/`SetValue`
  cache-line flushes for one whole-DCache flush around the operator — which is exactly what vllm-ascend passes as
  `{"dcci_after_kernel_end": [".*"]}` in section 7.

---

## 20. The exact cross-core `flagId` allocation table (what is already taken, per architecture)

https://github.com/hicann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/key_features.md
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/key_features.md

> ## 核间同步flagId占用说明
>
> ### 概述
>
> 开发者使用CrossCoreSetFlag和CrossCoreWaitFlag接口进行核间同步时，需要传入核间同步标记**flagId**，每个flagId对应一个用于控制同步的计数器。
>
> 部分接口的内部实现也会占用一部分flagId。当开发者同时使用这些接口与CrossCoreSetFlag/CrossCoreWaitFlag时，若flagId发生冲突（即相互独立的同步操作复用了同一个flagId），其对应的计数器会被错误地共享和修改，导致核间同步行为异常：可能出现阻塞无法解除而使程序卡死，或同步提前完成、阻塞提前解除而导致计算结果错误。
>
> 因此，当开发者同时调用CrossCoreSetFlag/CrossCoreWaitFlag与这些占用flagId的接口时，应**避开各接口内部已占用的flagId**，选用未被占用的flagId。
>
> 核间同步分为**模式0、1、2**与**模式4**，两者的底层硬件指令不同，flagId相互独立
>
> ### 模式0、1、2的flagId占用
>
> **表1**  模式0、1、2flagId占用情况
>
> | 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
> | :--- | :--- | :--- | :--- | :--- |
> | SyncAll | `isAIVOnly=true` | 14 | AIV：14 | 2201、3510 |
> | SyncAll | `isAIVOnly=false` | 11、12、13 | AIC：11、12、13；AIV：12、13 | 2201、3510 |
> | SetNextTaskStart | SuperKernel子核函数（Kernel）中调用 | 11、14 | AIC：11；AIV：14 | 2201、3510 |
> | WaitPreTaskEnd | SuperKernel子核函数（Kernel）中调用 | 11、12、13、14 | AIC：11、12、13；AIV：12、13、14 | 2201、3510 |
> | Matmul | 定义N个Matmul对象 | `[0, 2N-1]` | AIV/AIC按对象与subBlock分配 | 2201 |
> | Matmul | SuperKernel融合场景（GetTaskRatio返回2，即1:2配比） | 15 | AIV：15 | 2201 |
>
> ### 模式4的flagId占用
>
> **表2**  模式4flagId占用情况
>
> | 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
> | :--- | :--- | :--- | :--- | :--- |
> | SyncAll | `isAIVOnly=false`（核函数（Kernel）使用`__mix__(1, 2)`修饰时） | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
> | WaitPreTaskEnd | SuperKernel子核函数（Kernel）中调用 | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
> | Matmul | 定义N个Matmul对象 | `[0, N+17]` | AIC/AIV按对象、eventType、subBlock分配 | 3510 |
> | Matmul | A矩阵和B矩阵同时开启IBSHARE的场景 | 15 | AIV：15 | 3510 |
> | TSCM | 从UB发起的L1 Buffer（TSCM）队列 | 0~11（从11向下逐个分配） | AIV | 3510 |
> | DataCopy（GM→L1） | 无 | 1、17 | AIC：1、17；AIV：1 | 3510 |
>
> ### 各接口限定条件说明
>
> #### SyncAll
>
> - **isAIVOnly=true**：纯Vector算子的全核同步，占用模式0、1、2的flagId为14（AIV）。
> - **isAIVOnly=false**：Mix（包含Cube和Vector计算）算子的全核同步，占用情况随NPU架构与核函数（Kernel）类型不同：
>     - **2201架构**：占用模式0、1、2的flagId为11、12、13。
>     - **3510架构**：
>         - 核函数（Kernel）使用`__mix__(1, 1)`修饰时，占用模式0、1、2的flagId为11、12、13。
>         - 核函数（Kernel）使用`__mix__(1, 2)`修饰时，占用模式0、1、2的flagId为11，以及模式4的flagId为12、13、28、29。
>
> #### SetNextTaskStart / WaitPreTaskEnd
>
> - 二者为**SuperKernel**场景专用接口，仅在算子以SuperKernel方式融合、且子核函数（Kernel）中调用时才生效。
> - **SetNextTaskStart**：占用模式0、1、2的flagId为11（AIC）、14（AIV）。
> - **WaitPreTaskEnd**：
>     - **2201架构**：占用模式0、1、2的flagId为11、12、13、14。
>     - **3510架构**：占用模式0、1、2的flagId为11、12、13、14，以及模式4的flagId为12、13、28、29。
>
> #### Matmul
>
> - 占用flagId的范围与定义的**Matmul对象数目N**相关（N最大为4），并且随NPU架构不同而不同。
> - **2201架构**：占用模式0、1、2的flagId为[0, 2N-1]（N=4时占用`[0,7]`）；SuperKernel融合（1:2配比，即GetTaskRatio返回2）场景下还占用flagId为15。
> - **3510架构**：占用模式4的flagId为[0, N+17]（N=4时占用`[0,21]`）；A矩阵和B矩阵同时开启IBSHARE的场景下还占用flagId为15。
>
> #### TSCM
>
> - 仅当使用从UB发起的L1 Buffer（TSCM）队列时才触发。
> - 占用模式4的flagId，范围为**0~11**：第1个TSCM队列占用11，第2个占用10，依次向下递减分配，最多可分配到0。

The four modes restated with the pipe-blocking semantics, verbatim — **and the critical A3 caveat**:

> - 模式0：AI Core核间的同步控制。对于AIC全核场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的全部流水或者由模板参数pipe指定的流水（与NPU架构有关）中的指令才会执行；对于AIV全核场景，同步所有的AIV核...
> - 模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的全部流水或者由模板参数pipe指定的流水（与NPU架构有关）中的指令才会执行。
> - 模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后，两个AIV上CrossCoreWaitFlag后续的全部流水或者由模板参数pipe指定的流水（与NPU架构有关）中的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的全部流水或者由模板参数pipe指定的流水（与NPU架构有关）中的指令才能执行。
> - 模式4：AI Core内部，AIC与单个AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后，单个AIV上CrossCoreWaitFlag后续的由模板参数pipe指定的流水中的指令才会继续执行；单个AIV执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的由模板参数pipe指定的流水中的指令才能执行。该模式仅在NPU架构版本3510上支持。
>
> > [!NOTE]说明
> > 模式0、1、2下`CrossCoreWaitFlag`阻塞的流水类型因NPU架构而异：
> > - 在NPU架构版本2201上，`CrossCoreWaitFlag`传入的`pipe`参数无效，无论取值为何都默认阻塞全部流水的后续指令，建议省略`pipe`参数并使用默认值。
> > - 在NPU架构版本3510上，`CrossCoreWaitFlag`传入的`pipe`参数生效，阻塞由模板参数`pipe`指定的流水的后续指令。

> 下述同步特性均以如下场景配置为例：核函数（Kernel）使用`__mix__(1, 2)`修饰，即每个AI Core包含1个AIC和2个AIV，并设置逻辑核数`numBlocks=2`，即共启动2个AI Core，因此存在2个AIC和4个AIV。为便于描述，将2个AIC分别编号为AIC0、AIC1；AI Core0中的2个AIV分别编号为AIV0-0、AIV0-1，AI Core1中的2个AIV分别编号为AIV1-0、AIV1-1。**各核中与`flagId`对应的计数器初始值均为0。**

> ```cpp
> // 进行核间同步时，即使只有AIC参与同步也不能用__cube__修饰核函数（Kernel），具体原因请参考CrossCoreSetFlag的约束说明。
> if (ASCEND_IS_AIC) {
>     // 每个核都应该有类似如下的成对调用CrossCoreSetFlag和CrossCoreWaitFlag。
>     // modeId必须配置为0，flagId要一致；CrossCoreWaitFlag的pipe使用默认值。
>     AscendC::CrossCoreSetFlag<0, PIPE_M>(0);       // 待前置PIPE_M流水任务完成后，通知调度模块。
>     AscendC::CrossCoreWaitFlag<0>(0);              // 直到所有AIC都完成前置PIPE_M流水，调度模块更新flagId=0的计数器后，解除所有流水后续指令的阻塞。
> }
> ```

## Relevance
This is the budget sheet for a hand-synchronized megakernel on A3 (`__NPU_ARCH__ == 2201`). The usable flagId space is
0-10 (section 4), and of that:
- `Matmul` with N objects takes `[0, 2N-1]` on 2201. With the max N=4 that is `[0,7]`, leaving only **8, 9, 10** free.
  With N=1 it takes `[0,1]`, leaving 2-10.
- `SyncAll<false>` takes 11, 12, 13 and `SyncAll<true>` takes 14 — both outside the user range 0-10, so they do not
  collide with hand-written flags. Same for `SetNextTaskStart` (11, 14) and `WaitPreTaskEnd` (11-14).
- Under SuperKernel at 1:2 ratio, `Matmul` additionally takes flagId **15** on 2201.
So: a megakernel using one Matmul object plus Early-Start can safely hand-allocate flagIds 2 through 10 — nine
independent cross-core events, each with a counter that saturates at 15 Sets.
One more A3-specific fact that matters for cost: on 2201 「`CrossCoreWaitFlag`传入的`pipe`参数无效，无论取值为何都默认
阻塞全部流水的后续指令」 — a cross-core wait on A3 stalls **all** pipes, not just the named one. Pipe-selective waits
and mode 4 (AIC to a *single* AIV) are 3510-only. That is a concrete, documented reason the same fused design costs
more on A3 than on 950PR, and it means every AIC->AIV handoff in our kernel is a full-pipe barrier on the waiting core.

---

## 21. Getting a `<<<>>>` kernel into SuperKernel: the complete `__sk__` adaptation recipe

https://github.com/hicann/asc-devkit/blob/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/kernel_direct_call_adaptation.md
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/guide/programming_guide/advanced_programming/super_kernel/kernel_direct_call_adaptation.md

> # 核函数（Kernel）直调算子额外适配说明
>
> 对于使用`<<<>>>`方式开发的Ascend C算子，除了遵循算子适配说明中的通用约束外，还需要在算子核函数（Kernel）入口侧增加SuperKernel入口函数。
>
> >[!NOTE]说明
> >核函数（Kernel）直调算子目前仅支持在npugraph_ex后端进入SuperKernel，不支持GE图模式。
>
> ## SuperKernel与普通核函数（Kernel）的区别
>
> ### 普通核函数（Kernel）入口函数
>
> - 函数签名：`__global__ __vector__ void func(参数列表)`
> - 参数直接作为函数参数传递。
> - 直接调用即可。
>
> ### SuperKernel入口函数
>
> - 函数签名：`__sk__ __vector__ void func(const ArgsStruct *args, sk::SkSystemArgs *sysArgs)`
> - 参数通过结构体指针传递，需要用户定义参数结构体并封装入参。
> - 可选添加`sk::SkSystemArgs *sysArgs`参数，用于获取系统信息（如block num）。
> - 需要与普通核函数（Kernel）通过SK_BIND宏绑定。
>
> ### 规则1：函数签名格式
>
> ```cpp
> __sk__ __vector__ void function_name_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs)
> ```
>
> > **注意**：只有`__sk__`是强约束，必须出现在函数签名中。
>
> ### 规则2：Kernel Type标识与原global函数保持一致
>
> - 如果原global函数使用`__cube__`，则SK子函数也必须使用`__cube__`。
> - 如果原global函数使用`__vector__`，则SK子函数也必须使用`__vector__`。
> - 如果原global函数是`__mix__(c, v)`，则SK子函数也必须使用`__mix__(c, v)`。

```cpp
// 原global函数为cube类型
__global__ __cube__ void func(GM_ADDR x, GM_ADDR y);
// SK子函数也需要cube标识
__sk__ __cube__ void func_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs);

SK_BIND(func, 4, func_sk);

// 原global函数为vector类型
__global__ __vector__ void func_vec(GM_ADDR x, GM_ADDR y);
__sk__ __vector__ void func_vec_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs);

SK_BIND(func_vec, 4, func_vec_sk);

// 原global函数为mix类型
__global__ __mix__(1, 2) void func_mix(GM_ADDR x, GM_ADDR y);
__sk__ __mix__(1, 2) void func_mix_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs);

SK_BIND(func_mix, 4, func_mix_sk);

// 原global函数为mix(1, 0)类型
__global__ __mix__(1, 0) void func_mix_10(GM_ADDR x, GM_ADDR y);
__sk__ __mix__(1, 0) void func_mix_10_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs);

SK_BIND(func_mix_10, 4, func_mix_10_sk);

// 原global函数为mix(0, 1)类型
__global__ __mix__(0, 1) void func_mix_01(GM_ADDR x, GM_ADDR y);
__sk__ __mix__(0, 1) void func_mix_01_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs);

SK_BIND(func_mix_01, 4, func_mix_01_sk);
```

> ### 规则3：定义参数结构体

```cpp
// 示例：假设原global函数为
// __global__ __vector__ void my_kernel(GM_ADDR x, GM_ADDR y, uint32_t length, int16_t flag)
// 则对应的参数结构体定义如下
struct MyArgs {
    GM_ADDR x;                      // 第一个参数
    GM_ADDR y;                      // 第二个参数
    uint32_t length;                // 第三个参数
    alignas(4) int16_t flag;        // 第四个参数（小于4字节，需使用alignas(4)）
};
```

> > **注意**：
> > - 结构体必须根据用户实际算子核函数（Kernel）（global函数）的参数进行定义，不要直接复制示例中的字段名。
> > - 结构体字段必须按原函数参数顺序排列。
> > - 对于size小于4字节的类型（如`int16_t`、`int8_t`、`uint16_t`、`uint8_t`），必须使用`alignas(4)`确保内存对齐（ABI要求）。
>
> ### 规则4：可选添加SkSystemArgs参数

```cpp
// 场景一：算子使用了AscendC::GetBlockNum()，需要添加sysArgs参数
template<uint32_t splitNum>
__sk__ __vector__ void func_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs)
{
    // 从系统参数获取block num（替代AscendC::GetBlockNum()）
    uint32_t blockNum = sysArgs->skNumBlocks;
    // 或者使用接口获取
    uint32_t blockNum = sysArgs->SkGetNumBlocks();
    ...
}
```

> > - 与`AscendC::GetBlockNum()`的逻辑差异是，MIX 1:2场景中，vector核中的`skBlockNum`为`blockNum * 2`。
>
> ### 规则5：使用TPipe场景下，需要手动调用DestroyWithoutPipeAll接口
>
> 为了优化SK函数之间的同步，若使用了TPipe对象，需要在其自然析构之前调用`DestroyWithoutPipeAll()`接口主动销毁TPipe（不调用PipeBarrierAll）。

```cpp
template<uint32_t splitNum>
__sk__ __vector__ void func_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs)
{
    ...
    // 使用TPipe场景
    TPipe pipe;
    ...
    // 手动调用接口销毁TPipe，不依赖默认析构函数
    pipe.DestroyWithoutPipeAll();
}
```

> ### 规则6：逻辑与global函数一致
>
> SK子函数内部的逻辑实现必须与原global函数完全一致，包括数据初始化、计算处理、结果输出等所有后续逻辑。
>
> ### 规则7：使用SK_BIND宏绑定
>
> ```cpp
> SK_BIND(original_func, 4, sk_func<0>, sk_func<1>, sk_func<2>, sk_func<3>);
> ```
>
> | 参数 | 说明 |
> | --- | --- |
> | `original_func` | 原global函数，如果是模板函数需要手动实例化 |
> | `4` | 掩码参数（uint64_t类型），用于配置SuperKernel特性 |
> | `sk_func<0>` ~ `sk_func<3>` | 最多4个SK子函数，如果是模板函数需要手动实例化 |
>
> **掩码参数取值**：
> 1/2/4/8/16分别代表不同bit位上置值的结果，比如8为第4bit置值的结果
>
> | 值 | 含义 |
> | --- | --- |
> | 1 | early start wait flag |
> | 2 | early start set flag |
> | 4 | disable_dcci |
> | 8 | disable_batchmode_check |
> | 16 | blockdim_scale_up |

適配步骤总结, verbatim:

> **步骤1：保留原global函数**
>
> 原有的`__global__ __vector__`函数保持不变，继续用于非SuperKernel场景。
>
> **步骤2：创建SK子函数**
>
> 1. 复制原global函数的代码
> 2. 根据原global函数的实际参数定义参数结构体（对于小于4字节的类型使用`alignas(4)`）
> 3. 修改函数签名为`__sk__ __vector__ void func_sk(const ArgsStruct *args, sk::SkSystemArgs *sysArgs)`（根据原函数的核函数（Kernel）类型添加对应标识）
> 4. 如果算子未使用`AscendC::GetBlockNum()`，可以省略`sk::SkSystemArgs *sysArgs`参数
> 5. 使用模板参数实例化出多个符号（模板参数仅用于实例化出不同的符号，不影响函数逻辑）
> 6. 从结构体中获取参数
> 7. 如果使用了`AscendC::GetBlockNum()`，修改为使用`sysArgs->skNumBlocks`或`sysArgs->SkGetNumBlocks()`
> 8. 使用TPipe场景下，需要手动调用`DestroyWithoutPipeAll`接口销毁TPipe
> 9. 保持函数内部逻辑与原global函数完全一致

> **Q1：为什么要定义参数结构体？**
>
> A：SuperKernel使用结构体传递参数，用户需要根据原global函数的实际参数定义一个结构体来封装所有入参，这样可以实现参数的统一管理和跨split共享。

## Relevance
This is a complete, step-by-step path from our existing `<<<>>>` kernels into SuperKernel on A3, which is the
cheapest route to collapsing 3008 launches without rewriting the kernels themselves. Key facts:
- `__mix__(1, 0)` and `__mix__(0, 1)` exist as kernel qualifiers alongside `__cube__`, `__vector__`, `__mix__(1,2)` —
  the source-level counterparts of `KERNEL_TYPE_MIX_AIC_1_0` / `MIX_AIV_1_0` from section 4.
- Only `__sk__` is a hard requirement in the signature; the kernel-type qualifier must match the original exactly.
- Arguments move from a flat parameter list into a struct passed by pointer, with `alignas(4)` mandatory for any
  sub-4-byte field (ABI). The struct is shared across the up-to-4 instantiated splits ("跨split共享").
- `AscendC::GetBlockNum()` must be replaced by `sysArgs->skNumBlocks` / `sysArgs->SkGetNumBlocks()`, and in MIX 1:2
  the vector core's `skBlockNum` is `blockNum * 2`.
- `TPipe::DestroyWithoutPipeAll()` must be called explicitly, specifically to avoid the `PipeBarrier<PIPE_ALL>` that
  normal destruction would emit between SK sub-functions — the same elision described in section 19.
- GE graph mode is not an option for `<<<>>>` kernels; only the npugraph_ex backend, which matches the
  `enable_npugraph_ex` + `enable_static_kernel` + `enable_super_kernel` triple in section 7.

---

## 22. TorchAir SuperKernel reference: scope semantics and the complete option tables

### `docs/zh/npugraph_ex/advanced/superkernel.md` — SuperKernel融合优化功能

https://gitcode.com/Ascend/torchair/blob/master/docs/zh/npugraph_ex/advanced/superkernel.md
raw: https://raw.gitcode.com/Ascend/torchair/raw/master/docs/zh/npugraph_ex/advanced/superkernel.md
Repo `Ascend/torchair` on GitCode, branch `master`.

> ## 功能简介
>
> SuperKernel是一种算子二进制融合技术。与源码融合不同，它聚焦于内核函数（Kernel）的二进制调度方案优化，在已编译的二进制代码基础上融合创建一个超级Kernel函数（简称SuperKernel），以子函数调用的方式整合多个内核函数，从而优化计算任务、提升性能和资源利用率。
>
> 与单算子下发相比，SuperKernel技术能够优化任务调度的等待时间和调度开销，并可利用Task间隙资源进一步优化算子头开销。
>
> SuperKernel的实现原理如下：
>
> 基于aclgraph捕获后的Model，SuperKernel模块识别可被融合的连续Task，将其合并为一个SuperKernel Task并替换原有Task，通过Runtime接口更新Model后基于新Model执行。
>
> ## 使用约束
>
> - 本功能支持如下产品：
>
>   - Atlas A3 训练系列产品/Atlas A3 推理系列产品
>   - Atlas A2 训练系列产品/Atlas A2 推理系列产品
>   - Ascend 950PR/Ascend 950DT，该型号下SuperKernel特性是试验特性
>
> - 需要注意的是，SuperKernel融合会按照网络中算子的顺序依次判断是否可被融合。当**识别到不可融合的算子时**，系统会生成第一段SuperKernel，并自动跳过该算子进行第二段SuperKernel融合。
> - 目前支持SuperKernel融合的通信类算子包括AllReduce、ReduceScatter、AllGather、AlltoAll。
> - 开启SuperKernel融合优化时，需要同时开启静态Kernel编译功能。
>
>   >[!NOTE]说明
>   >同一进程内存在多个Model时，若不同Model中存在输入输出Shape完全相同的算子，但SuperKernel相关选项配置不一致，后续相同Shape算子可能复用前一次静态Kernel编译产物，导致SuperKernel融合不符合预期。建议这些Model保持配置一致，或仅在需要SuperKernel的Model上开启静态Kernel编译。
>
> - 开启SuperKernel融合优化后，算子Data Dump功能将会失效。

Scope marking, verbatim:

```python
torch.npu.super_kernel_scope_begin(scope_name: str)
待融合的算子操作
torch.npu.super_kernel_scope_end(scope_name: str)
```

> scope_name：表示该范围内算子融合后的SuperKernel名称，相同的scope\_name代表相同的融合范围，由用户控制。若传入None，则该范围内的算子不进行SuperKernel融合。
>
> >[!NOTE]说明
> >- scope_name名称不超过255字节。
> >- 全局支持的scope_name（不同）数量不超过1024个。
> >- 标定范围不代表SuperKernel的融合结果。
>
> 当多个标定范围有交集时，按照标记集对算子进行划分。当交集不为子集时，op1和op2的标记集是{sk1}，归入一组；op3和op4的标记集是{sk1，sk2}，归入一组；op5、op6和op7的标记集是{sk2}，归入一组。op8、op9没有被标记，不进行融合。
>
> 当交集为子集时，嵌套范围内的算子会同时带有外层和内层scope标记。
>
> 当传入的标记为None，则被框定范围内的算子不进行融合，且该类型的标记具备最高优先级。
>
> 当全局只存在为None的标记时，未被标记的算子都将进入SuperKernel的融合流程。

```python
import torch
import torch_npu

opt_model = torch.compile(model, backend="npugraph_ex", options={"static_kernel_compile": True, "super_kernel_optimize": True, "super_kernel_optimize_options": dict, "super_kernel_debug_options": dict}, dynamic=False, fullgraph=True)
```

> **表 1**  参数说明
>
> |**参数名**|**参数说明**|
> |--|--|
> |super_kernel_optimize|布尔类型，是否开启SuperKernel融合优化。<br>•False（默认值）：默认关闭。<br>•True：开启SuperKernel融合优化。|
> |super_kernel_optimize_options|字典类型，SuperKernel融合优化参数。|
> |super_kernel_debug_options|字典类型，SuperKernel融合调试参数。<br>**说明：super_kernel_debug_options中的选项均会影响SuperKernel融合效果或运行性能，建议仅在功能调试时使用。**|

表 2 `super_kernel_optimize_options`, verbatim:

> |**参数名**|**参数说明**|
> |--|--|
> |dcci_before_kernel_start|通过本选项指定的算子，其内部调用GlobalTensor的GetValue/SetValue时不会自动插入缓存刷新指令，**而在SuperKernel调用该算子前**，会插入DataCacheCleanAndInvalid指令刷新ENTIRE_DATA_CACHE。<br>•当dcci_before_kernel_start、dcci_after_kernel_end和dcci_disable_on_kernel均未配置时，子算子内部调用GlobalTensor的GetValue/SetValue时默认不自动插入缓存刷新指令，SuperKernel默认会在所有子算子调用后插入DataCacheCleanAndInvalid指令刷新ENTIRE_DATA_CACHE。<br>•配置格式形如：`{"dcci_before_kernel_start": [".*op1_type.*", ".*op2_type.*"]}`。仅支持匹配算子符号名而不是op_type，算子符号名为xx_op_type_xxx，带有前缀及后缀，仅支持`.*`格式的正则表达。<br>•若本选项指定的算子为<<<>>>算子或通信类算子，将无法去除算子内部调用GlobalTensor的GetValue/SetValue时插入的缓存刷新指令，仅支持控制SuperKernel调用算子前是否插入。<br>•本选项指定的算子op_type可通过Profiling查看，例如：`{"dcci_before_kernel_start": [".*GroupedMatmul.*", ".*MoeGatingTopK.*"]}`。|
> |dcci_after_kernel_end|通过本选项指定的算子，其内部调用GlobalTensor的GetValue/SetValue时不会自动插入缓存刷新指令，**而在SuperKernel调用该算子后**，会插入DataCacheCleanAndInvalid指令刷新ENTIRE_DATA_CACHE。<br>•配置格式形如：`{"dcci_after_kernel_end": [".*op1_type.*", ".*op2_type.*"]}`。|
> |dcci_disable_on_kernel|通过本选项指定的算子，其内部调用GlobalTensor的GetValue/SetValue会默认自动插入缓存刷新指令，**而在SuperKernel调用该算子前后**，不会插入任何DataCacheCleanAndInvalid指令。<br>•当某个算子同时配置了dcci_disable_on_kernel及dcci_before_kernel_start、dcci_after_kernel_end时，dcci_disable_on_kernel优先级低于其余两者，其余两者的功能将生效。|
> |ubuf_lock_ignore_kernel|通过本选项声明指定算子不依赖UB Buffer的加锁、解锁机制保证数据访问顺序，自动优化融合策略。<br>•仅在Ascend 950PR/Ascend 950DT上生效。默认值为空列表。|
> |auto_op_parallel|多流融合场景下，SuperKernel默认按照算子下发顺序执行，相比单算子执行，可能无法达到最大化算子并行度。配置该选项后，在确保算子间依赖关系不变的前提下，可以将多条流上的算子按照Cube/Vector类型并行排布，获得相对较优的算子执行流水。<br>•0（默认值）：不使能多流自动Cube/Vector自动并行排布。<br>•1：使能多流自动Cube/Vector自动并行排布。|
> |early_start|配置是否启用SuperKernel Early-Start优化。<br>•0：关闭本功能（默认值）。<br>•1：开启本功能。<br>开启后，SuperKernel会识别并生效算子内适配的AscendC::SetNextTaskStart()/AscendC::WaitPreTaskEnd()任务间同步接口，达到算子头部Scalar指令提前执行的优化效果。|
> |aggressive_opt_strategies|字典类型，为保证功能正确性，SuperKernel默认采用保守融合策略，通过本选项可按需开启激进融合策略，实现更深度的优化。配置格式形如：`{"aggressive_opt_strategies": {"task_breaker_bypass": 0, "value_breaker_bypass": 0b00}}`，各子项说明如下：<br>1. task_breaker_bypass：<br>•0（默认值）：SuperKernel融合过程中，遇到非AICore类型Task（如AICPU算子）会自动断开；<br>•1：SuperKernel融合范围内遇到了非AICore类型Task，且该流范围内没有其他AICore算子，则不做断开处理，仅将非AICore算子从融合范围内剔除。<br>2. value_breaker_bypass，比特位组合控制ValueWait节点的融合策略，各比特位含义如下：<br>•bit0（0b01）：已配对的ValueWait节点（存在对应的ValueWrite节点且满足Flag匹配规则），在通过死锁检测后可进行融合。<br>•bit1（0b10）：未配对的ValueWait节点（不存在对应的ValueWrite节点），允许进行融合。<br>取值示例：<br>•0b00（默认值）：ValueWait节点不进行融合；<br>•0b01：仅允许已配对的ValueWait节点融合；<br>•0b10：仅允许未配对的ValueWait节点融合；<br>•0b11：同时允许已配对和未配对的ValueWait节点融合。<br>说明：若ValueWait节点被多个ValueWrite匹配，则将会触发SuperKernel报错，整体网络融合失败。|

表 3 `super_kernel_debug_options`, verbatim:

> |**参数名**|**参数说明**|
> |--|--|
> |debug_sync_all|配置本选项后，SuperKernel内每个算子间会自动插入SyncAll全核同步指令，可辅助定界SuperKernel机制中的算子间同步问题。<br>•0：关闭本功能（默认值），SuperKernel子算子调用后不插入SyncAll全核同步。<br>•1：开启本功能。|
> |debug_op_exec_trace|配置本选项后，启用算子执行轨迹追踪功能。该功能会在Kernel侧记录每个子算子的执行状态（包括SK入口启动、子算子启动、子算子完成、SK入口完成），在异常发生时会在plog中打印所有核的算子执行进度信息（含当前执行到的算子ID及符号信息），辅助定位算子级执行异常。|
> |debug_cross_core_sync_check|配置本选项后，启用子算子Cube&Vector核间同步（参见CrossCoreSetFlag接口mode 2介绍）校验功能，检测同步数量不匹配的问题。开启本功能时会隐式启用debug_op_exec_trace选项，用于辅助定位出错子算子。|
> |debug_per_op_max_core_num|配置本选项后，启用单算子满核验证模式，用于在SuperKernel融合场景下单独验证每个算子在满核条件下的功能正确性。开启后，融合范围内的每个算子将独立成为一个SuperKernel，并以设备最大核数启动运行（Cube&Vector均启动最大核数），从而覆盖核数相关的边界场景。开启本功能时会隐式启用debug_cross_core_sync_check选项。|

Working example, verbatim:

```python
import torch
import torch_npu

torch.random.manual_seed(42)


# 定义模型model
class Model(torch.nn.Module):
    def __init__(self, top_k):
        super().__init__()
        self.top_k = top_k

    def forward(self, gating_input, smooth_scales):
        moe_gating_res = torch_npu.npu_moe_gating_top_k_softmax(
            gating_input, None, self.top_k
        )
        dynamic_quant_res = torch_npu.npu_dynamic_quant(
            moe_gating_res[0], smooth_scales=smooth_scales
        )
        return dynamic_quant_res


if __name__ == "__main__":
    token_num = 864
    expert_num = 2048
    top_k = 1024
    gating_input = torch.randn((token_num, expert_num), dtype=torch.bfloat16, device="npu")
    smooth_scales = torch.randn((top_k,), dtype=torch.bfloat16, device="npu")

    # 使用图模式后端编译并优化模型
    print("--------------------\t[SuperKernel][compile and optimize]\t--------------------")
    model_sk = torch.compile(Model(top_k), backend="npugraph_ex",
        options={
            "static_kernel_compile": True,
            "super_kernel_optimize": True, # 使能SuperKernel融合优化
        }
    )
    res_sk = model_sk(gating_input, smooth_scales)
```

### `docs/zh/ascend_ir/features/advanced/super_kernel_scope.md` — the GE-graph-mode options

https://gitcode.com/Ascend/torchair/blob/master/docs/zh/ascend_ir/features/advanced/super_kernel_scope.md
raw: https://raw.gitcode.com/Ascend/torchair/raw/master/docs/zh/ascend_ir/features/advanced/super_kernel_scope.md

> 实现SuperKernel的原理如下：
>
> 1. 通过SuperKernel融合策略识别可被融合的子图。
> 2. 将子图内的算子按SuperKernel融合规则合并为一个大Kernel，在新Kernel内通过生成一段子Kernel调用代码将子图上所有Kernel入口函数完成一次调用，并基于图的依赖完成同步插入。
>
> ## 使用约束
>
> - 本功能仅适用于GE图模式场景，并且需要在静态图场景下使用。
> - 本功能支持如下产品：
>     - Atlas A5 训练系列产品/Atlas A5 推理系列产品
>     - Atlas A3 训练系列产品/Atlas A3 推理系列产品
>     - Atlas A2 训练系列产品/Atlas A2 推理系列产品

```python
with torchair.scope.super_kernel(scope: str, options: str = ''):
```

> - scope：表示上下文算子被融合的SuperKernel名，相同的scope代表相同的范围，由用户控制。若传入None，表示该范围内的算子不进行SuperKernel融合。
> - options：表示融合SuperKernel的编译选项...同时支持用户自定义组合编译选项，配置格式形如"<option1\>=<value1\>:<option2\>=<value2\>:<option3\>=......"，多个选项时用英文冒号分割。

表 1 编译选项说明, verbatim (the three most load-bearing for us):

> |选项参数|说明|
> |--|--|
> |feed-sync-all|当子算子启动核数小于SuperKernel启动核数且使用了SyncAll全核同步指令，若出现算子执行卡住或超时，可尝试配置本选项解决此问题。<br>0：关闭本功能（默认值），若子算子使用SyncAll全核同步指令，用户需自行保证子算子与SuperKernel启动核数相同。<br>1：开启本功能，系统自动识别SuperKernel内算子是否调用SyncAll全核同步指令，同时判断子算子启动核数是否小于SuperKernel启动核数。若小于SuperKernel启动核数，会在SuperKernel内子算子的其余核中插入SyncAll指令，保证与子算子内调用SyncAll次数匹配，防止卡住超时。<br>SuperKernel启动核数为子算子的最大启动核数。假设SuperKernel包括算子a（启动核数为4）和算子b（启动核数为2），此时SuperKernel启动核数为4。<br>启动核数可通过Profiling采集的性能数据获取，即"kernel_details.csv"文件中"Block Dim"字段<br>子算子启动核数：非SuperKernel场景下开启Profiling，"Block Dim"字段表示每个算子的启动核数。<br>SuperKernel启动核数：SuperKernel场景下开启Profiling，"Block Dim"字段表示SuperKernel的启动核数。|
> |stream-fusion|控制SuperKernel内是否启用多流融合，从而提升算子运行效率，选项取值如下：<br>0（默认值）：关闭多流融合。当标定范围内存在算子分布在多条流上的场景时，将触发编译报错，无法完成融合。<br>1：启用多流融合，表示SuperKernel融合范围的算子可分布在多条流上。<br>多流融合的收益来自减少各流上算子的调度开销，而非增加并行度，融合前后跨流并行能力不变。SuperKernel内部因同步约束可能引入串行化，实际收益取决于算子排布，通常Cube算子和Vector算子多流并行融合可以获得较好收益。|
> |strict-scope-check|本选项用于检查SuperKernel融合的范围是否符合预期。对于断开的SuperKernel、不支持融合的算子可通过本功能查询：<br>bypass：打印C++侧Warning级别日志，忽略该范围的SuperKernel生成。<br>abort：打印C++侧Error级别日志，对该范围的SuperKernel直接报错退出。<br>Warning或Error级别日志信息可在plog文件（文件名为plog-*pid_**.log）中查看，搜索关键字"super_kernel_scope"即可。<br>本功能暂不支持检查SuperKernel融合范围内的集合通信算子，如AllGather、AlltoAll等。|
> |dcci-before-kernel-start|通过本选项指定的算子，其内部调用GlobalTensor的GetValue/SetValue时不会自动插入缓存刷新指令，**而在SuperKernel调用该算子前**会插入DataCacheCleanAndInvalid指令，刷新整个DCache（数据缓存）...配置格式形如：dcci-before-kernel-start=<op1_type>,<op2_type>...若本选项指定的算子为支持Tiling下沉的算子或通信类算子，功能将不生效。...本选项指定的算子op_type可通过Profiling查看，例如：dcci-before-kernel-start=GroupedMatmul,MoeGatingTopK。|
> |dcci-after-kernel-end|通过本选项指定的算子，其内部调用GlobalTensor的GetValue/SetValue时不会自动插入缓存刷新指令，**而在SuperKernel调用该算子后**，会插入DataCacheCleanAndInvalid指令，刷新整个DCache（数据缓存），保证该算子内的数据缓存不会影响后续的算子。<br>配置格式形如：dcci-after-kernel-end=<op1_type>,<op2_type>。<br>其他要求与dcci-before-kernel-start一样。|

## Relevance
Operationally decisive for us.
- The fusion algorithm is a **linear scan with hard breaks**: 「SuperKernel融合会按照网络中算子的顺序依次判断是否可被
  融合。当识别到不可融合的算子时，系统会生成第一段SuperKernel，并自动跳过该算子进行第二段SuperKernel融合」. With 3008 kernels
  per round, the practical question is not "does it fuse" but "how many breaks", and `strict-scope-check=abort` /
  `bypass` plus the plog keyword `super_kernel_scope` is the way to enumerate them. By default a non-AICore task
  (e.g. an AICPU operator) **breaks** fusion; `task_breaker_bypass = 1` relaxes that.
- `early_start = 1` is the switch that activates the `SetNextTaskStart` / `WaitPreTaskEnd` pair, and the stated
  benefit is literally 「算子头部Scalar指令提前执行」 — early execution of the operator's head Scalar instructions. That
  is the same "operator-head overhead" the Matmul static-tiling case study in section 12 measured at ~4 us per call.
- `auto_op_parallel = 1` reorders multi-stream operators by Cube/Vector type inside the SuperKernel; `stream-fusion`
  in GE mode notes the benefit is 「减少各流上算子的调度开销，而非增加并行度」 and that Cube+Vector cross-stream fusion
  usually pays best.
- `feed-sync-all = 1` auto-pads `SyncAll` on the extra cores when a sub-kernel's blockDim is smaller than the
  SuperKernel's — the fix for the hang described in section 19's 全核同步约束.
- Two costs to plan for: SuperKernel **disables operator Data Dump**, and SuperKernel options participate in the
  static-kernel compilation cache key, so mismatched options across models in one process can silently reuse the
  wrong binary.
- Collective ops that can be fused are exactly `AllReduce, ReduceScatter, AllGather, AlltoAll` — relevant to our
  TP16 decode round, where the per-layer allreduce would otherwise break every fusion segment.
- Debug levers worth knowing: `debug_op_exec_trace` logs SK-entry/sub-kernel start/finish per core to plog,
  `debug_cross_core_sync_check` validates mode-2 Cube/Vector sync counts, and `debug_per_op_max_core_num` isolates
  each operator into its own SuperKernel at full core count.

---

## 23. `TPipe` / `TQueBind` / `TQue` / `TBuf` — the declared API surface, verbatim from the header

https://gitcode.com/cann/asc-devkit/blob/master/include/basic_api/kernel_tpipe.h
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/include/basic_api/kernel_tpipe.h
Repo `cann/asc-devkit`, branch `master`.

```cpp
template <TPosition src, TPosition dst, int32_t depth, auto mask = 0>
class TQueBind {
public:
    __aicore__ inline TQueBind();
    __aicore__ inline void FreeBuffer(TBufHandle buf);
    __aicore__ inline TBuffAddr GetBufferAddr(TBufHandle buf);
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
    template <typename T>
    __aicore__ inline __sync_noalias__ LocalTensor<T> AllocTensor();
    template <typename T>
    __aicore__ inline __sync_noalias__ void AllocTensor(LocalTensor<T>& tensor);
#else
    template <typename T>
    __aicore__ inline __sync_alias__ LocalTensor<T> AllocTensor();
    template <typename T>
    __aicore__ inline __sync_alias__ void AllocTensor(LocalTensor<T>& tensor);
#endif
    template <typename T>
    __aicore__ inline void FreeTensor(LocalTensor<T>& tensor);
    template <typename T>
    __aicore__ inline bool EnQue(const LocalTensor<T>& tensor);
    __aicore__ inline bool EnQue(TBufHandle buf);
    template <TPosition srcUserPos, TPosition dstUserPos, typename T>
    __aicore__ inline bool EnQue(const LocalTensor<T>& tensor);
    template <typename T>
    __aicore__ inline void DeQue(LocalTensor<T>& tensor);
    template <typename T>
    __aicore__ inline LocalTensor<T> DeQue();
    __aicore__ inline TBufHandle DeQue();
    template <TPosition srcUserPos, TPosition dstUserPos, typename T>
    __aicore__ inline LocalTensor<T> DeQue();
    __aicore__ inline bool VacantInQue();
    __aicore__ inline bool HasTensorInQue();
    __aicore__ inline int32_t GetTensorCountInQue();
    __aicore__ inline bool HasIdleBuffer();
    __aicore__ inline void FreeAllEvent();
    template <typename T>
    __aicore__ inline TBufState GetState(const LocalTensor<T>& tensor) const;
    __aicore__ inline void InitStartBufHandle(TBufHandle startBufhandle, uint8_t num, uint32_t len);
    template <typename T>
    __aicore__ inline void InitBufHandle(
        T* bufPool, uint32_t index, TBufHandle bufhandle, uint32_t curPoolAddr, uint32_t len);

protected:
    static constexpr TQueConfig config = GetTQueConfig(mask);
    static constexpr bool nd2nz = config.nd2nz;
    static constexpr bool nz2nd = config.nz2nd;
    static constexpr bool scmBlockGroup = config.scmBlockGroup;
    static constexpr bool enableLoopQueue = config.enableLoopQueue;
```

```cpp
template <TPosition pos, int32_t depth, auto mask = 0>
class TQue : public TQueBind<GetBufferLogicPos(pos, true), GetBufferLogicPos(pos, false), depth, mask> {
public:
    __aicore__ inline TQue() = default;
...
};

template <TPosition pos = TPosition::LCM>
class TBuf : public TQueBind<pos, pos, 0, 0> {
public:
    __aicore__ inline TBuf() = default;
    template <typename T>
    __aicore__ inline LocalTensor<T> Get();
    template <typename T>
    __aicore__ inline LocalTensor<T> Get(uint32_t len);
    template <typename T>
    __aicore__ inline LocalTensor<T> GetWithOffset(uint32_t size, uint32_t bufOffset);
    // inheritance function from Class TQueBind
    template <typename T>
    __aicore__ inline void EnQue(const LocalTensor<T>& tensor);
    template <typename T>
    __aicore__ inline LocalTensor<T> DeQue();
    template <typename T>
    __aicore__ inline LocalTensor<T> AllocTensor();
    template <typename T>
    __aicore__ inline void FreeTensor(LocalTensor<T>& tensor);
    template <typename T>
    __aicore__ inline TBufState GetState(const LocalTensor<T>& tensor) const;
    __aicore__ inline bool EnQue(TBufHandle buf);
    __aicore__ inline TBufHandle DeQue();
    __aicore__ inline void FreeBuffer(TBufHandle buf);
    __aicore__ inline TBuffAddr GetBufferAddr(TBufHandle buf);
    __aicore__ inline void InitStartBufHandle(TBufHandle startBufhandle, uint8_t num, uint32_t len);
```

```cpp
class TPipe : public TPipeBase {
public:
#if defined(__NPU_ARCH__)
    __aicore__ inline TPipe();
    __aicore__ inline ~TPipe();
#else
    __aicore__ inline TPipe() {}
    __aicore__ inline ~TPipe() {}
#endif
    __aicore__ inline void Init();
    template <class T>
    __aicore__ inline bool InitBuffer(T& que, uint8_t num, uint32_t len);
    template <class T, class U, class V, class... Addrs>
    __aicore__ inline bool InitBuffer(T& que, const Std::tuple<U, V>& addr0, const Addrs&... addrs);
    template <TPosition pos>
    __aicore__ inline bool InitBuffer(TBuf<pos>& buf, uint32_t len);
    template <class T>
    __aicore__ inline bool InitBufPool(T& bufPool, uint32_t len);
    template <class T, class U>
    __aicore__ inline bool InitBufPool(T& bufPool, uint32_t len, U& shareBuf);
    template <HardEvent evt>
    __aicore__ inline TEventID AllocEventID();
    template <HardEvent evt>
    __aicore__ inline void ReleaseEventID(TEventID id);
    template <HardEvent evt>
    __aicore__ inline TEventID FetchEventID();
    __aicore__ inline TEventID FetchEventID(HardEvent evt);
    // NOTICE: GetAbsAddr has been deprecated and will be removed in the next version. Please do not use it!
    template <TPosition pos, typename T>
    __aicore__ inline LocalTensor<T> GetAbsAddr(int32_t offset, int32_t size) const;
    // NOTICE: GetAbsAddr has been deprecated and will be removed in the next version. Please do not use it!
    template <TPosition pos>
    __aicore__ inline TBuffAddr GetAbsAddr(int32_t offset, int32_t len) const;
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 3510 || __NPU_ARCH__ == 5102 || __NPU_ARCH__ == 5162 || \
                              __NPU_ARCH__ == 9201 || __NPU_ARCH__ == 9202)
    __aicore__ inline MutexID AllocMutexID();
    __aicore__ inline void ReleaseMutexID(MutexID id);
#endif
    /*
     * brief: these functions are used to use spm buffer;
     * demo case:
     * GlobalTensor<T> workTensor;
     * tpipe.InitSpmBuffer(workTensor, size);
     * LocalTensor<T> calcTensor = tpip.Get<T>(size);
     * // when local buffer is not enough, spill local to spm buffer;
     * tpipe.WriteSpmBuffer(calcTensor, size);
     * // ...
     * // read buffer from spm buffer into local
     * tpipe.ReadSpmBuffer(calcTensor, size);
     */
    template <typename T>
    __aicore__ inline void InitSpmBuffer(const GlobalTensor<T>& workspace, const int32_t bufferSize);
    __aicore__ inline void InitSpmBuffer(const int32_t bufferSize);
    template <typename T>
    __aicore__ inline void WriteSpmBuffer(
        const LocalTensor<T>& writeBuffer, const DataCopyParams& copyParams, int32_t writeOffset = 0);
    template <typename T>
    __aicore__ inline void ReadSpmBuffer(
        const LocalTensor<T>& readBuffer, const DataCopyParams& copyParams, int32_t readOffset = 0);
    template <typename T>
    __aicore__ inline void WriteSpmBuffer(
        const LocalTensor<T>& writeBuffer, const int32_t writeSize, int32_t writeOffset = 0);
    template <typename T>
    __aicore__ inline void ReadSpmBuffer(
        const LocalTensor<T>& readBuffer, const int32_t readSize, int32_t readOffset = 0);
    __aicore__ inline void DestroyWithoutPipeAll();
    __aicore__ inline void Destroy();
    __aicore__ inline void Reset();
```

## Relevance
Three things we need are declared here and nowhere in the prose docs.
(1) `DestroyWithoutPipeAll()` is a real `TPipe` member — the SuperKernel rule in section 21 is satisfiable.
(2) `InitBuffer(T& que, const Std::tuple<U, V>& addr0, const Addrs&... addrs)` is the variadic explicit-address
overload that lets a megakernel hand-place each stage's UB region instead of bump-allocating, and `Reset()` is the
documented way to re-partition UB between stages.
(3) `AllocEventID<HardEvent>` / `ReleaseEventID<HardEvent>` / `FetchEventID<HardEvent>` are the sanctioned way to
obtain intra-core event IDs (section 8 warns IDs are finite and that 6 and 7 are reserved).
Also note the `__NPU_ARCH__` guard: `AllocMutexID` / `ReleaseMutexID` exist only on 3510/5102/5162/9201/9202 — **not**
on our 2201 — and `AllocTensor` is `__sync_alias__` on 2201 versus `__sync_noalias__` on 3510, i.e. the compiler
assumes aliasing between queue buffers on A3 and inserts conservative sync that it skips on A5.
`InitSpmBuffer` / `WriteSpmBuffer` / `ReadSpmBuffer` give a documented UB-spill-to-GM mechanism ("when local buffer is
not enough, spill local to spm buffer") that a multi-stage megakernel can use when 192 KiB of UB is not enough.

---

## 24. `Mmad` / `MmadParams` and the `GET_TILING_DATA` family

### `Mmad` — the raw cube instruction wrapper

https://github.com/hicann/asc-devkit/blob/master/include/basic_api/kernel_operator_mm_intf.h
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/include/basic_api/kernel_operator_mm_intf.h

```cpp
/* **************************************************************************************************
 * Mmad                                             *
 * ************************************************************************************************* */
/*
 * @ingroup Mmad
 * @brief Matrix multiplication and addition
 * @param [out] dst output LocalTensor
 * @param [in] fm input LocalTensor
 * @param [in] filter input LocalTensor
 * @param [in] mmadParams.m Left matrix row number
 * @param [in] mmadParams.n right matrix column number
 * @param [in] mmadParams.k Left matrix column number m
 * @param [in] mmadParams.unitFlag whether enable unit flag
 * @param [in] mmadParams.kDirectionAlign is the indicator for alignment in L0A/L0B in the K direction
 * @param [in] mmadParams.cmatrixSource indicates the C matrix source, 1: the C matrix is in bias table buffer, 0: the C
 * matrix is in L0C
 * @param [in] mmadParams.cmatrixInitVal indicates the initial matrix, 1: the number in C matrix is 0, 0：use the real
 * number in C matrix
 */

template <typename T, typename U, typename S>
__aicore__ inline void Mmad(
    const LocalTensor<T>& dst, const LocalTensor<U>& fm, const LocalTensor<S>& filter, const MmadParams& mmadParams);

template <typename T, typename U, typename S, typename V>
__aicore__ inline void Mmad(
    const LocalTensor<T>& dst, const LocalTensor<U>& fm, const LocalTensor<S>& filter, const LocalTensor<V>& bias,
    const MmadParams& mmadParams);

#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
template <typename T, typename U, typename S>
__aicore__ inline void Mmad(
    const LocalTensor<T>& dst, const LocalTensor<U>& fm, const LocalTensor<S>& filter,
    const MmadBitModeParams& mmadParams);

template <typename T, typename U, typename S, typename V>
__aicore__ inline void Mmad(
    const LocalTensor<T>& dst, const LocalTensor<U>& fm, const LocalTensor<S>& filter, const LocalTensor<V>& bias,
    const MmadBitModeParams& mmadParams);
#endif
```

Also declared in the same header: `MmadMx` ("Matrix multiplication and addition in microscaling scenario") and
`MmadWithSparse`:

```cpp
template <
    typename T = int32_t, typename U = int8_t,
    typename Std::enable_if<Std::is_same<PrimT<T>, int32_t>::value, bool>::type = true,
    typename Std::enable_if<Std::is_same<PrimT<U>, int8_t>::value, bool>::type = true>
__aicore__ inline void MmadWithSparse(
    const LocalTensor<T>& dst, const LocalTensor<U>& fm, const LocalTensor<U>& filter, const MmadParams& mmadParams);
```

### `MmadParams`

https://github.com/hicann/asc-devkit/blob/master/include/basic_api/kernel_struct_mm.h
raw: https://raw.githubusercontent.com/hicann/asc-devkit/master/include/basic_api/kernel_struct_mm.h

```cpp
struct MmadParams {
    __aicore__ MmadParams() {}

    __aicore__ MmadParams(
        const uint16_t mIn, const uint16_t nIn, const uint16_t kIn, const bool isBiasIn, const int32_t fmOffsetIn,
        const bool enSsparseIn, const bool enWinogradAIn, const bool enWinogradBIn)
        : m(mIn), n(nIn), k(kIn), isBias(isBiasIn), fmOffset(fmOffsetIn), enSsparse(enSsparseIn),
          enWinogradA(enWinogradAIn), enWinogradB(enWinogradBIn)
    {}

    __aicore__ MmadParams(
        const uint16_t mIn, const uint16_t nIn, const uint16_t kIn, const uint8_t unitFlagIn,
        const bool cmatrixSourceIn, const bool cmatrixInitValIn)
        : m(mIn), n(nIn), k(kIn), unitFlag(unitFlagIn), cmatrixSource(cmatrixSourceIn), cmatrixInitVal(cmatrixInitValIn)
    {}

    uint16_t m = 0;
    uint16_t n = 0;
    uint16_t k = 0;
    // Indicates whether to accumulate the initial matrix, 0: matrix multiplication, 1: matrix multiplication and
    // addition
    bool isBias = false;
    // Left matrix offset
    int32_t fmOffset = 0;
    // Enable the structured sparse feature, default value is false
    bool enSsparse = false;
    // Indicates whether matrix a is generated by winograd_feature_map_transform, default value is false;
    bool enWinogradA = false;
    // Indicates whether matrix b is generated by winograd_feature_map_transform, default value is false;
    bool enWinogradB = false;
    uint8_t unitFlag = 0;
    // also mean gemvCtrl in 3101 and 5102
    bool kDirectionAlign = false;
    // Indicates the C matrix source, 1: the C matrix is in bias table buffer, 0: the C matrix is in L0C
    bool cmatrixSource = false;
    // Indicates the initial matrix, 1: the number in C matrix is 0, 0：use the real number in C matrix
    bool cmatrixInitVal = true;
#if defined(__NPU_ARCH__) && \
    ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
    bool disableGemv = false;
#endif
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 9201 || __NPU_ARCH__ == 9202)
    bool hif4Amode = false;
    bool hif4Bmode = false;
    bool cScaleCtrl = false;
#endif
#ifdef CANN_ASC_ENABLE_FIX_SHIFT
    uint8_t fixShiftVal = 0;
#endif
};
```

### `GET_TILING_DATA_WITH_STRUCT`

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0215.html

> 功能说明
>
> 使用该接口指定结构体名称，可获取指定的tiling信息，并填入对应的Tiling结构体中，此函数会以宏展开的方式进行编译。与GET_TILING_DATA的区别是：GET_TILING_DATA只能获取默认注册的结构体，该接口可以根据指定的结构体名称获取对应的结构体，常用于针对不同的TilingKey注册了不同结构体的情况下。
>
> 函数原型
>
> ```
> GET_TILING_DATA_WITH_STRUCT(struct_name, tiling_data, tiling_arg)
> ```
>
> | 参数 | 输入/输出 | 说明 |
> |---|---|---|
> | struct_name | 输入 | 指定的结构体名称。 |
> | tiling_data | 输出 | 返回指定Tiling结构体变量。 |
> | tiling_arg | 输入 | 此参数为算子入口函数处传入的tiling参数。 |
>
> 约束说明
>
> 本函数需在算子Kernel代码处使用，并且传入的tiling_data参数不需要声明类型。
>
> 暂不支持Kernel直调工程。

```cpp
extern "C" __global__ __aicore__ void add_custom(__gm__ uint8_t *x, __gm__ uint8_t *y, __gm__ uint8_t *z, __gm__ uint8_t *tiling)
{
    KernelAdd op;
    if (TILING_KEY_IS(1)) {
        GET_TILING_DATA_WITH_STRUCT(Add_Struct_Special, tilingData, tiling); // 使用算子指定注册的结构体
        op.Init(x, y, z, tilingData.totalLengthSpecial, tilingData.tileNumSpecial);
    } else {
        GET_TILING_DATA(tilingData, tiling);   // 使用算子默认注册的结构体
        op.Init(x, y, z, tilingData.totalLength, tilingData.tileNum);
    }
    if (TILING_KEY_IS(1)) {
        op.Process();
```

### `GET_TILING_DATA_MEMBER`

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0216.html

> 功能说明: 用于获取tiling结构体的成员变量。
>
> ```
> GET_TILING_DATA_MEMBER(struct_name, mem_name, tiling_data, tiling_arg)
> ```
>
> | 参数 | 输入/输出 | 说明 |
> |---|---|---|
> | struct_name | 输入 | 指定的结构体名称。 |
> | mem_name | 输入 | 指定的成员变量名称。 |
> | tiling_data | 输出 | 返回指定Tiling结构体的成员变量。 |
> | tiling_arg | 输入 | 此参数为算子入口函数处传入的tiling参数。 |
>
> 约束说明
>
> 本函数需在算子kernel代码处使用，并且传入的tiling_data参数不需要声明类型。
>
> 暂不支持Kernel直调工程。

Both macros: 产品支持情况 lists `Atlas A3 训练系列产品/Atlas A3 推理系列产品 √`, `Atlas A2 ... √`,
`Atlas 200I/500 A2 推理产品 √`, `Atlas 推理系列产品AI Core √`, `Atlas 推理系列产品Vector Core √`, `Atlas 训练系列产品 x`.

## Relevance
`MmadParams.unitFlag` is the field behind `mmCFG.enUnitFlag = true` from section 15 (512-byte MMAD/FixPipe overlap),
and `cmatrixInitVal` is what lets consecutive `Mmad` calls accumulate into the same L0C tile instead of zeroing it —
the low-level mechanism under the `TPosition::CO1` accumulation pattern in section 11. `isBias` toggles
multiply vs multiply-accumulate; `cmatrixSource` selects bias-table vs L0C as the C source. `MmadWithSparse`
(int8 only, `int32_t` dst) and `enSsparse` expose structured sparsity. Note `disableGemv` and the `hif4*` / `cScaleCtrl`
fields are gated off 2201, so they are unavailable to us.
Both `GET_TILING_DATA_WITH_STRUCT` and `GET_TILING_DATA_MEMBER` are explicitly **暂不支持Kernel直调工程** — not
supported in kernel-direct-launch projects. Since the `__sk__`/`SK_BIND` SuperKernel path in section 21 *is* the
kernel-direct-launch path, a megakernel on that route cannot use the tiling-struct macros and must pass its
parameters through the `SK_BIND` args struct instead. That is consistent with section 12's 全量常量化 advice: make
the tiling compile-time constant and pass a null tiling pointer.

---

## 25. `__schedmode__` / batch scheduling in a production kernel, with measured hang rate

### `hicann/ops-nn` `rnn/lstm_block_cell/op_kernel/arch35/sync_helper.h`

https://github.com/hicann/ops-nn/blob/master/rnn/lstm_block_cell/op_kernel/arch35/sync_helper.h
raw: https://raw.githubusercontent.com/hicann/ops-nn/master/rnn/lstm_block_cell/op_kernel/arch35/sync_helper.h
Repo `hicann/ops-nn`, branch `master`. Copyright (c) 2026 Huawei Technologies Co., Ltd.
Header comment says "Generated By CANNBot". **This file targets Ascend 950PR (dav_3510), not A3** — the mode-4
specifics below do not apply on 2201 (see section 20), but the `__schedmode__` discussion and the pairing discipline do.

```cpp
/* sync_helper.h -- ALL synchronization for the raw Ascend 950PR (dav_3510) kernels, in one place.
 *
 * WHY THIS IS ITS OWN HEADER, against the "split by who issues it" rule the other headers follow:
 *
 *   A HANDSHAKE IS A PROTOCOL, AND A PROTOCOL HAS TWO ENDS. The thing that goes wrong is not one
 *   side or the other -- it is the PAIRING. A dedicated cross-core measurement pins the pairing rule, because the three
 * plausible pairings do not all work (1 set : 1 consume deadlocks, 2 : 2 deadlocks, 2 : 1 runs). Putting the two ends
 * in two different files would separate exactly the thing that must be read together.
 *
 * So cube_helper.h and vec_helper.h are pure dataflow, and every ordering question lives here.
 *
 * TWO KINDS OF ORDERING, DO NOT CONFUSE THEM
 *   intra-core   between PIPES of one core (MTE2 / MTE1 / M / FIX / V / MTE3). Set+Wait on a
 *                typed HardEvent. Cheap, and purely local.
 *   cross-core   between the AIC and its two AIVs. CrossCoreSetFlag / CrossCoreWaitFlag.
 *                Semantics differ BY DIRECTION -- see below, this is the part that bites.
 */
```

The `__schedmode__` comment block, verbatim — **with a measured hang rate**:

```cpp
/* ---------------------------------------------------------------------------------------------
 * BATCH SCHEDULING (`__schedmode__` / `SetScheduleMode`) -- WHAT IT IS, AND WHY IT MATTERS
 *
 * A cross-core wait only holds if the AIC and its two AIVs are dispatched as a BATCH:
 * without batch scheduling the wait can be posted with nobody to answer it. A reference
 * recurrent-operator probe measured 3 hangs in 49 runs (~6%) without it, 0 in 240 with --
 * concentrated on SMALL shapes, where both AIVs reach the barrier at nearly the same moment.
 *
 * TWO SEPARATE LEVERS, AND ONLY ONE OF THEM EXISTS ON EACH PATH:
 *   op framework   `gert::TilingContext::SetScheduleMode(uint32_t)` -- an OUTPUT SLOT of
 *                  tiling, so it only exists when tiling runs. This kernel's TilingFunc
 *                  sets it (batch scheduling: AIC + 2 AIV dispatched together).
 *   raw <<<>>>     `__schedmode__(N)` -- there is no TilingContext on a raw launch, so
 *                  this attribute is the only lever there.
 * ------------------------------------------------------------------------------------------- */
```

Intra-core helpers, verbatim:

```cpp
/* ---------------------------------------------------------------------------------------------
 * Intra-core: order one pipe against another, within a single core.
 *
 * Each is a Set immediately followed by a Wait on the same event id -- a full stop rather than
 * true overlap. That is deliberate: correctness first, and the pipe pair stays legible at the
 * call site. Software-pipelining these (Set early, Wait late, multiple event ids) is a later
 * optimisation, not a cleanup.
 * ------------------------------------------------------------------------------------------- */
template <AscendC::HardEvent E>
__aicore__ inline void PipeWait(event_t id = EVENT_ID0)
{
    AscendC::SetFlag<E>(id);
    AscendC::WaitFlag<E>(id);
}

__aicore__ inline void WaitMte2ToMte1() { PipeWait<AscendC::HardEvent::MTE2_MTE1>(); } // GM->L1 before L1->L0
__aicore__ inline void WaitMte1ToM() { PipeWait<AscendC::HardEvent::MTE1_M>(); }       // L1->L0/BT before Mmad
__aicore__ inline void WaitMToFix() { PipeWait<AscendC::HardEvent::M_FIX>(); }         // Mmad before the drain
__aicore__ inline void WaitFixToM() { PipeWait<AscendC::HardEvent::FIX_M>(); }         // drain read before reusing L0C
```

Cross-core discipline, verbatim (dav_3510 / mode 4):

```cpp
/* ---------------------------------------------------------------------------------------------
 * Cross-core. Both ends of each protocol are adjacent ON PURPOSE.
 *
 * (!) MODE 4 (intra-block) IS USED, NOT MODE 0x2. Mode 0x2 leaks across MIX blocks within
 * a group at blockDim > 1, and the "barrier, not counting semaphore" pairing (both AIVs
 * set, cube waits x1) breaks: a flag set by one block's AIV is consumed by another
 * block's AIC, deadlocking the producer. Mode 4 (`set_intra_block` /
 * `wait_intra_block`) is strictly intra-MIX-block (1 AIC + 2 AIV) and is what every
 * vendor MIX-1:2 op uses (quant_batch_matmul_v3, mat_mul_v3 arch35).
 *
 * Mode-4 pairing rules (measured by vendor + confirmed by dav_c310 impl):
 *   set_intra_block from AIC  -> flag visible to BOTH AIVs (subBlock-scoped: AIV0 sees
 *                               flagId, AIV1 sees flagId + INTRA_NUM=16).
 *   set_intra_block from AIV  -> flag visible to AIC only (subBlock-scoped: AIC distinguishes
 *                               AIV0 by flagId and AIV1 by flagId + INTRA_NUM).
 *   wait_intra_block from AIC -> must wait for BOTH AIVs: flagId AND flagId + INTRA_NUM.
 *   wait_intra_block from AIV -> waits for its own flagId (hardware routes by subBlockId).
 *
 * So the AIC sets/waits TWO flags (one per AIV slot), each AIV sets/waits ONE.
 *
 * (!) MODE-4 FLAGS ARE COUNTERS, NOT ONE-SHOT BARRIERS. A set landing while an earlier
 * set on the same id is still unwaited ACCUMULATES -- it is neither lost nor
 * latched-as-edge (proven on real 3510 by count==0 fast paths pre-firing several
 * consumed slots ahead of their waits). The counter reading does NOT relax the
 * cross-launch pairing discipline: a set left unwaited at launch end stays armed
 * into the NEXT launch and makes its wait return early -- every protocol below
 * keeps one set + one wait per flag slot per launch.
 * ------------------------------------------------------------------------------------------- */
constexpr uint16_t INTRA_NUM = 16; // dav_c310 subBlock flag offset (AIV0: 0..15, AIV1: 16..31)
```

```cpp
constexpr uint16_t V2C_PREPASS = 7;

__aicore__ inline void VecSignalPrepass() { AscendC::CrossCoreSetFlag<0x4, PIPE_MTE3>(V2C_PREPASS); }
__aicore__ inline void CubeWaitPrepass()
{
    /* (!) PIPE_MTE2, NOT PIPE_M. This wait guards the
     * bias workspace reads, which are MTE2 copies (GM->L1 CopyInFlat /
     * CopyInNd2Nz inside CubeProjectKS). On PIPE_M it stalled the M pipe and
     * left the MTE2 reads ungated -- the AIC could read the fp32 bias
     * workspace before the AIV pre-pass wrote it. Vendor pattern: wait on the
     * consuming pipe (same rule as every other cross-core wait here). */
    AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE2>(V2C_PREPASS);
    AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE2>(V2C_PREPASS + INTRA_NUM);
    AscendC::PipeBarrier<PIPE_ALL>();
}
```

```cpp
/* ---------------------------------------------------------------------------------------------
 * K-SPLIT PHASE HANDOFF -- the K-split two-phase structure:
 * the AICs write their partials straight to GM (L0C->GM fixpipe), then every
 * AIV waits for its OWN AIC and only then joins the grid-wide
 * AscendC::SyncAll(). The ledger is one set + one wait per flag slot per
 * launch -- no ring, no reuse.
 *
 * (!) WHY THE AIV WAITS ON PIPE_MTE3: SyncAll() on 3510 is an AIV-only ffts
 * barrier whose ARRIVE instruction rides the MTE3 queue (dav_3510
 * kernel_operator_sync_impl.h: ffts_cross_core_sync(PIPE_MTE3, ...)). Enqueuing
 * this wait on the SAME queue makes the arrive queue-ordered behind the
 * own-AIC flag, so the barrier cannot pass while any AIC is still draining
 * (ops-nn kernel_matmul_streamk.h: CrossCoreWaitFlag<MODE_4, PIPE_MTE3> then
 * SyncAll -- the exact vendor form). After SyncAll() returns, EVERY cluster's
 * partials are GM-visible to every AIV.
 * ------------------------------------------------------------------------------------------- */
constexpr uint16_t KS_DONE = 8; // distinct from V2C_PREPASS; 16 logical ids total

/* AIC: my LAST partial drain is on the FIX queue -- this set rides PIPE_FIX,
 * so it is delivered only after every GM write of the phase is complete. */
__aicore__ inline void CubeSignalKsDone()
{
    AscendC::CrossCoreSetFlag<0x4, PIPE_FIX>(KS_DONE);
    AscendC::CrossCoreSetFlag<0x4, PIPE_FIX>(KS_DONE + INTRA_NUM);
}
/* AIV: my AIC's partials are in GM. Call BEFORE AscendC::SyncAll(). */
__aicore__ inline void VecWaitKsDone() { AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE3>(KS_DONE); }
```

## Relevance
First, the number we could not find in the docs: without batch scheduling, a MIX cross-core wait **hangs ~6% of the
time** (3/49 runs), concentrated on small shapes where both AIVs hit the barrier simultaneously, and 0/240 with it.
At batch=1 decode our shapes are the small ones, so `__schedmode__(N)` on a `<<<>>>` megakernel is mandatory, not
advisory. The two levers are mutually exclusive by path: `gert::TilingContext::SetScheduleMode(uint32_t)` only exists
when tiling runs; `__schedmode__(N)` is the only lever for a raw `<<<>>>` launch.
Second, the pairing rule discovered empirically — 「1 set : 1 consume deadlocks, 2 : 2 deadlocks, 2 : 1 runs」 — and the
named failure mode of mode 0x2 at `blockDim > 1`: 「Mode 0x2 leaks across MIX blocks within a group... a flag set by
one block's AIV is consumed by another block's AIC, deadlocking the producer」. On 3510 the fix is mode 4. **On our
A3 (2201) mode 4 does not exist** (section 4: 「模式4仅支持Atlas 350 加速卡」; section 20: 「该模式仅在NPU架构版本3510上
支持」), so a multi-block MIX megakernel on A3 must either keep `blockDim == 1` per group for mode-2 handshakes or
route the AIC<->AIV handoff through GM workspace with mode-0 grid barriers instead. This is a concrete A3 hazard
we should design around rather than discover.
Third, the pipe-selection rule: 「wait on the consuming pipe」 — a cross-core wait placed on `PIPE_M` left MTE2 reads
ungated. (On 2201 the `pipe` template argument of `CrossCoreWaitFlag` is ignored and all pipes block, which makes this
class of bug impossible but every wait more expensive — see section 20.)
Fourth, a set left unwaited at the end of one launch **stays armed into the next launch** and makes its wait return
early. For a persistent/looping megakernel that is the dominant correctness hazard: one set + one wait per flag slot
per iteration, no exceptions.

---

## 26. Static kernel compilation and its cache key

https://gitcode.com/Ascend/torchair/blob/master/docs/zh/npugraph_ex/basic/static_kernel_compile.md
raw: https://raw.gitcode.com/Ascend/torchair/raw/master/docs/zh/npugraph_ex/basic/static_kernel_compile.md

> # 静态Kernel编译功能
>
> ## 功能简介
>
> 对于纯静态shape网络或者shape变化较少的动态shape网络，如需提升网络执行性能，可通过算子预先静态编译达到目的，该方式简称为静态Kernel编译。它是指在模型编译时指定shape大小，运行时不需要指定shape大小，减少运行时开销，具体优势如下：
>
> - 编译时已知所有Tensor的大小，存储空间利用率高。
> - 编译时可以针对实际的shape大小做针对性优化。
> - AI处理器擅长并行指令运行，不擅长逻辑计算，如果有太多的Scalar操作可能会打断并行指令的运行，从而导致性能下降。静态编译可以在编译时完成标量的计算，一定程度上可以提升性能。
> - 算子编译工具（op_compiler）在编译时知道确切的操作数据大小，不会额外插入同步，不会导致并行执行多个指令变成串行执行，一定程度上可以提升性能。
>
> 开启静态Kernel编译后，系统根据输入的算子信息统计文件，得到确定的shape信息，针对每一个shape都编译出一个算子二进制。
>
> ## 使用约束
>
> - 需注意的是，当Ascend PyTorch Profiler中**"experimental_config"参数**开启算子信息统计功能（即record_op_args=True），且"**schedule**"**参数**设置的预先跳过的step轮数为0时（即skip_first=0），不支持同时使用本功能。
>
> - 多卡场景使用限制：必须配置环境变量**LOCAL_WORLD_SIZE**，其每个节点的LOCAL_WORLD_SIZE必须一致。
>
>     > [!NOTE]说明
>     >- 由于多卡场景在安装静态kernel run包时，会更新算子库公共文件，若没有环境变量LOCAL_WORLD_SIZE的协同，可能会读取到过程态的内容，从而导致未定义行为（undefined behavior）。因此，在多卡场景使用该功能时，必须配置LOCAL_WORLD_SIZE。

```python
import torch
import torch_npu

options = {"static_kernel_compile": True, "disable_static_kernel_compile_cache": False}

opt_model = torch.compile(model, backend="npugraph_ex", options=options, dynamic=False, fullgraph=True)
```

> |**参数名**|**参数说明**|
> |--|--|
> |static_kernel_compile|布尔类型，是否开启静态Kernel编译。False（默认值）：默认关闭。True：开启静态Kernel编译。编译产物路径默认为当前执行脚本的同级目录，当同时启用了模型编译缓存功能但未启用force_eager功能时，编译产物路径为模型缓存文件所在目录。请确保该路径用户具有读、写操作权限。|
> |disable_static_kernel_compile_cache|布尔类型，是否禁用静态Kernel缓存功能。<br>False（默认）：使用缓存功能。二次运行且缓存命中时，将直接复用编译好的kernel run包。<br>True：禁用缓存功能。每次运行都会触发静态Kernel编译过程。<br>仅在 `static_kernel_compile` 为 `True` 时生效。缓存映射关系记录于静态编译产物路径下的 `static_kernel_cache` 目录中。|

> > [!NOTE]说明
> > 在使用静态Kernel缓存功能时，系统会对比当前运行特征与缓存记录。只有当以下所有条件全部满足且缓存中对应的kernel run包存在时，才会判定为缓存命中，跳过静态Kernel编译过程：
> >
> > 1. CANN版本不变、硬件型号不变；
> > 2. 模型中所有参与静态Kernel编译的算子属性（包括算子类型、输入输出Shape、Format、数据类型等）保持一致;
> > 3. 静态编译时的特定选项保持一致，包括：确定性计算配置、`super_kernel_optimize` 配置（含 `super_kernel_optimize_options` 和 `super_kernel_debug_options`）。
> >
> > 若上述任一条件不匹配，则判定缓存未命中，将触发完整的静态Kernel编译流程，并更新 `static_kernel_cache` 目录下对应的缓存记录。

## Relevance
Static kernel compilation is the prerequisite for SuperKernel (section 7's `Super Kernel -> static kernel -> Npugraph_ex`),
and the stated mechanism is the same one section 12 measured: 「静态编译可以在编译时完成标量的计算」 — resolve Scalar work
at compile time, plus 「不会额外插入同步」. At batch=1, seq 8K, TP16 decode our shapes are fixed, which is precisely the
「纯静态shape网络」 case. Two operational facts: the multi-card requirement `LOCAL_WORLD_SIZE` must be set and identical
per node (it appears in the GLM-5.2 A3 config in section 7 as `LOCAL_WORLD_SIZE: "16"`), and the cache key includes
the SuperKernel option dicts — so flipping any SuperKernel option forces a full recompile, which the vendor warns
takes 「several minutes to tens of minutes」.

---

## 27. CV fusion rationale and the logical-position data flow (`CO2 -> VECIN`, `VECOUT -> A1 -> A2`)

### CANN 9.0 算子开发指南 — CV融合 / 基础知识

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/programug/Ascendcopdevg/atlas_ascendc_10_0049.html
Publisher: Huawei / Ascend, parent topic 「CV融合」.

> ## CV融合算子
>
> 融合算子由多个独立的小算子融合而成，其功能与多个小算子的功能等价，性能方面通常优于独立的小算子。用户可以根据实际业务场景诉求，按照具体算法自由融合向量（Vector）、矩阵（Cube）算子以达到性能上的收益。融合了Cube计算、Vector计算的算子统称为CV融合算子。
>
> 比如对于LLM大模型中最核心的一个融合算子Flash Attention， 其核心实现如下图。图中的Matmul算子（Cube）、Scale算子（Vector）、Mask算子（Vector）、SoftMax算子（Vector）融合为一个大的算子Flash Attention。
>
> ## 使用场景和优势
>
> 针对有数据依赖的矢量算子和矩阵算子，可以通过融合算子编程的方式，将矢量算子和矩阵算子进行融合，通过一个算子Kernel函数来承载，由此来获得性能上的收益。下图展示了独立矢量算子和矩阵算子、Mix融合算子的执行耗时对比，由此可以看出为什么开发Mix融合算子会带来性能上的收益。
>
> 独立的矢量算子和矩阵算子实现：矩阵计算后的结果需要搬运到Global Memory上，然后由Global Memory搬运到Local Memory，再进行矢量算子的计算，计算和搬运都是串行执行，另外多个算子的调度执行，会增加算子的调度耗时。
>
> 融合算子的实现方法：可以对数据进行切片，再通过流水的设计，使得矢量计算单元和矩阵计算单元实现并行计算；另外相比于不融合的单算子，减少了算子的调度耗时。
>
> 除了有效提升算子性能，充分发挥AI处理器的算力，融合算子还有如下优势：
>
> 减少计算量：融合算子可以将多个算子合并为一个，简化计算过程，减少计算量，提高计算效率。
>
> 减少内存占用：融合算子可以将多个算子的中间结果合并为一个，从而减少内存占用，提高内存利用率。
>
> 优化数据流：融合算子可以优化数据流，减少数据在不同算子之间的传输，从而提高数据处理效率。
>
> 简化代码实现：融合算子可以简化代码实现，减少代码量，提高代码可读性和可维护性。
>
> ## 编程范式
>
> Ascend C提供融合算子的编程范式，方便开发者基于该范式表达融合算子的数据流，快速实现自定义的融合算子。
>
> 融合算子数据流指融合算子的输入输出在各存储位置间的流向。以一个典型的Cube和Vector融合算子为例，逻辑位置间的数据流向如下图所示：
>
> Cube的输出可以作为Vector的输入：CO2->VECIN
>
> Vector的输出可以作为Cube的输入：VECOUT->A1->A2、VECOUT->B1->B2
>
> 基于Matmul高阶API的融合算子编程范式，对上述数据流简化表达如下：
>
> 初始化一个Matmul对象。
>
> 进行Matmul内部的计算。
>
> 将Matmul的计算结果搬运到Vector核上。
>
> 进行Vector矢量计算。
>
> 将输出结果搬运到Global Memory上。

```cpp
template<typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::Process()
{
    uint32_t computeRound = 0;
    matmulObj.SetTensorA(aGlobal);
    matmulObj.SetTensorB(bGlobal);
    matmulObj.SetBias(biasGlobal);
    while (matmulObj.template Iterate<true>()) { // 步骤2：进行Matmul内部的计算。
        // 步骤3：将Matmul的计算结果搬运到Vector核上。
        reluOutLocal = reluOutQueue_.AllocTensor<cType>();
        matmulObj.template GetTensorC<true>(reluOutLocal, false, true);
       // 步骤4：进行Vector矢量计算。
        AscendC::LeakyRelu(reluOutLocal, reluOutLocal, (cType)alpha, tiling.baseM * tiling.baseN);
        reluOutQueue_.EnQue(reluOutLocal);
        // 步骤5：将输出结果搬运到Global Memory上
        reluOutQueue_.DeQue<cType>();
        ...
        AscendC::DataCopy(cGlobal[startOffset], reluOutLocal, copyParam);
        reluOutQueue_.FreeTensor(reluOutLocal);
        computeRound++;
    }
    matmulObj.End();
}
// kernel入口函数，__mix__(1, 2)表示：mix场景，AIC:AIV=1:2。
__global__ __mix__(1, 2) void matmul_leakyrelu_custom(GM_ADDR a, GM_ADDR b, GM_ADDR bias, GM_ADDR c,
                                                      __kfc_workspace__ GM_ADDR workspace, AscendC::tiling::TCubeTiling tiling)
{
    AscendC::TPipe pipe;
    MatmulLeakyKernel<half, half, float, float> matmulLeakyKernel;
    matmulLeakyKernel.Init(a, b, bias, c, workspace, tiling, &pipe);
    // 步骤1：初始化Matmul对象。
    REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), matmulLeakyKernel.matmulObj, &matmulLeakyKernel.tiling);
    matmulLeakyKernel.Process(&pipe);
}
```

### `KERNEL_TASK_TYPE_DEFAULT` in a shipping attention kernel (arch-conditional)

https://github.com/hicann/ops-transformer/blob/master/attention/compressor/op_kernel/compressor.cpp
raw: https://raw.githubusercontent.com/hicann/ops-transformer/master/attention/compressor/op_kernel/compressor.cpp
Repo `hicann/ops-transformer`, branch `master`.

```cpp
                                      __gm__ uint8_t* cmpKvOut, __gm__ uint8_t* stateCacheOut,
                                      __gm__ uint8_t* softmaxScoreOut, __gm__ uint8_t* kvOut, __gm__ uint8_t* workspace,
                                      __gm__ uint8_t* tiling)
{
    REGISTER_TILING_DEFAULT(optiling::CompressorTilingData);
#if (defined(__NPU_ARCH__) && (__NPU_ARCH__ == 9201))
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_1);
#else
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);
#endif
    GET_TILING_DATA_WITH_STRUCT(optiling::CompressorTilingData, tilingDataIn, tiling);
    if constexpr (static_cast<TEMPLATE_ID>(TemplateId) == TEMPLATE_ID::EMPTY_X) {
        return;
    }
    const optiling::CompressorTilingData* __restrict tilingData = &tilingDataIn;
    TPipe pipe;
```

Other shipping kernels found by code search that call `KERNEL_TASK_TYPE_DEFAULT` / `KERNEL_TASK_TYPE`
(all in `hicann/ops-transformer`, `master`, under `op_kernel/`):
`attention/quant_compressor/op_kernel/quant_compressor.cpp`,
`attention/lightning_indexer_v2/op_kernel/lightning_indexer_v2.cpp`,
`mhc/mhc_pre_sinkhorn/op_kernel/mhc_pre_sinkhorn_apt.cpp`,
`mhc/mhc_pre_sinkhorn_backward/op_kernel/mhc_pre_sinkhorn_backward_apt.cpp`,
`mc2/allto_all_matmul_v2/op_kernel/arch35/allto_all_matmul_v2_apt.cpp`,
`mc2/all_gather_matmul_v3/op_kernel/arch35/all_gather_matmul_v3_apt.cpp`.
Also `sgl-project/sgl-kernel-npu` `csrc/lora/op_kernel/sgemmc_shrink_kernel.cpp` and
`csrc/lora/op_kernel/sgemmc_expand_kernel.cpp`, `xLLM-AI/xllm-ops` `xllm_ops/index_group_matmul/op_kernel/index_group_matmul.cpp`,
and `tile-ai/tilelang-ascend` `src/target/codegen_ascend.cc` (which emits the macro).

## Relevance
The vendor's own stated reason for CV fusion is our reason, in two parts: 「矩阵计算后的结果需要搬运到Global Memory上，
然后由Global Memory搬运到Local Memory，再进行矢量算子的计算，计算和搬运都是串行执行，另外多个算子的调度执行，会增加算子的
调度耗时」 — the serialization *and* the per-operator dispatch cost. Flash Attention is given as the canonical example
(Matmul + Scale + Mask + SoftMax in one kernel), which is the shape of our attention block.
The logical-position data flow is stated as `CO2 -> VECIN` for cube-to-vector and `VECOUT -> A1 -> A2` /
`VECOUT -> B1 -> B2` for vector-to-cube — note this is the *logical* position flow the Matmul high-level API
presents, while the *physical* path on A3 still passes through GM (sections 8 and 16). `VECOUT -> A1 -> A2` is
why `MatmulType<TPosition::VECOUT, ...>` exists for the A and B matrices (section 11): a vector stage's UB output
can feed the next matmul's L1/L0A without the kernel re-reading GM — which is the direction that *is* available
on A3 and is the one worth exploiting for a vector->cube handoff in a megakernel.
The production attention kernel shows the real-world pattern we should copy: select the kernel task type by
`__NPU_ARCH__` at compile time (`MIX_AIC_1_1` on 9201, `MIX_AIC_1_2` otherwise, so A3/2201 takes `MIX_AIC_1_2`).

---

## 28. Measured SuperKernel A/B on A2/A3: 5.61% end-to-end, 21% on the fused segment

https://gitcode.com/cann/graph-autofusion/blob/master/super_kernel/examples/super_kernel_profiling/README.md
raw: https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/examples/jit/example02_super_kernel_profiling/README.md
(English copy: https://gitcode.com/cann/graph-autofusion/blob/master/super_kernel/examples/super_kernel_profiling/README_en.md)
Repo `cann/graph-autofusion`, branch `master`. Sample script `superkernel_compare.py`.

> # super_kernel 用例演示
>
> ## 用例功能
>
> 模型包含6个sk片段，部分sk相同复用缓存，部分多了可输入bias或option配置不同走在线编译
>
> 编译使用super_kernel和不使用super_kernel的模型，将性能数据输出
>
> ## 融合算子
>
> 使用如下with语句块（super_kernel），语句块内算子均被融合为一个超级Kernel进行计算
> ```python
> with torchair.scope.super_kernel("sk1"):
> ```
>
> ## 环境依赖
>
> 支持如下产品型号：
>
> - Atlas A3 训练系列产品/Atlas A3 推理系列产品
> - Atlas A2 训练系列产品/Atlas A2 推理系列产品

> ## 预期执行结果
>
> 在执行目录生成prof_result文件夹，目录如下，获取数据后对比耗时
> ```text
> prof_result
> ├── sk_model                             # 带superkernel结果
> │  ├── localhost.localdomain_ascend_pt
> │     ├── PROF_*
> │        ├── mindstudio_profiler_output
> │           ├── op_statistic.csv         # profiling数据
> ├── no_sk_model                          # 不带superkernel结果
> │  ├── localhost.localdomain_ascend_pt
> │     ├── PROF_*
> │        ├── mindstudio_profiler_output
> │           ├── op_statistic.csv         # profiling数据
> ```
> 分别从两份op_statistic.csv表中得到如下数据
>
> | OP_Type | Core Type | Total Time(us) |
> |--|--|--|
> | GroupedMatmul | MIX_AIC | 126.26 |
> | Transpose | AI_VECTOR_CORE | 90.02 |
> | MoeGatingTopK | AI_VECTOR_CORE |  68.32|
> |Tile  |  AI_VECTOR_CORE| 24.96 |
> | DequantSwigluQuant |AI_VECTOR_CORE  | 24.18 |
> | ReduceMeanD |  MIX_AIV| 16.36 |
> | ConcatV2D|  AI_VECTOR_CORE| 14.9 |
> | ReduceMeanD | AI_VECTOR_CORE | 14.14 |
> | SplitVD |AI_VECTOR_CORE  | 10.04 |
> | MatMul |AI_CORE  | 6.26 |
> | Cast |  AI_VECTOR_CORE|3.96 |
> | Data |  AI_VECTOR_CORE| 3.3 |
> | StridedSliceD | AI_VECTOR_CORE |3.18  |
> | AutomaticBufferFusionOp |AI_VECTOR_CORE  |1.66  |
> |no_sk_model|总耗时|407.54|
>
> | OP_Type | Core Type | Total Time(us) |
> |--|--|--|
> |SuperKernel | MIX_AIC| 172.4|
> |Transpose |AI_VECTOR_CORE | 92.42|
> |Tile |AI_VECTOR_CORE |24.66 |
> |SuperKernel |MIX_AIV | 18.48|
> |ReduceMeanD |MIX_AIV | 16.34|
> |ConcatV2D |AI_VECTOR_CORE |14.74 |
> |ReduceMeanD | AI_VECTOR_CORE| 14.24|
> |SplitVD |AI_VECTOR_CORE |10.12 |
> |MatMul |AI_CORE | 8.6|
> |Cast |AI_VECTOR_CORE |4.08 |
> |Data |AI_VECTOR_CORE | 3.72|
> |StridedSliceD |AI_VECTOR_CORE |3.1 |
> |AutomaticBufferFusionOp |AI_VECTOR_CORE | 1.76|
> |sk_model|总耗时|384.66|
>
> 对比获得使用super_kernel融合算子的收益是5.61%

## Relevance
The only measured SuperKernel A/B we found, and it is on A2/A3-supported hardware with an MoE-shaped graph
(`GroupedMatmul`, `MoeGatingTopK`, `DequantSwigluQuant`) close to our W4A8 MoE decode. Reading the two tables:
the three fused operators `GroupedMatmul` (MIX_AIC 126.26) + `MoeGatingTopK` (AI_VECTOR_CORE 68.32) +
`DequantSwigluQuant` (AI_VECTOR_CORE 24.18) = 218.76 us collapse into one `SuperKernel` MIX_AIC entry of 172.4 us —
a **21% reduction on the fused segment**. End-to-end it is 407.54 -> 384.66 us, **5.61%**, because most of the
remaining time (`Transpose` 90.02, `Tile` 24.96, `ConcatV2D` 14.9, ...) stayed unfused. Two readings matter for us:
(a) the per-segment win is real and sizeable where fusion actually lands; (b) the end-to-end win is gated entirely by
coverage, and in this sample coverage was poor — `Transpose` alone is 22% of the graph and did not fuse. Our 3008
kernels per round would need broad coverage, not just the MIX_AIC stages, for SuperKernel alone to approach our
11.6 -> 2.x ms target. Note also that SuperKernel produced **two** entries, `SuperKernel MIX_AIC` and
`SuperKernel MIX_AIV` — the fusion segmented by core type, consistent with section 6's 同步优化.
Lastly, the measurement recipe is reusable verbatim: run with and without, read `op_statistic.csv` under
`mindstudio_profiler_output`, compare `Total Time(us)` by `OP_Type` / `Core Type`.

---

## 29. `MatmulCallBackFunc` — user callbacks for CopyA1 / CopyB1 / DataCopyOut, with quant fields

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0618.html
Parent topic 「Matmul Kernel侧接口」.

产品支持情况: `Atlas 350 加速卡 √ / Atlas A3 训练系列产品/Atlas A3 推理系列产品 √ / Atlas A2 训练系列产品/Atlas A2 推理系列产品 √ / Atlas 200I/500 A2 推理产品 x / Atlas 推理系列产品AI Core x / Atlas 推理系列产品Vector Core x / Atlas 训练系列产品 x`

功能说明, verbatim:

> 模板参数MatmulCallBackFunc支持用户定制化Matmul的A矩阵、B矩阵及C矩阵的搬入搬出功能，如非连续搬入或针对搬出设置不同的数据片段间隔等。具体方式为：用户根据实际需要，实现一个或多个自定义的搬运函数，定义Matmul对象时，通过模板参数MatmulCallBackFunc，传入实现的搬运函数的函数指针，传入的函数指针会替换Matmul流程中默认的搬运函数。
>
> MatmulCallBackFunc中包含3个可由用户自定义的回调函数接口，即用户可配置3个函数指针。3个函数指针分别为C矩阵从CO1拷贝到GM、A矩阵从GM拷贝到A1、B矩阵从GM拷贝到B1的回调函数指针。3个函数指针的位置固定，不使用自定义搬运函数的函数指针位置需要设为空指针。每个回调函数实现矩阵搬运中单个基本块（A矩阵基本块baseM * baseK、B矩阵基本块baseK * baseN、C矩阵基本块baseM * baseN）的搬运策略，无法对整块内存空间进行管理。Matmul默认的搬运函数实现单核上单个基本块的搬运，搬运的基本块大小是固定的，在完整的Matmul计算过程中，多次调用搬运函数，对连续排布的基本块按顺序逐个搬运

表1 MatmulCallBackFunc回调函数接口及参数说明, verbatim:

> | 回调函数功能 | 回调函数接口 | 参数说明 |
> |---|---|---|
> | 可自定义设置不同的搬出数据片段数目等参数，实现将Matmul计算结果从CO1搬出到GM的功能 | `void DataCopyOut(const __gm__ void *gm, const LocalTensor<int8_t> &co1Local, const void *dataCopyOutParams, const uint64_t tilingPtr, const uint64_t dataPtr)` | gm：输出的GM地址。<br>co1Local: CO1上的计算结果。<br>dataCopyOutParams：Matmul定义的DataCopyOutParams结构体指针。<br>tilingPtr: 用户使用SetUserDefInfo设置的tiling参数地址。<br>dataPtr: 用户使用SetSelfDefineData设置的计算数据地址。 |
> | 可自定义左矩阵搬入首地址、搬运块位置、搬运块大小，实现左矩阵从GM搬入L1的功能 | `void CopyA1(const LocalTensor<int8_t> &aMatrix, const __gm__ void *gm, int row, int col, int useM, int useK, const uint64_t tilingPtr, const uint64_t dataPtr)` | aMatrix: 目标L1Buffer地址。<br>gm：左矩阵GM首地址。<br>row、col：搬运块在M、K方向的索引，即在M、K方向上搬运块的序号，序号从0开始。<br>useM、useK：搬运块M、K方向大小，单位为元素个数。通过row、col和useM、useK计算出该搬运块左上角在左矩阵中的地址偏移。 |
> | 可自定义右矩阵搬入首地址、搬运块位置、搬运块大小，实现右矩阵从GM搬入L1的功能 | `void CopyB1(const LocalTensor<int8_t> &bMatrix, const __gm__ void *gm, int row, int col, int useK, int useN, const uint64_t tilingPtr, const uint64_t dataPtr)` | bMatrix: 目标L1Buffer地址。<br>gm：右矩阵GM首地址。<br>row、col：搬运块在K、N方向的索引。<br>useK、useN：搬运块K、N方向大小，单位为元素个数。 |

```cpp
struct DataCopyOutParams {
    uint16_t cBurstNum; //传输数据片段数目
    uint16_t burstLen; //连续传输数据片段长度
    uint16_t srcStride;//源tensor相邻连续数据片段间隔
    uint32_t dstStride; // 目的tensor相邻连续数据片段间隔
    uint16_t oriNSize; // NZ转ND时，源tensorN方向大小
    bool enUnitFlag; // 是否使能UnitFlag
    uint64_t quantScalar; // 量化场景下量化Scalar的值
    uint64_t cbufWorkspaceAddr; //量化场景下量化Tensor地址
}
```

调用示例, verbatim:

```cpp
//用户自定义回调函数
void DataCopyOut(const __gm__ void *gm, const LocalTensor<int8_t> &co1Local, const void *dataCopyOutParams, const uint64_t tilingPtr, const uint64_t dataPtr);
void CopyA1(const LocalTensor<int8_t> &aMatrix, const __gm__ void *gm, int row, int col, int useM, int useK, const uint64_t tilingPtr, const uint64_t dataPtr);
void CopyB1(const LocalTensor<int8_t> &bMatrix, const __gm__ void *gm, int row, int col, int useK, int useN, const uint64_t tilingPtr, const uint64_t dataPtr);
AscendC::Matmul<aType, bType, cType, biasType, CFG_NORM, MatmulCallBackFunc<DataCopyOut, CopyA1, CopyB1>> mm;
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, &tiling);
uint64_t tilingPtr = reinterpret_cast<uint64_t>(tiling);
mm.SetUserDefInfo(tilingPtr); // 设置算子tiling地址，用于回调函数使用
```

> 完整的使用样例请参考Matmul回调函数样例。

## Relevance
Supported on A3, and the cleanest documented hook for a W4A8 epilogue: `DataCopyOut` receives the raw
`LocalTensor<int8_t> co1Local` (the L0C accumulator) plus a `DataCopyOutParams` that already carries
`quantScalar` ("量化场景下量化Scalar的值") and `cbufWorkspaceAddr` ("量化场景下量化Tensor地址") and `enUnitFlag`.
That means the requantization of the int32 cube result can be expressed inside the Matmul high-level API's own
drain path, on the AIC side via Fixpipe, rather than as a separate AIV kernel — which attacks our MIX call count
directly. `CopyA1` / `CopyB1` receive `(row, col, useM, useK)` block indices and the GM base, so a custom loader can
pull non-contiguous or differently-packed weights (relevant for int4 packing) without a pre-pass kernel.
Hard limit stated by the doc: each callback handles exactly one base block (`baseM*baseK`, `baseK*baseN`,
`baseM*baseN`) and 「无法对整块内存空间进行管理」 — no whole-tensor orchestration. `SetUserDefInfo(tilingPtr)` and
`SetSelfDefineData` are how per-call context reaches the callbacks.

---

## 30. `BareMix` — the complete low-level MIX fusion kernel, start to finish

The sample referenced by section 5's 「完整样例请参考BareMix样例」. Located in community mirrors of the Ascend samples tree:

https://github.com/XJ19023/ascend_samples/blob/master/operator/ascendc/0_introduction/22_baremix_kernellaunch/BareMixInvocation/baremix_custom.cpp
raw: https://raw.githubusercontent.com/XJ19023/ascend_samples/master/operator/ascendc/0_introduction/22_baremix_kernellaunch/BareMixInvocation/baremix_custom.cpp
(same file also at `c303803919-jpg/transmit` under `samples-master/operator/ascendc/0_introduction/22_baremix_kernellaunch/`)
Header: `Copyright (C) 2025. Huawei Technologies Co., Ltd. All rights reserved.`

Verbatim, the whole kernel:

```cpp
/**
 * @file baremix_custom.cpp
 *
 * Copyright (C) 2025. Huawei Technologies Co., Ltd. All rights reserved.
 */
#define ASCENDC_CUBE_ONLY
#include "kernel_operator.h"
#include "lib/matmul_intf.h"

using namespace matmul;

__aicore__ inline uint32_t Ceiling(uint32_t a, uint32_t b)
{
    return (a + b - 1) / b;
}

/**
  * @brief  Copy tiling data to TCubeTiling ptr from tiling gm addr.
  */
__aicore__ inline void CopyTiling(TCubeTiling *tiling, GM_ADDR tilingGM)
{
    uint32_t *ptr = reinterpret_cast<uint32_t *>(tiling);
    auto tiling32 = reinterpret_cast<__gm__ uint32_t *>(tilingGM);

    for (uint32_t i = 0; i < sizeof(TCubeTiling) / sizeof(uint32_t); i++, ptr++) {
        *ptr = *(tiling32 + i);
    }
    return;
}

template <typename aType, typename bType, typename cType, typename biasType> class MatmulLeakyKernel {
public:
    __aicore__ inline MatmulLeakyKernel(){};
    __aicore__ inline void Init(GM_ADDR a, GM_ADDR b, GM_ADDR bias, GM_ADDR c, GM_ADDR workspace,
                                const TCubeTiling &tiling, AscendC::TPipe *pipe);
    __aicore__ inline void Process(AscendC::TPipe *pipe);

    __aicore__ inline void CalcOffset(int32_t blockIdx, const TCubeTiling &tiling, int32_t &offsetA, int32_t &offsetB,
                                      int32_t &offsetC, int32_t &offsetBias);

    Matmul<MatmulType<AscendC::TPosition::GM, CubeFormat::ND, aType>, MatmulType<AscendC::TPosition::GM, CubeFormat::ND, bType>,
           MatmulType<AscendC::TPosition::VECIN, CubeFormat::ND, cType>, MatmulType<AscendC::TPosition::GM, CubeFormat::ND, biasType>>
        matmulObj;

    AscendC::GlobalTensor<aType> aGlobal;
    AscendC::GlobalTensor<bType> bGlobal;
    AscendC::GlobalTensor<cType> cGlobal;
    AscendC::GlobalTensor<biasType> biasGlobal;
    TCubeTiling tiling;
};

template <typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::Init(GM_ADDR a, GM_ADDR b, GM_ADDR bias,
                                                                              GM_ADDR c, GM_ADDR workspace,
                                                                              const TCubeTiling &tiling, AscendC::TPipe *pipe)
{
    this->tiling = tiling;
    aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ aType *>(a), tiling.M * tiling.Ka);
    bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ bType *>(b), tiling.Kb * tiling.N);
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ cType *>(c), tiling.M * tiling.N);
    biasGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ biasType *>(bias), tiling.N);

    int32_t offsetA, offsetB, offsetC, offsetBias;
    CalcOffset(AscendC::GetBlockIdx(), tiling, offsetA, offsetB, offsetC, offsetBias); // Calculate the gm offset based on the blockidx.
    aGlobal = aGlobal[offsetA];
    bGlobal = bGlobal[offsetB];
    cGlobal = cGlobal[offsetC];
    biasGlobal = biasGlobal[offsetBias];
}

template <typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void MatmulLeakyKernel<aType, bType, cType, biasType>::Process(AscendC::TPipe *pipe)
{
    matmulObj.SetTensorA(aGlobal);
    matmulObj.SetTensorB(bGlobal);
    matmulObj.SetBias(biasGlobal);

    matmulObj.template IterateAll(cGlobal);
    matmulObj.End();
    AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(3);
}

template <typename aType, typename bType, typename cType, typename biasType>
__aicore__ inline void
MatmulLeakyKernel<aType, bType, cType, biasType>::CalcOffset(int32_t blockIdx, const TCubeTiling &tiling,
                                                             int32_t &offsetA, int32_t &offsetB, int32_t &offsetC,
                                                             int32_t &offsetBias)
{
    auto mSingleBlocks = Ceiling(tiling.M, tiling.singleCoreM);
    auto mCoreIndx = blockIdx % mSingleBlocks;
    auto nCoreIndx = blockIdx / mSingleBlocks;

    offsetA = mCoreIndx * tiling.Ka * tiling.singleCoreM;
    offsetB = nCoreIndx * tiling.singleCoreN;
    offsetC = mCoreIndx * tiling.N * tiling.singleCoreM + nCoreIndx * tiling.singleCoreN;
    offsetBias = nCoreIndx * tiling.singleCoreN;
}

template <typename cType> class LeakyReluKernel {
public:
    __aicore__ inline LeakyReluKernel(){};
    __aicore__ inline void Init(GM_ADDR c, const TCubeTiling &tiling, AscendC::TPipe *pipe);
    __aicore__ inline void Process(AscendC::TPipe *pipe);

    __aicore__ inline void LeakyReluCopyIn(const TCubeTiling &tiling);
    __aicore__ inline void LeakyReluCompute(const TCubeTiling &tiling);
    __aicore__ inline void LeakyReluCopyOut(const TCubeTiling &tiling);

    AscendC::GlobalTensor<cType> cGlobal;

    AscendC::LocalTensor<cType> reluInLocal;
    AscendC::LocalTensor<cType> reluOutLocal;
    TCubeTiling tiling;
    AscendC::TQue<AscendC::TPosition::VECIN, 1> reluInQueue_;
    AscendC::TQue<AscendC::TPosition::VECOUT, 1> reluOutQueue_;
};

template <typename cType>
__aicore__ inline void LeakyReluKernel<cType>::Init(GM_ADDR c, const TCubeTiling &tiling, AscendC::TPipe *pipe)
{
    this->tiling = tiling;
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ cType *>(c) + AscendC::GetBlockIdx() * tiling.M * tiling.N / 2); //c:v = 1:2, split into 2 parts, for vector calculation

    pipe->InitBuffer(reluInQueue_, 1, tiling.singleCoreM * tiling.singleCoreN * sizeof(cType) /2); // Init input buffer.
    pipe->InitBuffer(reluOutQueue_, 1, tiling.singleCoreM * tiling.singleCoreN * sizeof(cType)/2); // Init output buffer.
}

template <typename cType>
__aicore__ inline void LeakyReluKernel<cType>::Process(AscendC::TPipe *pipe)
{
    AscendC::CrossCoreWaitFlag(3);
    LeakyReluCopyIn(tiling);
    LeakyReluCompute(tiling);
    LeakyReluCopyOut(tiling);
}
template <typename cType>
__aicore__ inline void LeakyReluKernel<cType>::LeakyReluCopyIn(const TCubeTiling &tiling)
{
    AscendC::LocalTensor<float> reluInLocal = reluInQueue_.AllocTensor<float>();
    AscendC::DataCopy(reluInLocal, cGlobal, tiling.singleCoreM * tiling.singleCoreN / 2);
    reluInQueue_.EnQue<float>(reluInLocal);
}

template <typename cType>
__aicore__ inline void LeakyReluKernel<cType>::LeakyReluCompute(const TCubeTiling &tiling)
{
    AscendC::LocalTensor<float> reluInLocal = reluInQueue_.DeQue<float>();
    AscendC::LocalTensor<float> reluOutLocal = reluOutQueue_.AllocTensor<float>();
    AscendC::LeakyRelu(reluOutLocal, reluInLocal, (float)0.001, tiling.singleCoreM * tiling.singleCoreN /2);
    reluOutQueue_.EnQue<float>(reluOutLocal);
    reluInQueue_.FreeTensor(reluInLocal);
}

template <typename cType>
__aicore__ inline void LeakyReluKernel<cType>::LeakyReluCopyOut(const TCubeTiling &tiling)
{
    AscendC::LocalTensor<float> reluOutLocal = reluOutQueue_.DeQue<float>();
    AscendC::DataCopy(cGlobal, reluOutLocal, tiling.singleCoreM * tiling.singleCoreN / 2);
    reluOutQueue_.FreeTensor(reluOutLocal);
}

/**
  * @brief  baremix kernel function entry
  */
extern "C" __global__ __aicore__ void baremix_custom(GM_ADDR a, GM_ADDR b, GM_ADDR bias, GM_ADDR c,
                                                              GM_ADDR workspace, GM_ADDR tilingGm)
{
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);
    AscendC::TPipe pipe;
    TCubeTiling tiling;
    CopyTiling(&tiling, tilingGm);

    if ASCEND_IS_AIC {
        MatmulLeakyKernel<half, half, float, float> matmulLeakyKernel;
        matmulLeakyKernel.Init(a, b, bias, c, workspace, tiling, &pipe);
        REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), matmulLeakyKernel.matmulObj, &matmulLeakyKernel.tiling); // Initialize the matmul object.
        matmulLeakyKernel.Process(&pipe);
    }
    if ASCEND_IS_AIV {
        LeakyReluKernel<float> leakyReluKernel;
        leakyReluKernel.Init(c, tiling, &pipe);
        leakyReluKernel.Process(&pipe);
    }
}
```

## Relevance
This is the smallest complete, compilable template for the hand-synchronized MIX kernel our megakernel will be —
every element section 5 described in prose, in one file:
- `#define ASCENDC_CUBE_ONLY` **before** `#include "lib/matmul_intf.h"`, so the Matmul high-level API compiles
  AIC-only and does not install the AIV-side KFC controller.
- `KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2)` at the top of the kernel body, plus
  `if ASCEND_IS_AIC { ... }` / `if ASCEND_IS_AIV { ... }` as the two halves. Note the entry is a plain
  `extern "C" __global__ __aicore__` function — **not** `__global__ __mix__(1,2)` with `__kfc_workspace__`; the kernel
  type macro does the work instead, and `GM_ADDR tilingGm` is copied in by hand (`CopyTiling`) rather than via
  `GET_TILING_DATA` (which section 24 notes is unsupported in kernel-direct-launch projects).
- Exactly one handshake: `AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(3)` after `matmulObj.End()` on the AIC side, and
  a bare `AscendC::CrossCoreWaitFlag(3)` (default `modeId = 0`... note the asymmetry: the Set is mode 2, the Wait
  uses the default template argument) at the top of the AIV `Process`. flagId 3 is inside the user range 0-10 but
  **collides with `Matmul`'s `[0, 2N-1]` allocation** for N >= 2 (section 20) — a live hazard if a megakernel defines
  more than one Matmul object.
- The AIV side reads the cube result back from `cGlobal` in GM (`DataCopy(reluInLocal, cGlobal, ...)`), confirming
  section 16's conclusion: on this architecture the cube->vector handoff is a GM round trip, L2-absorbed.
- `cGlobal` is offset by `GetBlockIdx() * tiling.M * tiling.N / 2` with the comment `//c:v = 1:2, split into 2 parts,
  for vector calculation` — the AIV-side blockIdx-based work split under `MIX_AIC_1_2`, matching section 16's
  `GetBlockIdx() / 2` logic from the other direction.
- `MatmulType<TPosition::VECIN, CubeFormat::ND, cType>` for the C matrix even though `IterateAll(cGlobal)` writes to
  GM — the logical position, per section 27.

---

---

## 31. The A3 cube→vector GM visibility rule: `CrossCoreSetFlag` is NOT enough, `DataCacheCleanAndInvalid` + `DataSyncBarrier<DDR>` on **both** sides is

This section answers the concrete failure "AIC writes INT32 to a GM `partial` buffer, `PipeBarrier<PIPE_ALL>()`,
`CrossCoreSetFlag<0x02, PIPE_FIX>(8)`; AIV does `CrossCoreWaitFlag(8)`, `PipeBarrier<PIPE_ALL>()`, `DataCopy` — and
reads zeros non-deterministically, while the same buffer downloaded to the host is always correct."

### 31.1 The rule, stated by the people who hit the identical bug

https://github.com/flashserve/flash-linear-attention-npu/blob/main/fla/ops/ascendc/cp/pre_process_fwd_kernel_merged/op_kernel/arch22/pre_process_fwd_kernel_merged_cube.h
Repo `flashserve/flash-linear-attention-npu`, branch `main`, file
`fla/ops/ascendc/cp/pre_process_fwd_kernel_merged/op_kernel/arch22/pre_process_fwd_kernel_merged_cube.h`,
`arch22` = our DAV_2201. Retrieved 2026-10-20.

This is the **producer (AIC) side**, verbatim, including its comment. `vTmpF_` and `t1F_` are `GlobalTensor<float>`
holding the cube's `C` output; `AicSetToAiv` is the `CrossCoreSetFlag` wrapper:

```cpp
        // 注意： 写侧也要 clean（写回），只靠读者 DCCI 不够：FIX
        // 写回可能还停在写缓冲里，
        //   此时 AIV 即便 DCCI 也会读到旧值。实测（PPFM_DIAG 指纹）：AIV 读到 vTmp 全 0，
        //   而 AIC 实际写了 -0.013/+0.0092 → v_new 退化成 v，h 半边随机整头崩（m
        // 不受影响）。
#if !PPFM_T1_FIXPIPE_BF16
#if !PPFM_VTMP_UB
#if PPFM_LEGACY_CACHEOPS
        DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(vTmpF_);
#endif
#endif
#endif
#if PPFM_LEGACY_CACHEOPS
        DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(t1F_);
#endif
#if !PPFM_T1_FIXPIPE_BF16
        // 注意： 正式原语：DDR 数据同步屏障——保证 C 的写回对其他核可见后再抬 flag。
        //   诊断版实验表明竞态是"flag 已到、写回仍在途"的时序窗口（加探针即掩盖）。
#if PPFM_LEGACY_CACHEOPS
        DataSyncBarrier<MemDsbT::DDR>();
#endif
        AicSetToAiv(kFlagHalf1);
#endif
```

Translated for the record, because this is the rule: *the write side must clean too — the reader's DCCI alone is not
enough: the FIX write-back may still be sitting in the write buffer, in which case the AIV reads the old value even
after a DCCI. Measured (PPFM_DIAG fingerprint): the AIV read vTmp as all zeros while the AIC had actually written
-0.013/+0.0092.* And: *the proper primitive is the DDR data-sync barrier — it guarantees C's write-back is visible to
other cores before raising the flag. The diagnostic build showed the race is the timing window "flag already arrived,
write-back still in flight" (adding a probe masks it).*

"AIV 读到 vTmp 全 0" is our symptom exactly, and "加探针即掩盖" is why our host download of `partial` is always correct.

The same file, the **consumer-of-the-other-core's-GM** direction (here AIC reading what AIV wrote — the mirror image,
same rule):

```cpp
        AicWaitFromAiv(kFlagInputs);
        // 注意： 读别的核（AIV）刚写过的 GM 之前必须让本核的 cache 失效：h/m 每 chunk 都被
        //    AIV 重写，若 AIC 命中自己缓存的旧行，mm1/mm3 就会拿到过期的 h/m
        //    （实测表现为概率性的 h 半边大面积错、m 只是略偏，且随调度时好时坏）。
#if PPFM_LEGACY_CACHEOPS
        DataCacheCleanAndInvalid<bfloat16_t, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(wBf_);
#endif
#if PPFM_LEGACY_CACHEOPS
        DataCacheCleanAndInvalid<bfloat16_t, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(hBf_);
#endif
#if PPFM_LEGACY_CACHEOPS
        DataCacheCleanAndInvalid<bfloat16_t, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(mBf_);
#endif
```

### 31.2 The AIV side of the same kernel — our exact case, cube product read back by vector

https://github.com/flashserve/flash-linear-attention-npu/blob/main/fla/ops/ascendc/cp/pre_process_fwd_kernel_merged/op_kernel/arch22/pre_process_fwd_kernel_merged_vector.h
Same repo/branch, `arch22` vector half. Retrieved 2026-10-20.

Verbatim — note the cited precedent "CANN `matmul_client.h` does a DCCI before reading a cross-core GM flag", and the
hard-won detail that **every** alias of the buffer must be invalidated, not just the one the even iteration uses:

```cpp
            AivWaitFromAic(kFlagDH);
            // 读别的核（AIC）写的 GM 前必须让本核缓存行失效，否则会读到过期数据
            // （与 CANN matmul_client.h 中"读跨核 GM flag 前先 DCCI"的用法一致）
            // 注意： 原来只失效了**偶数奇偶**的 dHF_/t2F_，而下面按 chunk 奇偶读的是
            //   `dhBuf`/`t2Buf`（两份）⇒ 奇数 chunk 读的 `dHF1_`/`t2F1_` 从来没被失效过，
            //   命中旧行就会把过期 T2 减进 m（表现为 m 半边小范围错、h 正常）。
            //   这个缺口在 A2 上（PPFM_LEGACY_CACHEOPS=1）才暴露得出来；补齐两份。
#if PPFM_KEEP_CACHEOPS_R
            DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                     DcciDst::CACHELINE_OUT>(dHF_);
#endif
#if PPFM_KEEP_CACHEOPS_R
            DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                     DcciDst::CACHELINE_OUT>(dHF1_);
#endif
#if PPFM_KEEP_CACHEOPS_R
            DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                     DcciDst::CACHELINE_OUT>(t2F_);
#endif
#if PPFM_KEEP_CACHEOPS_R
            DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                     DcciDst::CACHELINE_OUT>(t2F1_);
#endif
```

And the AIV reading the cube's `vTmpF_` / `t1F_`, i.e. literally "vector reads the cube's INT32/FP32 product out of
GM" — the invalidate sits immediately before the consuming vector code:

```cpp
#if !PPFM_VTMP_UB
#if PPFM_KEEP_CACHEOPS_R
        DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(vTmpF_);
#endif
#endif
#if PPFM_KEEP_CACHEOPS_R
        DataCacheCleanAndInvalid<float, CacheLine::ENTIRE_DATA_CACHE,
                                 DcciDst::CACHELINE_OUT>(t1F_);
#endif
        // v_new = (v - vTmp) · dg → bf16（逐行；整块版本会引入 ~0.4% 的 GDN 偏差，待查）
```

### 31.3 The flag wrappers — where the cache ops go relative to the flag, and the `pipe` that matters

https://github.com/flashserve/flash-linear-attention-npu/blob/main/fla/ops/ascendc/cp/pre_process_fwd_kernel_merged/op_kernel/pre_process_fwd_kernel_merged_common.h
Same repo/branch. Retrieved 2026-10-20. All four wrappers, verbatim and complete:

```cpp
// ---------------- CrossCore flag（MIX 内 AIC <-> 2×AIV）----------------
// 两个平台的同步模型不同（见 PPFM_XCORE_MODE / PPFM_ARCH_IS_950）：
//   * 950 用 mode 0x4：flag ID 按 subblock 分槽（第二个子核 = id + 16），AIC 侧显式
//     wait/set 两个 slot。与仓内 arch35 算子的约定一致
//     （见 chunk_fwd_h/op_kernel/chunk_fwd_h_policy.h、kda/chunk_kda_fwd/.../fwd_h.h）。
//     实测反例：用 A2/A3 风格的 `CrossCoreSetFlag<0x2, ...>` 时，950 上先干完的那个
//     子核就会把 AIC 放行，AIC 的 mm1/mm3 读到"只写了一半"的 h/m bf16 状态，
//     表现为 h 半边约一半行数据错、m 基本对（GDN 快路径暴露，KDA 慢路径看不出来）。
//   * 910B/910_93 用 mode 0x2：AIC 与「本 block 的 2 个 AIV」是集合同步 —— AIC 的一次
//     set 对本 block 两个 AIV 同时置起；两个 AIV 都 set 同一个 ID 才算 AIC 侧事件置起。
//     因此 AIC 侧每轮只需一对 set/wait（多 set/多 wait 会让 flag 计数失衡）。
constexpr uint16_t PPFM_SUBFLAG_STRIDE = 16;   // AIV 子核 1 的 slot 偏移
constexpr uint16_t kFlagInputs = 1;   // AIV -> AIC：本 chunk staging 就位
constexpr uint16_t kFlagState = 2;    // AIV -> AIC：h/m 状态就位
constexpr uint16_t kFlagHalf1 = 3;    // AIC -> AIV：vTmp 与 T1 就位
constexpr uint16_t kFlagVNew = 4;     // AIV -> AIC：bf16(v_new) 与 bf16(T1) 就位
constexpr uint16_t kFlagDH = 5;       // AIC -> AIV：dH 与 T2 就位
// （dH 走 L0C->UB）：dH 的 UB 槽「归还」信用（AIV -> AIC）。槽 j 用 id + j，
// AIC 侧按 subblock 各等一次（id 与 id+PPFM_SUBFLAG_STRIDE），
// 与仓内 arch35 的 MATRIX_CV_AIV_TO_AIC_FLAG_BEGIN/CV_SUBBLOCK_FLAG_STRIDE 同构。
constexpr uint16_t kFlagDhFree = 8;
// T2 的 UB 槽归还信用（AIV -> AIC），单槽。
constexpr uint16_t kFlagT2Free = 10;

// AIV 子核：写自己本地 slot（硬件按子核自动映射到 id / id+16）
__aicore__ inline void AivSetToAic(uint16_t id)
{
    // set_intra_block 不保证"之前的搬运已落地"，这里显式排空 MTE3
    PipeBarrier<PIPE_MTE3>();
    // 对称于 AIC 侧：本核写出的 GM（kBf_/wBf_/lBf_/vNewBf_/t1Bf_/状态）也要先对其他核可见
#if PPFM_LEGACY_CACHEOPS
    DataSyncBarrier<MemDsbT::DDR>();
#endif
    CrossCoreSetFlag<PPFM_XCORE_MODE, PIPE_MTE3>(id);
}

__aicore__ inline void AivWaitFromAic(uint16_t id)
{
    // 950：用 PIPE_S 排队 —— 等待指令卡住后续指令的发射（否则后面的 MTE2/V 会先跑）。
    // 910B/910_93：消费方是 MTE2（从 GM 回读 cube 的 C），按 A2 惯用法在 MTE2 上排队
    //   （见仓内 arch22 的 `CrossCoreWaitFlag<0x2, PIPE_MTE2>(..._READY_FLAG)`）。
    //   实测 A2 上用 PIPE_S 等待时，随后的 MTE2 会提前发射，读到"半新半旧"的 C：
    //   表现为 h 半边误差 ~1.5e-2 且逐次小幅跳动（v=0 的探针本应得到 h≡0）。
#if PPFM_ARCH_IS_950
    CrossCoreWaitFlag<PPFM_XCORE_MODE, PIPE_S>(id);
#else
    CrossCoreWaitFlag<PPFM_XCORE_MODE, PIPE_MTE2>(id);
#endif
}
```

and the AIC half (note `PipeBarrier<PIPE_FIX>()` before the set, and the "15 consecutive sets hangs" citation):

```cpp
//   950 (mode 0x4)：flag ID 按 subblock 分槽，两个 AIV 子核各自 set 自己的 ID ⇒ 这里要等两次
//   910B/910_93 (mode 0x2)：AIC 与「本 block 的 2 个 AIV」是**集合同步**——两个 AIV 必须
//     都 set 同一个 ID，事件才会对 AIC 置起 ⇒ 这里只等一次
//   （约定出处：仓内 chunk_fwd_h/op_kernel/chunk_fwd_h_policy.h 的 FwdHAicPeerFlag 注释）
__aicore__ inline void AicWaitFromAiv(uint16_t id)
{
#if PPFM_ARCH_IS_950
    CrossCoreWaitFlag<PPFM_XCORE_MODE, PIPE_S>(id);
    CrossCoreWaitFlag<0x4, PIPE_S>(static_cast<uint16_t>(id + PPFM_SUBFLAG_STRIDE));
#else
    // 910B：AIC 侧消费方同样是 MTE2（把 AIV 写好的 k/w/h/m/vNew 搬进 L1/L0）
    CrossCoreWaitFlag<PPFM_XCORE_MODE, PIPE_MTE2>(id);
#endif
}

// AIC -> AIV：
//   950：两个 slot 都要置位，否则只会唤醒一个子核；
//   910B/910_93：0x2 下一次 set 即对本 block 的两个 AIV 同时置起，只能 set 一次
//   （多 set 会让计数失衡 —— 单条 flag 连续 set 超过 15 次会挂死，见 catlass
// cross_core_sync.hpp）
__aicore__ inline void AicSetToAiv(uint16_t id)
{
    PipeBarrier<PIPE_FIX>();
    CrossCoreSetFlag<PPFM_XCORE_MODE, PIPE_FIX>(id);
#if PPFM_ARCH_IS_950
    CrossCoreSetFlag<PPFM_XCORE_MODE, PIPE_FIX>(static_cast<uint16_t>(id + PPFM_SUBFLAG_STRIDE));
#endif
}
```

https://github.com/flashserve/flash-linear-attention-npu/blob/main/fla/ops/ascendc/cp/pre_process_fwd_kernel_merged/op_kernel/pre_process_fwd_kernel_merged_policy.h
Same repo/branch. The mode and the per-arch default of the cache ops, verbatim:

```cpp
constexpr int32_t PPFM_XCORE_MODE = 0x4;
```
```cpp
constexpr int32_t PPFM_XCORE_MODE = 0x2;
```
```cpp
// 950：实测只用跨核 flag 就够（并且去掉 DCCI 后竞态由 3/6 降到 1/6），默认 0。
// 910B/910_93：实测 AIC 会读到 AIV 尚未对其他核可见的 bf16(h)（chunk0 的 h≡0 探针
//   仍得到 1.6e-2 的 h），故先按 A2 老做法启用 DCCI/DSB；若后续定位到更精确的边，
//   可只保留必要的那一条。
#ifndef PPFM_LEGACY_CACHEOPS
#if PPFM_ARCH_IS_950
#define PPFM_LEGACY_CACHEOPS 0
#else
#define PPFM_LEGACY_CACHEOPS 1
#endif
#endif

// ---- C3 实验（A2 专用；默认 = 现状，950 机器码按构造不变）----
// 动机：A2 的 DCCI/DSB 目前"不分生产方"地全开（AIC 每 chunk 10 次整缓存 DCCI + AIV 6 次
//   + 4 次 DSB），而 950 的实测记录是"去掉 DCCI 后竞态由 3/6 降到 1/6"。
//   把 A2 的缓存操作按**数据生产方**拆成两组，做 4 组 A/B（默认都是 1 = 现状）：
//     W 组 = AIC 抬 flag 前，对**自己算出的 C** 做的 DCCI/DSB（vTmp / t1Bf_ / dH / T2 及末尾 DSB）
//     R 组 = AIV 读 **AIC 算出的 C** 之前做的失效（dHF_/dHF1_/t2F_/t2F1_/vTmpF_/t1F_）
//   保留不动的是"消费 AIV 产物"的那一半（AIC 读 wBf_/kBf_/hBf_/mBf_/lBf_/vNewBf_ 前的 DCCI，
//   以及 AivSetToAic 的 DSB）—— 那一半有明确故障证据（AIC 读到尚未可见的 bf16(h)）。
//   实验矩阵：W1R1（基线）/ W0R1 / W1R0 / W0R0，判据 = PROC S≥40 的失败率 + L1 + perf。
#ifndef PPFM_A2_CACHEOPS_W
//   **结论（2026-10-08，234 上机）**：W0R1（=A2 默认）在 60 进程位级口径下残差 1/60，
//   基线 W1R1 是 9/60 ⇒ 去掉 W 组的 DCCI 没有让竞态变差，反而随 C7/C9 一起变好。
#define PPFM_A2_CACHEOPS_W (PPFM_ARCH_IS_950 ? 1 : 0)
#endif
#ifndef PPFM_A2_CACHEOPS_R
#define PPFM_A2_CACHEOPS_R 1
#endif
```

Read that last block carefully: their final A2/A3 default is **W0R1** — producer-side DCCI *off*, consumer-side DCCI
*on*, with `DataSyncBarrier<MemDsbT::DDR>()` kept on the producer before the flag
(`PPFM_KEEP_CACHEOPS_W` gates both the producer DCCI *and* its DSB, but the DSB inside `AivSetToAic` is gated by
`PPFM_LEGACY_CACHEOPS` alone, which stays 1 on A2/A3). Measured: W1R1 baseline 9/60 processes mismatched, W0R1 1/60.
So the producer-side *cache* op was not what paid; the producer-side *barrier* and the consumer-side *invalidate* did.

### 31.4 A second, independent kernel that hit the same thing — the V→C relay, with a 2000-trial A/B

https://github.com/flashserve/flash-linear-attention-npu/pull/860
Author `weinachuan` (Collaborator), opened 2026-10-10T09:33:09Z, title
「fix(kda): ChunkKdaFwdPrepare 的 V6→C7 relay 交接补保守可见性同步（Arch22，临时验证）」. Draft, 2 commits
(`1a606d6`, `af7a2af`). Retrieved 2026-10-20.

PR body, verbatim excerpt — this is the general statement of the rule, and it is attributed to a repo-wide
"established conclusion":

```
// AIV → AIC 跨核 GM 交接的保守同步档位（Arch22 现场 A/B 用）。
//
// V6 把 K_beta_g/V_beta 写进 workspace relay，随后由 AIC 的 C7 读回并计算
// W/U；这条交接当前只依赖 ready/free 跨核 flag。A2/A3 上"只靠跨核 flag 传递
// GM 数据"不足以稳定保证写侧已经对读侧可见（同 CP/PPFM 的既定结论），这里提供
// 一个可回退的加固开关：
//   0 = 与改动前逐字节一致（基线）；
//   1 = 只在 V6 → C7 这条交接上补"写侧 clean + 读侧失效 + DSB"；
//   2 = 再把 C2/C4 读入 AIV payload 的位置按同样方式加固（默认，现场验证档位 1 无效、
//       档位 2 消除漂移；见 PR 描述）。
// 只影响同步强度，不改变任何计算、地址、输出档位或 tiling 数据。
#ifndef CHUNK_KDA_FWD_PREPARE_RELAY_SYNC
#define CHUNK_KDA_FWD_PREPARE_RELAY_SYNC 2
#endif
```

The producer-side hunk from the same PR's diff (`.../arch22/chunk_kda_fwd_prepare_vec.h`), verbatim, showing the
order **DataCopy → DCCI → DSB → flag**:

```cpp
         AscendC::DataCopy(kBetaRelay, kBetaG, rhsRows * Shape::kHeadDim);
         AscendC::DataCopy(vBetaRelay, vBeta, rhsRows * Shape::kValueDim);
+#if CHUNK_KDA_FWD_PREPARE_RELAY_SYNC >= 1
+        // 写侧加固（保守）：这两份 relay 马上会被 AIC 的 C7 跨核读回。只靠
+        // ready 跨核 flag 时，MTE3 写缓冲/L2 里的数据可能还没对读侧可见，读侧
+        // 就会拿到 relay 的旧内容（现场表现为单个 work item 的 U 整块错、同一
+        // Stage 的 W 正常）。先把两份 relay clean 出去再放行下一步。
+        AscendC::DataCacheCleanAndInvalid<bfloat16_t, AscendC::CacheLine::ENTIRE_DATA_CACHE,
+                                          AscendC::DcciDst::CACHELINE_OUT>(kBetaRelay);
+        AscendC::DataCacheCleanAndInvalid<bfloat16_t, AscendC::CacheLine::ENTIRE_DATA_CACHE,
+                                          AscendC::DcciDst::CACHELINE_OUT>(vBetaRelay);
+        AscendC::DataSyncBarrier<AscendC::MemDsbT::DDR>();
+#endif
         AscendC::SetFlag<AscendC::HardEvent::MTE3_MTE2>(ioFree_[pair]);
```

and the consumer-side hunk (`.../arch22/chunk_kda_fwd_prepare_cube.h`), order **wait → DCCI → DSB → DataCopy**:

```cpp
+#if CHUNK_KDA_FWD_PREPARE_RELAY_SYNC >= 1
+            // 读侧加固（保守）：读 AIV 刚写过的 relay 之前先让本核缓存行失效，
+            // 否则 MTE2 可能命中旧行，把上一代（或空）的 K_beta_g/V_beta 读成
+            // 本代的 RHS（现场表现为同一 Stage 里 W 正常、U 整块错）。
+            AscendC::DataCacheCleanAndInvalid<bfloat16_t, AscendC::CacheLine::ENTIRE_DATA_CACHE,
+                                              AscendC::DcciDst::CACHELINE_OUT>(kBetaRelay);
+            AscendC::DataCacheCleanAndInvalid<bfloat16_t, AscendC::CacheLine::ENTIRE_DATA_CACHE,
+                                              AscendC::DcciDst::CACHELINE_OUT>(vBetaRelay);
+            AscendC::DataSyncBarrier<AscendC::MemDsbT::DDR>();
+#endif
             AscendC::DataCopy(kBetaL1, kBetaRelay, rhsCopy);
             AscendC::DataCopy(vBetaL1, vBetaRelay, rhsCopy);
```

Measured A/B from the PR's commit `af7a2af` message and body: tier 0 (baseline) gave
「~19-22/2000 trial 出现跨 stream 不一致」, tier 1 (that one handoff only) 「仍然 ~19/2000，无改善」, tier 2 (also
hardening the two other read sites) 「漂移消失」. The diagnostic signature, verbatim:

```
现场反馈 KDA 前向在并发场景下 fwd / recompute 输出不一致。离线逐元素分析显示：差异集中在一个
`(value head, chunk)` work item 的 `u` 上，而同一 Stage 的 `w`、更早 Stage 的 `gk / Aqk / Akk / qg / kg`
逐位一致；`u` 的等效右操作数中位幅值比正常小约 4 个数量级、约 1.4% 元素为巨大脏值，指向"读到了尚未写入或已过期的
relay 缓冲"。
```

and the author's own verdict on the cost, verbatim:

```
- 代价是每个 work item 多两次 `ENTIRE_DATA_CACHE` 级 clean/invalidate 与 DSB，属于保守选择，**可能带来性能回退**。
  若现场验证有效，后续应换成 slot 级双缓冲 + 代际号（或 L1 中转）的结构性方案再收口，不建议以本 PR 形态合入。
```

The "tier 1 ineffective, tier 2 effective" result is the single most useful datum here: **it is not enough to harden
the one handoff you suspect.** Every GM buffer that one core writes and another reads needs the treatment, or the
drift survives.

### 31.5 `DataCacheCleanAndInvalid` — the official API page, exact spelling and parameters

https://www.hiascend.com/doc_center/source/zh/canncommercial/800/apiref/ascendcopapi/atlasascendc_api_07_0177.html
CANN Commercial 8.0 API reference, 「缓存处理」. Retrieved 2026-10-20. Verbatim:

```
DataCacheCleanAndInvalid
功能说明
在AI Core内部，Scalar单元和DMA单元都可能对Global Memory进行访问。
图1 DataCache内存层次示意图
如上图所示：
DMA搬运单元读写Global Memory，数据通过DataCopy等接口在UB等Local Memory和Global Memory间交互，没有Cache一致性问题；
Scalar单元访问Global Memory，首先会访问每个核内的Data Cache，因此存在Data Cache与Global Memory的Cache一致性问题。
该接口用来刷新Cache，保证Cache的一致性，使用场景如下：
读取Global Memory的数据，但该数据可能在外部被其余核修改，此时需要使用DataCacheCleanAndInvalid接口，直接访问Global Memory，获取最新数据；
用户通过Scalar单元写Global Memory的数据，希望立刻写出，也需要使用DataCacheCleanAndInvalid接口。
函数原型
template <typename T, CacheLine entireType, DcciDst dcciDst>
__aicore__ inline void DataCacheCleanAndInvalid(const GlobalTensor<T>& dstTensor)
template <typename T, CacheLine entireType, DcciDst dcciDst>
__aicore__ inline void DataCacheCleanAndInvalid(const LocalTensor<T>& dstTensor)
该原型支持的硬件平台型号：
Atlas A2 训练系列产品/Atlas 800I A2 推理产品
Atlas 200I/500 A2 推理产品
template <typename T, CacheLine entireType>
__aicore__ inline void DataCacheCleanAndInvalid(const GlobalTensor<T>& dstTensor)
该原型支持的硬件平台型号：
Atlas 推理系列产品AI Core
参数说明
dstTensor  输入  需要刷新Cache的Tensor。
entireType 输入  指令操作的模式：
SINGLE_CACHE_LINE：只刷新传入地址所在的cacheLine，注意如果该地址非64B对齐，只会操作传入地址到64B对齐的部分。
ENTIRE_DATA_CACHE：此时传入的地址无效，核内会刷新整个Data Cache，但是耗时较大，性能敏感的场景慎用。
dcciDst    输入  表示使用该接口来保证Data Cache与哪一种存储保持一致性，类型为DcciDst枚举类。
CACHELINE_ALL：与CACHELINE_OUT效果一致;
CACHELINE_UB：预留参数，暂未支持;
CACHELINE_OUT：表示通过该接口来保证Data Cache与Global Memory的一致性;
CACHELINE_ATOMIC：预留参数，暂未支持。
```

and its multi-core warning, verbatim:

```
// 示例3：SINGLE_CACHE_LINE 模式，假设mmAddr_为0x40（64B对齐），多核处理场景（本样例仅做示例说明，便于开发者理解使用限制，非正常使用样例）
AscendC::GlobalTensor<uint64_t> global;
global.SetGlobalBuffer((__gm__ uint64_t*)mmAddr_);
global.SetValue(AscendC::GetBlockIdx(), AscendC::GetBlockIdx());
// 算子中多核操作虽然不在同一个地址，但在同一个CacheLine, 会出现数据的随机覆盖，和通用CPU的行为不同
// 调用DataCacheCleanAndInvalid指令后，由于多核操作的时间不一致，最终结果存在随机性，后执行的核会覆盖前面核的结果
AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global);
```

Note the tension worth carrying forward: the official page asserts 「DMA搬运单元读写Global Memory ... 没有Cache一致性
问题」 — DMA has no coherence problem — while both kernels in §31.1-31.4 are pure-DMA handoffs (FIXPIPE out, MTE2 in)
that measurably needed DCCI and DSB on DAV_2201. Treat the doc's claim as scoped to a single core's own DMA, not to
cross-core publication.

### 31.6 `DataSyncBarrier` — the primitive that actually waits for the write-back

https://www.hiascend.com/doc_center/source/zh/canncommercial/800/apiref/ascendcopapi/atlasascendc_api_07_0272.html
CANN Commercial 8.0 API reference, 「核内同步」. Retrieved 2026-10-20. Verbatim, complete:

```
DataSyncBarrier(ISASI)
功能说明
用于阻塞后续的指令执行，直到所有之前的内存访问指令（需要等待的内存位置可通过参数控制）执行结束。
函数原型
template <MemDsbT arg0>
__aicore__ inline void DataSyncBarrier()
参数说明
arg0  模板参数，表示需要等待的内存位置，类型为MemDsbT，可取值为：
ALL，等待所有内存访问指令。
DDR，等待GM访问指令。
UB，等待UB访问指令。
SEQ，预留参数，暂未启用，为后续的功能扩展做保留。
返回值
无。
支持的型号
Atlas A2 训练系列产品/Atlas 800I A2 推理产品
Atlas 200I/500 A2 推理产品
约束说明
无。
调用示例
AscendC::Mmad(...);
AscendC::DataSyncBarrier<MemDsbT::ALL>();
AscendC::Fixpipe(...);
```

This is the semantic distinction our problem turns on. `PipeBarrier<PIPE_ALL>()` is declared as
「阻塞相同流水」 — it orders instruction *issue* between pipes inside one core. `DataSyncBarrier<MemDsbT::DDR>()` is
declared as blocking until the *memory access instructions themselves have finished*. Only the second one can close
the window PPFM named: 「flag 已到、写回仍在途」.

It is declared in the public AscendC header alongside the other sync primitives (see §1):

```cpp
template <MemDsbT arg0>
__aicore__ inline void DataSyncBarrier();
```

### 31.7 `CrossCoreSetFlag` / `CrossCoreWaitFlag` — what they do and do not promise

https://www.hiascend.com/doc_center/source/zh/canncommercial/800/apiref/ascendcopapi/atlasascendc_api_07_0273.html
https://www.hiascend.com/doc_center/source/zh/canncommercial/800/apiref/ascendcopapi/atlasascendc_api_07_0274.html
CANN Commercial 8.0 API reference, 「核间同步」. Retrieved 2026-10-20. `CrossCoreSetFlag`, verbatim:

```
CrossCoreSetFlag(ISASI)
功能说明
面向分离架构的核间同步控制接口。
该接口和CrossCoreWaitFlag接口配合使用。使用时需传入核间同步的标记ID(flagId)，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。
同步控制分为以下几种模式，如图1所示：
模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。
模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。
模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后， 两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
函数原型
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
参数说明
modeId  核间同步的模式，取值范围为0~2。
pipe    设置这条指令所在的流水类型，流水类型可参考硬件流水类型。
flagId  输入  核间同步的标记。
Atlas A2 训练系列产品/Atlas 800I A2 推理产品，取值范围是0-10。
返回值
无
支持的型号
Atlas A2 训练系列产品/Atlas 800I A2 推理产品
约束说明
因为Matmul高阶API内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则会有flagID冲突的风险。
同一flagId的计数器最多设置16次。
调用示例
// 注意：如果调用高阶API,无需开发者处理AIC和AIV的同步
// AIC侧做完Matmul计算后通知AIV进行后处理
if (g_coreType == AscendC::AIC) {
 // Matmul处理
 AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8);
}
// AIV侧等待AIC Set消息, 进行Vector后处理
if (g_coreType == AscendC::AIV) {
 AscendC::CrossCoreWaitFlag(0x8);
 // Vector后处理
}
父主题： 核间同步
```

`CrossCoreWaitFlag`, verbatim:

```
CrossCoreWaitFlag(ISASI)
功能说明
面向分离架构的核间同步控制接口。该接口和CrossCoreSetFlag接口配合使用。具体使用方法请参考CrossCoreSetFlag。
函数原型
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId)
参数说明
modeId  核间同步的模式，取值范围为0~2。
pipe    设置这条指令所在的流水类型，流水类型可参考硬件流水类型。
flagId  输入  核间同步的标记。
Atlas A2 训练系列产品/Atlas 800I A2 推理产品，取值范围是0-10。
约束说明
CrossCoreWaitFlag必须与CrossCoreSetFlag接口配合使用，避免计算核一直处于阻塞阶段。
如果执行CrossCoreWaitFlag时该flagId的计数器的值为0，则CrossCoreWaitFlag之后的所有指令都将被阻塞，直到该flagId的计数器的值不为0。同一个flagId的计数器最多设置16次。
```

Three things to extract. (a) The entire documented semantics are a **counter**: set increments, wait decrements and
blocks at zero. Nothing in either page claims any memory-ordering or cache effect. The flag is a token, not a fence.
(b) 「因为Matmul高阶API内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则
会有flagID冲突的风险」 — the vendor explicitly advises against hand-rolling `CrossCoreSetFlag` in the same kernel as
the Matmul high-level API, which is exactly what a `Matmul<...>::IterateAll` + hand-written flag kernel does. See §20
for the per-arch occupancy table. (c) The published example uses flagId `0x8` with a bare, un-templated
`CrossCoreWaitFlag(0x8)` on the AIV side — which, per the header in §1, defaults to `modeId = 0, pipe = PIPE_S`:

```cpp
template <uint8_t modeId = 0, pipe_t pipe = PIPE_S>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId);
```

And flagId 8 is not neutral: `catlass` reserves it (§31.8).

### 31.8 `catlass/arch/cross_core_sync.hpp` — the 15-set limit in vendor source, and the reserved flagIds

https://gitcode.com/cann/catlass/blob/master/include/catlass/arch/cross_core_sync.hpp
raw: https://raw.gitcode.com/cann/catlass/raw/master/include/catlass/arch/cross_core_sync.hpp
Repo `cann/catlass`, branch `master`, copyright 2025 Huawei, CANN Open Software License Agreement Version 2.0.
Retrieved 2026-10-20. Verbatim, the whole substantive part of the file:

```cpp
// A certain cross core flag can be continuously set up to 15 times without waiting. In scenarios where there is only
// one-way synchronization between cores and the synchronization operation is executed multiple times, if the core
// performing the set operation runs faster, it may result in the flag being set more than 15 times consecutively,
// leading to a system freeze. To prevent such a freeze, we need to wait for the waiting cores to perform a reverse
// synchronization operation after executing the set operation MAX_REVERSE_DEPTH times.
constexpr uint32_t MAX_REVERSE_DEPTH = 15;

using FlagID = uint16_t;
constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
constexpr FlagID AIC_INTER_BLOCK_BARRIER = 9;
constexpr FlagID AIV_INTER_SUBBLOCK_BARRIER = 10;
constexpr FlagID FFTS_MAX_FLAG = 7;

struct CrossCoreFlag {
    CATLASS_DEVICE
    CrossCoreFlag() : id(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlag(FlagID id) : id(id)
    {}

    FlagID id;
};

template <uint32_t REVERSE_DEPTH_ = MAX_REVERSE_DEPTH>
struct CrossCoreFlagWithReverse {
    CATLASS_DEVICE
    CrossCoreFlagWithReverse() : id(0), reverseId(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlagWithReverse(FlagID id, FlagID reverseId) : id(id), reverseId(reverseId)
    {}

    FlagID id;
    FlagID reverseId;
    uint32_t count{0};
};

template <uint8_t MODE, int32_t CORE_TYPE>
struct BarrierFlag {
    static_assert(MODE != 255 && MODE == 255, "Unsupported cross core barrier flag, can not find the specialization.");
};

template <>
struct BarrierFlag<0x0, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x0, AscendC::AIC> {
    static constexpr FlagID ID = AIC_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x1, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_SUBBLOCK_BARRIER;
};

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreBarrier()
{
    constexpr FlagID flagId = BarrierFlag<MODE, g_coreType>::ID;
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flagId);
    AscendC::CrossCoreWaitFlag(flagId);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreSetFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
}

CATLASS_DEVICE
void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag<MODE, PIPE>(flag.id);
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreSetFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreWaitFlag(flag.reverseId);
        flag.count = 0;
    }
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreWaitFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.reverseId);
        flag.count = 0;
    }
}
```

This file answers two separate questions at once. For §31 it says flagId **8 is `AIV_INTER_BLOCK_BARRIER`** in vendor
library convention and 9 and 10 are the AIC inter-block and AIV inter-subblock barriers; `FFTS_MAX_FLAG = 7` marks the
boundary of what FFTS+ itself may use. For question 2's "78 layers of handshakes" it is the canonical answer —
`CrossCoreFlagWithReverse` + `CrossCoreSetFlagWithReverse`, which pairs every flag with a `reverseId` and, every
`REVERSE_DEPTH = 15` sets, blocks on the consumer's reverse set. That is how a one-way producer→consumer handshake
survives an unbounded number of stages: back-pressure every 15, not a reset.

### 31.9 `IterateAll` and `End` — what they guarantee

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0640.html
CANN Community Edition 9.0 API reference, 「Matmul Kernel侧接口」 → `IterateAll`. Retrieved 2026-10-20. Verbatim:

```
功能说明
调用一次IterateAll，会计算出singleCoreM * singleCoreN大小的C矩阵。迭代顺序可通过tiling参数iterateOrder调整。
函数原型
template <bool sync = true> __aicore__ inline void IterateAll(const GlobalTensor<DstT>& gm, uint8_t enAtomic = 0, bool enSequentialWrite = false, bool waitIterateAll = false, bool fakeMsg = false)
template <bool sync = true> __aicore__ inline void IterateAll(const LocalTensor<DstT>& ubCmatrix, uint8_t enAtomic = 0)
参数说明
sync
获取C矩阵过程分为同步和异步两种模式：
同步：需要同步等待IterateAll执行结束
异步：不需要同步等待IterateAll执行结束
通过该参数设置同步或者异步模式：同步模式设置为true；异步模式设置为false，默认为同步模式。
Atlas 200I/500 A2 推理产品只支持设置为true。
...
waitIterateAll
输入
仅在异步场景下使用，是否需要通过WaitIterateAll接口等待IterateAll执行结束。
true：需要通过WaitIterateAll接口等待IterateAll执行结束。
false：不需要通过WaitIterateAll接口等待IterateAll执行结束，开发者自行处理等待IterateAll执行结束的过程。
fakeMsg
输入
仅在IBShare场景（模板参数中开启了doIBShareNorm开关）和IntraBlockPartSum场景（模板参数中开启了intraBlockPartSum开关）使用。
...
约束说明
传入的C矩阵地址空间大小需要保证不小于singleCoreM * singleCoreN个元素。
调用示例
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, &tiling);
mm.SetTensorA(gm_a);
mm.SetTensorB(gm_b);
if (tiling.isBias) {
 mm.SetBias(gmBias);
}
mm.IterateAll(gm_c); // 计算
mm.End();
```

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0645.html
`End`. Retrieved 2026-10-20. Verbatim, complete:

```
End
功能说明
多个Matmul对象之间切换计算时，必须调用一次End函数，用于释放Matmul计算资源，防止多个Matmul对象的计算资源冲突。
函数原型
__aicore__ inline void End()
参数说明
无
返回值说明
无
约束说明
无
调用示例
mm1.IterateAll(gm_c1);
mm1.End();
mm2.IterateAll(gm_c2);
mm2.End();
```

So: `IterateAll<true>` (the default) does mean "wait for IterateAll to finish" at the issuing core, and `End()` is
documented purely as resource release — 「释放Matmul计算资源，防止多个Matmul对象的计算资源冲突」 — and is
**mandatory between two Matmul objects**, which is exactly the two-projection shape. Neither one says anything about
publishing the result to another core. There is no visibility guarantee anywhere in the Matmul API; it has to come
from §31.5/§31.6.

### 31.10 The third witness: scalar-store vs DMA incoherence, with a 12.9M-mismatch A/B

https://github.com/tile-ai/tilelang-ascend/pull/1834
Title 「[Bugfix] Scalar GM stores race MTE3 DMA through an incoherent write-back cache (#1304)」, author
`2Sheldonlaw` (commits authored by `m0_69757319`), opened 2026-09-23, closed 2026-09-28, head
`2Sheldonlaw:fix/copy-ub2gm-scalar-cache-1304-investigation` → base `tile-ai:ascendc_pto`, commits `e187fbe`,
`27b0a78`. Environment stated as Ascend910 A3 (dav-c220), CANN 9.0.0. Retrieved 2026-10-20.

The mechanism, verbatim fragments as published:

```
标量路径「经过写回缓存」：写 4 字节前先从 GM 拉入整条 64B cache line（read-modify-write），标脏，
把该行的写回推迟到逐出时。
MTE3 DMA 则「绕过该缓存直写 GM」。
```
```
t1: row oh 的标量尾触发 RMW → 下一行头部的旧值（0）被夹带进写回缓存（标脏）
t2: row oh+1 的 DMA 把正确新值写进 GM（绕过缓存）
t3: t1 的脏行被逐出 → 整条 64B 写回 GM → 旧值 0 覆盖 t2 的新值 ✗
```
```
DataCacheCleanAndInvalid<ENTIRE_DATA_CACHE, CACHELINE_OUT> before the DMA
```

and the scoping fact that matters for a megakernel, verbatim: both `dcci` and `MTE3_S` are 「本核作用域的」 — this
core's scope only — which is why synchronization alone left ~27% residual mismatches when t1/t3 ran on core A and t2
on core B. Measured: 12,967,510 → 3,496,136 mismatches with commit 1 (−73%), → 0 with commit 2 (which rewrote the
scalar store loop into a UB staging buffer plus one DMA burst). A template-level fix was rejected for ~12% slowdown
on GM-traffic-heavy kernels. `AllocateEventId` was also changed to cycle 1..7 instead of 0..7 because the C++
template `copy_gm_to_ub` in `tl_templates/ascend/common.h` hard-codes event id 0, and a pass-emitted id-0 allocation
on kernels with 8+ sync points collapsed two sets into one and deadlocked the second wait.

### 31.11 SuperKernel confirms the framework normally issues DCCI ALL around every operator

Already quoted in §19 and §22, repeated here because it is the direct confirmation the question asked for.
`cap` bit 4, verbatim:

```
• 4：disable_dcci，表示当前算子需要SuperKernel框架关闭调用前后的DCCI ALL指令。
```

and the TorchAir default, verbatim:

```
•当dcci_before_kernel_start、dcci_after_kernel_end和dcci_disable_on_kernel均未配置时，子算子内部调用GlobalTensor的GetValue/SetValue时默认不自动插入缓存刷新指令，SuperKernel默认会在所有子算子调用后插入DataCacheCleanAndInvalid指令刷新ENTIRE_DATA_CACHE。
```

and the single-operator compile behaviour, verbatim from §19:

```
- 在单算子编译场景下，毕昇编译器自动在算子末尾添加DataCacheCleanAndInvalid指令，刷新整个DCache（数据缓存）。
```
```
在开发自定义算子时，开发者必须确保所有对GM的标量读写操作都按需正确插入DataCacheCleanAndInvalid指令。
```

Confirmed, then: in the ordinary single-operator path the Bisheng compiler appends a whole-DCache
`DataCacheCleanAndInvalid` at the **end of the operator**, and SuperKernel by default inserts a
`ENTIRE_DATA_CACHE` DCCI **after every sub-operator call**. Both are per-operator-boundary flushes. A hand-written
megakernel that fuses 78 layers into one launch crosses zero operator boundaries, therefore receives exactly one
trailing flush for the whole kernel, and must issue every intermediate flush itself.

## Relevance
This is the answer to the blocking `mix_expert_kernel.cpp` failure: 0/0/416/672/896/896 wrong of 1024 across six runs
of one binary, with `partial` downloaded to the host always bit-correct, and wrong values being 0 — AIV saw zeros.
- The matching report is verbatim in §31.1: 「实测（PPFM_DIAG 指纹）：AIV 读到 vTmp 全 0，而 AIC 实际写了
  -0.013/+0.0092」, on `arch22` = DAV_2201, with the race named as 「flag 已到、写回仍在途」 and the note
  「加探针即掩盖」 — which is why our host readback is always clean.
- The ordering to write, both sides, is therefore:
  producer `Matmul::IterateAll(...)` → `End()` → `DataCacheCleanAndInvalid<int32_t, CacheLine::ENTIRE_DATA_CACHE,
  DcciDst::CACHELINE_OUT>(partialGlobal)` → `DataSyncBarrier<MemDsbT::DDR>()` → `PipeBarrier<PIPE_FIX>()` →
  `CrossCoreSetFlag<0x02, PIPE_FIX>(flag)`; consumer `CrossCoreWaitFlag<0x02, PIPE_MTE2>(flag)` →
  `DataCacheCleanAndInvalid<int32_t, ENTIRE_DATA_CACHE, CACHELINE_OUT>(partialGlobal)` →
  `DataSyncBarrier<MemDsbT::DDR>()` → `DataCopy`. `PipeBarrier<PIPE_ALL>()` cannot substitute: it is documented as
  「阻塞相同流水」, an issue-order barrier, whereas `DataSyncBarrier` blocks until the memory accesses themselves
  retire (§31.6).
- PPFM's own A/B (§31.3) says which half pays: W1R1 → 9/60 failures, W0R1 → 1/60. The producer's **DSB** and the
  consumer's **invalidate** are load-bearing; the producer's DCCI was not. Start with both on, then A/B the producer
  DCCI away — it is an `ENTIRE_DATA_CACHE` flush, the expensive one, and at 2.x ms TPOT we cannot afford one per
  stage per layer.
- Two further suspects in the same kernel, independent of cache coherence. (i) `CrossCoreWaitFlag(8)` with no
  template arguments resolves to `modeId = 0, pipe = PIPE_S` (§31.7 header). Mode 0 is the all-AIV inter-block sync,
  not the AIC↔AIV mode, and PPFM measured that on A2 a `PIPE_S` wait lets the following MTE2 issue early and read
  「半新半旧」 C — they use `CrossCoreWaitFlag<0x2, PIPE_MTE2>` on 2201 for exactly this. (That measurement sits
  against §20's official claim that on 2201 the `pipe` argument is inert and all pipes block; the conflict is
  unresolved, but writing `<0x02, PIPE_MTE2>` costs nothing.) (ii) flagId 8 is `AIV_INTER_BLOCK_BARRIER` in
  `catlass` (§31.8) and the vendor explicitly warns against mixing hand-written `CrossCoreSetFlag` with the Matmul
  high-level API because of flagId collision (§31.7) — and this kernel does both, with two Matmul objects.
- `End()` is **mandatory** between two Matmul objects (§31.9), which is the two-projection shape in
  `mix_expert_kernel.cpp`; but it is resource release only and buys no visibility.
- §31.4's tier-1-vs-tier-2 result is the design lesson for the per-layer kernel: hardening the one handoff you
  suspect left ~19/2000 trials still wrong; only hardening *every* cross-core GM buffer removed the drift. For 78
  fused layers that means the visibility protocol has to be a property of the buffer abstraction, not something
  sprinkled at suspected sites.
- §31.11 closes the question the `disable_dcci` capability bit raised: the Bisheng compiler appends a whole-DCache
  DCCI at the end of each single operator and SuperKernel inserts an `ENTIRE_DATA_CACHE` DCCI after every
  sub-operator by default. Our 3008 kernels/round each got one for free. One fused kernel per layer gets 78 instead
  of 3008, so the flushes we now need inside the kernel are ours to place — and their cost is a new line item
  against the 11.5 ms launch floor we are trying to remove.
- §31.8's `CrossCoreFlagWithReverse` / `MAX_REVERSE_DEPTH = 15` is the pre-answer to question 2.1.


---

## 32. `matmul_fused_manual` — the vendor's own A3 `ASCENDC_CUBE_ONLY` + manual `CrossCoreSetFlag` sample, complete, and what it does *not* do

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_fused_manual/README.md
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_fused_manual/matmul_fused_manual.asc
Repo `cann/asc-devkit`, branch `master`. Copyright 2025 Huawei, CANN Open Software License Agreement Version 2.0.
Retrieved 2026-10-20.

This is the nearest official analogue of `tests/glm52/mixbrick/mix_expert_kernel.cpp`: the same `ASCENDC_CUBE_ONLY`
pure-Cube Matmul object, the same `IterateAll` to a `GlobalTensor`, the same hand-written `CrossCoreSetFlag` /
`CrossCoreWaitFlag` handoff, the same `__mix__(1, 2)`, the same `<<<>>>` launch, the same `dav-2201`.

Its own description of itself, verbatim:

```
# 融合编程matmul_fused_manual样例

## 概述

分核AIC、AIV融合编程实现，主要介绍了Matmul高阶API的纯Cube模式，需要调用相关接口实现手动控制AIC、AIV的核间同步。

## 本样例支持的产品及CANN软件版本

| 产品 | CANN软件版本 |
|------|-------------|
| Ascend 950PR&950DT系列产品 | >= CANN 9.1.0 |
| Atlas A3系列产品 | >= CANN 9.0.0 |
| Atlas A2系列产品 | >= CANN 9.0.0 |

## 样例描述

- 样例功能：
  本样例在AIC核创建纯Cube模式的Matmul对象，实现Matmul计算，中间结果输出至GM。AIC核计算完成后，通过调用CrossCoreSetFlag和CrossCoreWaitFlag接口手动控制核间同步，继续在AIV核对GM上的中间结果进行LeakyRelu的计算。

- 样例规格：
  本样例中：M = 128, N = 128, K = 256
```

and its documented handoff, verbatim:

```
  - Kernel关键步骤
    - AIC侧具体步骤：
      - 创建Matmul对象并初始化。
        在#include "lib/matmul_intf.h"前配置ASCENDC_CUBE_ONLY宏，创建纯Cube模式的Matmul对象
          ```cpp
          #define ASCENDC_CUBE_ONLY
          #include "lib/matmul_intf.h"
          ```
      - 完成Matmul计算。
      - 设置核间同步。
        ```cpp
        if ASCEND_IS_AIC {
          AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(3);
        }
        ```
    - AIV侧具体步骤：
      - 创建LeakyRelu对象并初始化。
      - 等待核间同步。
        ```cpp
        if ASCEND_IS_AIV {
          AscendC::CrossCoreWaitFlag<0x2>(3);
        }
        ```
      - 完成LeakyRelu计算。
```

and the stated acceptance criterion, verbatim:

```
- 执行结果

  执行结果如下，说明精度对比成功：
  ```bash
  test pass!
  ```
```

The build line, verbatim — `dav-2201` is the default and A2/A3 both map to it:

```
  cmake -DCMAKE_ASC_ARCHITECTURES=dav-2201 ..;make -j;             # 编译工程，默认npu模式
```
```
  | `CMAKE_ASC_ARCHITECTURES` | `dav-2201`（默认）、`dav-3510` | NPU 架构：dav-2201 对应 Atlas A2系列产品和 Atlas A3系列产品，dav-3510 对应 Ascend 950PR&950DT系列产品 |
```

### 32.1 The kernel, verbatim

The entry point and the handoff, verbatim and complete:

```cpp
extern "C" __global__ __mix__(1, 2) void matmul_fused_manual_custom(
    __gm__ uint8_t* a, __gm__ uint8_t* b, __gm__ uint8_t* bias, __gm__ uint8_t* c,
    __gm__ uint8_t* __kfc_workspace__ workspace, __gm__ uint8_t* tilingGm)
{
    AscendC::TPipe pipe;
    TCubeTiling tiling;
    CopyTiling(&tiling, tilingGm);

    if ASCEND_IS_AIC {
        MatmulLeakyKernel<half, half, float, float> matmulLeakyKernel;
        matmulLeakyKernel.Init(a, b, bias, c, workspace, tiling, &pipe);
        REGIST_MATMUL_OBJ(
            &pipe, GetSysWorkSpacePtr(), matmulLeakyKernel.matmulObj,
            &matmulLeakyKernel.tiling); // Initialize the matmul object.
        matmulLeakyKernel.Process(&pipe);
        AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(3);
    }
    if ASCEND_IS_AIV {
        LeakyReluKernel<float> leakyReluKernel;
        leakyReluKernel.Init(c, tiling, &pipe);
        AscendC::CrossCoreWaitFlag<0x2>(3);
        leakyReluKernel.Process(&pipe);
    }
}
```

The Matmul object's declared types — note the **C matrix is declared `TPosition::VECIN`**, not `GM`, even though
`IterateAll` is handed a `GlobalTensor`:

```cpp
    Matmul<
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, AType>,
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BType>,
        MatmulType<AscendC::TPosition::VECIN, CubeFormat::ND, CType>,
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BiasType>>
        matmulObj;
```

`Process` — the whole cube side, verbatim. `End()` is called, and it is called **before** the flag set:

```cpp
template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::Process(AscendC::TPipe* pipe)
{
    matmulObj.SetTensorA(aGlobal);
    matmulObj.SetTensorB(bGlobal);
    matmulObj.SetBias(biasGlobal);

    matmulObj.template IterateAll(cGlobal);
    matmulObj.End();
}
```

The consumer side, verbatim — a bare `DataCopy` from the same `c` pointer the cube wrote, with no cache op:

```cpp
template <typename CType>
__aicore__ inline void LeakyReluKernel<CType>::Init(__gm__ uint8_t* c, const TCubeTiling& tiling, AscendC::TPipe* pipe)
{
    this->tiling = tiling;
    // c:v = 1:2, split into 2 parts, for vector calculation.
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ CType*>(c) + AscendC::GetBlockIdx() * tiling.M * tiling.N / 2);

    // Init input buffer.
    pipe->InitBuffer(reluInQueue_, 1, tiling.singleCoreM * tiling.singleCoreN * sizeof(CType) / 2);
    // Init output buffer.
    pipe->InitBuffer(reluOutQueue_, 1, tiling.singleCoreM * tiling.singleCoreN * sizeof(CType) / 2);
}
```
```cpp
template <typename CType>
__aicore__ inline void LeakyReluKernel<CType>::LeakyReluCopyIn(const TCubeTiling& tiling)
{
    AscendC::LocalTensor<float> reluInLocal = reluInQueue_.AllocTensor<float>();
    AscendC::DataCopy(reluInLocal, cGlobal, tiling.singleCoreM * tiling.singleCoreN / 2);
    reluInQueue_.EnQue<float>(reluInLocal);
}
```

The tiling, verbatim — one `baseM = baseN = 128` tile, i.e. a single `Iterate` worth of work, `FIRSTM` traversal, and
the tiling side declares the result position as **GM** while the kernel side declared it `VECIN`:

```cpp
    matmul_tiling::TPosition resultPosition = matmul_tiling::TPosition::GM;
    matmul_tiling::CubeFormat resultFormat = matmul_tiling::CubeFormat::ND;
    matmul_tiling::DataType resultDtype = matmul_tiling::DataType::DT_FLOAT;
```
```cpp
    int baseM = 128;
    int baseN = 128;
```
```cpp
    tilingApi.SetOrgShape(M, N, K);
    tilingApi.SetShape(M, N, K);
    tilingApi.SetBias(isBias);
    tilingApi.SetTraverse(matmul_tiling::MatrixTraverse::FIRSTM); // Set the matmul traverse is FIRSTM.
    tilingApi.SetFixSplit(baseM, baseN, -1);                      // Set the fixed baseM=128, baseN=128.
    tilingApi.SetBufferSpace(-1, -1, -1);
```

And the launch, verbatim — **one block**:

```cpp
    uint32_t numBlocks = 1;
```
```cpp
    matmul_fused_manual_custom<<<numBlocks, 0, stream>>>(
        inputADevice, inputBDevice, inputBiasDevice, outputCDevice, workspaceDevice, tilingDevice);
```

### 32.2 What the sample omits

Enumerated plainly, because the absences are the finding. The sample contains, across the whole file:
no `DataCacheCleanAndInvalid`, no `DataSyncBarrier`, no `PipeBarrier` of any pipe, and no `SetFlag`/`WaitFlag`.
The entire producer-to-consumer protocol is three lines:

```cpp
    matmulObj.template IterateAll(cGlobal);
    matmulObj.End();
    AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(3);
```
```cpp
    AscendC::CrossCoreWaitFlag<0x2>(3);
```

Four structural differences from our failing kernel, any of which could be why the sample gets away with it:
`numBlocks = 1` (our brick launches `<<<blocks>>>` with blocks > 1, and §4 records mode 2 as documented to leak
across MIX blocks at `blockDim > 1`); a single `IterateAll` of a single `baseM × baseN = 128 × 128` tile (ours is two
projections); `flagId = 3`, not 8 — 8 is `catlass`'s `AIV_INTER_BLOCK_BARRIER` (§31.8); and the mode template
argument is written out on the wait, `CrossCoreWaitFlag<0x2>(3)`, so only `pipe` takes its default.

## Relevance
This is the "known-good hand-written MIX kernel passing cube results to the vector side through global memory,
documented to be correct" that the brick was looking for, and it is structurally identical to
`tests/glm52/mixbrick/mix_expert_kernel.cpp` down to the `__mix__(1, 2)`, `ASCENDC_CUBE_ONLY`, `IterateAll` to GM and
`CrossCoreSetFlag<0x2, PIPE_FIX>`. Copy its skeleton.
- But read it against §31 rather than instead of §31. The sample's acceptance criterion is a single `test pass!` on
  M=N=128, K=256, one block, one tile. The failures §31 documents are probabilistic at rates of 19/2000 trials,
  9/60 processes, and our own 2-of-6 runs clean — a rate that one verification run of one shape cannot distinguish
  from correct. The sample is evidence that the flag-only protocol is *sufficient at blockDim = 1 on one tile*. It is
  not evidence that it is sufficient at `blockDim > 1` across 78 layers, and the three third-party kernels in §31 all
  broke in exactly the regime the sample does not enter.
- Two free corrections it hands us regardless: `End()` goes **between** `IterateAll` and the flag set, and the
  wait should be written `CrossCoreWaitFlag<0x2>(...)` with the mode spelled out (our bare `CrossCoreWaitFlag(8)`
  takes `modeId = 0`, the all-AIV inter-block mode, per the header in §1). And move off flagId 8.
- The `MatmulType<TPosition::VECIN, ...>` for C while the host tiling says `TPosition::GM` is the vendor's own
  configuration for this pattern — worth copying exactly rather than "fixing", since the Matmul high-level API's
  choice of fixpipe path depends on it.
- `__gm__ uint8_t* __kfc_workspace__ workspace` is the attribute that marks the KFC (kernel function call) workspace
  argument in a `__mix__` kernel; our brick must carry it too, sized from
  `ascendcPlatform->GetLibApiWorkSpaceSize()`.
- The sample's one-tile shape is also a reminder of the economics: at `M = 1` decode our MIX_AIC launch floor is
  13.58 us against a GroupedMatmul family that spends 5.596 ms moving 1.212 ms of bytes. The brick exists to delete
  the launch, not to make the tile faster.


---

## 33. `MixDualMaster` — turning off the AIV→AIC message drive, on A3, with `ASCENDC_CUBE_ONLY`

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_mixdualmaster/README.md
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_mixdualmaster/matmul_mixdualmaster.asc
Repo `cann/asc-devkit`, branch `master`. Copyright 2025 Huawei, CANN Open Software License Agreement Version 2.0.
Retrieved 2026-10-20.

The README, verbatim and in full for the substantive part:

```
# Matmul 双主模式直调样例
## 概述
使能双主模式（MixDualMaster）的Matmul样例，AIC和AIV独立运行代码，不依赖消息驱动，用于提升性能。

Matmul API在默认的MIX模式下，通过消息机制由AIV驱动AIC运行；而在双主模式下，AIC和AIV独立运行代码，不依赖消息驱动，性能更优。
当满足以下条件之一时，可以开启双主模式：
- 核函数类型为MIX，且AIC核数：AIV核数=1：1
- 核函数类型为MIX，且AIC核数：AIV核数=1：2，且A矩阵和B矩阵同时使能IBSHARE参数

## 本样例支持的产品及CANN软件版本

| 产品 | CANN软件版本 |
|------|-------------|
| Ascend 950PR&950DT系列产品 | >= CANN 9.1.0 |
| Atlas A3系列产品 | >= CANN 9.0.0 |
| Atlas A2系列产品 | >= CANN 9.0.0 |
```

and its acceptance criterion, verbatim: 「执行结果如下，说明精度对比成功：`test pass!`」, built with
`cmake -DCMAKE_ASC_ARCHITECTURES=dav-2201`.

The switch, verbatim — one `MatmulConfig` field off `CFG_NORM`:

```cpp
__aicore__ inline constexpr MatmulConfig GetCustomCFG()
{
    auto mmCfg = CFG_NORM;
    mmCfg.enableMixDualMaster = true;
    return mmCfg;
}
```

The Matmul object, verbatim — note `IBSHARE` is the **sixth** `MatmulType` template argument, `true` on both A and B,
which is what the 1:2 ratio requires:

```cpp
    constexpr static MatmulConfig CUSTOM_CFG = GetCustomCFG();
    // Enable IBSHARE parameters for matrix A and matrix B
    AscendC::Matmul<
        AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, AType, IS_TRANS_A, LayoutMode::NONE, true>,
        AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BType, IS_TRANS_B, LayoutMode::NONE, true>,
        AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, CType>,
        AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BiasType>, CUSTOM_CFG>
        matmulObj;
```

The entry point, verbatim — declared `__cube__`, **not** `__mix__`, with `ASCENDC_CUBE_ONLY` defined before
`lib/matmul_intf.h`, and no `ASCEND_IS_AIC` / `ASCEND_IS_AIV` split at all:

```cpp
#define ASCENDC_CUBE_ONLY
#include "lib/matmul_intf.h"

constexpr uint32_t M = 12288;
constexpr uint32_t N = 256;
constexpr uint32_t K = 128;
constexpr bool IS_TRANS_A = false;
constexpr bool IS_TRANS_B = false;
constexpr bool IS_BIAS = true;
```
```cpp
__global__ __cube__ void matmul_mixdualmaster_custom(
    __gm__ uint8_t* a, __gm__ uint8_t* b, __gm__ uint8_t* bias, __gm__ uint8_t* c, __gm__ uint8_t* workspace,
    __gm__ uint8_t* tilingGm)
{
    TCubeTiling tiling;
    CopyTiling(&tiling, tilingGm);
    AscendC::TPipe pipe;

    MatmulKernel<half, half, float, float> matmulKernel;
    REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), matmulKernel.matmulObj, &tiling);
    matmulKernel.Init(a, b, bias, c, tiling);
    matmulKernel.Process();
}
```

The compute body, verbatim — `SetTail` for the ragged edge, then `IterateAll` then `End()`:

```cpp
    // process with tail block
    int tailM = tiling.M - mCoreIndex * tiling.singleCoreM;
    tailM = tailM < tiling.singleCoreM ? tailM : tiling.singleCoreM;
    int tailN = tiling.N - nCoreIndex * tiling.singleCoreN;
    tailN = tailN < tiling.singleCoreN ? tailN : tiling.singleCoreN;
    if (tailM < tiling.singleCoreM || tailN < tiling.singleCoreN) {
        matmulObj.SetTail(tailM, tailN);
    }

    matmulObj.SetTensorA(aGlobal, IS_TRANS_A);
    matmulObj.SetTensorB(bGlobal, IS_TRANS_B);
    if (tiling.isBias) {
        matmulObj.SetBias(biasGlobal);
    }
    matmulObj.IterateAll(cGlobal);
    matmulObj.End();
```

and the host side, verbatim — the grid is the AIC core count, taken from the tiling:

```cpp
    tilingApi.SetDim(ascendcPlatform->GetCoreNumAic());
```
```cpp
    uint32_t numBlocks = reinterpret_cast<TCubeTiling*>(tilingBuf)->usedCoreNum;
```

## Relevance
This is the named, A3-supported mechanism for deleting the thing that makes a MIX launch cost 13.58 us instead of
2.30 us: 「Matmul API在默认的MIX模式下，通过消息机制由AIV驱动AIC运行；而在双主模式下，AIC和AIV独立运行代码，不依赖消息
驱动，性能更优」. 505 MIX_AIC calls/round at 13.58 us is 6.86 ms of our 11.6198 ms TPOT, and §15 already showed the
MIX controller as the cost `ASCENDC_CUBE_ONLY` is meant to avoid — `enableMixDualMaster` is the matching
`MatmulConfig` field.
- The eligibility rule is the catch, verbatim: either 1:1 AIC:AIV, or 1:2 **with IBSHARE enabled on both A and B**.
  Our brick is `KERNEL_TYPE_MIX_AIC_1_2`, so the 1:2 branch applies and both operands must be IBShare. §11 records
  the A3 restriction that comes with that: 「Atlas A3 训练系列产品 / Atlas A3 推理系列产品，获取矩阵计算结果时，只支持
  调用IterateAll接口，且只支持输出到GlobalTensor」 — which is already what the brick does, so the two constraints are
  compatible. But IBShare on A *and* B means both operands are L1-resident and shared across Matmul objects, which
  for our W4A8 routed experts (128 columns of `moe_intermediate` per rank) is a real tiling constraint, not a free
  switch.
- Note what the sample is *not*: it is a pure-cube `__global__ __cube__` kernel with no vector half and therefore no
  cross-core handoff. So it demonstrates the config flag and its eligibility rule, not a dual-master CV handoff. The
  combination we actually want — `enableMixDualMaster` plus a hand-written `CrossCoreSetFlag` to an AIV half — is not
  exhibited by any sample found.
- `SetTail(tailM, tailN)` is the documented way to run the ragged last tile without a second Matmul object, which at
  M=1 decode with 128 columns per rank is the normal case rather than the exception.


---

## 34. The official 220x memory model for AIC→AIV — the vendor says the flag *is* the ordering mechanism

https://www.hiascend.com/doc_center/source/zh/canncommercial/83RC1/opdevg/Ascendcopdevg/atlas_ascendc_10_0011.html
CANN Commercial 8.3.RC1 算子开发指南 → 架构规格 → 「NPU架构版本220」. This page covers
「Atlas A3 训练系列产品 / Atlas A3 推理系列产品 / Atlas A2 训练系列产品 / Atlas A2 推理系列产品」, i.e. our
DAV_2201. Retrieved 2026-10-20.

This is the authoritative statement of the question §31 was asked about, and it answers it in the opposite
direction. Read §31 and §34 together; the contradiction is the finding.

The architecture, verbatim:

```
如下图所示，本架构中AI Core分为AIC和AIV两个独立的核，分别用于矩阵计算和向量计算。每个核都有自己的Scalar单元，能独立加载自己的代码段。AIV与AIC之间通过Global Memory进行数据传递。
```

The inter-core section, verbatim and complete:

```
 核间同步 
 当不同核之间操作同一块全局内存时，可能存在读后写、写后读以及写后写等数据依赖问题，需要进行核间同步控制。
 核间同步控制分为以下几种模式，如下图所示：
 模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。
 模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。
 模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后， 两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
 例如，在AIC中将L0C的计算结果搬运到GM后，AIV需要将GM的数据搬运到UB。此时，可以使用CrossCoreSetFlag和CrossCoreWaitFlag命令，确保数据从L0C成功搬运到GM后，再从GM搬运到UB，流程如下图所示。
 CrossCoreSetFlag和CrossCoreWaitFlag接口配合使用。使用时需传入核间同步的标记ID(flagId)，即上图中的ID1，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。flagId取值范围是0-10。
 需要注意以下几点：
 成对使用
 CrossCoreSetFlag和CrossCoreWaitFlag必须成对使用，否则可能导致算子超时问题。
 一致性要求
 CrossCoreSetFlag 的模板参数和flagId必须与CrossCoreWaitFlag完全一致，否则视为不同的flagId。例如，CrossCoreSetFlag<0x0, PIPE_MTE3>(0x8) 和 CrossCoreSetFlag<0x2, PIPE_FIX>(0x8) 设置的不是同一个flagId。
 避免连续设置
 不允许连续设置同一个flagId，以防止计数器状态混乱。
 与高阶 API 的使用冲突
 Matmul高阶API内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则会有flagId冲突的风险。
 计数器限制
 同一flagId的计数器最多可以设置15次。
 默认流水类型
 CrossCoreWaitFlag不需要显式设置指令所在的流水类型，默认使用PIPE_S。
```

The intra-core section, verbatim — the `SetFlag`/`WaitFlag` identity rule and the reserved event ids:

```
 核内同步 
 由于AI Core内部的执行单元（如MTE2搬运单元、Vector计算单元等）以异步并行的方式运行，在读写Local Memory（如Unified Buffer）时可能存在数据依赖关系。为确保数据一致性及计算正确性，需通过同步控制协调操作时序。
...
 需要注意以下几点： 
 建议通过AllocEventID或者FetchEventID接口获取EventID，以确保其合法性和有效性。
 EventID的数量有限，使用后应立即调用ReleaseEventID释放资源，避免EventID耗尽，影响系统正常运行。
 SetFlag和WaitFlag必须成对使用，且SetFlag和WaitFlag的参数必须完全一致（包括模板参数和事件ID）。如果不匹配，可能导致当前核的计算异常，或影响下一个核的算子执行，引发timeout问题。 
 例如，SetFlag<HardEvent::S_MTE3>(1)和SetFlag<HardEvent::MTE3_MTE1>(1)设置的不是同一个EventID，因为其模板参数不同。只有当模板参数和事件ID完全一致时，才表示同一个EventID。
 不允许连续设置同一个EventID，因为这可能导致事件状态混乱或未被正确处理。
 不建议手动插入 TEventID，不能手动插入6和7的TEventID，因为它们可能被系统预留或用于特殊用途。
```

The Fixpipe capability list, verbatim — this is the quantisation and activation set available *on the way out of
L0C*, i.e. for free, before the result ever reaches GM:

```
 支持Fixpipe硬件化加速
 Fixpipe是NPU将典型操作进行硬化的加速模块，位于AIC内部，配合Cube计算单元完成随路计算，主要功能如下：
 量化反量化：包括S322FP16、S322S32、S322S4、S322S8、S322S16、FP322FP16、FP322BF16、FP322S8、FP322S4、FP322FP32。
 Relu功能，包括ReLu、PReLu和Leaky ReLu等典型的激活函数。
 数据格式转换，包括： 
 通过Channel merge、Channel split可以实现分形大小的转换，保证输出到L1 Buffer/GM的分形满足诉求。
 NZ2ND数据格式转换。
```

and the alignment table, verbatim:

```
 核 存储单元 对齐要求
 AIV Unified Buffer 32Byte对齐。
 AIC L1 Buffer 32Byte对齐。
 L0A Buffer 512Byte对齐。
 L0B Buffer 512Byte对齐。
 L0C Buffer 64Byte对齐。
 BiasTable Buffer 64Byte对齐。
```

and the cross-card note, verbatim — relevant to the TP reduce, since it says `DataCopy` itself can cross cards but
only over HCCS on A2:

```
 支持跨卡数据搬运（Hccs物理链路）
 在跨卡通信算子开发场景，DataCopy类接口支持跨卡数据搬运，在
 Atlas A2 训练系列产品 / Atlas A2 推理系列产品
 设备上，仅支持Hccs物理链路，不支持其他通路；开发者开发过程中，请关注涉及卡间通信的物理通路； 通过npu-smi info -t topo指令查询Hccs 物理通路。
```

## Relevance
This page is the official answer to "what makes an AIC's global write visible to an AIV's `DataCopy`", and the answer
it gives is: the flag, and nothing else. Verbatim, in exactly our scenario:
「例如，在AIC中将L0C的计算结果搬运到GM后，AIV需要将GM的数据搬运到UB。此时，可以使用CrossCoreSetFlag和
CrossCoreWaitFlag命令，**确保数据从L0C成功搬运到GM后，再从GM搬运到UB**」. No cache maintenance is mentioned
anywhere on the page. Combined with §32's vendor sample, which carries no DCCI either, the documented contract is
flag-only.
- Against that stand the three measured third-party failures in §31 on this same DAV_2201, including one whose
  symptom is ours to the letter (AIV reads all zeros where AIC wrote nonzero). The resolution is not available from
  any source found: either the hardware does not honour the documented contract in some regime (multi-block, multi-
  tile, high occupancy), or all three kernels had a different bug that DCCI happened to mask. Treat the DCCI+DSB as
  an empirical workaround with a measured effect, not as the documented rule — and A/B it rather than adopting it.
- Four hard constraints to take at face value, all new or sharper than what §20 and §4 carried:
  (a) 「CrossCoreSetFlag 的模板参数和flagId必须与CrossCoreWaitFlag完全一致，否则视为不同的flagId」 — the Set's
  template arguments must match the Wait's exactly, or they are different flagIds. Our brick sets
  `<0x02, PIPE_FIX>(8)` and waits with a bare `CrossCoreWaitFlag(8)`, which is `<0x0, PIPE_S>`. By the letter of this
  rule those are two different flags and the wait should block forever. It does not — the kernel produces output —
  and the same page's own 「默认流水类型：CrossCoreWaitFlag不需要显式设置指令所在的流水类型，默认使用PIPE_S」 plus
  §20's 「在NPU架构版本2201上，CrossCoreWaitFlag传入的pipe参数无效」 plus the `CrossCoreSetFlag` page's own example
  pairing `<0x2, PIPE_FIX>(0x8)` with a bare `CrossCoreWaitFlag(0x8)` all say the Wait's template arguments are not
  part of the flag's identity on 2201. So the consistency requirement is, in practice, about matching two *Sets* —
  which is how the page's own illustration reads, both of its examples being `CrossCoreSetFlag`. Write
  `CrossCoreWaitFlag<0x02>(...)` anyway, as `matmul_fused_manual` does; it costs nothing and removes the ambiguity.
  (b) 「同一flagId的计数器最多可以设置15次」 — **15** here, against 「同一flagId的计数器最多设置16次」 on both the
  `CrossCoreSetFlag` and `CrossCoreWaitFlag` API pages (§31.7) and 「continuously set up to 15 times」 in `catlass`
  (§31.8). Two of three sources say 15; design to 15.
  (c) 「不允许连续设置同一个flagId」 — restated, and it is the reason §31.3's `AicSetToAiv` sets once under mode 2
  rather than once per AIV.
  (d) 「不建议手动插入 TEventID，不能手动插入6和7的TEventID」 — intra-core event ids 6 and 7 are reserved, which
  narrows the usable `SetFlag`/`WaitFlag` event space to 0-5 per pipe pair, tighter than the "8 ids" figure in
  `ascend-launch-overhead-and-sync.md` §3. Note `tile-ai/tilelang-ascend` PR #1834 (§31.10) independently moved its
  allocator to cycle 1..7 for a different reason (a template hard-coding id 0).
- The Fixpipe list is a direct lever on our measured numbers. `Cast` costs 2.300 ms/round against 0.076 ms of bytes
  moved — a pure overhead family — and Fixpipe does `S322FP16`, `S322S8`, `S322S16`, `FP322BF16`, `FP322S8` and
  ReLU/PReLU/LeakyReLU *in the AIC on the way out of L0C*. For W4A8 routed experts producing INT32, the
  `S322S8`/`S322FP16` conversion and the NZ2ND format change can happen before the data is ever written, which both
  removes the Cast and shrinks the GM traffic the AIV must then read back.
- 「AIV与AIC之间通过Global Memory进行数据传递」 is the official confirmation of README finding 3b: there is no
  L0C→UB path on 220x, so a per-layer fused kernel's cube→vector edge is always a GM round trip, and the only
  question is whether it stays in L2.


---

## 35. `asc.gitcode.com` — the full AscendC API reference as static HTML, and the definitive 2201 cache model it contains

### 35.0 The source itself

https://asc.gitcode.com/api/
A complete mirror of the Ascend C API reference, served as static HTML (VitePress), with a product-version selector
listing 「全量 / Ascend 950 / Atlas A3 / Atlas A2 / Atlas 训练系列 / Atlas 推理系列 / Atlas 200I/500 A2 / Kirin X90 /
Kirin 9030」, and **every page carries an explicit 「产品支持情况」 block naming Atlas A3 by name**. Retrieved
2026-10-20.

This matters operationally: `hiascend.com/document/detail/...` is a JavaScript SPA that returns an empty body to a
fetcher, and `hiascend.com/doc_center/source/...` works but has a sparse, undiscoverable id space (see this file's
Gaps). `asc.gitcode.com` resolves by readable path and contains the sidebar of every page, so one fetch yields the
whole URL map. URL shape:

```
https://asc.gitcode.com/api/SIMD-API/基础API/同步控制/核间同步/SyncAll.html
https://asc.gitcode.com/api/SIMD-API/基础API/同步控制/核内同步/DataSyncBarrier_ISASI.html
https://asc.gitcode.com/api/SIMD-API/基础API/缓存控制/系统缓存概述.html
https://asc.gitcode.com/api/SIMD-API/基础API/缓存控制/DataCacheCleanAndInvalid.html
https://asc.gitcode.com/api/SIMD-API/基础API/标量计算/WriteGmByPassDCache_ISASI.html
https://asc.gitcode.com/api/SIMD-API/基础API/标量计算/ReadGmByPassDCache_ISASI.html
https://asc.gitcode.com/api/SIMD-API/基础API/cube_compute_ISASI/矩阵计算的搬出/Fixpipe_L0CToUB.html
```
(percent-encode the Chinese path segments.) It is also newer than the CANN 8.0 `doc_center` copies quoted in §31:
several pages carry content those do not.

### 35.1 「系统缓存概述」 — the authoritative per-cache coherence table for 2201

https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E7%BC%93%E5%AD%98%E6%8E%A7%E5%88%B6/%E7%B3%BB%E7%BB%9F%E7%BC%93%E5%AD%98%E6%A6%82%E8%BF%B0.html
Retrieved 2026-10-20. This is the page `WriteGmByPassDCache` cross-references as 「Cache写策略与Cache一致性问题」.
Verbatim, the parts that settle §31 and §34:

```
表1 Cache类型及功能说明 
Cache类型
说明
L2 Cache
L2 Cache作为二级缓存，专门用于存储频繁访问的数据和指令，以便减少对GM的读写。
•通过MTE2单元读取GM时，优先从L2 Cache中读取数据；当L2 Cache未命中时，再从GM加载数据并更新到L2 Cache中。
•通过Scalar单元读取GM时，优先从DCache中读取数据；当DCache未命中时，再从L2 Cache中读取数据。当L2 Cache也未命中时，再从GM加载数据并更新到L2 Cache和DCache中。
•通过Scalar单元读取GM指令时，优先从ICache中读取指令；当ICache未命中时，再从L2 Cache中读取指令。当L2 Cache也未命中时，再从GM加载指令并更新到L2 Cache和ICache中。
DCache
DCache（Data Cache）用于缓存Scalar单元近期可能被重复访问的数据段。
通过Scalar单元读取GM时，优先从DCache中读取数据；当DCache未命中时，再从L2 Cache中读取数据。当L2 Cache也未命中时，再从GM加载数据并更新到L2 Cache和DCache中。
ICache
ICache（Instruction Cache）用于缓存Scalar单元最近使用或频繁使用的指令。
```

and the architecture inventory, verbatim:

```
以NPU架构版本3510为例，图1展示了AI Core中支持的五类Cache（L2 Cache、DCache、ICache、SIMT DCache、NDDMA Cache）在硬件架构中的位置关系。
以NPU架构版本2201为例，图2展示了AI Core中支持的三类Cache（L2 Cache、DCache和ICache）在硬件架构中的位置关系。
```

the write policies, verbatim:

```
Cache写策略与Cache一致性问题​
当向GM写入数据，并且启用Cache时，存在以下两种Cache写策略：延迟写回（Write-Back）和直写（Write-Through）。
当向GM写数据时采取延迟写回策略，工作原理如下：
开发者预期向GM写入数据（即期望数据直接写入GM），硬件实际行为是：
当数据被修改时，只在缓存中更新数据。
缓存中的数据标记为“脏”。
当该Cache Line被替换时（或通过软件显式执行Clean操作时），数据才会被写回GM，Cache Line何时被替换由硬件决定。
...
在延迟写回策略下，被修改的数据仅更新在本地缓存中，不会立即同步到GM。当其他核读取GM上同一地址时，获取的将是过时数据，从而导致不同核间缓存数据不一致。 Cache一致性是多核中确保数据正确性的核心机制。简单来说，当多个核各自拥有独立的Cache时，它们可能同时缓存相同的数据。如果某个核修改了缓存中的数据，其他核的缓存副本就会变得“过时”，如果不及时同步，就会导致多个核间的数据不一致，进而引发计算错误。
```

and — the single most load-bearing paragraph in this file — the per-cache verdict for **our architecture**, verbatim:

```
针对NPU架构版本2201，支持的三类Cache在多核间数据一致性方面的情况如下： L2 Cache：多核间共享的缓存，因此不需要考虑多核间数据不一致的问题。
DCache：多核独立缓存，因此需要考虑多核间数据一致性的问题。
ICache：只读，因此不需要考虑多核间数据不一致的问题。
```

the four cache operations, verbatim — note that `Invalid` discards dirty lines:

```
表2 Cache操作及功能说明
操作名称
功能说明
Prefetch
硬件根据访问模式自动将预期访问的数据提前加载到缓存，提升后续访问速度。
Preload
软件通过显式指令将指定数据主动加载到缓存，为即将到来的读写操作做准备。
Invalid
•将指定地址范围的Cache Line（缓存的最小操作单元）标记为“无效”，使其从缓存中移除。
•保证下一次访问这些内存地址时，会从GM重新加载数据，而不是使用可能过期的缓存数据。
•注意：Invalid操作不检查缓存行是否为“脏”（dirty，表示该数据已被修改但尚未写回到GM），若存在脏数据将被直接丢弃。
Clean
将缓存中被修改过的数据（脏数据）写回到GM中，避免数据丢失。Clean操作不将缓存行标记为“无效”，缓存行仍保持有效状态。
```

and the control-interface summary, verbatim:

```
表3 缓存控制接口汇总
L2 Cache  SetL2CacheHint  读写GM的数据都默认被缓存在L2 Cache（默认启用L2 Cache），SetL2CacheHint能够设置GlobalTensor是否启用L2 Cache。
DCache  DataCachePreload  DataCachePreload接口从源地址所在的特定GM地址预加载数据到DCache中，每次调用只能预加载一个Cache Line大小的数据。
DCache  DataCacheCleanAndInvalid  当Scalar单元访问GM时，使用该接口刷新Cache，保证Cache的一致性，使用场景如下：
•读取GM的数据，但该数据可能在外部被其余核修改，此时需要使用DataCacheCleanAndInvalid接口，直接访问GM，获取最新数据。
•用户通过Scalar单元写GM的数据，希望立刻写出，也需要使用DataCacheCleanAndInvalid接口。
DCache  ReadGmByPassDCache/WriteGmByPassDCache  不经过DCache向GM地址上读/写数据。使用场景：
•当多个核写入的数据落在同一条Cache Line内时，经过DCache的读写将以64B为粒度，可能引发多核数据随机覆盖问题。使用该接口不经过DCache直接按操作数大小读/写GM，可避免此问题。
•使用该接口不经过DCache直接向GM读/写数据，可避免由DCache缓存引发的多核间数据不一致问题。
ICache  ICachePreLoad  开发者手动调用ICachePreLoad接口，能够从指令所在GM地址预加载指令到ICache中。
ICache  GetICachePreloadStatus  GetICachePreloadStatus为调试接口，在调用ICachePreLoad后调用，用于获取ICache的PreLoad的状态。当返回值为0时，说明ICache的PreLoad已完成；当返回值为1时，说明ICache的PreLoad未完成。
NDDMA Cache  NdDmaDci  在使用DataCopy（GMToUB多维数据搬运NDDMA）接口进行数据搬运前，需要使用NdDmaDci接口刷新NDDMA Cache缓存保证为最新状态。
```

### 35.2 `DataSyncBarrier` — the official cross-core publication idiom, with a complete worked example

https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E5%90%8C%E6%AD%A5%E6%8E%A7%E5%88%B6/%E6%A0%B8%E5%86%85%E5%90%8C%E6%AD%A5/DataSyncBarrier_ISASI.html
Retrieved 2026-10-20. This page is materially different from the CANN 8.0 copy in §31.6 — the `MemDsbT::ALL`
definition is narrower and `SEQ` is now live. Verbatim:

```
DataSyncBarrier(ISASI)
产品支持情况​
Ascend 950PR/Ascend 950DT：支持
Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
Atlas A2 训练系列产品/Atlas A2 推理系列产品：支持
Atlas 200I/500 A2 推理产品：支持
Atlas 推理系列产品AI Core：不支持
Atlas 推理系列产品Vector Core：不支持
Atlas 训练系列产品：不支持
功能说明​
头文件路径为："basic_api/kernel_operator_block_sync_intf.h"。
阻塞后续的指令执行，直到所有之前的内存访问指令（需要等待的内存位置可通过参数控制）执行结束，用于解决Scalar的内存依赖。
函数原型​
template <MemDsbT arg0>
__aicore__ inline void DataSyncBarrier()
参数说明​
arg0
模板参数，表示需要等待的内存位置，类型为MemDsbT，可取值为：
• ALL，等待GM和UB的访问指令（不包括其他内存位置，例如L0C Buffer、L1 Buffer）。
• DDR，等待GM访问指令。
• UB，等待UB访问指令。
• SEQ，等待SEQ访问指令。
约束说明​
等待的内存位置取值为ALL时，只能等待GM和UB的访问指令，不包括其他内存位置，例如L0C Buffer、L1 Buffer。
```

and its 调用示例, verbatim and complete — this is a producer/consumer handoff between two blocks with **no
`CrossCoreSetFlag` at all**, just a GM flag, `DataSyncBarrier<DDR>` and the bypass-DCache accessors:

```cpp
if (blockIdx == 0) {
 // 先写入被依赖数据，再通过DataSyncBarrier等待GM访问完成。
 AscendC::WriteGmByPassDCache<T>(reinterpret_cast<__gm__ T *>(srcGm) + 1, DATA_VALUE);
 // DataSyncBarrier<DDR>阻塞后续GM写，确保上一条GM写对其他核可见。
 AscendC::DataSyncBarrier<AscendC::MemDsbT::DDR>();
 // 最后写入同步标记，block 1读到该标记后即可安全读取srcGm[1]。
 AscendC::WriteGmByPassDCache<T>(reinterpret_cast<__gm__ T *>(srcGm), SYNC_FLAG);
 }
 if (blockIdx == 1) {
 while (true) {
 __gm__ T *addr = const_cast<__gm__ T *>(srcGlobal.GetPhyAddr());
 // 轮询GM第0个元素，等待block 0写入同步标记。
 T flagValue = AscendC::ReadGmByPassDCache<T>(addr);
 if (flagValue == SYNC_FLAG) {
 // DataSyncBarrier保证同步标记之前的srcGm[1]写入已完成。
 T dataValue = AscendC::ReadGmByPassDCache<T>(addr + 1);
 AscendC::WriteGmByPassDCache<T>(reinterpret_cast<__gm__ T *>(dstGm), 2 * dataValue);
 return;
 }
 }
 }
```

### 35.3 `WriteGmByPassDCache` / `ReadGmByPassDCache` — A3-supported, and the ordering rule between them and DCCI

https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E6%A0%87%E9%87%8F%E8%AE%A1%E7%AE%97/WriteGmByPassDCache_ISASI.html
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E6%A0%87%E9%87%8F%E8%AE%A1%E7%AE%97/ReadGmByPassDCache_ISASI.html
Retrieved 2026-10-20. Verbatim:

```
WriteGmByPassDCache(ISASI)
产品支持情况​
Ascend 950PR/Ascend 950DT：支持
Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
Atlas A2 训练系列产品/Atlas A2 推理系列产品：支持
Atlas 200I/500 A2 推理产品：不支持
Atlas 推理系列产品AI Core：不支持
Atlas 推理系列产品Vector Core：不支持
Atlas 训练系列产品：不支持
功能说明​
头文件路径为："basic_api/kernel_operator_scalar_intf.h"。
不经过DCache向GM地址上写数据。使用场景：
当多个核写入的数据落在同一条Cache Line内时，经过DCache的读写将以64B为粒度，可能引发多核数据随机覆盖问题（参考DataCacheCleanAndInvalid调用示例3）。使用该接口不经过DCache直接按操作数大小写GM，可避免此问题。
经过DCache写GM时可能导致多核间的数据不一致问题（详细原因请参考Cache写策略与Cache一致性问题），使用该接口不经过DCache直接向GM写数据，可避免此问题。
由于WriteGmByPassDCache接口向GM写数据时不经过DCache，因此开发者需要考虑如下场景：
当GM上地址addr已经在DCache缓存并且其对应的Cache Line标记为“脏”（dirty，表示该数据已被修改但尚未写回到GM）时，开发者应该在WriteGmByPassDCache接口之前调用DataCacheCleanAndInvalid接口将addr对应的Cache Line立即写回GM，否则WriteGmByPassDCache接口写入addr的数据后续可能被DCache写回的脏数据覆盖。
DataCacheCleanAndInvalid接口与WriteGmByPassDCache接口向GM写数据时硬件不能保证两个接口的执行顺序，因此开发者应该在WriteGmByPassDCache接口之前调用DataSyncBarrier接口对这两个接口进行同步，否则WriteGmByPassDCache接口写入addr的数据依然可能被DCache写回的脏数据覆盖。
根据以上的描述，为了简化编程（开发者无需关心addr是否在DCache缓存以及是否被标记为“脏”），建议开发者在使用WriteGmByPassDCache接口时采用如下代码片段：
```
```cpp
AscendC::GlobalTensor<T> global; // global为addr对应的GlobalTensor
AscendC::DataCacheCleanAndInvalid<T, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global);
// 保证WriteGmByPassDCache接口向addr写入value之前，DCache中的脏数据已经写回GM。
AscendC::DataSyncBarrier<AscendC::MemDsbT::DDR>();
AscendC::WriteGmByPassDCache<T>(addr, value);
```
```
函数原型​
template <typename T>
__aicore__ inline void WriteGmByPassDCache(__gm__ T* addr, T value)
数据类型​
支持的数据类型为int8_t、uint8_t、int16_t、uint16_t、int32_t、uint32_t、int64_t、uint64_t。
```
```
ReadGmByPassDCache(ISASI)
功能说明​
头文件路径为："basic_api/kernel_operator_scalar_intf.h"。
不经过DCache从GM地址上读数据。
函数原型​
template <typename T>
__aicore__ inline T ReadGmByPassDCache(__gm__ T* addr)
数据类型​
支持的数据类型为int8_t、uint8_t、int16_t、uint16_t、int32_t、uint32_t、int64_t、uint64_t。
```

### 35.4 The A3 cube→vector data-path support matrix, checked page by page

Each of these is the verbatim 「产品支持情况」 line for `Atlas A3 训练系列产品/Atlas A3 推理系列产品`, from the
mirror, retrieved 2026-10-20.

`Fixpipe（L0C Buffer到UB数据搬运）` —
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/cube_compute_ISASI/%E7%9F%A9%E9%98%B5%E8%AE%A1%E7%AE%97%E7%9A%84%E6%90%AC%E5%87%BA/Fixpipe_L0CToUB.html
```
Ascend 950PR/Ascend 950DT：支持包含FixpipeParamsArch3510参数的接口。
Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
Atlas A2 训练系列产品/Atlas A2 推理系列产品：不支持
Atlas 200I/500 A2 推理产品：支持包含FixpipeParamsM300参数的接口。
```

`DataCopy（L0C Buffer到UB数据搬运）` —
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/cube_compute_ISASI/%E7%9F%A9%E9%98%B5%E8%AE%A1%E7%AE%97%E7%9A%84%E6%90%AC%E5%87%BA/DataCopy_L0CToUB.html
```
说明： 本接口搬运功能仅在Atlas 推理系列产品AI Core产品型号的L0C Buffer->UB（CO1 -> CO2）通路支持。其他型号和其他通路支持接口调用但功能不生效，功能等同于基础数据搬运。
Ascend 950PR/Ascend 950DT：不支持
Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
Atlas A2 训练系列产品/Atlas A2 推理系列产品：不支持
```

`DataCopyL1ToUB（L1到UB数据搬运）` —
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/cube_compute_ISASI/%E7%9F%A9%E9%98%B5%E8%AE%A1%E7%AE%97%E7%9A%84%E6%90%AC%E5%87%BA/DataCopyL1ToUB.html
```
Ascend 950PR/Ascend 950DT：支持
Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
Atlas A2 训练系列产品/Atlas A2 推理系列产品：不支持
```
and its constraint, verbatim — worth recording for the 950 port even though A3 lacks it:
```
该接口仅适用于Mix算子场景，且仅支持Cube核数与Vector核数比例为1:2的配置。在该场景下，subBlockId仅支持取值0或1。
如果需要执行多个DataCopyL1ToUB指令，且DataCopyL1ToUB的目的地址存在重叠，需要通过调用PipeBarrier(ISASI)来插入同步指令，保证多个DataCopyL1ToUB指令的串行化，防止出现异常数据。
```
with `subBlockId` documented as 「AI Core上的Vector核ID。根据输入的Vector核ID，将数据搬运至对应核上的UB地址。」

`Fixpipe（L0C到L1数据搬运）` — the one on-chip egress A3 *does* have —
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/cube_compute_ISASI/%E7%9F%A9%E9%98%B5%E8%AE%A1%E7%AE%97%E7%9A%84%E6%90%AC%E5%87%BA/Fixpipe_L0CToL1.html
```
Ascend 950PR/Ascend 950DT：支持包含FixpipeParamsV220/FixpipeParamsArch3510参数的接口。
Atlas A3 训练系列产品/Atlas A3 推理系列产品：仅支持包含FixpipeParamsV220参数的接口。
Atlas A2 训练系列产品/Atlas A2 推理系列产品：仅支持包含FixpipeParamsV220参数的接口。
```
with the A3-specific caveat on its `config`, verbatim:
```
  • CFG_ROW_MAJOR（默认取值）：开启NZ2ND，输出数据格式为ND格式。针对Atlas A3 训练系列产品/Atlas A3 推理系列产品，
Atlas A2 训练系列产品/Atlas A2 推理系列产品，
在L0C Buffer -> L1 Buffer通路下不生效。
  • CFG_NZ：NZ2NZ，输出数据格式为NZ格式。
```

### 35.5 `SyncAll` on A3 — a MIX grid barrier that does three syncs in one, and its 2201 flagId bill

https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E5%90%8C%E6%AD%A5%E6%8E%A7%E5%88%B6/%E6%A0%B8%E9%97%B4%E5%90%8C%E6%AD%A5/SyncAll.html
Retrieved 2026-10-20. The three prototypes and their A3 support, verbatim:

```
软同步原型​
Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
硬同步（不支持config指定流水）原型​
Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
硬同步（支持config指定流水）原型​
Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
```

the semantics, verbatim — the fused-operator hard sync is three barriers in one instruction:

```
SyncAll是核间同步控制接口，根据不同的函数原型介绍其功能：
硬件同步接口： 用于多个核之间的同步控制，支持以下同步场景：
纯Vector算子的全核同步，可参考CrossCoreSetFlag的模式0。
融合算子的全核同步，一次性实现三个核间同步能力（参考CrossCoreSetFlag的关键特性说明）：首先完成单个AI Core内，AIC与所有AIV同步（AIC等AIV）；接着完成多个AI Core间，所有AIC的同步；最后完成单个AI Core内，所有AIV与AIC同步（AIV等AIC）。
软件同步接口： 仅支持纯Vector算子的多核（参与同步的核数可通过入参指定）同步。每一个AIV都向全局内存对应位置写入信号值1，接着每一个AIV都持续轮询全局内存中所有AIV对应的信号值，直到所有AIV核对应的信号值都变为1。
在纯Vector算子场景中，若所有AIV核默认参与同步，推荐采用性能更优的硬件同步接口；若需指定部分AIV核参与同步，则应使用软件同步接口，并通过入参usedCores完成配置。
```

the hard-sync constraints, verbatim — the kernel-modifier requirement and the `isAIVOnly` traps:

```
硬件同步接口约束：
使用硬同步接口时，需根据场景使用合适的核函数修饰符：
在纯Vector算子，需使用__mix__(0, 1)修饰核函数，而不是使用__vector__，具体原因请参考CrossCoreSetFlag约束说明中的Kernel类型配置说明。
对于Mix（包含Cube和Vector计算）算子，需使用__mix__(1, 1)或__mix__(1, 2)修饰核函数。
对于纯Vector算子，模板参数isAIVOnly必须设置为true，否则会导致程序卡死。
对于Mix（包含Cube和Vector计算）算子，模板参数isAIVOnly设置为true，会导致接口实际只能完成Vector全核同步与预期同步行为不符。
使用该接口时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
多流并发场景（≥2条执行流）。
≥2个算子并发执行。
所有并发算子的核数总和超过物理核数。
≥2个并发算子使用了核间同步功能。
具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。 Kernel直调场景下通过__schedmode__(mode)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式
```

the flagId bill for 2201, verbatim:

```
SyncAll硬件同步接口内部实现中使用了CrossCoreSetFlag和CrossCoreWaitFlag进行核间同步控制，因此开发者同时使用CrossCoreSetFlag（或CrossCoreWaitFlag）和SyncAll硬件同步接口时，需注意避免以下flagId冲突：
表4 SyncAll硬件同步接口flagId占用情况
SyncAll 使用场景
占用flagId汇总
各计算核flagId占用情况
isAIVOnly=true
14
AIV：14
isAIVOnly=false
11、12、13
AIC：11、12、13；AIV：12、13
```
(and for 3510, for comparison: 「isAIVOnly=false（核函数使用__mix__(1, 2)修饰时）| 11、12、13、28、29」.)

the common constraint, verbatim:

```
硬件同步接口和软件同步接口公共约束：使用该接口进行多核控制时，算子调用时指定的逻辑AI Core核数numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel“卡死”现象。
```

and the soft-sync sizing, verbatim:

```
软件同步接口约束：
gmWorkspace缓存申请的空间大小要求大于等于GetBlockNum()*32Bytes，并且缓存的值需要初始化为0。目前常见的有两种初始化方式： 通过在host侧进行初始化操作，确保传入该接口时，gmWorkspace缓存已经初始化为0；
在kernel侧初始化的时候对gmWorkspace缓存初始化，需要注意的是，每个核上都需要初始化全部的gmWorkspace缓存空间。
ubWorkspace申请的空间大小要求大于等于GetBlockNum()*32Bytes。
usedCores传入数值不能超过算子调用时指定的逻辑AI Core中AIV的数量：GetBlockNum()*GetTaskRatio()，不传此参数表示全核软同步。
```

and `SyncAllConfig`, which A3 does **not** get, verbatim:

```
struct SyncAllConfig {
 pipe_t triggerPipe;
 pipe_t waitPipe;
};
// 默认使用全部流水来进行触发和等待行为。
constexpr SyncAllConfig DEFAULT_SYNC_ALL_CONFIG = {PIPE_ALL, PIPE_ALL};
• triggerPipe：指定哪个流水用于“发送触发信号”。仅支持MTE2、MTE3、PIPE_ALL。
• waitPipe：指定哪个流水用于“接收等待信号”。仅支持MTE2、MTE3、PIPE_ALL。
```

## Relevance
§35.1 settles question 1.1, and it revises the recommendation I drew from §31. On NPU architecture 2201, verbatim:
「L2 Cache：多核间共享的缓存，因此不需要考虑多核间数据不一致的问题。DCache：多核独立缓存，因此需要考虑多核间数据
一致性的问题。」 — and 「通过MTE2单元读取GM时，优先从L2 Cache中读取数据」. So:
- **The AIC→FIXPIPE→GM→MTE2→AIV path has no cache-coherence problem on A3.** Both ends go through the shared L2.
  The only incoherent cache on 2201 is the per-core DCache, which only the **Scalar** unit uses. That is exactly what
  the `DataCacheCleanAndInvalid` page means by 「Scalar单元访问Global Memory ... 存在 ... 一致性问题」, and it is why
  §31's producer-side DCCI on a FIXPIPE-written buffer was aimed at the wrong cache — which is also, retrospectively,
  why PPFM's measured A/B found the producer DCCI *unnecessary* (W0R1 1/60 beat W1R1 9/60) while the producer's
  `DataSyncBarrier` stayed in.
- **What `mix_expert_kernel.cpp` is missing is completion ordering, not cache maintenance.** The primitive for it is
  named and its contract is quoted in the vendor's own example comment: 「DataSyncBarrier<DDR>阻塞后续GM写，确保上一条
  GM写对其他核可见」. So the minimal correct producer sequence is `IterateAll` → `End()` →
  `DataSyncBarrier<MemDsbT::DDR>()` → `CrossCoreSetFlag<0x02, PIPE_FIX>(flag)`, and the consumer needs **nothing**
  beyond `CrossCoreWaitFlag<0x02>(flag)` → `DataCopy`, unless it also touches the buffer with Scalar
  (`GetValue`/`SetValue`). One instruction, no `ENTIRE_DATA_CACHE` flush, no per-stage cost worth measuring. Try
  that before the §31 protocol.
- **Caveat on `MemDsbT`:** 「ALL，等待GM和UB的访问指令（不包括其他内存位置，例如L0C Buffer、L1 Buffer）」. `ALL` does
  not cover L0C or L1, so there is no `DataSyncBarrier` flavour that waits on the cube's own L0C staging; the FIXPIPE
  write to GM is what `DDR` covers, which is the edge we need. Note also that the CANN 8.0 page in §31.6 defined
  `ALL` as 「等待所有内存访问指令」 and `SEQ` as reserved; the newer page narrows `ALL` and activates `SEQ`. Use the
  newer wording.
- **For every flag, counter and epoch tag in the megakernel, use `WriteGmByPassDCache` / `ReadGmByPassDCache`
  instead of `GetValue`/`SetValue` + DCCI.** Both are A3-supported, both are in
  `basic_api/kernel_operator_scalar_intf.h`, and §35.2's example is a complete host-barrier-free producer/consumer
  handoff built from nothing but them plus `DataSyncBarrier<DDR>` — no `CrossCoreSetFlag` at all. That is the
  building block for question 2.1 (78 layers of handshakes without burning flagIds), question 2.3 (epoch-tagged
  in-kernel collective) and question 2.4 (GM-counter grid reduction), and it sidesteps the flagId budget entirely.
  The one rule to respect, verbatim: DCCI and `WriteGmByPassDCache` have no hardware-guaranteed order, so a
  `DataSyncBarrier` must separate them — the vendor's own three-line recipe is quoted in §35.3.
- §35.4 **confirms README finding 3b rather than overturning it**, and closes the "go via L1" idea: on A3,
  `Fixpipe(L0C→UB)` 不支持, `DataCopy(L0C→UB)` 不支持, and `DataCopyL1ToUB` 不支持. `Fixpipe(L0C→L1)` *is* supported
  (with `FixpipeParamsV220`), but with no L1→UB egress, L1 is only useful for feeding back into the cube. So the
  cube→vector edge of a per-layer kernel is unavoidably `L0C → Fixpipe → GM → MTE2 → UB` and the design goal stays
  "stay in L2", consistent with the measured `aiv_mte2_time` 320.543 → 57.145 us when fused.
- §35.5 is a grid barrier for a MIX megakernel that we did not have. `SyncAll<false>()` under `__mix__(1, 2)` does
  three barriers in one — AIC waits all its AIVs, then all AICs across blocks, then all AIVs wait their AIC — which
  is exactly the inter-layer boundary a 78-layer fused kernel needs, and it costs flagIds **11, 12, 13** on 2201
  rather than any of the hand-allocatable ones. Two traps to encode now: `isAIVOnly=true` in a MIX kernel silently
  degrades to a Vector-only barrier (「与预期同步行为不符」), and `numBlocks` must not exceed the physical core count
  or the framework's multi-round scheduling inserts a bad sync and hangs. `__schedmode__` is restated as the
  anti-deadlock requirement, with the four co-occurring conditions spelled out — consistent with
  `ascend-fusion-mechanics.md` §25's measured 3-hangs-in-49.
- Finally, §35.0 is a tooling result for this channel: every future AscendC API question should start at
  `asc.gitcode.com`, because it is static, path-addressable, newer than the `doc_center` copies, and states A3
  support explicitly on every page.


---

## 36. Grid-wide (cross-block) reduction on A3: `SyncAll` verified first-hand, the atomics that exist, and the canonical per-token row max

Collected 2026-10-20 for question 2.4, "the dynamic-quantisation row maximum as a cross-block
reduction". Everything below is verbatim. This complements §35.5, which quotes the `SyncAll` API
page; this section quotes the **implementation** and the kernels that use it.

## Relevance
The answer to "how do hand-written kernels do a grid-wide reduction on A3" turns out to be
"mostly they don't", and that is the useful result.
- **The canonical CANN grid-wide row max is not atomics.**
  `ops-nn/quant/dynamic_quant/.../pertoken_large_multicore.h` does
  `ProcessScaleRow(); SyncAll(); ProcessScaleCol();` — one float per core published into a GM
  workspace by `DataCopyPad` (MTE3, so inside the barrier's reach), then a second reduce pass. A
  sweep of `hicann/ops-nn` found **no** kernel using `SetAtomicMax` for a row max.
- `SetAtomicMax` does exist on A3 (UB/L0C/L1 → GM; int8/int16/half/bf16/int32/float), but it does
  not auto-zero GM, and on arch 2201 integers and bf16 are **non-saturating by default** with
  saturation settable only via `npu-smi` — two sharp edges for a W4A8 dynamic-quant path.
- The no-argument `SyncAll<isAIVOnly>()` is **two FFTS instructions**, needs no workspace, and
  performs no cache maintenance. Flag 14 for AIV-only, 11/12/13 for mixed — matching the §35.5
  table. The `SyncAllConfig` overload is gated to `__NPU_ARCH__ ∈ {3510, 5102, 5162, 9201, 9202}`:
  **2201 is excluded**, and there is no `dav_2201` impl directory — A3 is served by `dav_c220`.
- The soft form takes a GM workspace and is **itself epoch-counted** —
  `curValue = *localUb + 1`, terminate on `count >= totalBlocks * curValue` — so it never needs the
  workspace zeroed between calls. That is the pattern to copy for a 78-layer kernel: a counter that
  only goes up, compared against `blocks × generation`, rather than a flag that must be reset.
- Two best-case results for us: B4 and B5 show per-token dynamic quant done with **no grid
  reduction at all** — per-core row ownership with a two-pass sweep over column tiles, and the row
  max never leaving the core inside a Catlass-style matmul epilogue. At batch=1, seq_len 8K, our
  row count is 1, so the row-ownership form degenerates to "one core owns the row" and the
  cross-block reduction disappears. Check that before building a barrier.
- The official memory-model chapter at `asc.gitcode.com/.../cache_coherence.html` names
  `NPU架构版本2201` and gives its cache geometry: L2 line 512 B / 192 MB, AIC DCache 64 B / 16 KB,
  AIV DCache 64 B / 32 KB — and requires a DSB **after** DCCI to wait for the write-back, which
  `shmem`'s own `dcci_cacheline` does not do (it uses only `__asm__ __volatile__("")` compiler
  barriers). That sharpens §35: DCCI alone does not wait, so any hand-written flag protocol that
  uses DCCI must follow it with `DataSyncBarrier<MemDsbT::DDR>()`.
- `SyncAll` is **mutually exclusive with the shmem barriers** and both depend on the `ffts` config
  being set at kernel entry — so a layer kernel cannot use `SyncAll` for its inter-layer boundary
  and `aclshmem_barrier_all` for its TP edge. Pick one.

# TOPIC B — grid-wide (cross-block) reduction on A3 in a hand-written kernel

## B1. A hand-written cross-rank + cross-core sync in a real fused megakernel — `SyncAll` sandwiching an epoch-counted remote flag

https://raw.githubusercontent.com/immengzi/shmem/master/examples/dispatch_gmm_combine/include/sync_util.h
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04 — complete file

This is the closest published artifact to a hand-rolled `tp_push`: no host barrier, `SyncAll`
for the intra-die grid barrier, a monotone epoch `count` for the inter-die flags, a 16 × int32
(= 64 B, one cacheline) stride per rank slot, and `dcci` on both sides.

```cpp
#ifndef SYNC_UTIL_H
#define SYNC_UTIL_H
#include "kernel_operator.h"
using namespace AscendC;

#define FORCE_INLINE_AICORE inline __attribute__((always_inline)) __aicore__
constexpr int32_t BUFF_SIZE = 500 * 1024 * 1024;
constexpr int32_t FLAG_OFFSET = 500 * 1024 * 1024 / sizeof(int32_t);


template<typename T>
FORCE_INLINE_AICORE void gm_store(__gm__ T *addr, T val) {
    *((__gm__ T *)addr) = val;
}

template<typename T>
FORCE_INLINE_AICORE T gm_load(__gm__ T *cache) {
    return *((__gm__ T *)cache);
}

FORCE_INLINE_AICORE void gm_dcci(__gm__ uint8_t * addr) {
    using namespace AscendC;
    GlobalTensor<uint8_t> global;
    global.SetGlobalBuffer(addr);

    // Important: add hint to avoid dcci being optimized by compiler
    __asm__ __volatile__("");
    DataCacheCleanAndInvalid<uint8_t, CacheLine::SINGLE_CACHE_LINE, DcciDst::CACHELINE_OUT>(global);
    __asm__ __volatile__("");
}

FORCE_INLINE_AICORE int32_t gm_signal_wait_until_eq_for_barrier(__gm__ int32_t *sig_addr, int32_t cmp_val) {
    do {
        gm_dcci((__gm__ uint8_t *)sig_addr);

        if (*sig_addr == cmp_val) {
            return *sig_addr;
        }

        // in case when peer pe enters next barrier
        if (*sig_addr == cmp_val + 1) {
            return *sig_addr;
        }
    } while (true);

    return -1;
}
 
FORCE_INLINE_AICORE void CrossRankSync(GM_ADDR symmetricPtr, int32_t rank, int32_t rankSize)
{
    // 全核同步
    __gm__ int32_t* sync_counter = (__gm__ int32_t*)symmetricPtr + FLAG_OFFSET;
    __gm__ int32_t* sync_base = (__gm__ int32_t*)symmetricPtr + FLAG_OFFSET + 1024;
    int count = gm_load(sync_base) + 1;
    int vec_id = AscendC::GetBlockIdx();
    int vec_size = AscendC::GetBlockNum() * AscendC::GetTaskRation();
    for (int i = vec_id; i < rankSize; i += vec_size) {
        __gm__ int32_t* sync_remote = (__gm__ int32_t*)(aclshmem_ptr(symmetricPtr, i)) + FLAG_OFFSET + rank * 16;
        gm_store(sync_remote, count);
        gm_dcci((__gm__ uint8_t*)sync_remote);
        auto sync_check = sync_counter + i * 16;
        gm_signal_wait_until_eq_for_barrier(sync_check, count);
    }

    AscendC::SyncAll<true>();
    gm_store(sync_base, count);
}

// 全卡同步接口
FORCE_INLINE_AICORE void CrossRankSyncV1(GM_ADDR symmetricPtr, int32_t rank, int32_t rankSize)
{
    // 全核同步
    AscendC::SyncAll<true>();
    __gm__ int32_t* sync_counter = (__gm__ int32_t*)symmetricPtr + FLAG_OFFSET;
    __gm__ int32_t* sync_base = (__gm__ int32_t*)symmetricPtr + FLAG_OFFSET + 32;
    int count = gm_load(sync_base) + 1;
    int vec_id = AscendC::GetBlockIdx();
    int vec_size = AscendC::GetBlockNum() * AscendC::GetTaskRation();
    for (int i = vec_id; i < rankSize; i += vec_size) {
        __gm__ int32_t* sync_remote = (__gm__ int32_t*)(aclshmem_ptr(symmetricPtr, i)) + FLAG_OFFSET + rank * 16;
        gm_store(sync_remote, count);
        gm_dcci((__gm__ uint8_t*)sync_remote);
        auto sync_check = sync_counter + i * 16;
        gm_signal_wait_until_eq_for_barrier(sync_check, count);
    }

    AscendC::SyncAll<true>();
    gm_store(sync_base, count);
}
#endif
```

Note the signature difference between the two: `CrossRankSync` does flag exchange *then*
`SyncAll`; `CrossRankSyncV1` brackets it with `SyncAll` on both sides. `AscendC::SyncAll<true>()`
is the AIV-only template form, called with no workspace argument (i.e. the hard-sync form).

## B2. The two forms of intra-die grid barrier, side by side, with the selection condition

https://raw.githubusercontent.com/immengzi/shmem/master/src/device/gm2gm/shmemi_device_cc.h
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04 (lines 74-83)

```cpp
/* Level 1: barrier between vec cores (within a device) */
template<bool IS_AIV_ONLY>
ACLSHMEM_DEVICE void aclshmemi_barrier_core()
{
#ifdef __CCE_AICORE_ENABLE_MIX__
    AscendC::SyncAll<IS_AIV_ONLY>();
#else
    aclshmemi_barrier_core_soft();
#endif
}
```

i.e. the library uses the hardware `SyncAll` *only* in MIX kernels, and falls back to its own
GM-flag dissemination barrier (`aclshmemi_barrier_core_soft`, quoted verbatim in A9) otherwise.
The soft form needs two GM regions (`core_sync_pool`, `core_sync_counter`) that are allocated at
`aclshmem_init` time, uses `ACLSHMEM_LOG_MAX_AIV_PER_NPU` slots per core, and is epoch-counted
rather than zeroed.

## B3. `SyncAll` is mutually exclusive with the shmem barriers, and both depend on the `ffts` config

https://raw.githubusercontent.com/immengzi/shmem/master/include/device/gm2gm/shmem_device_cc.h
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04 (lines 13-33)

```c
/*
    WARNING：Restrictions of Barrier APIs.

    1. Barrier APIs can be used only in MIX kernels. The compiler will optimize the kernel to VEC or CUBE if
       it lacks effective cube instructions (eg. Mmad) or vector instructions (eg: DataCopy).
    Need compiler updates to remove this feature, or insert Mmad/DataCopy calls manully.

    2. Barrier APIs conflict with SyncAll. Avoid mixing them together.

    3. We provide 2 kinds of barrier:
        a. aclshmem_barrier_xxx
            Barrier of all cores. On systems with only HCCS: All operations of all pes of a team on excuting
            stream before the barrier are visiable to all pes of the team after the barrier.
        b. aclshmemx_barrier_xxx_vec
            Barrier of all VEC cores. On systems with only HCCS: All operations of ALL VEC CORES of all pes of a
            team on excuting stream before the barrier are visiable to ALL VEC CORES of all pes of the team after
            the barrier.

    4. The scalar unit of cube core is not affected by aclshmem_barrier_xxx. Make sure don't use that.
*/
```

https://raw.githubusercontent.com/immengzi/shmem/master/docs/principles.md
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04

```
<p style="text-indent: 2em;">该部分仅获取一个ffts地址，后续可通过<code>shmemx_get_ffts_config</code>获得，在算子内通过<code>shmemx_set_ffts_config</code>设置，用于runtime同步，AscendC层面会影响的<code>SyncAll</code>、<code>CrossCoreSetFlag</code>和<code>CrossCoreWaitFlag</code>接口，shmem层面会影响到barrier相关接口。（</ode>shmemx_set_ffts_config</code>开销较小，建议算子内都调用一次该接口）。</p>
```

## B4. Per-token dynamic quant with NO grid reduction — per-core row ownership, two-pass over column tiles

https://raw.githubusercontent.com/immengzi/shmem/master/examples/dispatch_gmm_combine/include/moe_init_routing_quant_v2/moe_v2_gather_dynamic_quant.h
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04

Single-pass path (whole row fits one UB tile) — `ReduceMax` then `GetValue(0)`, all inside one core:

```cpp
    Abs(tempLocal, inLocal, this->cols);
    pipe_barrier(PIPE_V);

    ReduceMax(dynamicQuantLocal, tempLocal, tempLocal, this->cols);
    pipe_barrier(PIPE_V);

    float maxValue = dynamicQuantLocal.GetValue(0) / 127.0f;

    Duplicate<float>(dynamicQuantLocal, maxValue, 8);
    Duplicate<float>(tempLocal, maxValue, this->cols);
    pipe_barrier(PIPE_V);

    Div(tempLocal, inLocal, tempLocal, this->cols);
    pipe_barrier(PIPE_V);

    Cast(tempLocal.ReinterpretCast<half>(), tempLocal, RoundMode::CAST_TRUNC, this->cols);
    pipe_barrier(PIPE_V);

    Cast(outLocal, tempLocal.ReinterpretCast<half>(), RoundMode::CAST_ROUND, this->cols);
```

Tiled path — the explicit two-pass structure. Pass 1 (`ComputeMax` per column tile) accumulates
`reduceMax` in a *scalar register*, spilling the fp32 row to a GM scratch (`quantSrcGm`) so pass 2
can re-read it. Note `rowOffset` is derived from `blockIdx`, i.e. each core owns whole rows, which
is precisely why no cross-block reduction is needed. Note also the hex-literal `-FLT_MAX` init:

```cpp
    for (int64_t i = 0; i < this->currentLoopRows; i++) {
        int64_t rowOffset = this->gatherOutTilingData->perCoreRows * this->blockIdx + this->perLoopRows * progress;
        if (this->dropPadMode == DROPLESS_MODE && rowOffset + i >= this->activateRows) {
            break;
        }
        int32_t srcIdx = indicesLocal.GetValue(i);
        int32_t expertIdx = indicesLocal.GetValue(currentLoopRowsAlign + i);

        LocalTensor<float> inLocal = inputXInQueue.AllocTensor<float>();
        LocalTensor<float> tempLocal = calcQueue.AllocTensor<float>();
        LocalTensor<float> quantScaleLocal = scaleOutQueue.AllocTensor<float>();

        uint32_t tmp = 0xFF7FFFFF;
        float reduceMax = *((float *) &tmp);
        for (int64_t j = 0; j < this->colLoops; j++) {
            colsTileLength = this->perLoopCols;
            if (j == this->colLoops - 1) {
                colsTileLength = this->lastLoopCols;
            }
            float tileMax = ComputeMax(inLocal, tempLocal, quantScaleLocal, srcIdx / this->k, expertIdx, j);
            reduceMax = (reduceMax > tileMax) ? reduceMax : tileMax;
        }

        float scaleTemp = reduceMax / 127.0f;
        Duplicate<float>(quantScaleLocal, scaleTemp, 8);
        scaleOutQueue.EnQue(quantScaleLocal);
        quantScaleLocal = scaleOutQueue.DeQue<float>();

        DataCopyPad(dynamicQuantScaleGm[(rowOffset + i)], quantScaleLocal, {1, 4, 0, 0, 0});

        for (int64_t j = 0; j < this->colLoops; j++) {
            colsTileLength = this->perLoopCols;
            if (j == this->colLoops - 1) {
                colsTileLength = this->lastLoopCols;
            }

            ComputeScale(inLocal, tempLocal, scaleTemp, rowOffset + i, j);
        }

        inputXInQueue.FreeTensor(inLocal);
        calcQueue.FreeTensor(tempLocal);
        scaleOutQueue.FreeTensor(quantScaleLocal);
    }
```

`ComputeMax` — the per-tile half. The max lands at `dynamicQuantLocal[8]` and is read back with
`GetValue(8)`; the fp32 input is written to the GM scratch in the same pass, with
`SetWaitFlag<HardEvent::MTE3_MTE2>` as the only ordering:

```cpp
    Abs(tempLocal, inLocal, colsTileLength);
    pipe_barrier(PIPE_V);

    ReduceMax(dynamicQuantLocal[8], tempLocal, tempLocal, colsTileLength);

    DataCopyPad(quantSrcGm[j * this->perLoopCols], inLocal, intriParamsFp32);
    smoothInQueue.FreeTensor(smoothLocal);
    SetWaitFlag<HardEvent::MTE3_MTE2>(HardEvent::MTE3_MTE2);

    return dynamicQuantLocal.GetValue(8);
```

`ComputeScale` — pass 2 re-reads the staged fp32 row from GM and applies the scalar scale:

```cpp
    DataCopyPad(inLocal, quantSrcGm[j * this->perLoopCols], copyInParams, {false, 0, 0, 0});
    inputXInQueue.EnQue<float>(inLocal);
    inLocal = inputXInQueue.DeQue<float>();

    Duplicate<float>(tempLocal, scaleTemp, colsTileLength);
    pipe_barrier(PIPE_V);

    Div(tempLocal, inLocal, tempLocal, colsTileLength);
    pipe_barrier(PIPE_V);

    Cast(tempLocal.ReinterpretCast<half>(), tempLocal, RoundMode::CAST_TRUNC, colsTileLength);
    pipe_barrier(PIPE_V);

    Cast(outLocal, tempLocal.ReinterpretCast<half>(), RoundMode::CAST_ROUND, colsTileLength);
```

## B5. Per-token quant inside a Catlass-style matmul epilogue — row max never leaves the core

https://raw.githubusercontent.com/immengzi/shmem/master/examples/dispatch_gmm_combine/include/block_epilogue_pertoken_swiglu.h
Huawei Technologies Co., Ltd. (CANN `shmem`), mirror HEAD 2026-03-04

Row-to-core assignment (`epilogueCoreIdx`), then a per-row SwiGLU + `Abs` + `ReduceMax` fused
in the epilogue. The `false` final argument to `ReduceMax<float>` suppresses the index output,
and `sharedUbTmpBuffer` is aliased onto the max buffer:

```cpp
        uint32_t tasksForIdx  = epilogueCoreIdx < remainderData ? perCoreData + 1 : perCoreData;
        uint32_t loopStartIdx = epilogueCoreIdx * perCoreData +
            (epilogueCoreIdx < remainderData? epilogueCoreIdx : remainderData);

        uint32_t alignedPerCoreData = RoundUp<BYTE_PER_BLK / sizeof(ElementPerTokenScale)>(perCoreData + 1);

        uint32_t ChunkTileLen = blockN / 2;
        uint32_t HalfChunkTileLen = ChunkTileLen / 2;

        for (uint32_t loopIdx = loopStartIdx; loopIdx < loopStartIdx + tasksForIdx; ++loopIdx) {
            auto gmTileC = gmC[loopIdx * blockN];

            auto &ubC = ubCList[ubListId];
            auto &ubD = ubDList[ubListId];

            auto &ubCFp32 = ubCFp32List[ubListId];
            auto &ubCFp32ChunkN = ubCFp32ChunkNList[ubListId];
            auto &ubAbs = ubCFp32ChunkNAbsList[ubListId];
            auto &ubReduceMax = ubCFp32ChunkNMaxList[ubListId];
            auto &ubOutputTmp = ubAbs;
            auto &sharedUbTmpBuffer = ubReduceMax;
            auto &ubQuantS32 = ubQuantS32List[ubListId];
            auto &ubQuantF16 = ubQuantF16List[ubListId];

            auto gmTileD = gmD[loopIdx * ChunkTileLen];
            LayoutC layoutUbC{1, blockN};

            // 把C从GM workspace搬到UB
            AscendC::WaitFlag<AscendC::HardEvent::V_MTE2>(eventUbCVMTE2List[ubListId]);
            copyGmToUbC(ubC, gmTileC, layoutUbC, layoutUbC);
            AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(eventUbCMTE2VList[ubListId]);

            // 在UB上做把C cast成FP32
            AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(eventUbCMTE2VList[ubListId]);
            AscendC::Cast(ubCFp32, ubC, AscendC::RoundMode::CAST_NONE, blockN);
            AscendC::SetFlag<AscendC::HardEvent::V_MTE2>(eventUbCVMTE2List[ubListId]);

            // 获取pertoken scale值，gmPerTokenScale的第loopIdx行
            ElementPerTokenScale perTokenScale = gmPerTokenScale1(loopIdx);
```

```cpp
            AscendC::Muls(ubCFp32, ubCFp32, perTokenScale, blockN);
            AscendC::PipeBarrier<PIPE_V>();

            // swiglue计算过程
            AscendC::Muls(ubCFp32ChunkN, ubCFp32, -1.0f, ChunkTileLen);
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::Exp(ubCFp32ChunkN, ubCFp32ChunkN, ChunkTileLen);
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::Adds(ubCFp32ChunkN, ubCFp32ChunkN, 1.0f, ChunkTileLen);
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::Div(ubCFp32ChunkN, ubCFp32, ubCFp32ChunkN, ChunkTileLen);
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::Mul(ubCFp32ChunkN, ubCFp32ChunkN, ubCFp32[ChunkTileLen], ChunkTileLen);
            
            // quant过程，两种方式区别；
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::Abs(ubAbs, ubCFp32ChunkN, ChunkTileLen);
            AscendC::PipeBarrier<PIPE_V>();
            AscendC::ReduceMax<float>(ubReduceMax, ubAbs, sharedUbTmpBuffer, ChunkTileLen, false);
            AscendC::PipeBarrier<PIPE_V>();
```

Zero-max guard (relevant if a row can be all zeros in a quantised decode step):

```cpp
            ElementPerTokenScale GMubDequantScale = ubReduceMax.GetValue(0) == float(0) ? 1 : ubReduceMax.GetValue(0);
```

---

# TOPIC B, addendum — `SyncAll` verified first-hand from `hicann/asc-devkit`

I re-fetched these myself rather than relying on the delegated sweep, because the arch gating is
the load-bearing detail for a `dav-2201` target.

## B0a. The declared `SyncAll` / `IBSet` / `IBWait` surface, and the arch gate on the no-argument form

https://raw.githubusercontent.com/hicann/asc-devkit/master/include/basic_api/kernel_operator_block_sync_intf.h
hicann / asc-devkit, `master` (fetched 2026-10-20); file header `Copyright (c) 2025 Huawei Technologies Co., Ltd.`

```cpp
/*
 * @ingroup：IBSet, IBWait
 * @brief：Set the flag bit of a core
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 * @param [in] blockIdx the idx number waiting for the core
 * @param [in] eventID Set and wait events
 */
template <bool isAIVOnly = true>
__aicore__ inline void IBSet(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);

template <bool isAIVOnly = true>
__aicore__ inline void IBWait(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);
/*
 * @ingroup：SyncALL
 * @brief：Set flag bits of all cores
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 */
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0);

#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 5162) || \
                              (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
__aicore__ inline void SyncAll();
#else
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll();
#endif
```

Read the gate carefully: the `SyncAllConfig`-carrying no-argument overload exists only for
`__NPU_ARCH__` in {3510, 5102, 5162, 9201, 9202}. `2201` is *not* in that set, so on A3 the
no-argument form is the plain `template <bool isAIVOnly = true> SyncAll()`.

Corroboration that 2201 is a live, recognised arch id in the same tree (it sits in the
V200/V210 group that gets `QUE_MAX_EVENT = 8`):

https://raw.githubusercontent.com/hicann/asc-devkit/master/impl/basic_api/kernel_macros.h
hicann / asc-devkit, `master` (fetched 2026-10-20)

```cpp
namespace AscendC {
#if defined(__NPU_ARCH__) &&                                                                                 \
    ((__NPU_ARCH__ == 2002) || (__NPU_ARCH__ == 2201) || (__NPU_ARCH__ == 3002) || (__NPU_ARCH__ == 3102) || \
     (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 3003) || (__NPU_ARCH__ == 3113) || \
     (__NPU_ARCH__ == 5101) || (__NPU_ARCH__ == 5161) || (__NPU_ARCH__ == 5165) || (__NPU_ARCH__ == 5163) || \
     (__NPU_ARCH__ == 5162) || (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202)) // Available for V200 and V210
constexpr int32_t QUE_MAX_EVENT = 8;
#else
constexpr int32_t QUE_MAX_EVENT = 4;
#endif
```

There is no `impl/basic_api/dav_2201/` directory in the repository. The arch directories present
under `impl/basic_api/` are, exactly:
`dav_3510, dav_5161, dav_5162, dav_9201, dav_c100, dav_c220, dav_l300, dav_l311, dav_m200,
dav_m300, dav_m310, dav_m510` (plus `reg_compute`, `utils`). `2201` appears only under
`tests/api/c_api/npu_arch_2201/` and in `docs/.../deprecated_interface/*_arch_2201_deprecated.md`.
The implementation that serves it is `dav_c220`.

## B0b. Hard sync — `SyncAll<isAIVOnly>()` with no workspace is two FFTS instructions

https://raw.githubusercontent.com/hicann/asc-devkit/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h
hicann / asc-devkit, `master` (fetched 2026-10-20)

```cpp

constexpr uint16_t SYNC_AIV_FLAG = 12;
constexpr uint16_t SYNC_AIC_FLAG = 11;
constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;

__aicore__ inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId)

template <bool isAIVOnly = true>
__aicore__ inline void SyncAllImpl()
{
#if defined(__ASCENDC_SUPERKERNEL_AUTO_SYNC_ALL__)
    if (g_superKernelAutoSyncAllEnable) {
        if (GetBlockIdxImpl() == 0) {
            g_superKernelAutoSyncAllSyncIdx += 1;
            // |    32bits  |   16bits  |   8bits   |   8bits   |
            // |  sync idx  | sync type |   is end  | is valid  |
            *reinterpret_cast<__gm__ uint64_t*>(g_superKernelAutoSyncAllConfigGmAddr) =
                (static_cast<uint64_t>(g_superKernelAutoSyncAllSyncIdx)
                 << SK_AUTO_SYNC_ALL_SYNC_IDX_CONFIG_BIT_OFFSET) |
                (static_cast<uint64_t>(isAIVOnly) << SK_AUTO_SYNC_ALL_SYNC_TYPE_CONFIG_BIT_OFFSET) |
                static_cast<uint64_t>(SK_AUTO_SYNC_ALL_VALID_MAGIC_NUM);
            dcci(
                reinterpret_cast<__gm__ uint64_t*>(g_superKernelAutoSyncAllConfigGmAddr),
                cache_line_t::SINGLE_CACHE_LINE, dcci_dst_t::CACHELINE_OUT);
        }
    }
#endif

    PipeBarrier<PIPE_ALL>();
    if constexpr (isAIVOnly) {
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x0, SYNC_AIV_ONLY_ALL));
        wait_flag_dev(SYNC_AIV_ONLY_ALL);
        return;
    }
    // trans software sync to hardware sync
    if ASCEND_IS_AIC {
        wait_flag_dev(SYNC_AIV_FLAG);
        ffts_cross_core_sync(PIPE_FIX, GetffstMsg(0x0, SYNC_AIC_FLAG));
        wait_flag_dev(SYNC_AIC_FLAG);
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIC_AIV_FLAG));
        return;
    }
    if ASCEND_IS_AIV {
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIV_FLAG));
        wait_flag_dev(SYNC_AIC_AIV_FLAG);
        return;
    }
```

So: AIV-only is one `ffts_cross_core_sync` + one `wait_flag_dev` on flag 14; the mixed form is a
three-hop V→C→V handshake on flags 12 / 11 / 13. `PipeBarrier<PIPE_ALL>()` first, and *no* cache
maintenance at all — which is why it orders cores but says nothing about a remotely written line.

## B0c. Soft sync — `SoftSyncAllImpl` needs a GM workspace, and is itself epoch-counted

Same file. Note `curValue = *localUb + 1` and the termination test
`count >= totalBlocks * curValue`: the workspace is never reset between barriers, it just keeps
counting, which is the same generation-tag discipline as A8/A9/B1. `DEFAULT_BLK_NUM` /
`ONE_BLK_FLOAT_NUM` striding gives each block its own 32-byte slot.

```cpp
__aicore__ inline int64_t GetBlockNum();
template <bool isAIVOnly = true>
__aicore__ inline void SoftSyncAllImpl(
    __gm__ int32_t* gmWorkspaceAddr, __ubuf__ int32_t* ubWorkspaceAddr, const int usedCores)
{
    if ASCEND_IS_AIC {
        return;
    }
    __sync_all_stub(usedCores, isAIVOnly);
    PipeBarrier<PIPE_ALL>();

    int32_t totalBlocks = isAIVOnly ? GetBlockNum() : (GetTaskRationImpl() * GetBlockNum());
    totalBlocks = usedCores != 0 ? usedCores : totalBlocks;
#ifdef __ASCENDC_ENABLE_SUPER_KERNEL__
    int32_t blockIdx = GetBlockIdxImpl();
#else
    int32_t blockIdx = isAIVOnly ? get_block_idx() : GetBlockIdxImpl();
#endif

    __gm__ int32_t* localSyncGM = gmWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);
    __ubuf__ int32_t* localUbAddr = ubWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);

    copy_gm_to_ubuf(static_cast<__ubuf__ void*>(localUbAddr), static_cast<__gm__ void*>(localSyncGM), 0, 1, 1, 0, 0);
    event_t eventIdMte2ToS = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE2_S));
    SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    int32_t curValue = *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) + 1;
    bool isFirst = curValue == 1 ? true : false;
    *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) = curValue;
    event_t eventIdSToMte3 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE3));
    SetFlag<HardEvent::S_MTE3>(eventIdSToMte3);
    WaitFlag<HardEvent::S_MTE3>(eventIdSToMte3);
    copy_ubuf_to_gm(static_cast<__gm__ void*>(localSyncGM), static_cast<__ubuf__ void*>(localUbAddr), 0, 1, 1, 0, 0);
    event_t eventIDMTE3ToMTE2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE3_MTE2));
    SetFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
    WaitFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
    int32_t totalBlockCount = ONE_BLK_FLOAT_NUM * totalBlocks;
    uint16_t blockLen = totalBlockCount / AscendCUtils::GetC0Count(sizeof(int32_t));
    while (true) {
        copy_gm_to_ubuf(
            static_cast<__ubuf__ void*>(ubWorkspaceAddr), static_cast<__gm__ void*>(gmWorkspaceAddr), 0, 1, blockLen, 0,
            0);
        SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        int32_t count = 0;
        ClcSyncCount(localSyncGM, ubWorkspaceAddr, blockIdx, totalBlocks, isFirst, count);
        event_t eventIdSToMte2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE2));
        SetFlag<HardEvent::S_MTE2>(eventIdSToMte2);
        WaitFlag<HardEvent::S_MTE2>(eventIdSToMte2);
        if (count >= (totalBlocks * curValue)) {
            break;
        }
```

The counting helper it calls, including the `isFirst` special case that avoids counting your own
stale slot:

```cpp
#include "../../../include/basic_api/kernel_tpipe.h"
#if !defined(__ASCENDC_INCLUDE_INTERNAL_HEADERS__)
#define __ASCENDC_INCLUDE_INTERNAL_HEADERS__
#define __UNDEF_ASCENDC_INCLUDE_INTERNAL_HEADERS_KERNEL_TPIPE_H__
#endif
#include "../../../include/basic_api/kernel_common.h"
namespace AscendC {

__aicore__ inline void ClcSyncCount(
    __gm__ int32_t* localSyncGM, __ubuf__ int32_t* ubWorkspaceAddr, const int32_t blockIdx, const int32_t totalBlocks,
    bool isFirst, int32_t& count)
{
    if (isFirst) {
        __ubuf__ int32_t* localUbAddr = ubWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);
        *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) = 1;
        event_t eventIdSToMte3 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE3));
        SetFlag<HardEvent::S_MTE3>(eventIdSToMte3);
        WaitFlag<HardEvent::S_MTE3>(eventIdSToMte3);
        copy_ubuf_to_gm(
            static_cast<__gm__ void*>(localSyncGM), static_cast<__ubuf__ void*>(localUbAddr), 0, 1, 1, 0, 0);
        event_t eventIDMTE3ToMTE2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE3_MTE2));
        SetFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
        WaitFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
        count = 1;
        for (int32_t i = 0; i < totalBlocks; i++) {
            if (i != blockIdx) {
                count += *(reinterpret_cast<__ubuf__ int32_t*>(ubWorkspaceAddr) + i * ONE_BLK_FLOAT_NUM);
            }
        }
    } else {
        for (int32_t i = 0; i < totalBlocks; i++) {
            count += *(reinterpret_cast<__ubuf__ int32_t*>(ubWorkspaceAddr) + i * ONE_BLK_FLOAT_NUM);
        }
    }
}
```

## B0d. The canonical grid-wide row max in CANN, verified first-hand: partials-in-workspace + `SyncAll()` + second reduce pass

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/dynamic_quant/op_kernel/arch35/dynamic_quant_regbase_pertoken_large_multicore.h
hicann / ops-nn, `master` (fetched 2026-10-20)

This is the one `DynamicQuant` template in the open operator library where a token's row is wider
than one core's slice, so the per-token max genuinely must cross blocks. The whole mechanism is
three lines:

```cpp
template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::ProcessScale()
{
    ProcessScaleRow();
    SyncAll();
    ProcessScaleCol();
}
```

Core→(token, slice) mapping. `coreNumPerToken` cores cooperate on one token; `coreLocalIdx` is
the slice index within the token:

```cpp
    coreNumPerToken = tilingData_.headCoreNum;

    totalTokenNum = tilingData_.coreNum / coreNumPerToken;
    tokenIdx = blockIdx / coreNumPerToken;
    coreLocalIdx = blockIdx % coreNumPerToken;
    headSlices = tilingData_.multiRowNumHeadCore;

    elePerHeadCore = tilingData_.rowPerHeadCore;
    elePerTailCore = tilingData_.rowPerTailCore;
    eleCount = (coreLocalIdx < headSlices) ? elePerHeadCore : elePerTailCore;

    if (coreLocalIdx < headSlices) {
        coreStartOffset = static_cast<int64_t>(coreLocalIdx) * static_cast<int64_t>(elePerHeadCore);
    } else {
        coreStartOffset = static_cast<int64_t>(headSlices) * static_cast<int64_t>(elePerHeadCore) +
                          static_cast<int64_t>(coreLocalIdx - headSlices) * static_cast<int64_t>(elePerTailCore);
    }
```

Workspace layout — exactly one float per core (two arrays when asymmetric: max and min), sized
`tilingData_.coreNum`, no padding, no per-core cacheline isolation:

```cpp
    if constexpr (isSymmetrical == false) {
        workspaceTmp1.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace), tilingData_.coreNum);
        workspaceTmp2.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace + tilingData_.coreNum * sizeof(float)),
                                      tilingData_.coreNum);
    } else {
        workspaceTmp1.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace), tilingData_.coreNum);
    }
```

Pass 1 — each core seeds its accumulator to `MIN_FLOAT_VALUE` / `MAX_FLOAT_VALUE`, reduces its
own column slice, and publishes one float:

```cpp
template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::ProcessScaleRow()
{
    LocalTensor<float> MaxToWorkSpaceLocal;
    LocalTensor<float> MinToWorkSpaceLocal;
    LocalTensor<float> scaleToWorkSpaceLocal;

    if constexpr (isSymmetrical == false) {
        MaxToWorkSpaceLocal = MaxToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(MaxToWorkSpaceLocal, MIN_FLOAT_VALUE, 64, 1, 1, 8);
        MaxToWorkSpaceQueue.EnQue(MaxToWorkSpaceLocal);

        MinToWorkSpaceLocal = MinToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(MinToWorkSpaceLocal, MAX_FLOAT_VALUE, 64, 1, 1, 8);
        MinToWorkSpaceQueue.EnQue(MinToWorkSpaceLocal);
    } else {
        scaleToWorkSpaceLocal = scaleToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(scaleToWorkSpaceLocal, (float)0.0, 64, 1, 1, 8);
        scaleToWorkSpaceQueue.EnQue(scaleToWorkSpaceLocal);
    }

    ProcessScaleRowLoop(0, 0);

    CopyUB2Workspace(1);
}
```

The publish itself. Note it is `DataCopyPad` (MTE3 traffic), not a scalar store — which is what
puts it inside `SyncAll`'s reach:

```cpp
template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::CopyUB2Workspace(
    int64_t size)
{
    if constexpr (isSymmetrical == false) {
        auto tmp1 = MaxToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp1[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp1, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        MaxToWorkSpaceQueue.FreeTensor(tmp1);

        auto tmp2 = MinToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp2[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp2, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        MinToWorkSpaceQueue.FreeTensor(tmp2);
    } else {
        auto tmp = scaleToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp1[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        scaleToWorkSpaceQueue.FreeTensor(tmp);
    }
}
```

Pass 2 — read back all `coreNumPerToken` partials as one contiguous vector and reduce them:

```cpp
    }
    scaleOffset = 0;
    CopyInScaleByEle(static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken), coreNumPerToken);
    ComputeMaxColScale(coreNumPerToken, MaxOutLocalAddr, MinOutLocalAddr, scaleOutLocalAddr, offsetLocalAddr);
    if constexpr (isSymmetrical == false) {
```

```cpp
template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::CopyInScaleByEle(
    int64_t offset, uint32_t elementNum)
{
    DataCopyParams copyParams{1, (uint16_t)(elementNum * sizeof(float)), 0, 0};
    if constexpr (isSymmetrical == false) {
        LocalTensor<float> MaxFromWorkSpaceLocal = MaxFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(MaxFromWorkSpaceLocal, workspaceTmp1[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        MaxFromWorkSpaceQueue.EnQue(MaxFromWorkSpaceLocal);

        LocalTensor<float> MinFromWorkSpaceLocal = MinFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(MinFromWorkSpaceLocal, workspaceTmp2[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        MinFromWorkSpaceQueue.EnQue(MinFromWorkSpaceLocal);
    } else {
        LocalTensor<float> scaleFromWorkSpaceLocal = scaleFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(scaleFromWorkSpaceLocal, workspaceTmp1[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        scaleFromWorkSpaceQueue.EnQue(scaleFromWorkSpaceLocal);
    }
}
```

And the per-token scale is written out by one core only:

```cpp
    ProcessYRow(0, 0, scaleOutLocalAddr, offsetLocalAddr);

    if (coreLocalIdx == 0) {
        DataCopyParams copyParams{1, (uint16_t)(sizeof(float)), 0, 0};
        DataCopyPad(scaleGm[tokenIdx], scaleOutLocal, copyParams);
        if constexpr (isSymmetrical == false) {
            DataCopyPad(offsetGm[tokenIdx], offsetLocal, copyParams);
```

No atomic. No `dcci`. No flag. The barrier is the only synchronisation, and the published data
rides MTE3.

---

# TOPIC B — official `SyncAll` docs, cross-core sync primitives, atomics, and real DynamicQuant kernel source

Items below are verbatim quotations collected from the URLs shown. `hicann/asc-devkit` is the
open AscendC SIMD-API devkit (docs + headers + impl, including the per-architecture
`impl/basic_api/dav_c220/` sources); `hicann/ops-nn` is the open CANN operator library
(`arch35` subtrees are the newest generation).

### item 0

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/82RC1/API/ascendcopapi/atlasascendc_api_07_0204.html
Huawei, CANN Community Edition 8.2.RC1 「Ascend C API 参考」; retrieved 2026-10-20, page date not stated
Official CANN Ascend C API reference topic for SyncAll / 核间同步, text-extracted verbatim from the rendered page (tables flattened to lines). Same topic id on the commercial host: https://www.hiascend.com/document/detail/zh/canncommercial/850/API/ascendcopapi/atlasascendc_api_07_0204.html
```text
SyncAll
产品支持情况
产品
是否支持（软同步原型）
是否支持（硬同步原型）
Atlas A3 训练系列产品/Atlas A3 推理系列产品
√
√
Atlas A2 训练系列产品/Atlas 800I A2 推理产品/A200I A2 Box 异构组件
√
√
Atlas 200I/500 A2 推理产品
x
x
Atlas 推理系列产品
AI Core
√
x
Atlas 推理系列产品
Vector Core
x
x
Atlas 训练系列产品
√
x
Atlas 200/300/500 推理产品
x
x
功能说明
当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用该函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬件同步是利用硬件自带的全核同步指令由硬件保证多核同步，软件同步是使用软件算法模拟实现。
函数原型
软同步
1
2
template
<
bool
isAIVOnly
=
true
>
__aicore__
inline
void
SyncAll
(
const
GlobalTensor
<
int32_t
>&
gmWorkspace
,
const
LocalTensor
<
int32_t
>&
ubWorkspace
,
const
int32_t
usedCores
=
0
)
硬同步
1
2
template
<
bool
isAIVOnly
=
true
>
__aicore__
inline
void
SyncAll
()
参数说明
表1
模板参数说明
参数名
描述
isAIVOnly
控制SyncAll作用于纯Vector算子或融合（Cube和Vector融合）算子。可选值：
true
（默认值）：纯Vector算子的全核同步，仅执行Vector核的全核同步。
false
：融合算子的全核同步，先分别完成Vector核和Cube核的全核同步，再执行两者之间的同步。
表2
参数说明
参数名称
输入/输出
含义
gmWorkspace
输入
gmWorkspace为用户定义的全局Global空间，作为所有核共用的缓存，用于保存每个核的状态标记，类型为GlobalTensor，支持的数据类型为int32_t。GlobalTensor数据结构的定义请参考
GlobalTensor
。
所需空间大小和使用注意项参见
约束说明
。
硬同步接口不支持该参数。
ubWorkspace
输入
ubWorkspace为用户定义的局部Local空间，每个核单独自用，用于标记当前核的状态。
类型为
LocalTensor
，支持的TPosition为VECIN/VECCALC/VECOUT，支持的数据类型为int32_t。
所需空间大小参见
约束说明
。
硬同步接口不支持该参数。
usedCores
输入
指定多少个核之间的同步，传入数值不能超过算子调用时指定的逻辑blockDim。此参数为默认参数，不传此参数表示全核软同步。
仅在软同步接口中支持，硬同步接口不支持该参数。
返回值
无
约束说明
gmWorkspace缓存申请的空间大小要求大于等于核数*32Bytes，并且缓存的值需要初始化为0。目前常见的有两种初始化方式：
通过在host侧进行初始化操作，确保传入该接口时，gmWorkspace缓存已经初始化为0；
在kernel侧初始化的时候对gmWorkspace缓存初始化，需要注意的是，每个核上都需要初始化全部的gmWorkspace缓存空间。
ubWorkspace申请的空间大小要求大于等于核数*32Bytes。
使用该接口进行多核控制时，算子调用时指定的逻辑blockDim必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel“卡死”现象。
在分离架构中，建议使用硬同步接口而非软同步接口。软同步接口仅适用于纯Vector场景，且性能较低。使用硬同步接口时，需根据场景设置Kernel类型：
在纯Vector/Cube场景下，需设置Kernel类型为KERNEL_TYPE_MIX_AIV_1_0或KERNEL_TYPE_MIX_AIC_1_0。
对于Vector和Cube混合场景，需根据实际情况灵活配置Kernel类型。
调用示例
本示例实现功能为使用8个核进行数据处理，每个核均是处理32个float类型数据，对该数据乘2后再与其他核上进行同样乘2的数据进行相加，中间结果保存到workGm，因此多个核之间需要进行数据同步。此样例中，使用软同步，入口函数传入的syncGm里的值都已经在host侧初始化为0。若以下用例改成使用硬同步，则不需要传入syncGm，并且不需要使用workQueue。
```

## ITEM 2

### item 1

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/SyncAll.md
hicann/asc-devkit, last commit 2026-10-16 by munanhw
Current-master official SyncAll doc: all three prototypes (soft / hard-without-config / hard-with-config), per-product support, 参数说明, and the complete split 约束说明 (software-sync vs hardware-sync vs common).
````markdown
# SyncAll<a id="ZH-CN_TOPIC_0000001538296817"></a>

## 产品支持情况<a id="section1550532418810"></a>

### 软同步原型

<!-- npu="950" id1 -->
- Ascend 950PR&950DT系列产品：支持
<!-- end id1 -->
<!-- npu="A3" id2 -->
- Atlas A3系列产品：支持
<!-- end id2 -->
<!-- npu="910b" id3 -->
- Atlas A2系列产品：支持
<!-- end id3 -->
<!-- npu="310b" id4 -->
- Atlas 200I/500 A2推理产品：不支持
<!-- end id4 -->
<!-- npu="310p" id5 -->
- Atlas推理系列产品AI Core：支持
<!-- end id5 -->
<!-- npu="310p" id6 -->
- Atlas推理系列产品Vector Core：不支持
<!-- end id6 -->
<!-- npu="910" id7 -->
- Atlas训练系列产品：支持
<!-- end id7 -->
<!-- npu="x90" id8 -->
- Kirin X90处理器系列产品：支持
<!-- end id8 -->
<!-- npu="9030" id9 -->
- Kirin 9030处理器系列产品：支持
<!-- end id9 -->
<!-- @ref: asc-devkit/res/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/SyncAll_res.md#id1 -->

### 硬同步（不支持config指定流水）原型

<!-- npu="950" id10 -->
- Ascend 950PR&950DT系列产品：支持
<!-- end id10 -->
<!-- npu="A3" id11 -->
- Atlas A3系列产品：支持
<!-- end id11 -->
<!-- npu="910b" id12 -->
- Atlas A2系列产品：支持
<!-- end id12 -->
<!-- npu="310b" id13 -->
- Atlas 200I/500 A2推理产品：不支持
<!-- end id13 -->
<!-- npu="310p" id14 -->
- Atlas推理系列产品AI Core：不支持
<!-- end id14 -->
<!-- npu="310p" id15 -->
- Atlas推理系列产品Vector Core：不支持
<!-- end id15 -->
<!-- npu="910" id16 -->
- Atlas训练系列产品：不支持
<!-- end id16 -->
<!-- npu="x90" id17 -->
- Kirin X90处理器系列产品：支持
<!-- end id17 -->
<!-- npu="9030" id18 -->
- Kirin 9030处理器系列产品：支持
<!-- end id18 -->
<!-- @ref: asc-devkit/res/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/SyncAll_res.md#id2 -->

### 硬同步（支持config指定流水）原型

<!-- npu="950" id19 -->
- Ascend 950PR&950DT系列产品：支持
<!-- end id19 -->
<!-- npu="A3" id20 -->
- Atlas A3系列产品：不支持
<!-- end id20 -->
<!-- npu="910b" id21 -->
- Atlas A2系列产品：不支持
<!-- end id21 -->
<!-- npu="310b" id22 -->
- Atlas 200I/500 A2推理产品：不支持
<!-- end id22 -->
<!-- npu="310p" id23 -->
- Atlas推理系列产品AI Core：不支持
<!-- end id23 -->
<!-- npu="310p" id24 -->
- Atlas推理系列产品Vector Core：不支持
<!-- end id24 -->
<!-- npu="910" id25 -->
- Atlas训练系列产品：不支持
<!-- end id25 -->
<!-- npu="x90" id26 -->
- Kirin X90处理器系列产品：不支持
<!-- end id26 -->
<!-- npu="9030" id27 -->
- Kirin 9030处理器系列产品：不支持
<!-- end id27 -->
<!-- @ref: asc-devkit/res/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/SyncAll_res.md#id3 -->

## 功能说明<a id="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_block_sync_intf.h"`。

SyncAll是核间同步控制接口，根据不同的函数原型介绍其功能：

- 硬件同步接口：
    用于多个核之间的同步控制，支持以下同步场景：
    - 纯Vector算子的全核同步，可参考[CrossCoreSetFlag的模式0](key_features.md)。
    - 融合算子的全核同步，一次性实现三个核间同步能力（参考[CrossCoreSetFlag的关键特性说明](key_features.md)）：首先完成单个AI Core内，AIC与所有AIV同步（AIC等AIV）；接着完成多个AI Core间，所有AIC的同步；最后完成单个AI Core内，所有AIV与AIC同步（AIV等AIC）。

- 软件同步接口：
    仅支持纯Vector算子的多核（参与同步的核数可通过入参指定）同步。每一个AIV都向全局内存对应位置写入信号值1，接着每一个AIV都持续轮询全局内存中所有AIV对应的信号值，直到所有AIV核对应的信号值都变为1。

在纯Vector算子场景中，若所有AIV核默认参与同步，推荐采用性能更优的硬件同步接口；若需指定部分AIV核参与同步，则应使用软件同步接口，并通过入参usedCores完成配置。

## 函数原型<a id="section620mcpsimp"></a>

- 软同步

    ```cpp
    template <bool isAIVOnly = true>
    __aicore__ inline void SyncAll(const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0)
    ```

- 硬同步
    - 不支持config指定流水

        ```cpp
        template <bool isAIVOnly = true>
        __aicore__ inline void SyncAll()
        ```

    - 支持config指定流水

        ```cpp
        template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
        __aicore__ inline void SyncAll()
        ```

## 参数说明<a id="section622mcpsimp"></a>

**表1**  模板参数说明

| 参数名 | 描述 |
| --- | --- |
| isAIVOnly | 控制SyncAll作用于纯Vector算子或Mix（包含Cube和Vector计算）算子。可选值：<br>&bull; **true**（默认值）：纯Vector算子的全核同步，仅执行Vector核的全核同步。<br>&bull; **false**：Mix（包含Cube和Vector计算）算子的全核同步，先分别完成Vector核和Cube核的全核同步，再执行两者之间的同步（软同步接口不支持此功能）。 |
| config | **该配置仅当isAIVOnly=True时有效。**<br>struct SyncAllConfig {&#x000A;    pipe_t triggerPipe;&#x000A;    pipe_t waitPipe;&#x000A;};&#x000A;&#x000A;// 默认使用全部流水来进行触发和等待行为。<br>constexpr SyncAllConfig DEFAULT_SYNC_ALL_CONFIG = {PIPE_ALL, PIPE_ALL};<br>控制SyncAll函数的行为，在多个AI Core之间进行流水同步时，指定哪些流水（pipe）用于触发和等待。<br>&bull; **triggerPipe**：指定哪个流水用于“发送触发信号”。仅支持MTE2、MTE3、PIPE_ALL。<br>&bull; **waitPipe**：指定哪个流水用于“接收等待信号”。仅支持MTE2、MTE3、PIPE_ALL。<br>// 多个AIV进行计算&#x000A;<br>Compute();&#x000A;<br>// 多个AIV将计算结果搬出到GM&#x000A;<br>CopyToGM();&#x000A;<br>// 等待所有数据拷贝到GM后，进行累加&#x000A;<br>constexpr AscendC::SyncAllConfig CustomConfig = {PIPE_MTE3, PIPE_ALL};&#x000A;<br>AscendC::SyncAll&lt;true, CustomConfig&gt;();&#x000A;<br>for (int i = 0; i &lt; blockNum; i++) {&#x000A;<br>    if (i != blockIdx) {&#x000A;<br>        CopyFromGm();&#x000A;<br>        Accumulate();&#x000A;<br>    }&#x000A;<br>}&#x000A;<br>// 累加后的数据写回&#x000A;<br>CopyToGm(); |

**表2**  参数说明

| 参数名称 | 输入/输出 | 含义 |
| --- | --- | --- |
| gmWorkspace | 输入 | gmWorkspace为用户定义的全局空间，作为所有核共用的缓存，用于保存每个核的状态标记，类型为GlobalTensor，支持的数据类型为int32_t。GlobalTensor数据结构的定义请参考[GlobalTensor](../../data_structures/GlobalTensor/GlobalTensor.md)。<br>所需空间大小和使用注意项参见[约束说明](#section633mcpsimp)。<br>硬同步接口不支持该参数。 |
| ubWorkspace | 输入 | ubWorkspace为用户定义的局部空间，每个核单独自用，用于标记当前核的状态。<br>类型为[LocalTensor](../../data_structures/LocalTensor/LocalTensor.md)，支持的TPosition为VECIN、VECCALC、VECOUT，支持的数据类型为int32_t。<br>所需空间大小参见[约束说明](#section633mcpsimp)。<br>硬同步接口不支持该参数。 |
| usedCores | 输入 | 指定多少个核之间的同步，传入数值不能超过算子调用时指定的逻辑numBlocks。此参数为默认参数，不传此参数表示全核软同步。<br>仅在软同步接口中支持，硬同步接口不支持该参数。 |

## 返回值说明<a id="section91032023123812"></a>

无

## 约束说明<a id="section633mcpsimp"></a>

SyncAll硬件同步和软件同步接口的内部实现不同，约束条件也有所区别。

- 软件同步接口约束：
    - gmWorkspace缓存申请的空间大小要求大于等于GetBlockNum()*32Bytes，并且缓存的值需要初始化为0。目前常见的有两种初始化方式：
        - 通过在host侧进行初始化操作，确保传入该接口时，gmWorkspace缓存已经初始化为0；
        - 在核函数（Kernel）侧初始化的时候对gmWorkspace缓存初始化，需要注意的是，每个核上都需要初始化全部的gmWorkspace缓存空间。
    - ubWorkspace申请的空间大小要求大于等于GetBlockNum()*32Bytes。
    - 在纯Vector算子场景中，若所有AIV核默认参与同步，推荐采用性能更优的硬件同步接口；若需指定部分AIV核参与同步，则应使用软件同步接口，并通过入参usedCores完成配置。
    - usedCores传入数值不能超过算子调用时指定的逻辑AI Core中AIV的数量：GetBlockNum()*GetTaskRatio()，不传此参数表示全核软同步。

- 硬件同步接口约束：
    - 使用硬同步接口时，需根据场景使用合适的核函数（Kernel）修饰符：
        - 在纯Vector算子，需使用\_\_mix\_\_\(0, 1\)修饰核函数（Kernel），而不是使用\_\_vector\_\_，具体原因请参考[CrossCoreSetFlag约束说明](CrossCoreSetFlag_ISASI.md#约束说明)中的核函数（Kernel）类型配置说明。
        - 对于Mix（包含Cube和Vector计算）算子，需使用\_\_mix\_\_\(1, 1\)或\_\_mix\_\_\(1, 2\)修饰核函数（Kernel）。
    - 对于纯Vector算子，模板参数isAIVOnly必须设置为true，否则会导致程序卡死。
    - 对于Mix（包含Cube和Vector计算）算子，模板参数isAIVOnly设置为true，会导致接口实际只能完成Vector全核同步与预期同步行为不符。
    - 使用该接口时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
        - 多流并发场景（≥2条执行流）。
        - ≥2个算子并发执行。
        - 所有并发算子的核数总和超过物理核数。
        - ≥2个并发算子使用了核间同步功能。

        具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。
        核函数（Kernel）直调场景下通过[\_\_schedmode\_\_\(mode\)](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式，具体请参考[《基础数据结构和接口》](https://gitcode.com/cann/metadef/blob/master/docs/zh/api/README.md)。
    - SyncAll硬件同步接口内部实现中使用了[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)进行核间同步控制，因此开发者同时使用CrossCoreSetFlag（或CrossCoreWaitFlag）和SyncAll硬件同步接口时，需注意避免flagId冲突，各接口flagId占用的完整说明参见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。

- 硬件同步接口和软件同步接口公共约束：使用该接口进行多核控制时，算子调用时指定的逻辑AI Core核数numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致核函数（Kernel）“卡死”现象。

## 调用示例<a id="section642mcpsimp"></a>

本示例实现功能为使用8个核进行数据处理，每个核均是处理32个float类型数据，对该数据乘2后再与其他核上进行同样乘2的数据进行相加，中间结果保存到workGm，因此多个核之间需要进行数据同步。此样例中，使用软同步，入口函数传入的syncGm里的值都已经在host侧初始化为0。若以下用例改成使用硬同步，则不需要传入syncGm，并且不需要使用workQueue。

```cpp
// syncGlobal为用户定义的全局空间，作为所有核共用的缓存，类型为GlobalTensor；workLocal为用户定义的局部空间，每个核单独自用，类型为LocalTensor。
int srcDataSize = 256; // 参与计算的元素个数。
int32_t blockNum = AscendC::GetBlockNum(); // 获取核总数。
int32_t blockIdx = AscendC::GetBlockIdx(); // 获取当前工作的核ID。
uint32_t perBlockSize = srcDataSize / blockNum; // 每个核平分处理相同个数。
// 当前工作核计算后的数据先保存到外部工作空间，workGlobal为GlobalTensor，dstLocal为LocalTensor。
AscendC::DataCopy(workGlobal[blockIdx * perBlockSize], dstLocal, perBlockSize);
// 等待所有核都完成计算。
AscendC::SyncAll(syncGlobal, workLocal);
```

完整样例请参考[SyncAll样例](../../../../../../../examples/01_simd_cpp_api/03_basic_api/05_sync_control/sync_all)。
````

## ITEM 3

### item 2

https://gitcode.com/cann/asc-devkit/blob/9.1.0-beta.1/docs/api/context/SyncAll.md
cann/asc-devkit on GitCode, tag 9.1.0-beta.1 (release date of 9.1.0-beta.1; commit date unknown)
CANN 9.1.0-beta.1 wording of SyncAll 功能说明 / 函数原型 / 约束说明 / 调用示例 — this release states the workspace size as 核数*32Bytes and makes SetScheduleMode batchmode mandatory ('必须通过SetScheduleMode使能batchmode模式'), stronger than master's '建议'. Raw: https://raw.gitcode.com/cann/asc-devkit/raw/9.1.0-beta.1/docs/api/context/SyncAll.md
````markdown
## 功能说明<a name="section618mcpsimp"></a>

当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用该函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬件同步是利用硬件自带的全核同步指令由硬件保证多核同步，软件同步是使用软件算法模拟实现。

## 函数原型<a name="section620mcpsimp"></a>

-   软同步

    ```
    template <bool isAIVOnly = true>
    __aicore__ inline void SyncAll(const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0)
    ```

-   硬同步

    ```
    template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
    __aicore__ inline void SyncAll()
    ```

## 参数说明<a name="section622mcpsimp"></a>

**表 1**  模板参数说明

<a name="table1596943217411"></a>
<table><thead align="left"><tr id="row1596916326417"><th class="cellrowborder" valign="top" width="13.43%" id="mcps1.2.3.1.1"><p id="p17970143211417"><a name="p17970143211417"></a><a name="p17970143211417"></a>参数名</p>
</th>
<th class="cellrowborder" valign="top" width="86.57000000000001%" id="mcps1.2.3.1.2"><p id="p8970163210416"><a name="p8970163210416"></a><a name="p8970163210416"></a>描述</p>
</th>
</tr>
</thead>
<tbody><tr id="row12970113214410"><td class="cellrowborder" valign="top" width="13.43%" headers="mcps1.2.3.1.1 "><p id="p9970193217417"><a name="p9970193217417"></a><a name="p9970193217417"></a>isAIVOnly</p>
</td>
<td class="cellrowborder" valign="top" width="86.57000000000001%" headers="mcps1.2.3.1.2 "><p id="p6912194943411"><a name="p6912194943411"></a><a name="p6912194943411"></a>控制SyncAll作用于纯Vector算子或融合（Cube和Vector融合）算子。可选值：</p>
<a name="ul1034511561784"></a><a name="ul1034511561784"></a><ul id="ul1034511561784"><li><strong id="b891244983410"><a name="b891244983410"></a><a name="b891244983410"></a>true</strong>（默认值）：纯Vector算子的全核同步，仅执行Vector核的全核同步。</li><li><strong id="b79121249133420"><a name="b79121249133420"></a><a name="b79121249133420"></a>false</strong>：融合算子的全核同步，先分别完成Vector核和Cube核的全核同步，再执行两者之间的同步（软同步接口不支持此功能）。</li></ul>
</td>
</tr>
<tr id="row47986408408"><td class="cellrowborder" valign="top" width="13.43%" headers="mcps1.2.3.1.1 "><p id="p18798194094017"><a name="p18798194094017"></a><a name="p18798194094017"></a>config</p>
</td>
<td class="cellrowborder" valign="top" width="86.57000000000001%" headers="mcps1.2.3.1.2 "><p id="p479815400409"><a name="p479815400409"></a><a name="p479815400409"></a>控制SyncAll函数的行为 ，在多个AI Core之间进行流水线同步时，指定哪些管道（pipe）用于触发和等待。</p>
<a name="ul047327174317"></a><a name="ul047327174317"></a><ul id="ul047327174317"><li><strong id="b7762111519458"><a name="b7762111519458"></a><a name="b7762111519458"></a>triggerPipe</strong>：指定哪个管道用于“发送触发信号”。</li><li><strong id="b1849919164510"><a name="b1849919164510"></a><a name="b1849919164510"></a>waitPipe</strong>：指定哪个管道用于“接收等待信号”。</li></ul>
<p id="p16336151565418"><a name="p16336151565418"></a><a name="p16336151565418"></a>默认为SyncAllConfig  DEFAULT_SYNC_ALL_CONFIG= {PIPE_ALL, PIPE_ALL} ，使用全部管道来进行触发和等待行为。</p>
<p id="p141061754195214"><a name="p141061754195214"></a><a name="p141061754195214"></a>该参数仅支持如下型号：</p>
<p id="p468305719192"><a name="p468305719192"></a><a name="p468305719192"></a><span id="ph126252025205"><a name="ph126252025205"></a><a name="ph126252025205"></a>Ascend 950PR/Ascend 950DT</span></p>
</td>
</tr>
</tbody>
</table>

**表 2**  参数说明

<a name="table62161631132810"></a>
<table><thead align="left"><tr id="row12216103118284"><th class="cellrowborder" valign="top" width="13.661366136613662%" id="mcps1.2.4.1.1"><p id="p1421643114288"><a name="p1421643114288"></a><a name="p1421643114288"></a>参数名称</p>
</th>
<th class="cellrowborder" valign="top" width="12.591259125912593%" id="mcps1.2.4.1.2"><p id="p82165310285"><a name="p82165310285"></a><a name="p82165310285"></a>输入/输出</p>
</th>
<th class="cellrowborder" valign="top" width="73.74737473747375%" id="mcps1.2.4.1.3"><p id="p1121663111288"><a name="p1121663111288"></a><a name="p1121663111288"></a>含义</p>
</th>
</tr>
</thead>
<tbody><tr id="row82161131182810"><td class="cellrowborder" valign="top" width="13.661366136613662%" headers="mcps1.2.4.1.1 "><p id="p68529181952"><a name="p68529181952"></a><a name="p68529181952"></a>gmWorkspace</p>
</td>
<td class="cellrowborder" valign="top" width="12.591259125912593%" headers="mcps1.2.4.1.2 "><p id="p208511818357"><a name="p208511818357"></a><a name="p208511818357"></a>输入</p>
</td>
<td class="cellrowborder" valign="top" width="73.74737473747375%" headers="mcps1.2.4.1.3 "><p id="p223862673213"><a name="p223862673213"></a><a name="p223862673213"></a>gmWorkspace为用户定义的全局Global空间，作为所有核共用的缓存，用于保存每个核的状态标记，类型为GlobalTensor，支持的数据类型为int32_t。GlobalTensor数据结构的定义请参考<a href="GlobalTensor.md">GlobalTensor</a>。</p>
<p id="p1585111181855"><a name="p1585111181855"></a><a name="p1585111181855"></a>所需空间大小和使用注意项参见<a href="#section633mcpsimp">约束说明</a>。</p>
<p id="p377231420357"><a name="p377231420357"></a><a name="p377231420357"></a>硬同步接口不支持该参数。</p>
</td>
</tr>
<tr id="row5216163192815"><td class="cellrowborder" valign="top" width="13.661366136613662%" headers="mcps1.2.4.1.1 "><p id="p17849918857"><a name="p17849918857"></a><a name="p17849918857"></a>ubWorkspace</p>
</td>
<td class="cellrowborder" valign="top" width="12.591259125912593%" headers="mcps1.2.4.1.2 "><p id="p1484911181458"><a name="p1484911181458"></a><a name="p1484911181458"></a>输入</p>
</td>
<td class="cellrowborder" valign="top" width="73.74737473747375%" headers="mcps1.2.4.1.3 "><p id="p01242034135414"><a name="p01242034135414"></a><a name="p01242034135414"></a>ubWorkspace为用户定义的局部Local空间，每个核单独自用，用于标记当前核的状态。</p>
<p id="p16703131355116"><a name="p16703131355116"></a><a name="p16703131355116"></a>类型为<a href="LocalTensor.md">LocalTensor</a>，支持的TPosition为VECIN/VECCALC/VECOUT，支持的数据类型为int32_t。</p>
<p id="p684819181755"><a name="p684819181755"></a><a name="p684819181755"></a>所需空间大小参见<a href="#section633mcpsimp">约束说明</a>。</p>
<p id="p1139714285356"><a name="p1139714285356"></a><a name="p1139714285356"></a>硬同步接口不支持该参数。</p>
</td>
</tr>
<tr id="row0101323102711"><td class="cellrowborder" valign="top" width="13.661366136613662%" headers="mcps1.2.4.1.1 "><p id="p2010172315276"><a name="p2010172315276"></a><a name="p2010172315276"></a>usedCores</p>
</td>
<td class="cellrowborder" valign="top" width="12.591259125912593%" headers="mcps1.2.4.1.2 "><p id="p131012372711"><a name="p131012372711"></a><a name="p131012372711"></a>输入</p>
</td>
<td class="cellrowborder" valign="top" width="73.74737473747375%" headers="mcps1.2.4.1.3 "><p id="p15101023102712"><a name="p15101023102712"></a><a name="p15101023102712"></a>指定多少个核之间的同步，传入数值不能超过算子调用时指定的逻辑numBlocks。此参数为默认参数，不传此参数表示全核软同步。</p>
<p id="p13881143914351"><a name="p13881143914351"></a><a name="p13881143914351"></a>仅在软同步接口中支持，硬同步接口不支持该参数。</p>
</td>
</tr>
</tbody>
</table>

## 返回值说明<a name="section91032023123812"></a>

无

## 约束说明<a name="section633mcpsimp"></a>

-   gmWorkspace缓存申请的空间大小要求大于等于核数\*32Bytes，并且缓存的值需要初始化为0。目前常见的有两种初始化方式：
    -   通过在host侧进行初始化操作，确保传入该接口时，gmWorkspace缓存已经初始化为0；
    -   在kernel侧初始化的时候对gmWorkspace缓存初始化，需要注意的是，每个核上都需要初始化全部的gmWorkspace缓存空间。

-   ubWorkspace申请的空间大小要求大于等于核数\*32Bytes。
-   使用该接口进行多核控制时，算子调用时指定的逻辑numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel“卡死”现象。
-   在分离模式下，建议使用硬同步接口而非软同步接口。软同步接口仅适用于纯Vector场景，且性能较低。使用硬同步接口时，需根据场景设置Kernel类型：
    -   在纯Vector/Cube场景下，需设置Kernel类型为KERNEL\_TYPE\_MIX\_AIV\_1\_0或KERNEL\_TYPE\_MIX\_AIC\_1\_0。
    -   对于Vector和Cube混合场景，需根据实际情况灵活配置Kernel类型。

-   使用该接口时，必须通过[SetScheduleMode](https://www.hiascend.com/document/detail/zh/canncommercial/850/API/basicdataapi/atlasopapi_07_00248.html)使能batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
    -   多流并发场景（≥2条执行流）。
    -   ≥2个算子并发执行。
    -   所有并发算子的核数总和超过物理核数。
    -   ≥2个并发算子使用了核间同步功能。

        具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。

## 调用示例<a name="section642mcpsimp"></a>

本示例实现功能为使用8个核进行数据处理，每个核均是处理32个float类型数据，对该数据乘2后再与其他核上进行同样乘2的数据进行相加，中间结果保存到workGm，因此多个核之间需要进行数据同步。此样例中，使用软同步，入口函数传入的syncGm里的值都已经在host侧初始化为0。若以下用例改成使用硬同步，则不需要传入syncGm，并且不需要使用workQueue。

```
#include "kernel_operator.h"

const int32_t DEFAULT_SYNCALL_NEED_SIZE = 8;

class KernelSyncAll {
public:
    __aicore__ inline KernelSyncAll() {}
    __aicore__ inline void Init(__gm__ uint8_t* srcGm, __gm__ uint8_t* dstGm, __gm__ uint8_t* workGm,
        __gm__ uint8_t* syncGm)
    {
        blockNum = AscendC::GetBlockNum(); // 获取核总数
        perBlockSize = srcDataSize / blockNum; // 每个核平分处理相同个数
        blockIdx = AscendC::GetBlockIdx(); // 获取当前工作的核ID
        srcGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(srcGm + blockIdx * perBlockSize * sizeof(float)),
            perBlockSize);
        dstGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(dstGm + blockIdx * perBlockSize * sizeof(float)),
            perBlockSize);
        workGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workGm), srcDataSize);
        syncGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ int32_t*>(syncGm), blockNum * DEFAULT_SYNCALL_NEED_SIZE);
        pipe.InitBuffer(inQueueSrc1, 1, perBlockSize * sizeof(float));
        pipe.InitBuffer(inQueueSrc2, 1, perBlockSize * sizeof(float));
        pipe.InitBuffer(workQueue, 1, blockNum * DEFAULT_SYNCALL_NEED_SIZE * sizeof(int32_t));
        pipe.InitBuffer(outQueueDst, 1, perBlockSize * sizeof(float));
    }
    __aicore__ inline void Process()
    {
        CopyIn();
        FirstCompute();
        CopyToWorkGlobal(); // 当前工作核计算后的数据先保存到外部工作空间
        // 等待所有核都完成计算
        AscendC::LocalTensor<int32_t> workLocal = workQueue.AllocTensor<int32_t>();
        AscendC::SyncAll(syncGlobal, workLocal);
        workQueue.FreeTensor(workLocal);
        // 最终累加结果需要等所有核都计算完成
        AscendC::LocalTensor<float> srcLocal2 = inQueueSrc2.DeQue<float>();
        AscendC::LocalTensor<float> dstLocal = outQueueDst.AllocTensor<float>();
        AscendC::DataCopy(dstLocal,srcLocal2,perBlockSize); // 当前核计算结果先保存到目的空间
        inQueueSrc2.FreeTensor(srcLocal2);
        for (int i = 0; i < blockNum; i++) {
            if (i != blockIdx) {
                CopyFromOtherCore(i); // 从外部工作空间读取数据
                Accumulate(dstLocal); // 所有数据都累加到目的空间
            }
        }
        outQueueDst.EnQue(dstLocal);
        CopyOut();
    }
private:
    __aicore__ inline void CopyToWorkGlobal()
    {
        AscendC::LocalTensor<float> dstLocal = outQueueDst.DeQue<float>();
        AscendC::DataCopy(workGlobal[blockIdx * perBlockSize], dstLocal, perBlockSize);
        outQueueDst.FreeTensor(dstLocal);
    }
    __aicore__ inline void CopyFromOtherCore(int index)
    {
        AscendC::LocalTensor<float> srcLocal = inQueueSrc1.AllocTensor<float>();
        AscendC::DataCopy(srcLocal, workGlobal[index * perBlockSize], perBlockSize);
        inQueueSrc1.EnQue(srcLocal);
    }
    __aicore__ inline void Accumulate(const AscendC::LocalTensor<float> &dstLocal)
    {
        AscendC::LocalTensor<float> srcLocal1 = inQueueSrc1.DeQue<float>();
        AscendC::Add(dstLocal, dstLocal, srcLocal1, perBlockSize);
        inQueueSrc1.FreeTensor(srcLocal1);
    }
    __aicore__ inline void CopyIn()
    {
        AscendC::LocalTensor<float> srcLocal = inQueueSrc1.AllocTensor<float>();
        AscendC::DataCopy(srcLocal, srcGlobal, perBlockSize);
        inQueueSrc1.EnQue(srcLocal);
    }
    __aicore__ inline void FirstCompute()
    {
        AscendC::LocalTensor<float> srcLocal1 = inQueueSrc1.DeQue<float>();
        AscendC::LocalTensor<float> srcLocal2 = inQueueSrc2.AllocTensor<float>();
        AscendC::LocalTensor<float> dstLocal = outQueueDst.AllocTensor<float>();
        float scalarValue(2.0);
        AscendC::Muls(dstLocal, srcLocal1, scalarValue, perBlockSize);
        AscendC::PipeBarrier<PIPE_V>();
        AscendC::DataCopy(srcLocal2,dstLocal,perBlockSize);
        inQueueSrc1.FreeTensor(srcLocal1);
        inQueueSrc2.EnQue(srcLocal2);
        outQueueDst.EnQue(dstLocal);
    }
    __aicore__ inline void CopyOut()
    {
        AscendC::LocalTensor<float> dstLocal = outQueueDst.DeQue<float>();
        AscendC::DataCopy(dstGlobal, dstLocal, perBlockSize);
        outQueueDst.FreeTensor(dstLocal);
    }
private:
    AscendC::TPipe pipe;
    AscendC::TQue<AscendC::TPosition::VECIN, 1> inQueueSrc1;
    AscendC::TQue<AscendC::TPosition::VECIN, 1> inQueueSrc2;
    AscendC::TQue<AscendC::TPosition::VECIN, 1> workQueue;
    AscendC::TQue<AscendC::TPosition::VECOUT, 1> outQueueDst;
    AscendC::GlobalTensor<float> srcGlobal;
    AscendC::GlobalTensor<float> dstGlobal;
    AscendC::GlobalTensor<float> workGlobal;
    AscendC::GlobalTensor<int32_t> syncGlobal;
    int srcDataSize = 256;
    int32_t blockNum = 0;
    int32_t blockIdx = 0;
    uint32_t perBlockSize = 0;
};

extern "C" __global__ __aicore__ void kernel_syncAll_float(__gm__ uint8_t* srcGm, __gm__ uint8_t* dstGm,
    __gm__ uint8_t* workGm, __gm__ uint8_t* syncGm)
{
    KernelSyncAll op;
    op.Init(srcGm, dstGm, workGm, syncGm);
    op.Process();
}
```

```
输入数据(srcGm):
[1,1,1,1,1,...,1]
输出数据(dstGm):
[16,16,16,16,16,...,16]
```
````

## ITEM 4

### item 3

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/inter_core_sync_overview.md
hicann/asc-devkit, master
核间同步 overview table that classifies SyncAll's two prototypes as 硬件同步 vs 软件同步 and states the soft-sync algorithm (write 1 to own GM slot, then poll all AIV slots until all are 1).
```markdown
# 核间同步能力概述<a name="ZH-CN_TOPIC_0000002555803758"></a>

核间同步的使用场景通常是：一个核计算所依赖的数据，需要等待其他相关核的计算全部完成后才能获取。  

以图1为例，AIC需要依赖于AIV的ReduceSum计算结果。由于整体矢量较大，必须拆分为多个部分，由每个AIV分别完成部分计算。每个AIV将其部分计算结果通过原子累加写入GM。AIC需要读取的必须是所有AIV均完成累加后的最终结果，因此需要通过核间同步来保证AIC读取ReduceSum结果时的时序正确性。

**图1**  核间同步业务场景示例图（AIC:AIV为1 : 2）<a name="zh-cn_topic_0000002542605351_fig1180684585013"></a>  
![](../../../../figures/inter_core_sync_scenario_example.png "核间同步业务场景示例图（AIC-AIV为1-2）")

AIC/AIV多核结构如下图2所示，AIC/AIV按group划分。一个group内包含1个block和N个subblock（N≥1），其中block表示“主核”，每个subblock表示一个“从核”。

算子按计算特征可分为三类：Cube算子（矩阵计算）、Vector算子（矢量计算）和Mix算子（同时包含矩阵和矢量计算）。如表1所示，算子类型决定了其所需的核间同步方式和可选的group配置模式。其中Mix算子通过函数执行空间限定符指定AIC与AIV的block/subblock关系；Cube算子和Vector算子为单类核执行，不涉及block/subblock划分。AIV为block且AIC为subblock的配置（即Vector核为主、Cube核为辅的模式）当前不支持。表2总结了核间同步接口及其支持的同步场景。

**图2**  block和subblock之间关系（灰色部分表示一个group，即1个block和N个subblock）<a name="zh-cn_topic_0000002542605351_fig52727114018"></a>
![](../../../../figures/block_subblock_relationship_3510.png "（NPU架构版本3510）block和subblock之间关系（灰色部分表示一个group，即1个block和N个subblock）")

**表1**  group配置<a name="zh-cn_topic_0000002542605351_table17238184964217"></a>

| 算子类型 | 函数执行空间限定符 | 核函数（Kernel）类型 | block/subblock | 1 ：N |
| --- | --- | --- | --- | --- |
| Cube算子 | \_\_cube\_\_ | KERNEL_TYPE_AIC_ONLY | AIC为block，无subblock | 不涉及 |
| Vector算子 | \_\_vector\_\_ | KERNEL_TYPE_AIV_ONLY | AIV为block，无subblock | 不涉及 |
| Mix算子 | \_\_mix\_\_(1, 0) | KERNEL_TYPE_MIX_AIC_1_0 | AIC为block，无subblock | 不涉及 |
| Mix算子 | \_\_mix\_\_(0, 1) | KERNEL_TYPE_MIX_AIV_1_0 | AIV为block，无subblock | 不涉及 |
| Mix算子 | \_\_mix\_\_(1, 1) | KERNEL_TYPE_MIX_AIC_1_1 | AIC为block，AIV为subblock | 1：1 |
| Mix算子 | \_\_mix\_\_(1, 2) | KERNEL_TYPE_MIX_AIC_1_2 | AIC为block，AIV为subblock | 1：2 |

**表2**  支持的核间同步场景

| 接口名称 | 核间同步场景概述 | 同步类别 |
| --- | --- | --- |
| [CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)/[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md) | 多个AIC或AIV之间的同步控制。CrossCoreSetFlag负责发送通知，CrossCoreWaitFlag负责阻塞直到CrossCoreSetFlag发送通知。<br>支持以下同步场景：<br>&bull;（模式0）同步等待全部AIC或者同步等待全部AIV执行结束。<br>&bull;（模式1）单个AI Core内，全部AIV之间的同步。<br>&bull;（模式2）单个AI Core内，AIC与全部AIV之间的同步。<br>&bull;（模式4）单个AI Core内，AIC核与单个AIV之间同步。 | 硬件同步 |
| [IBSet](IBSet.md)/[IBWait](IBWait.md) | IBSet和IBWait配合使用，用于一对AIV间的同步：等待核调用IBWait阻塞本核后续指令的执行，被等待核调用IBSet通知等待核解除阻塞。上述同步过程的原理如下：被等待核中调用IBSet，通过将值1写入全局内存中某块地址来通知等待核；而等待核中调用IBWait，持续读取全局内存中相应地址块的值，直到其值变为1。 | 软件同步 |
| [SyncAll](SyncAll.md) | 用于多个核之间的同步控制，支持以下同步场景：<br>&bull;纯Vector算子的全核同步，可参考[CrossCoreSetFlag的模式0](key_features.md)。<br>&bull;融合算子的全核同步，一次性实现三个核间同步能力（参考[CrossCoreSetFlag的关键特性说明](key_features.md)）：首先完成单个AI Core内，AIC与全部AIV之间的同步（AIC等AIV）；接着完成多个AI Core间，所有AIC的同步；最后完成单个AI Core内，所有AIV与AIC同步（AIV等AIC）。 | 硬件同步 |
| [SyncAll](SyncAll.md) | 仅支持纯Vector算子的多核（参与同步的核数可通过入参指定）同步。每一个AIV都向全局内存对应位置写入信号值1，接着每一个AIV都持续轮询全局内存中所有AIV对应的信号值，直到所有AIV核对应的信号值都变为1。 | 软件同步 |
| [InitDetermineComputeWorkspace](InitDetermineComputeWorkspace.md)/[NotifyNextBlock](NotifyNextBlock.md)/[WaitPreBlock](WaitPreBlock.md) | &bull; InitDetermineComputeWorkspace、NotifyNextBlock和WaitPreBlock三个接口必须组合使用，能够确保多个AIV核严格按照blockIdx的升序执行，适用于要求确定性计算的场景。<br>&bull; InitDetermineComputeWorkspace初始化GM共享内存的值，完成初始化后才可以调用NotifyNextBlock和WaitPreBlock。<br>&bull; NotifyNextBlock通过写全局内存来通知其他核当前核已执行完成，其他核可以继续往下执行；WaitPreBlock通过读取全局内存，判断当前核是否可以继续往下执行。 | 软件同步 |
```

## ITEM 5

### item 4

https://raw.githubusercontent.com/hicann/asc-devkit/master/include/basic_api/kernel_operator_block_sync_intf.h
hicann/asc-devkit, last commit 2026-10-16 by maohaodi
Declaration header: the exact SyncAll overloads as declared (soft 3-arg with default usedCores=0; hard templated on isAIVOnly and, only for __NPU_ARCH__ in {3510,5102,5162,9201,9202}, on SyncAllConfig), plus IBSet/IBWait and CrossCoreSetFlag/CrossCoreWaitFlag declarations in the same header. Note the hard-sync config overload is NOT declared for __NPU_ARCH__==2201.
```cpp

template <HardEvent event>
__aicore__ inline void SetFlag(int32_t eventID);

template <HardEvent event>
__aicore__ inline void WaitFlag(int32_t eventID);

template <pipe_t pipe>
__aicore__ inline void PipeBarrier();

template <MemDsbT arg0>
__aicore__ inline void DataSyncBarrier();

/*
 * @ingroup：IBSet, IBWait
 * @brief：Set the flag bit of a core
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 * @param [in] blockIdx the idx number waiting for the core
 * @param [in] eventID Set and wait events
 */
template <bool isAIVOnly = true>
__aicore__ inline void IBSet(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);

template <bool isAIVOnly = true>
__aicore__ inline void IBWait(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, int32_t blockIdx,
    int32_t eventID);
/*
 * @ingroup：SyncALL
 * @brief：Set flag bits of all cores
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 */
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int32_t usedCores = 0);

#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 5162) || \
                              (__NPU_ARCH__ == 9201) || (__NPU_ARCH__ == 9202))
template <bool isAIVOnly = true, const SyncAllConfig& config = DEFAULT_SYNC_ALL_CONFIG>
__aicore__ inline void SyncAll();
#else
template <bool isAIVOnly = true>
__aicore__ inline void SyncAll();
#endif

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId);

template <uint8_t modeId = 0, pipe_t pipe = PIPE_S>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId);

template <pipe_t src, pipe_t dst>
class TQueSync {
public:
    __aicore__ inline void SetFlag(TEventID id);
    __aicore__ inline void WaitFlag(TEventID id);
```

## ITEM 6

### item 5

https://raw.githubusercontent.com/hicann/asc-devkit/master/impl/basic_api/kernel_operator_block_sync_intf_impl.h
hicann/asc-devkit, last commit 2026-10-16 by maohaodi
Dispatch impl: __NPU_ARCH__==2201 selects dav_c220/kernel_operator_sync_impl.h; SyncAll(gm,ub,usedCores) forwards to SoftSyncAllImpl, SyncAll<isAIVOnly>() forwards to SyncAllImpl, and CrossCoreSetFlag/CrossCoreWaitFlag forward to NotifyEventImpl/WaitEventImpl.
```cpp
#include "dav_c100/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 2002
#include "dav_m200/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 2201
#include "dav_c220/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 3002
#include "dav_m300/kernel_operator_common_impl.h"
#elif __NPU_ARCH__ == 3003
#include "dav_l300/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 3102
#include "dav_m310/kernel_operator_common_impl.h"
#elif __NPU_ARCH__ == 3510
#include "dav_3510/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 9201
#include "dav_9201/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 9202
#include "dav_9202/kernel_operator_sync_impl.h"
#elif (__NPU_ARCH__ == 5102)
#include "dav_m510/kernel_operator_sync_impl.h"
#elif (__NPU_ARCH__ == 5162)
#include "dav_5162/kernel_operator_sync_impl.h"
#elif (__NPU_ARCH__ == 3113)
#include "dav_l311/kernel_operator_sync_impl.h"
#elif (__NPU_ARCH__ == 5101) || (__NPU_ARCH__ == 5161) || (__NPU_ARCH__ == 5165) || (__NPU_ARCH__ == 5163)
#include "dav_5161/kernel_operator_sync_impl.h"
#endif

namespace AscendC {


/* ... */

/*
 * @ingroup：SyncALL
 * @brief：Set flag bits of all cores
 * @param [in] gmWorkspace GlobalTensor to store core state
 * @param [in] ubWorkspce LocalTensor for current core
 */
template <bool isAIVOnly>
__aicore__ inline void SyncAll(
    const GlobalTensor<int32_t>& gmWorkspace, const LocalTensor<int32_t>& ubWorkspace, const int usedCores)
{
#if ASCENDC_CPU_DEBUG
    SoftSyncAllImpl<false>(
        (__gm__ int32_t*)gmWorkspace.GetPhyAddr(), (__ubuf__ int32_t*)ubWorkspace.GetPhyAddr(), usedCores);
#else
    SoftSyncAllImpl<isAIVOnly>(
        (__gm__ int32_t*)gmWorkspace.GetPhyAddr(), (__ubuf__ int32_t*)ubWorkspace.GetPhyAddr(), usedCores);
#endif
}

#if (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 5162) || (__NPU_ARCH__ == 9201) || \
    (__NPU_ARCH__ == 9202)
template <bool isAIVOnly, const SyncAllConfig& config>
__aicore__ inline void SyncAll()
{
    SyncAllImpl<isAIVOnly, config.triggerPipe, config.waitPipe>();
}
#else
template <bool isAIVOnly>
__aicore__ inline void SyncAll()
{
    SyncAllImpl<isAIVOnly>();
}
#endif

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
{
    NotifyEventImpl<modeId, pipe>(flagId);
}

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId)
{
    WaitEventImpl<modeId, pipe>(flagId);
}

#if (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 5162) || (__NPU_ARCH__ == 9201) || \
    (__NPU_ARCH__ == 9202)
template <pipe_t pipe, uint8_t subBlockSyncMode = 2>
__aicore__ inline void NotifyEvent(uint16_t flagId)
{
    NotifyEventImpl<subBlockSyncMode, pipe>(flagId);
}

template <pipe_t pipe = PIPE_S, uint8_t mode = 0>
__aicore__ inline void WaitEvent(uint16_t flagId)
{
    WaitEventImpl<mode, pipe>(flagId);
}
#else
template <pipe_t pipe>
__aicore__ inline void NotifyEvent(uint16_t flagId)
{
    constexpr uint8_t subBlockSyncMode = 0x02;
    NotifyEventImpl<subBlockSyncMode, pipe>(flagId);
}

template <pipe_t pipe = PIPE_S>
__aicore__ inline void WaitEvent(uint16_t flagId)
{
    constexpr uint8_t mode = 0;
    WaitEventImpl<mode, pipe>(flagId);
}
#endif
```

## ITEM 7

### item 6

https://raw.githubusercontent.com/hicann/asc-devkit/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h
hicann/asc-devkit, last commit 2026-07-11 by haipingmao
THE dav-2201 soft-sync implementation (__NPU_ARCH__==2201 maps to dav_c220). SoftSyncAllImpl + ClcSyncCount: GM slot per core at blockIdx*DEFAULT_BLK_NUM, read-modify-write own slot, then a `while(true)` loop re-copying the whole gmWorkspace GM->UB and summing all slots until count >= totalBlocks*curValue. AIC returns immediately. totalBlocks = usedCores if nonzero else GetBlockNum() (x GetTaskRation() when !isAIVOnly).
```cpp
namespace AscendC {

__aicore__ inline void ClcSyncCount(
    __gm__ int32_t* localSyncGM, __ubuf__ int32_t* ubWorkspaceAddr, const int32_t blockIdx, const int32_t totalBlocks,
    bool isFirst, int32_t& count)
{
    if (isFirst) {
        __ubuf__ int32_t* localUbAddr = ubWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);
        *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) = 1;
        event_t eventIdSToMte3 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE3));
        SetFlag<HardEvent::S_MTE3>(eventIdSToMte3);
        WaitFlag<HardEvent::S_MTE3>(eventIdSToMte3);
        copy_ubuf_to_gm(
            static_cast<__gm__ void*>(localSyncGM), static_cast<__ubuf__ void*>(localUbAddr), 0, 1, 1, 0, 0);
        event_t eventIDMTE3ToMTE2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE3_MTE2));
        SetFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
        WaitFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
        count = 1;
        for (int32_t i = 0; i < totalBlocks; i++) {
            if (i != blockIdx) {
                count += *(reinterpret_cast<__ubuf__ int32_t*>(ubWorkspaceAddr) + i * ONE_BLK_FLOAT_NUM);
            }
        }
    } else {
        for (int32_t i = 0; i < totalBlocks; i++) {
            count += *(reinterpret_cast<__ubuf__ int32_t*>(ubWorkspaceAddr) + i * ONE_BLK_FLOAT_NUM);
        }
    }
}

__aicore__ inline int64_t GetBlockNum();
template <bool isAIVOnly = true>
__aicore__ inline void SoftSyncAllImpl(
    __gm__ int32_t* gmWorkspaceAddr, __ubuf__ int32_t* ubWorkspaceAddr, const int usedCores)
{
    if ASCEND_IS_AIC {
        return;
    }
    __sync_all_stub(usedCores, isAIVOnly);
    PipeBarrier<PIPE_ALL>();

    int32_t totalBlocks = isAIVOnly ? GetBlockNum() : (GetTaskRationImpl() * GetBlockNum());
    totalBlocks = usedCores != 0 ? usedCores : totalBlocks;
#ifdef __ASCENDC_ENABLE_SUPER_KERNEL__
    int32_t blockIdx = GetBlockIdxImpl();
#else
    int32_t blockIdx = isAIVOnly ? get_block_idx() : GetBlockIdxImpl();
#endif

    __gm__ int32_t* localSyncGM = gmWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);
    __ubuf__ int32_t* localUbAddr = ubWorkspaceAddr + (blockIdx * DEFAULT_BLK_NUM);

    copy_gm_to_ubuf(static_cast<__ubuf__ void*>(localUbAddr), static_cast<__gm__ void*>(localSyncGM), 0, 1, 1, 0, 0);
    event_t eventIdMte2ToS = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE2_S));
    SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    int32_t curValue = *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) + 1;
    bool isFirst = curValue == 1 ? true : false;
    *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) = curValue;
    event_t eventIdSToMte3 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE3));
    SetFlag<HardEvent::S_MTE3>(eventIdSToMte3);
    WaitFlag<HardEvent::S_MTE3>(eventIdSToMte3);
    copy_ubuf_to_gm(static_cast<__gm__ void*>(localSyncGM), static_cast<__ubuf__ void*>(localUbAddr), 0, 1, 1, 0, 0);
    event_t eventIDMTE3ToMTE2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE3_MTE2));
    SetFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
    WaitFlag<HardEvent::MTE3_MTE2>(eventIDMTE3ToMTE2);
    int32_t totalBlockCount = ONE_BLK_FLOAT_NUM * totalBlocks;
    uint16_t blockLen = totalBlockCount / AscendCUtils::GetC0Count(sizeof(int32_t));
    while (true) {
        copy_gm_to_ubuf(
            static_cast<__ubuf__ void*>(ubWorkspaceAddr), static_cast<__gm__ void*>(gmWorkspaceAddr), 0, 1, blockLen, 0,
            0);
        SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        int32_t count = 0;
        ClcSyncCount(localSyncGM, ubWorkspaceAddr, blockIdx, totalBlocks, isFirst, count);
        event_t eventIdSToMte2 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE2));
        SetFlag<HardEvent::S_MTE2>(eventIdSToMte2);
        WaitFlag<HardEvent::S_MTE2>(eventIdSToMte2);
        if (count >= (totalBlocks * curValue)) {
            break;
        }
    }
    __sync_all_stub(usedCores, isAIVOnly);
}
```

## ITEM 8

### item 7

https://raw.githubusercontent.com/hicann/asc-devkit/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h
hicann/asc-devkit, last commit 2026-07-11 by haipingmao
THE dav-2201 hard-sync implementation: flag constants (SYNC_AIV_FLAG=12, SYNC_AIC_FLAG=11, SYNC_AIC_AIV_FLAG=13, SYNC_AIV_ONLY_ALL=14), GetffstMsg bit packing, SyncAllImpl itself (PipeBarrier<PIPE_ALL> then ffts_cross_core_sync(PIPE_MTE3, ...) + wait_flag_dev for isAIVOnly; the three-stage AIC/AIV handshake otherwise), and NotifyEventImpl/WaitEventImpl = the primitives behind CrossCoreSetFlag/CrossCoreWaitFlag.
```cpp
constexpr uint16_t SYNC_AIV_FLAG = 12;
constexpr uint16_t SYNC_AIC_FLAG = 11;
constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;

__aicore__ inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId)
{
    return (0x1 + ((mode & 0x3) << SYNC_MODE_SHIFT_VALUE) + ((flagId & 0xf) << SYNC_FLAG_SHIFT_VALUE));
}

/* ... */


template <bool isAIVOnly = true>
__aicore__ inline void SyncAllImpl()
{
#if defined(__ASCENDC_SUPERKERNEL_AUTO_SYNC_ALL__)
    if (g_superKernelAutoSyncAllEnable) {
        if (GetBlockIdxImpl() == 0) {
            g_superKernelAutoSyncAllSyncIdx += 1;
            // |    32bits  |   16bits  |   8bits   |   8bits   |
            // |  sync idx  | sync type |   is end  | is valid  |
            *reinterpret_cast<__gm__ uint64_t*>(g_superKernelAutoSyncAllConfigGmAddr) =
                (static_cast<uint64_t>(g_superKernelAutoSyncAllSyncIdx)
                 << SK_AUTO_SYNC_ALL_SYNC_IDX_CONFIG_BIT_OFFSET) |
                (static_cast<uint64_t>(isAIVOnly) << SK_AUTO_SYNC_ALL_SYNC_TYPE_CONFIG_BIT_OFFSET) |
                static_cast<uint64_t>(SK_AUTO_SYNC_ALL_VALID_MAGIC_NUM);
            dcci(
                reinterpret_cast<__gm__ uint64_t*>(g_superKernelAutoSyncAllConfigGmAddr),
                cache_line_t::SINGLE_CACHE_LINE, dcci_dst_t::CACHELINE_OUT);
        }
    }
#endif

    PipeBarrier<PIPE_ALL>();
    if constexpr (isAIVOnly) {
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x0, SYNC_AIV_ONLY_ALL));
        wait_flag_dev(SYNC_AIV_ONLY_ALL);
        return;
    }
    // trans software sync to hardware sync
    if ASCEND_IS_AIC {
        wait_flag_dev(SYNC_AIV_FLAG);
        ffts_cross_core_sync(PIPE_FIX, GetffstMsg(0x0, SYNC_AIC_FLAG));
        wait_flag_dev(SYNC_AIC_FLAG);
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIC_AIV_FLAG));
        return;
    }
    if ASCEND_IS_AIV {
        ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIV_FLAG));
        wait_flag_dev(SYNC_AIC_AIV_FLAG);
        return;
    }
}

/* ... */


template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void NotifyEventImpl(uint16_t flagId)
{
    ffts_cross_core_sync(pipe, GetffstMsg(modeId, flagId));
}

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void WaitEventImpl(uint16_t flagId)
{
    (void)modeId;
    wait_flag_dev(flagId);
}

__aicore__ inline void SetSyncBaseAddrImpl(uint64_t config) { set_ffts_base_addr(config); }

__aicore__ inline void SetSyncBaseAddr(uint64_t config) { SetSyncBaseAddrImpl(config); }
```

## ITEM 9

### item 8

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/key_features.md
hicann/asc-devkit, last commit 2026-09-30 by ai_xin
核间同步 flagId 占用说明: which flagIds SyncAll consumes internally on NPU 架构版本 2201 (isAIVOnly=true -> 14 on AIV; isAIVOnly=false -> 11/12/13), and the conflict failure modes. This is the CrossCoreSetFlag/CrossCoreWaitFlag-vs-SyncAll relationship stated normatively.
```markdown
## 核间同步flagId占用说明<a id="inter_core_sync_flagid_usage"></a>

### 概述

开发者使用[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)接口进行核间同步时，需要传入核间同步标记**flagId**，每个flagId对应一个用于控制同步的计数器。

部分接口的内部实现也会占用一部分flagId。当开发者同时使用这些接口与CrossCoreSetFlag/CrossCoreWaitFlag时，若flagId发生冲突（即相互独立的同步操作复用了同一个flagId），其对应的计数器会被错误地共享和修改，导致核间同步行为异常：可能出现阻塞无法解除而使程序卡死，或同步提前完成、阻塞提前解除而导致计算结果错误。

因此，当开发者同时调用CrossCoreSetFlag/CrossCoreWaitFlag与这些占用flagId的接口时，应**避开各接口内部已占用的flagId**，选用未被占用的flagId。

核间同步分为**模式0、1、2**与**模式4**，两者的底层硬件指令不同，flagId相互独立，因此各接口flagId的占用情况按**所属模式**和**NPU架构版本**分别参见[模式0、1、2的flagId占用](#inter_core_sync_flagid_mode012)和[模式4的flagId占用](#inter_core_sync_flagid_mode4)。

### 模式0、1、2的flagId占用<a id="inter_core_sync_flagid_mode012"></a>

**表1**  模式0、1、2flagId占用情况

| 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
| :--- | :--- | :--- | :--- | :--- |
| [SyncAll](SyncAll.md) | `isAIVOnly=true` | 14 | AIV：14 | 2201、3510 |
| [SyncAll](SyncAll.md) | `isAIVOnly=false` | 11、12、13 | AIC：11、12、13；AIV：12、13 | 2201、3510 |
| [SetNextTaskStart](../inter_task_sync/SetNextTaskStart.md) | SuperKernel子核函数（Kernel）中调用 | 11、14 | AIC：11；AIV：14 | 2201、3510 |
| [WaitPreTaskEnd](../inter_task_sync/WaitPreTaskEnd.md) | SuperKernel子核函数（Kernel）中调用 | 11、12、13、14 | AIC：11、12、13；AIV：12、13、14 | 2201、3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | 定义N个Matmul对象 | `[0, 2N-1]` | AIV/AIC按对象与subBlock分配 | 2201 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | SuperKernel融合场景（[GetTaskRatio](../../tool_interface/system_resources_and_variables/GetTaskRatio.md)返回2，即1:2配比） | 15 | AIV：15 | 2201 |

### 模式4的flagId占用<a id="inter_core_sync_flagid_mode4"></a>

**表2**  模式4flagId占用情况

| 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
| :--- | :--- | :--- | :--- | :--- |
| [SyncAll](SyncAll.md) | `isAIVOnly=false`（核函数（Kernel）使用`__mix__(1, 2)`修饰时） | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
| [WaitPreTaskEnd](../inter_task_sync/WaitPreTaskEnd.md) | SuperKernel子核函数（Kernel）中调用 | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | 定义N个[Matmul对象](../../../adv_api/cube_compute/Matmul_Kernel/REGIST_MATMUL_OBJ.md) | `[0, N+17]` | AIC/AIV按对象、eventType、subBlock分配 | 3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | A矩阵和B矩阵同时开启[IBSHARE](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_usage.md#p84551411817)的场景 | 15 | AIV：15 | 3510 |
| [TSCM](../../resource_management/TSCM/TSCM.md) | 从UB发起的L1 Buffer（TSCM）队列 | 0~11（从11向下逐个分配） | AIV | 3510 |
| [DataCopy（GM→L1）](../../cube_compute_ISASI/cube_compute_load/DataCopy_GMToL1_continuous.md) | 无 | 1、17 | AIC：1、17；AIV：1 | 3510 |

### 各接口限定条件说明

#### SyncAll

- **isAIVOnly=true**：纯Vector算子的全核同步，占用模式0、1、2的flagId为14（AIV）。
- **isAIVOnly=false**：Mix（包含Cube和Vector计算）算子的全核同步，占用情况随NPU架构与核函数（Kernel）类型不同：
    - **2201架构**：占用模式0、1、2的flagId为11、12、13。
    - **3510架构**：
        - 核函数（Kernel）使用`__mix__(1, 1)`修饰时，占用模式0、1、2的flagId为11、12、13。
        - 核函数（Kernel）使用`__mix__(1, 2)`修饰时，占用模式0、1、2的flagId为11，以及模式4的flagId为12、13、28、29。

    以上`isAIVOnly`模板参数的说明参见[SyncAll](SyncAll.md)；`__mix__(1, 1)`/`__mix__(1, 2)`修饰符的说明参见[函数执行空间限定符](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md#函数执行空间限定符)。

#### SetNextTaskStart / WaitPreTaskEnd

- 二者为**SuperKernel**场景专用接口，仅在算子以[SuperKernel](../../../../../guide/programming_guide/advanced_programming/super_kernel/principles.md)方式融合、且子核函数（Kernel）中调用时才生效。
- **SetNextTaskStart**：占用模式0、1、2的flagId为11（AIC）、14（AIV）。参见[SetNextTaskStart](../inter_task_sync/SetNextTaskStart.md)。
- **WaitPreTaskEnd**：参见[WaitPreTaskEnd](../inter_task_sync/WaitPreTaskEnd.md)。
    - **2201架构**：占用模式0、1、2的flagId为11、12、13、14。
    - **3510架构**：占用模式0、1、2的flagId为11、12、13、14，以及模式4的flagId为12、13、28、29。
```

## ITEM 10

### item 9

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreSetFlag_ISASI.md
hicann/asc-devkit, last commit 2026-09-21 by munanhw
CrossCoreSetFlag official doc: the four sync modes, pipe restrictions (no PIPE_S / PIPE_ALL for modes 0/1/2), flagId ranges and the 0-15 counter saturation rule, the mode-to-kernel-type table (mode 0 needs __mix__(0,1)/__mix__(1,0)/..., KERNEL_TYPE_MIX_AIV_1_0 etc. because AIV_ONLY/AIC_ONLY does not start the scheduler), out-of-order sets, and the batchmode deadlock condition.
````markdown
## 功能说明<a id="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_block_sync_intf.h"`。

在核间同步场景中，CrossCoreSetFlag接口和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)接口配对工作，使用时需传入核间同步的标记ID（flagId），每个ID对应一个用于控制同步的计数器。

- CrossCoreSetFlag：AI Core中的AIC/AIV在完成本核前置位的pipe流水任务后，调用该接口，向调度模块上报本核任务已完成。调度模块收集所有参与核的上报信息，作为全局完成标志。
- CrossCoreWaitFlag：用于阻塞本核后续指令的下发（已下发指令可正常执行），直至调度模块确认所有应调用CrossCoreSetFlag的核均已上报完成，随即解除阻塞，允许该核继续下发指令。

如[图1](#fig37581010773)所示（图中block代表AIC，sub_block代表AIV），同步控制分为以下几种模式：

- 模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。
- 模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。
- 模式2：AI Core内部，AIC与所有AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后，两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
- 模式4：AI Core内部，AIC与单个AIV之间的同步控制。当在AIC核执行CrossCoreSetFlag之后，AIV0或者AIV1上CrossCoreWaitFlag后续的指令才会继续执行；AIV0或者AIV1执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。

> [!NOTE]说明
> - 不同型号支持的模式不同，具体支持情况请参考[modeId支持的取值说明](#modeId支持的取值说明)。
> - 每个模式的具体执行逻辑与细节可以参考[关键特性说明](key_features.md)。

**图1**  同步控制模式示意图<a id="fig37581010773"></a>  
![](../../../../figures/block_subblock_relationship_3510.png "同步控制模式示意图")

## 函数原型<a id="section620mcpsimp"></a>

```cpp
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
```

## 参数说明<a id="section622mcpsimp"></a>

### 模板参数及输入参数说明

CrossCoreSetFlag的模板参数`modeId`和`pipe`均**没有默认值**，其取值用于配置硬件指令，调用接口时必须**显式传入**。与本接口不同，CrossCoreWaitFlag的两个模板参数均具有默认值，且在不同产品和同步模式下的生效情况不同，因此**两个接口对模板参数的传入要求并不相同**。具体请参见[CrossCoreWaitFlag模板参数说明](CrossCoreWaitFlag_ISASI.md#template-parameter-defaults)。

**表1**  模板参数说明

| 参数名 | 描述 |
| --- | --- |
| modeId | 核间同步的模式，不同产品对同步模式的支持情况请参见[modeId支持的取值说明](#modeId支持的取值说明)。<br>各个模式支持的对应核函数（Kernel）类型请参照[表3](#table3)。 |
| pipe | 标识在哪条流水的前序指令完成后，CrossCoreSetFlag才向调度模块发送通知。支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX，不支持PIPE_S和PIPE_ALL。不同产品对流水类型的支持情况请参见[pipe支持的流水类型说明](#pipe支持的流水类型说明)。 |

**表2**  参数说明

| 参数名 | 输入/输出 | 描述 |
| --- | --- | --- |
| flagId | 输入 | 核间同步的标记。不同产品对flagId的取值范围说明请参见[flagId取值范围说明](#flagId取值范围说明)。 |

### modeId支持的取值说明<a id="modeId支持的取值说明"></a>

不同产品对同步模式的支持情况如下：
<!-- npu="950" id8 -->
- 针对Ascend 950PR&950DT系列产品，支持的同步模式为：模式0、模式1、模式2、模式4。
<!-- end id8 -->
<!-- npu="A3,910b" id9 -->
- 针对如下产品，支持的同步模式为：模式0、模式1、模式2。
    <!-- npu="A3" id10 -->
    - Atlas A3系列产品
    <!-- end id10 -->
    <!-- npu="910b" id11 -->
    - Atlas A2系列产品
    <!-- end id11 -->
<!-- end id9 -->

### pipe支持的流水类型说明<a id="pipe支持的流水类型说明"></a>

- 核间同步的模式为模式0、1、2时，
    - 支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX。
    - 不支持的流水类型为PIPE_ALL、PIPE_S。
<!-- npu="950" id12 -->
- 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，
    - 支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX、PIPE_S。
    - 不支持的流水类型为PIPE_ALL。
<!-- end id12 -->

### flagId取值范围说明<a id="flagId取值范围说明"></a>

- 核间同步的模式为模式0、1、2时，支持的取值范围为0-15。
<!-- npu="950" id13 -->
- 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，支持的取值范围情况如下：
    - AIV0发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-15的操作。
    - AIV1发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-31的操作。
    - AIC发起的flagId 0-15的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-15的操作。
    - AIC发起的flagId 16-31的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-15的操作。
<!-- end id13 -->

此外，当本接口与Matmul高阶API或SyncAll接口同时使用时，开发者自行使用的flagId还需注意避免与这些接口内部已占用的flagId冲突，详见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。

## 返回值说明<a id="section640mcpsimp"></a>

无

## 约束说明<a id="section633mcpsimp"></a>

- 由于当核函数（Kernel）类型为KERNEL_TYPE_AIC_ONLY或KERNEL_TYPE_AIV_ONLY时，硬件不会开启调度模块，也就无法正常进行核间同步，因此不同的同步模式配置[核函数（Kernel）类型](../../Kernel-Tiling/set_Kernel_type.md)或[函数执行空间限定符](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md#函数执行空间限定符)的情况如下：
    - 在纯Vector/Cube场景下（模式0或模式1），建议设置核函数（Kernel）类型为KERNEL\_TYPE\_MIX\_AIV\_1\_0或KERNEL\_TYPE\_MIX\_AIC\_1\_0，其它支持的核函数（Kernel）类型请参考表3。
    - 对于Vector和Cube混合场景（模式2和模式4），需根据AI Core中AIC和AIV的比例灵活配置核函数（Kernel）类型，不同模式支持的函数执行空间限定符和核函数（Kernel）类型请参照表3。

        **表3**  模式与支持的核函数（Kernel）类型配置<a id="table3"></a>

        | 模式 | 支持的函数执行空间限定符 | 支持的核函数（Kernel）类型配置 |
        | --- | --- | --- |
        | 0 | \_\_mix\_\_(0, 1)、\_\_mix\_\_(1, 0)、\_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIV\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 1 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 2 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 4 | \_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_2 |

- 以下接口内部实现中使用了CrossCoreSetFlag和CrossCoreWaitFlag会占用一部分flagId，开发者同时使用CrossCoreSetFlag/CrossCoreWaitFlag与这些接口时，需注意避免flagId使用冲突，各接口flagId占用的完整说明参见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。

- 用户需要确保配套使用CrossCoreSetFlag和CrossCoreWaitFlag，否则会出现未定义行为。
- 核间同步的模式为模式0、1、2时，模板参数pipe不支持设置为PIPE\_ALL，PIPE\_S。
<!-- npu="950" id14 -->
- 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，模板参数pipe不支持配置为PIPE\_ALL。
<!-- end id14 -->
- 一个核连续发出的CrossCoreSetFlag，硬件不保证执行顺序。例如AIV依次发射CrossCoreSetFlag<0, PIPE\_V\>\(0\)，CrossCoreSetFlag<0, PIPE\_V\>\(1\)，实际的执行顺序可能是flagId=1的先执行。
- flagId相关的约束：
    - 对于模式0、1、2，每个AIC和每个AIV都各自有16个flagId，支持的取值范围为0-15。如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- npu="950" id15 -->
    - 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，AIC有32个flagId，支持的取值范围为0-31，如果flagId的值超出该范围，则截取低5bit（例如，flagId=35时，截取后为3）；AIV有16个flagId，支持的取值范围为0-15，如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- end id15 -->
    - 每个flagId都对应一个计数器，当调用[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)时，若计数器值为0则会阻塞后续指令下发，已下发指令可正常执行；当调度模块感知到所有参与同步的核（具体包含哪些核与设置的核间同步模式有关）完成（调用了CrossCoreSetFlag）同步后，会将与设置的flagId对应的计数器的值增加1。此时，计数器值为非0，阻塞解除，并且将对应计数器的值减去1进行还原。具体执行逻辑与细节可以参考[关键特性说明](key_features.md)。每一个计数器计数范围为0-15。如果调用CrossCoreSetFlag的次数超过15次，计数器的值超出该范围，则会异常报错，中断流程。
- 核间同步的模式为模式0、1、2时，同一个flagId用于不同核间同步模式的约束：
    - 同一核上，若同一个flagId需用于不同核间同步模式，须在模式切换前完成前一个模式的所有同步操作——即确保该flagId关联的所有CrossCoreSetFlag与配套CrossCoreWaitFlag调用均已执行完毕。
    - 对于不同的核，可以直接将同一flagId用于不同的核间同步模式，具体包括以下2种场景：
        - 多个AI Core之间，使用flagId=0同步所有的AIC（模式0）；单个AI Core内，使用flagId=0同步所有AIV（模式1）。
        - 单个AI Core内，使用flagId=0同步所有AIV（模式1）；另一个AI Core内，使用flagId=0同步AIC与所有AIV（模式2）。
- 使用该接口模式0时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
    - 多流并发场景（≥2条执行流）。
    - ≥2个算子并发执行。
    - 所有并发算子的核数总和超过物理核数。
    - ≥2个并发算子使用了核间同步功能。

    具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。
    核函数（Kernel）直调场景下通过[\_\_schedmode\_\_\(mode\)](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式，具体请参考《[基础数据结构和接口](https://gitcode.com/cann/metadef/blob/master/docs/zh/api/README.md)》。

## 调用示例<a id="section837496171220"></a>

**表4**  样例描述

| SCENARIO_NUM取值 | 业务场景 | 使用的同步模式 |
| --- | --- | --- |
| 0 | 纯Vector计算场景（16个AIV） | mode0（AIV全核同步） |
| 1 | 纯Vector计算场景（2个AIV） | mode1 |
| 2 | Cube与Vector融合计算场景 | mode2（AIC等AIV）、mode2（AIV等AIC）、mode0（AIC全核同步） |

如上表所示，当SCENARIO_NUM取不同值时，会分别演示纯Vector计算场景和Cube与Vector融合计算场景下三种同步模式的具体使用方法，下面展示了纯Vector计算场景的部分调用代码：

```cpp
    AscendC::Muls(xLocal, xLocal, float(AscendC::GetBlockIdx()), this->blockLength);
    AscendC::SetFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
    AscendC::WaitFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);

    // Unified Buffer（UB）到GM搬运启用原子累加。
    AscendC::SetAtomicAdd<float>();
    // DataCopy属于PIPE_MTE3流水操作。
    AscendC::DataCopy(atomicResultGm, xLocal, this->blockLength);
    // 当本AIV完成前置PIPE_MTE3(DataCopy)流水操作后，通知其他AIV核，本AIV已经完成。
    AscendC::CrossCoreSetFlag<0, PIPE_MTE3>(0);
    // 阻塞本AIV继续往下执行指令，直到其他AIV全部都完成PIPE_MTE3流水操作，才解除阻塞往下执行。
    AscendC::CrossCoreWaitFlag<0>(0);
    // 关闭原子累加。
    AscendC::DisableDmaAtomic();

    if (AscendC::GetBlockIdx() == 0) {
        AscendC::DataCopy(yLocal, atomicResultGm, this->blockLength);
        AscendC::SetFlag<AscendC::HardEvent::MTE2_MTE3>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE2_MTE3>(EVENT_ID0);
        AscendC::DataCopy(atomicResultGm, yLocal, this->blockLength);
        return;
    }
```

完整样例请参考[CrossCoreSetFlag和CrossCoreWaitFlag核间同步样例](../../../../../../../examples/01_simd_cpp_api/03_basic_api/05_sync_control/cross_core_set_wait_flag)。
````

## ITEM 11

### item 10

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreWaitFlag_ISASI.md
hicann/asc-devkit, last commit 2026-09-21 by munanhw
CrossCoreWaitFlag official doc: prototype with defaults (modeId=0, pipe=PIPE_S), which template params actually take effect per product/mode, and its constraints.
````markdown
## 功能说明<a id="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_block_sync_intf.h"`。

在核间同步场景中，CrossCoreSetFlag接口和CrossCoreWaitFlag接口配对工作，具体功能请参考[CrossCoreSetFlag功能说明](CrossCoreSetFlag_ISASI.md#section618mcpsimp)。

## 函数原型<a id="section620mcpsimp"></a>

```cpp
template <uint8_t modeId = 0, pipe_t pipe = PIPE_S>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId)
```

## 参数说明<a id="section622mcpsimp"></a>

### 模板参数及输入参数说明

**表1**  模板参数说明

| 参数名 | 描述 |
| --- | --- |
| modeId | 核间同步的模式，默认值为0。不同产品对该参数的生效情况及支持的流水类型请参见[模板参数默认值及生效情况](#template-parameter-defaults)。<br>不同产品对同步模式的支持情况请参见[modeId支持的取值说明](#modeId支持的取值说明)。<br>各个模式支持的对应核函数（Kernel）类型请参照[表3](#table3)。 |
| pipe | 设置该接口阻塞的流水类型，默认值为PIPE_S。不同产品对该参数的生效情况及支持的流水类型请参见[模板参数默认值及生效情况](#template-parameter-defaults)。 |

### 模板参数默认值及生效情况<a id="template-parameter-defaults"></a>

<!-- npu="950" id8 -->
- 针对Ascend 950PR&950DT系列产品，两个模板参数的使用描述如下：

    - modeId
        - `modeId`不直接作为硬件指令的输入，CrossCoreWaitFlag会根据该参数选择对应的硬件指令。
        - 模式0、模式1和模式2使用相同的硬件指令。省略`modeId`时使用默认值`0`，不影响接口功能；但**建议显式传入与CrossCoreSetFlag相同的`modeId`**，便于确认两个接口的同步模式匹配。
        - 模式4使用的硬件指令与模式0、模式1和模式2不同，**必须显式传入`modeId=4`**，否则接口会按照默认的模式0执行，导致同步行为不符合预期。
    - pipe
        - `pipe`作为硬件指令的输入，参数取值**生效**，用于指定CrossCoreWaitFlag阻塞的流水。
        - 省略`pipe`时使用默认值`PIPE_S`。
        - 模式0、模式1、模式2和模式4支持`PIPE_S`、`PIPE_V`、`PIPE_M`、`PIPE_MTE1`、`PIPE_MTE2`、`PIPE_MTE3`、`PIPE_FIX`，不支持`PIPE_ALL`。
<!-- end id8 -->
<!-- npu="A3,910b" id9 -->
- 针对如下产品，**参数取值不影响硬件指令功能**，两个模板参数的使用描述如下：

    <!-- npu="A3" id10 -->
    - Atlas A3系列产品
    <!-- end id10 -->
    <!-- npu="910b" id11 -->
    - Atlas A2系列产品
    <!-- end id11 -->

    `modeId`和`pipe`均不作为硬件指令的输入，建议按如下方式配置：

    - modeId：省略该参数不影响接口功能；但**建议显式传入与CrossCoreSetFlag相同的`modeId`**，便于确认两个接口的同步模式匹配。
    - pipe：**建议省略该参数并使用默认值`PIPE_S`**。无论`pipe`取值为何，CrossCoreWaitFlag都会阻塞**全部流水**的后续指令。
<!-- end id9 -->

**表2**  参数说明

| 参数名 | 输入/输出 | 描述 |
| --- | --- | --- |
| flagId | 输入 | 核间同步的标记。不同产品对flagId的取值范围说明请参见[flagId取值范围说明](#flagId取值范围说明)。 |

### modeId支持的取值说明<a id="modeId支持的取值说明"></a>

不同产品对同步模式的支持情况如下：
<!-- npu="950" id12 -->
- 针对Ascend 950PR&950DT系列产品，支持的同步模式为：模式0、模式1、模式2、模式4。
<!-- end id12 -->
<!-- npu="A3,910b" id13 -->
- 针对如下产品，支持的同步模式为：模式0、模式1、模式2。
    <!-- npu="A3" id14 -->
    - Atlas A3系列产品
    <!-- end id14 -->
    <!-- npu="910b" id15 -->
    - Atlas A2系列产品
    <!-- end id15 -->
<!-- end id13 -->

### flagId取值范围说明<a id="flagId取值范围说明"></a>

- 核间同步的模式为模式0、1、2时，支持的取值范围为0-15。
<!-- npu="950" id16 -->
- 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，支持的取值范围情况如下：
    - AIV0发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-15的操作。
    - AIV1发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-31的操作。
    - AIC发起的flagId 0-15的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-15的操作。
    - AIC发起的flagId 16-31的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-15的操作。
<!-- end id16 -->

此外，当与Matmul高阶API或SyncAll接口同时使用时，开发者自行使用的flagId还需注意避免与这些接口内部已占用的flagId冲突，详见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。

## 返回值说明<a id="section640mcpsimp"></a>

无

## 约束说明<a id="section633mcpsimp"></a>

- 由于当核函数（Kernel）类型为KERNEL_TYPE_AIC_ONLY或KERNEL_TYPE_AIV_ONLY时，硬件不会开启调度模块，也就无法正常进行核间同步，因此不同的同步模式配置[核函数（Kernel）类型](../../Kernel-Tiling/set_Kernel_type.md)或[函数执行空间限定符](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md#函数执行空间限定符)的情况如下：
    - 在纯Vector/Cube场景下（模式0或模式1），建议设置核函数（Kernel）类型为KERNEL\_TYPE\_MIX\_AIV\_1\_0或KERNEL\_TYPE\_MIX\_AIC\_1\_0，其它支持的核函数（Kernel）类型请参考表3。
    - 对于Vector和Cube混合场景（模式2和模式4），需根据AI Core中AIC和AIV的比例灵活配置核函数（Kernel）类型，不同模式支持的函数执行空间限定符和核函数（Kernel）类型请参照表3。

        **表3**  模式与支持的核函数（Kernel）类型配置<a id="table3"></a>

        | 模式 | 支持的函数执行空间限定符 | 支持的核函数（Kernel）类型配置 |
        | --- | --- | --- |
        | 0 | \_\_mix\_\_(0, 1)、\_\_mix\_\_(1, 0)、\_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIV\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 1 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 2 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 4 | \_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_2 |

- CrossCoreWaitFlag必须与[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)接口配合使用，避免计算核一直处于阻塞阶段。建议显式配置与配对CrossCoreSetFlag相同的modeId，以便确认Set与Wait使用相同的同步模式。

- 以下接口内部实现中使用了CrossCoreSetFlag和CrossCoreWaitFlag会占用一部分flagId，开发者同时使用CrossCoreSetFlag/CrossCoreWaitFlag与这些接口时，需注意避免flagId使用冲突，各接口flagId占用的完整说明参见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。

- flagId相关的约束：
    - 对于模式0、1、2，每个AIC和每个AIV都各自有16个flagId，支持的取值范围为0-15。如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- npu="950" id17 -->
    - 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，AIC有32个flagId，支持的取值范围为0-31，如果flagId的值超出该范围，则截取低5bit（例如，flagId=35时，截取后为3）；AIV有16个flagId，支持的取值范围为0-15，如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- end id17 -->
    - 每个flagId都对应一个计数器，当调用[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)时，若计数器值为0则会阻塞后续指令下发，已下发指令可正常执行；当调度模块感知到核间同步（CrossCoreSetFlag）全部完成后，会将对应CrossCoreWaitFlag的计数器的值增加1。此时，计数器值为非0，阻塞解除，并且将对应计数器的值减去1进行还原。具体执行逻辑与细节可以参考[关键特性说明](key_features.md)。flagId对应的计数器计数范围为0-15。如果计数器的值超出该范围，则会异常报错，中断流程。
- 模式0、1、2下，同一个flagId用于不同核间同步模式的约束：
    - 同一核上，若同一个flagId需用于不同核间同步模式，须在模式切换前完成前一个模式的所有同步操作——即确保该flagId关联的所有CrossCoreSetFlag与配套CrossCoreWaitFlag调用均已执行完毕。
    - 对于不同的核，可以直接将同一flagId用于不同的核间同步模式，具体包括以下2种场景：
        - 多个AI Core之间，使用flagId=0同步所有的AIC（模式0）；单个AI Core内，使用flagId=0同步所有AIV（模式1）。
        - 单个AI Core内，使用flagId=0同步所有AIV（模式1）；另一个AI Core内，使用flagId=0同步AIC与所有AIV（模式2）。
- 使用该接口模式0时，建议开启batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
    - 多流并发场景（≥2条执行流）。
    - ≥2个算子并发执行。
    - 所有并发算子的核数总和超过物理核数。
    - ≥2个并发算子使用了核间同步功能。

    具体而言，在多流场景下，某条流的核间同步算子虽分配到n个物理核，但可能仅有n-m个核先被调度执行，而其余m个核因被其他流的核间同步算子抢占而尚未启动。先启动的n-m个核执行到核间同步时等待剩余m核完成，而剩余m核因被其他流的核间同步算子占用而无法释放，形成死锁。

    核函数（Kernel）直调场景下通过[\_\_schedmode\_\_\(mode\)](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)限定符来设置batchmode模式；工程化算子开发场景下，通过TilingContext的SetScheduleMode接口来设置batchmode模式，具体请参考《[基础数据结构和接口](https://gitcode.com/cann/metadef/blob/master/docs/zh/api/README.md)》。

## 调用示例<a id="section837496171220"></a>

**表4**  样例描述

| SCENARIO_NUM取值 | 业务场景 | 使用的同步模式 |
| --- | --- | --- |
| 0 | 纯Vector计算场景（16个AIV） | mode0（AIV全核同步） |
| 1 | 纯Vector计算场景（2个AIV） | mode1 |
| 2 | Cube与Vector融合计算场景 | mode2（AIC等AIV）、mode2（AIV等AIC）、mode0（AIC全核同步） |

如上表所示，当SCENARIO_NUM取不同值时，会分别演示纯Vector计算场景和Cube与Vector融合计算场景下三种同步模式的具体使用方法，下面展示了纯Vector计算场景的部分调用代码：

```cpp
    AscendC::Muls(xLocal, xLocal, float(AscendC::GetBlockIdx()), this->blockLength);
    AscendC::SetFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
    AscendC::WaitFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);

    // Unified Buffer（UB）到GM搬运启用原子累加。
    AscendC::SetAtomicAdd<float>();
    // DataCopy属于PIPE_MTE3流水操作。
    AscendC::DataCopy(atomicResultGm, xLocal, this->blockLength);
    // 当本AIV完成前置PIPE_MTE3(DataCopy)流水操作后，通知其他AIV核，本AIV已经完成。
    AscendC::CrossCoreSetFlag<0, PIPE_MTE3>(0);
    // 阻塞本AIV继续往下执行指令，直到其他AIV全部都完成PIPE_MTE3流水操作，才解除阻塞往下执行。
    AscendC::CrossCoreWaitFlag<0>(0);
    // 关闭原子累加。
    AscendC::DisableDmaAtomic();

    if (AscendC::GetBlockIdx() == 0) {
        AscendC::DataCopy(yLocal, atomicResultGm, this->blockLength);
        AscendC::SetFlag<AscendC::HardEvent::MTE2_MTE3>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE2_MTE3>(EVENT_ID0);
        AscendC::DataCopy(atomicResultGm, yLocal, this->blockLength);
        return;
    }
```

完整样例请参考[CrossCoreSetFlag和CrossCoreWaitFlag核间同步样例](../../../../../../../examples/01_simd_cpp_api/03_basic_api/05_sync_control/cross_core_set_wait_flag)。
````

## ITEM 12

### item 11

https://raw.githubusercontent.com/hicann/asc-devkit/master/examples/01_simd_cpp_api/03_basic_api/05_sync_control/sync_all/sync_all.asc
hicann/asc-devkit, last commit 2026-08-06 by Geminiver
Complete official SyncAll sample (8 cores, 32 floats each, partials via workGm). Shows the soft-sync call site, the syncGm sizing blockNum*DEFAULT_SYNCALL_NEED_SIZE (=8 int32 = 32B per core) and the host-side zero-init via input_sync.bin.
```cpp
/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

/* !
 * \file sync_all.asc
 * \brief 本样例演示SyncAll核间同步接口的使用方法，适用于不同核操作同一块全局内存且存在读后写、
 *        写后读、写后写等数据依赖的场景。样例使用8个核进行数据处理，每个核处理32个float类型数据，
 *        对数据乘2后再与其他核的结果累加，通过SyncAll实现核间同步。
 */
#include "acl/acl.h"
#include "data_utils.h"
#include "kernel_operator.h"

const int32_t DEFAULT_SYNCALL_NEED_SIZE = 8;
const int32_t TOTAL_LENGTH = 256;
const int32_t TILE_LENGTH = 32;

/**
 * @brief SyncAll核间同步样例的Kernel实现类，实现多核数据累加并通过SyncAll进行核间同步
 */
class KernelSyncAll {
public:
    __aicore__ inline KernelSyncAll() {}
    __aicore__ inline void Init(
        __gm__ uint8_t* srcGm, __gm__ uint8_t* dstGm, __gm__ uint8_t* workGm, __gm__ uint8_t* syncGm)
    {
        blockNum = AscendC::GetBlockNum(); // 获取核总数
        blockIdx = AscendC::GetBlockIdx(); // 获取当前工作的核ID
        srcGlobal.SetGlobalBuffer(
            reinterpret_cast<__gm__ float*>(srcGm + blockIdx * TILE_LENGTH * sizeof(float)), TILE_LENGTH);
        dstGlobal.SetGlobalBuffer(
            reinterpret_cast<__gm__ float*>(dstGm + blockIdx * TILE_LENGTH * sizeof(float)), TILE_LENGTH);
        workGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workGm), TOTAL_LENGTH);
        syncGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ int32_t*>(syncGm), blockNum * DEFAULT_SYNCALL_NEED_SIZE);
    }
    __aicore__ inline void Process()
    {
        AscendC::LocalMemAllocator<AscendC::Hardware::UB> ubAllocator;
        AscendC::LocalTensor<float> srcLocal1 = ubAllocator.Alloc<float, 32>();
        AscendC::LocalTensor<float> dstLocal = ubAllocator.Alloc<float, 32>();

        AscendC::DataCopy(srcLocal1, srcGlobal, TILE_LENGTH);
        AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);

        FirstCompute(srcLocal1, dstLocal);
        CopyToWorkGlobal(dstLocal); // 当前工作核计算后的数据先保存到外部工作空间
        // 等待所有核都完成计算
        AscendC::SyncAll();
        // 最终累加结果需要等所有核都计算完成，dstLocal保留当前核计算结果。
        for (int i = 0; i < blockNum; i++) {
            if (i != blockIdx) {
                CopyFromOtherCore(i, srcLocal1); // 从外部工作空间读取数据
                Accumulate(dstLocal, srcLocal1); // 所有数据都累加到目的空间
            }
        }

        AscendC::SetFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
        AscendC::DataCopy(dstGlobal, dstLocal, TILE_LENGTH);
    }

private:
    __aicore__ inline void CopyToWorkGlobal(const AscendC::LocalTensor<float>& dstLocal)
    {
        AscendC::SetFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
        AscendC::DataCopy(workGlobal[blockIdx * TILE_LENGTH], dstLocal, TILE_LENGTH);
    }
    __aicore__ inline void CopyFromOtherCore(int index, const AscendC::LocalTensor<float>& srcLocal)
    {
        AscendC::SetFlag<AscendC::HardEvent::V_MTE2>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::V_MTE2>(EVENT_ID0);
        AscendC::DataCopy(srcLocal, workGlobal[index * TILE_LENGTH], TILE_LENGTH);
        AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
    }
    __aicore__ inline void Accumulate(
        const AscendC::LocalTensor<float>& dstLocal, const AscendC::LocalTensor<float>& srcLocal)
    {
        AscendC::Add(dstLocal, dstLocal, srcLocal, TILE_LENGTH);
        AscendC::PipeBarrier<PIPE_V>();
    }
    __aicore__ inline void FirstCompute(
        const AscendC::LocalTensor<float>& srcLocal1, const AscendC::LocalTensor<float>& dstLocal)
    {
        float scalarValue(2.0);
        AscendC::Muls(dstLocal, srcLocal1, scalarValue, TILE_LENGTH);
        AscendC::PipeBarrier<PIPE_V>();
    }

private:
    AscendC::GlobalTensor<float> srcGlobal;
    AscendC::GlobalTensor<float> dstGlobal;
    AscendC::GlobalTensor<float> workGlobal;
    AscendC::GlobalTensor<int32_t> syncGlobal;
    int32_t blockNum = 0;
    int32_t blockIdx = 0;
};

__global__ __vector__ void sync_all_custom(
    __gm__ uint8_t* srcGm, __gm__ uint8_t* dstGm, __gm__ uint8_t* workGm, __gm__ uint8_t* syncGm)
{
    AscendC::InitSocState();
    KernelSyncAll op;
    op.Init(srcGm, dstGm, workGm, syncGm);
    op.Process();
    AscendC::PipeBarrier<PIPE_ALL>();
}

int32_t main(int32_t argc, char* argv[])
{
    uint32_t numBlocks = TOTAL_LENGTH / TILE_LENGTH;
    size_t inputByteSize = TOTAL_LENGTH * sizeof(float);
    size_t outputByteSize = inputByteSize;
    size_t inputSyncByteSize = numBlocks * DEFAULT_SYNCALL_NEED_SIZE * sizeof(float);
    size_t inputWorkByteSize = inputByteSize;

    int32_t deviceId = 0;
    aclrtSetDevice(deviceId);
    aclrtStream stream = nullptr;
    aclrtCreateStream(&stream);

    uint8_t *xHost, *zHost, *workHost, *syncHost;
    uint8_t *xDevice, *zDevice, *workDevice, *syncDevice;

    aclrtMallocHost((void**)(&xHost), inputByteSize);
    aclrtMallocHost((void**)(&zHost), outputByteSize);
    aclrtMallocHost((void**)(&workHost), inputWorkByteSize);
    aclrtMallocHost((void**)(&syncHost), inputSyncByteSize);
    aclrtMalloc((void**)&xDevice, inputByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
    aclrtMalloc((void**)&zDevice, outputByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
    aclrtMalloc((void**)&workDevice, inputWorkByteSize, ACL_MEM_MALLOC_HUGE_FIRST);
    aclrtMalloc((void**)&syncDevice, inputSyncByteSize, ACL_MEM_MALLOC_HUGE_FIRST);

    ReadFile("./input/input_x.bin", inputByteSize, xHost, inputByteSize);
    ReadFile("./input/input_work.bin", inputWorkByteSize, workHost, inputWorkByteSize);
    ReadFile("./input/input_sync.bin", inputSyncByteSize, syncHost, inputSyncByteSize);
    aclrtMemcpy(xDevice, inputByteSize, xHost, inputByteSize, ACL_MEMCPY_HOST_TO_DEVICE);
    aclrtMemcpy(workDevice, inputWorkByteSize, workHost, inputWorkByteSize, ACL_MEMCPY_HOST_TO_DEVICE);
    aclrtMemcpy(syncDevice, inputSyncByteSize, syncHost, inputSyncByteSize, ACL_MEMCPY_HOST_TO_DEVICE);
    sync_all_custom<<<numBlocks, 0, stream>>>(xDevice, zDevice, workDevice, syncDevice);
    aclrtSynchronizeStream(stream);

    aclrtMemcpy(zHost, outputByteSize, zDevice, outputByteSize, ACL_MEMCPY_DEVICE_TO_HOST);
    WriteFile("./output/output.bin", zHost, outputByteSize);

    aclrtFree(xDevice);
    aclrtFree(zDevice);
    aclrtFree(workDevice);
    aclrtFree(syncDevice);
    aclrtFreeHost(xHost);
    aclrtFreeHost(zHost);
    aclrtFreeHost(workHost);
    aclrtFreeHost(syncHost);
    aclrtDestroyStream(stream);
    aclrtResetDevice(deviceId);
    aclFinalize();

    return 0;
}
```

## ITEM 13

### item 12

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/atomic_operations/SetAtomicMax_ISASI.md
hicann/asc-devkit, last commit 2026-09-21 by munanhw
SetAtomicMax official doc: prototype `template <typename T> __aicore__ inline void SetAtomicMax()`, supported dtypes, A3 data paths (UB/L0C/L1 -> GM), the 'does not auto-zero GM' warning, the 2201 non-saturating default note, and a 3-core atomic-max example that calls AscendC::SyncAll() between copy-in and atomic copy-out.
````markdown
## 功能说明<a name="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_set_atomic_intf.h"`。

设置后续搬运到GM的数据是否执行原子比较：将待拷贝的内容和GM已有内容进行比较，然后将最大值写入GM。SetAtomicMax接口可通过设置模板参数来设定不同的数据类型。

## 函数原型<a name="section620mcpsimp"></a>

```cpp
template <typename T>
__aicore__ inline void SetAtomicMax() 
```

## 参数说明<a name="section622mcpsimp"></a>

**表1**  模板参数说明

| 参数名 | 描述 |
|--------|------|
| T | 设定不同的原子最大操作数据类型。 |

## 数据类型

支持的数据类型为int8_t、int16_t、half、bfloat16_t、int32_t、float。

## 返回值说明<a name="section640mcpsimp"></a>

无

## 约束说明<a name="section633mcpsimp"></a>

<!-- npu="950" id1 -->
- Ascend 950PR&950DT系列产品，支持的数据通路为UB/L0C Buffer->GM。
<!-- end id1 -->

<!-- npu="A3" id2 -->
- Atlas A3系列产品，支持的数据通路为UB/L0C Buffer/L1 Buffer->GM。
<!-- end id2 -->

<!-- npu="910b" id3 -->
- Atlas A2系列产品，支持的数据通路为UB/L0C Buffer/L1 Buffer->GM。
<!-- end id3 -->

- 使用完后，建议通过[DisableDmaAtomic](DisableDmaAtomic.md)关闭原子最大操作，以免影响后续相关功能。
- 该接口执行前不会自动清零GM数据。开发者需根据算子逻辑判断是否清零，如需清零，请在执行前手动完成。
- SetAtomicMax内部已集成与[SetAtomicType](SetAtomicType.md)相同的功能。建议调用上述接口时，通过设置模板参数显式指定原子操作的数据类型，无需额外调用SetAtomicType接口。
<!-- npu="A3,910b" id4 -->
- 针对[NPU架构版本2201](../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)，整数类型和bfloat16_t数据类型**默认均为非饱和模式**，原子最大操作时的饱和模式无法通过[SetSaturationStrategy](../special_register_access/SetSaturationStrategy.md)或[SetCtrlSpr](../special_register_access/SetCtrlSpr_ISASI.md)设置，需要通过`npu-smi`命令进行设备级设置，具体设置方法请参考[SetAtomicAdd约束说明](SetAtomicAdd.md#npu_smi_saturation_mode)。
<!-- end id4 -->

## 调用示例<a name="section177231425115410"></a>

```cpp
#include "kernel_operator.h"

constexpr uint32_t SIZE = 256;
__aicore__ inline void CopyIn()
{
    AscendC::LocalTensor<T> srcLocal = queueSrc.AllocTensor<T>();
    // 清空原子操作的状态
    AscendC::DisableDmaAtomic();
    AscendC::DataCopy(srcLocal, srcGlobal, SIZE);
    queueSrc.EnQue(srcLocal);
    // 核间同步
    AscendC::SyncAll();
}

__aicore__ inline void CopyOut()
{
    AscendC::LocalTensor<T> srcLocal = queueSrc.DeQue<T>();
    // 开启原子MAX模式，3个核取最大值
    AscendC::SetAtomicMax<T>();
    AscendC::DataCopy(dstGlobal, srcLocal, SIZE);
    // 关闭原子操作
    AscendC::DisableDmaAtomic();
    queueSrc.FreeTensor(srcLocal);
}

/*
每个核的输入数据为: 
Src0: [1,1,1,1,1,...,1] // 256个1
Src1: [2,2,2,2,2,...,2] // 256个2
最终输出数据: [2,2,2,2,2,...,2] // 256个2
*/
```

完整样例请参考[DataMovementWithAtomicOperations样例](../../../../../../examples/01_simd_cpp_api/03_basic_api/06_atomic/data_movement_with_atomic_operations)。
````

## ITEM 14

### item 13

https://raw.githubusercontent.com/hicann/asc-devkit/master/docs/zh/api/SIMD-API/basic_api/cache_control/DataCacheCleanAndInvalid.md
hicann/asc-devkit, last commit 2026-09-29 by wang_shuli
DataCacheCleanAndInvalid official doc: why scalar GM reads need it (DCache vs DMA), the three prototypes, SINGLE_CACHE_LINE (64B-aligned caveat) vs ENTIRE_DATA_CACHE (expensive), DcciDst::CACHELINE_OUT/UB/ATOMIC, and the constraint table. CACHELINE_ATOMIC is explicitly NOT yet supported on Atlas A3.
````markdown
## 功能说明<a name="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_cache_intf.h"`。

如图1所示，在AI Core内部，Scalar单元和DMA单元都可能对GM进行访问：

- DMA搬运单元读写GM，数据通过DataCopy等接口在Unified Buffer（UB）等Local Memory和GM间交互，没有Cache一致性问题。
- Scalar单元访问GM，首先会访问每个核内的Data Cache（DCache），因此存在DCache与GM的Cache一致性问题，具体原因请参考[缓存一致性](../../../../guide/programming_guide/advanced_programming/memory_model/cache_coherence.md)。

**图1**  DCache内存层次示意图<a name="zh-cn_topic_0000002530021782_fig1161014168448"></a>

![](../../../figures/datacache.png)

DataCacheCleanAndInvalid接口用于解决上述一致性问题，其功能可以拆解为两部分：

- Clean：将缓存中被修改过的数据（脏数据，Dirty Data）写回到GM中，避免数据丢失。
- Invalid：
    - 将指定地址范围的Cache Line标记为“无效”，使其从缓存中移除。
    - 保证下一次访问这些内存地址时，会从GM重新加载数据，而不是使用可能过期的缓存数据。

该接口的典型使用场景如下：

- 读取GM的数据，但该数据可能在外部被其余核修改，此时需要使用DataCacheCleanAndInvalid接口，直接访问GM，获取最新数据。
- 用户通过Scalar单元写GM的数据，希望立刻写出，也需要使用DataCacheCleanAndInvalid接口。

<!-- npu="950" id15 -->
- 针对Ascend 950PR&950DT系列产品，原子操作过程中，如果希望改变后续数据的饱和模式，需要先使用DataCacheCleanAndInvalid接口将Cache Line中现存的数据立刻写出，再调用[SetCtrlSpr](../special_register_access/SetCtrlSpr_ISASI.md)设置后续数据的饱和模式。
<!-- end id15 -->

## 函数原型<a name="section620mcpsimp"></a>

- 配置dcciDst的原型

  ```cpp
  // 支持通过配置dcciDst确保DCache与GM存储的一致性。
  template <typename T, CacheLine entireType, DcciDst dcciDst>
  __aicore__ inline void DataCacheCleanAndInvalid(const GlobalTensor<T>& dst)
  // 支持通过配置dcciDst确保DCache与Local Memory存储的一致性。
  template <typename T, CacheLine entireType, DcciDst dcciDst>
  __aicore__ inline void DataCacheCleanAndInvalid(const LocalTensor<T>& dst)
  ```

- 不支持配置dcciDst，仅支持保证DCache与GM的一致性。

    ```cpp
    template <typename T, CacheLine entireType>
    __aicore__ inline void DataCacheCleanAndInvalid(const GlobalTensor<T>& dst)
    ```

<!-- npu="310p" id14 -->
> [!NOTE]说明 
> 对于Atlas推理系列产品AI Core，仅支持不配置dcciDst参数的原型。
<!-- end id14 -->


## 参数说明<a name="section622mcpsimp"></a>

**表1**  模板参数说明

| 参数名 | 描述 |
|--------|------|
| T | dst的数据类型。 |
| entireType | 指令操作的模式：<br>SINGLE_CACHE_LINE：只刷新传入地址所在的Cache Line，**注意如果该地址非64B对齐，只会操作传入地址到64B对齐的部分。**<br>ENTIRE_DATA_CACHE：此时传入的地址无效，核内会刷新整个DCache，但是耗时较大，**性能敏感的场景慎用**。 |
| dcciDst | 表示使用该接口来保证DCache与哪一种存储保持一致性，类型为DcciDst枚举类。<br>&bull; CACHELINE_ALL：与CACHELINE_OUT效果一致。<br>&bull; CACHELINE_UB：表示通过该接口来保证DCache与UB的一致性。<br>&bull; CACHELINE_OUT：表示通过该接口来保证DCache与GM的一致性。<br>&bull; CACHELINE_ATOMIC：原子操作过程中保证DCache和GM的一致性。<br><!-- npu="950" id16 -->&ensp;&ensp;- Ascend 950PR&950DT系列产品，支持。<br><!-- end id16 --><!-- npu="A3" id10 -->&ensp;&ensp;- Atlas A3系列产品，暂未支持。<br><!-- end id10 --><!-- npu="910b" id11 -->&ensp;&ensp;- Atlas A2系列产品，暂未支持。<br><!-- end id11 --><!-- npu="310b" id12 -->&ensp;&ensp;- Atlas 200I/500 A2推理产品，暂未支持。<br><!-- end id12 --><!-- npu="310p" id13 -->&ensp;&ensp;- Atlas推理系列产品AI Core，暂未支持。<!-- end id13 --> |

**表2**  参数说明

| 参数名 | 输入/输出 | 描述 |
|--------|-----------|------|
| dst | 输入 | 需要刷新Cache的Tensor。 |

## 返回值说明<a name="section640mcpsimp"></a>

无

## 约束说明<a name="section633mcpsimp"></a>

- 当`entireType`为`SINGLE_CACHE_LINE`时，`dst`生效，`dcciDst`不生效。
- 当`entireType`为`ENTIRE_DATA_CACHE`时，`dst`不生效，`dcciDst`生效。
- `dst`为`LocalTensor`类型的函数原型仅支持在AIV中调用。

## 调用示例<a name="section837496171220"></a>

- **示例1：SINGLE\_CACHE\_LINE模式（64B对齐场景）**  
  假设mmAddr\_为0x40（64B对齐），调用一次指令即可刷新整个Cache Line。

    ```cpp
    AscendC::GlobalTensor<uint64_t> global;
    global.SetGlobalBuffer((__gm__ uint64_t*)mmAddr_ + AscendC::GetBlockIdx() * 1024);
    for( int i = 0; i < 8; i++) {
        global.SetValue(i, AscendC::GetBlockIdx());
    }
    // 由于首地址64B对齐，调用DataCacheCleanAndInvalid指令后，会立刻刷新前8个数。
    AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global);
    ```

- **示例2：SINGLE\_CACHE\_LINE模式（非64B对齐场景）**  
  假设mmAddr\_为0x20（非64B对齐），需要调用两次指令才能刷新完整Cache Line。

    ```cpp
    AscendC::GlobalTensor<uint64_t> global;
    global.SetGlobalBuffer((__gm__ uint64_t*)mmAddr_ + AscendC::GetBlockIdx() * 1024);
    for( int i = 0; i < 8; i++) {
        global.SetValue(i, AscendC::GetBlockIdx());
    }
    // 由于首地址非64B对齐，调用1条指令，只会刷新起始地址至64B字节对齐的部分，即前4个数。
    AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global);
    // 需要再次调用DataCacheCleanAndInvalid指令，刷新后4个数。
    AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global[4]);
    ```

- **<a name="example3_multi_core"></a>示例3：SINGLE\_CACHE\_LINE模式（多核处理场景）**  
  假设mmAddr\_为0x40（64B对齐），多核操作同一条Cache Line时可能出现随机覆盖。本样例仅做示例说明，便于开发者理解使用限制，非正常使用样例。

    ```cpp
    AscendC::GlobalTensor<uint64_t> global;
    global.SetGlobalBuffer((__gm__ uint64_t*)mmAddr_);
    global.SetValue(AscendC::GetBlockIdx(), AscendC::GetBlockIdx());
    // 算子中多核操作虽然不在同一个地址，但在同一个Cache Line，会出现数据的随机覆盖，和通用CPU的行为不同。
    // 调用DataCacheCleanAndInvalid指令后，由于多核操作的时间不一致，最终结果存在随机性，后执行的核会覆盖前面核的结果。
    AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::SINGLE_CACHE_LINE, AscendC::DcciDst::CACHELINE_OUT>(global);
    ```

- **示例4：ENTIRE\_DATA\_CACHE模式**  
  假设mmAddr\_为0x20（非64B对齐），刷新整个DCache。本样例仅做示例说明，便于开发者理解使用限制，非正常使用样例。

    ```cpp
    AscendC::GlobalTensor<uint64_t> global;
    global.SetGlobalBuffer((__gm__ uint64_t*)mmAddr_ + AscendC::GetBlockIdx() * 1024);
    for( int i = 0; i < 8; i++) {
        global.SetValue(i, AscendC::GetBlockIdx());
    }
    // 刷新整个DCache，性能较差。
    AscendC::DataCacheCleanAndInvalid<uint64_t, AscendC::CacheLine::ENTIRE_DATA_CACHE, AscendC::DcciDst::CACHELINE_OUT>(global);
    ```
````

## ITEM 15

### item 14

https://raw.githubusercontent.com/sgl-project/sgl-kernel-npu/main/csrc/deepep/ops/op_kernel/dispatch_ffn_combine_kernel/utils/hccl_shmem.hpp
sgl-project/sgl-kernel-npu, last commit 2026-03-12 by ZFA
The canonical hand-written dcci spin-wait: gm_dcci() wraps DataCacheCleanAndInvalid<uint8_t, SINGLE_CACHE_LINE, CACHELINE_OUT> between two empty __asm__ __volatile__("") barriers so the compiler cannot hoist it; gm_signal_wait_until_eq_for_barrier / gm_signal_wait_until_ne are the `do { dcci; read; } while(true)` polling loops; CrossRankSync publishes a counter, polls peers, then calls AscendC::SyncAll<true>(). AicSyncAll() shows the AIC-side CrossCoreSetFlag<0x0,PIPE_FIX>(8)/CrossCoreWaitFlag<0x0>(8) barrier.
```cpp
#define FORCE_INLINE_AICORE inline __attribute__((always_inline)) __aicore__
constexpr int32_t MAX_RANK_SIZE = 32;
constexpr int32_t SHMEM_MEM = 700 * MB_SIZE;

constexpr uint16_t SEND_SYNC_EVENT_ID = 9;
constexpr uint16_t RECV_SYNC_EVENT_ID = 10;

constexpr uint32_t SELF_STATE_OFFSET = 256 * 1024;
constexpr uint32_t STATE_OFFSET = 512;

FORCE_INLINE_AICORE void AicSyncAll()
{
    AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(8);
    AscendC::CrossCoreWaitFlag<0x0>(8);
}

template <typename T>
FORCE_INLINE_AICORE void gm_store(__gm__ T *addr, T val)
{
    *((__gm__ T *)addr) = val;
}

template <typename T>
FORCE_INLINE_AICORE T gm_load(__gm__ T *cache)
{
    return *((__gm__ T *)cache);
}

template <typename T>
FORCE_INLINE_AICORE void gm_dcci(__gm__ T *addr)
{
    using namespace AscendC;
    GlobalTensor<uint8_t> global;
    global.SetGlobalBuffer(reinterpret_cast<GM_ADDR>(addr));

    // Important: add hint to avoid dcci being optimized by compiler
    __asm__ __volatile__("");
    DataCacheCleanAndInvalid<uint8_t, CacheLine::SINGLE_CACHE_LINE, DcciDst::CACHELINE_OUT>(global);
    __asm__ __volatile__("");
}

FORCE_INLINE_AICORE int32_t gm_signal_wait_until_eq_for_barrier(__gm__ int32_t *sig_addr, int32_t cmp_val)
{
    do {
        gm_dcci((__gm__ uint8_t *)sig_addr);
        if (*sig_addr == cmp_val) {
            return *sig_addr;
        }
        if (*sig_addr == cmp_val + 1) {
            return *sig_addr;
        }
    } while (true);
    return -1;
}

FORCE_INLINE_AICORE void gm_signal_wait_until_ne(__gm__ int32_t *sig_addr, int32_t cmp_val)
{
    do {
        AscendC::LocalTensor<int32_t> ub;
        ub.address_.logicPos = static_cast<uint8_t>(AscendC::TPosition::VECIN);
        ub.address_.bufferAddr = 0;
        AscendC::GlobalTensor<int32_t> sig;
        sig.SetGlobalBuffer(sig_addr);
        AscendC::DataCopy(ub, sig, 8);
        AscendC::SetFlag<AscendC::HardEvent::MTE2_S>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::MTE2_S>(EVENT_ID0);
        if (ub(0) != cmp_val) {
            return;
        }
    } while (true);
    return;

/* ... */


    FORCE_INLINE_AICORE
    void CrossRankSync()
    {
        uint64_t flag_offset = (m_segmentSize - MB_SIZE) / sizeof(int32_t);
        __gm__ int32_t *sync_counter = (__gm__ int32_t *)(*this)() + flag_offset;
        __gm__ int32_t *sync_base = (__gm__ int32_t *)(*this)() + flag_offset + 2048;
        int count = gm_load(sync_base) + 1;
        int vec_id = AscendC::GetBlockIdx();
        int vec_size = AscendC::GetBlockNum() * AscendC::GetTaskRation();
        for (int i = vec_id; i < m_rankSize; i += vec_size) {
            __gm__ int32_t *sync_remote = (__gm__ int32_t *)((*this)(i)) + flag_offset + m_rank * 16;
            gm_store(sync_remote, count);
            gm_dcci((__gm__ uint8_t *)sync_remote);
            auto sync_check = sync_counter + i * 16;
            gm_signal_wait_until_eq_for_barrier(sync_check, count);
        }

        AscendC::SyncAll<true>();
        gm_store(sync_base, count);
    }
```

## ITEM 16

### item 15

https://raw.githubusercontent.com/sgl-project/sgl-kernel-npu/main/csrc/deepep/ops/op_kernel/dispatch_ffn_combine_kernel.hpp
sgl-project/sgl-kernel-npu, last commit 2026-08-28 by 探照灯
UpdateAicFlags: a real GM polling loop (`while (flag < flagBase)`) that re-DataCopies the flag region GM->UB every iteration, reduces it with ReduceMin, reads it back with a V_S event pair, and publishes progress with a scalar GM store + gm_dcci. Also shows gm_signal_wait_until_ne used as a per-cacheline arrival check before a cross-rank DataCopy, followed by AscendC::SyncAll<true>().
```cpp
        for (int32_t dstEpIdx = coreIdx; dstEpIdx < params.EP; dstEpIdx += coreNum) {
            if (dstEpIdx != params.rank) {
                int32_t intPer512 = CACHE_LINE / sizeof(int);
                for (int32_t checkIdx = 0; checkIdx < AlignUp(params.EP * params.expertPerRank, 128);
                     checkIdx += intPer512) {
                    __gm__ int32_t *sync_check =
                        reinterpret_cast<__gm__ int32_t *>(shmem() + peermemInfo.offsetPeerTokenPerExpert) +
                        tokenPerExpertLayout(dstEpIdx, 0, checkIdx);
                    gm_signal_wait_until_ne(sync_check, 0);
                }
                AscendC::DataCopy(tmpBuffer, tokenPerExpert[tokenPerExpertLayout(dstEpIdx, 0, 0)], numPerCore);
                AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
                AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
                AscendC::Adds(tmpBuffer, tmpBuffer, -0x800000, numPerCore);
                AscendC::PipeBarrier<PIPE_V>();
                AscendC::SetFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
                AscendC::WaitFlag<AscendC::HardEvent::V_MTE3>(EVENT_ID0);
                AscendC::DataCopy(tokenPerExpert[tokenPerExpertLayout(dstEpIdx, 0, 0)], tmpBuffer, numPerCore);
            } else {
                AscendC::DataCopy(tmpBuffer, tokenPerExpert[tokenPerExpertLayout(dstEpIdx, 0, 0)], numPerCore);
                AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
                AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
            }
            AscendC::PipeBarrier<PIPE_ALL>();
            int32_t prevSum = 0;
            int32_t j = 0;
            for (int32_t i = 0; i < (params.rank + 1) * params.expertPerRank; i++) {
                if (i >= params.rank * params.expertPerRank) {
                    prevSumBuf(j) = prevSum;
                    j++;
                }
                prevSum += tmpBuffer(i);
            }
            AscendC::SetFlag<AscendC::HardEvent::S_MTE3>(EVENT_ID0);
            AscendC::WaitFlag<AscendC::HardEvent::S_MTE3>(EVENT_ID0);
            AscendC::DataCopyPad(
                preSumBeforeRank[dstEpIdx * params.expertPerRank], prevSumBuf,
                AscendC::DataCopyParams{1, static_cast<uint16_t>(params.expertPerRank * sizeof(int32_t)), 0, 0});
        }

        AscendC::SyncAll<true>();
    }


/* ... */

    void UpdateAicFlags(const Params &params)
    {
        float flagBase = 1.0f * params.expertPerRank;
        __gm__ float *aicFinishPtr = workspaceInfo.ptrSoftFlagBase + params.EP * FLAGSTRIDE;
        float flag = 0.0f;
        float lastflag = -1.0f;
        AscendC::LocalTensor<float> tmpBuffer1 = resource.ubBuf.template GetBufferByByte<float>(0);
        __gm__ float *flagPtr = workspaceInfo.ptrSoftFlagBase;
        AscendC::GlobalTensor<float> flagGM;
        flagGM.SetGlobalBuffer(flagPtr);
        int64_t flagBufferSize = static_cast<int64_t>(max(4, params.EP)) * static_cast<int64_t>(FLAGSTRIDE);
        AscendC::LocalTensor<float> dstValueBuffer = resource.ubBuf.template GetBufferByByte<float>(flagBufferSize);
        AscendC::LocalTensor<float> sharedTmpBuffer =
            resource.ubBuf.template GetBufferByByte<float>((flagBufferSize + 64));
        uint64_t mask[1] = {0};
        uint32_t repeatNum = (flagBufferSize / (4 * FLAGSTRIDE));
        for (int32_t i = 0; i < 4; i++) {
            if (i < params.EP) {
                mask[0] |= 1ull * (1ull << (i * 16));
            }
        }
        AscendC::SetFlag<AscendC::HardEvent::S_V>(EVENT_ID0);
        AscendC::WaitFlag<AscendC::HardEvent::S_V>(EVENT_ID0);
        while (flag < flagBase) {
            flag = flagBase;
            AscendC::DataCopy(tmpBuffer1, flagGM, params.EP * FLAGSTRIDE);
            AscendC::SetFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);
            AscendC::WaitFlag<AscendC::HardEvent::MTE2_V>(EVENT_ID0);

            AscendC::ReduceMin<float>(dstValueBuffer, tmpBuffer1, sharedTmpBuffer, mask, repeatNum, 8, false);

            AscendC::SetFlag<AscendC::HardEvent::V_S>(EVENT_ID0);
            AscendC::WaitFlag<AscendC::HardEvent::V_S>(EVENT_ID0);
            flag = min(flag, dstValueBuffer.GetValue(0));

            if (flag > lastflag) {
                *aicFinishPtr = flag;
                gm_dcci(aicFinishPtr);
                lastflag = flag;
            }
        }
    }

    CATLASS_DEVICE
    void CombineSetFlag()
    {
```

## ITEM 17

### item 16

https://raw.githubusercontent.com/sgl-project/sgl-kernel-npu/main/csrc/deepep/ops/op_kernel/data_copy.h
sgl-project/sgl-kernel-npu, last commit 2025-09-04 by BourneSun0527
SetAtomicOpType<T>: the SetAtomicAdd / SetAtomicMax / SetAtomicMin / SetAtomicNone selector used before a GM->GM DataCopy, i.e. the atomic-max reduction primitive in template form.
```cpp
#ifndef CAM_DATACOPY_GM2GM_H
#define CAM_DATACOPY_GM2GM_H
#include <type_traits>
#include "comm_args.h"

using namespace AscendC;
using namespace Moe;

template <typename T>
FORCE_INLINE_AICORE void SetAtomicOpType(int op)
{
    switch (op) {
        case ADD:
            AscendC::SetAtomicAdd<T>();
            break;
        case MUL:
            // Ignore setting the atomic register when performing mul
            break;
        case MAX:
            AscendC::SetAtomicMax<T>();
            break;
        case MIN:
            AscendC::SetAtomicMin<T>();
            break;
        default:
            AscendC::SetAtomicNone();
    }
}
```

## ITEM 18

### item 17

https://raw.githubusercontent.com/vllm-project/vllm-ascend/main/csrc/attention/k2q_csr/k2q_csr_common/op_kernel/k2q_csr_common.h
vllm-project/vllm-ascend, last commit 2026-08-20 by Haoxin Zong
AtomicAddOutInt32 (SetAtomicAdd<int32_t> -> DataCopyPad -> SetAtomicNone -> PipeBarrier<PIPE_ALL>), FlushGmInt32 (ENTIRE_DATA_CACHE + CACHELINE_OUT), and StoreScalarInt32 — with the in-source note that a single-point GM write must go through MTE3 because GlobalTensor::SetValue loses the write-back under multi-core concurrency.
```cpp
__aicore__ inline void CopyOutInt32(const AscendC::GlobalTensor<int32_t> &dst,
                                    const AscendC::LocalTensor<int32_t> &src, int64_t nElems)
{
    if (nElems <= 0) {
        return;
    }
    AscendC::DataCopyExtParams params{1, static_cast<uint32_t>(nElems * sizeof(int32_t)), 0, 0, 0};
    AscendC::DataCopyPad(dst, src, params);
    AscendC::PipeBarrier<PIPE_ALL>();
}

/** 整段 AtomicAdd 写 GM（对齐 CUDA Hist→row_counts） */
__aicore__ inline void AtomicAddOutInt32(const AscendC::GlobalTensor<int32_t> &dst,
                                         const AscendC::LocalTensor<int32_t> &src, int64_t nElems)
{
    if (nElems <= 0) {
        return;
    }
    AscendC::SetAtomicAdd<int32_t>();
    AscendC::DataCopyExtParams params{1, static_cast<uint32_t>(nElems * sizeof(int32_t)), 0, 0, 0};
    AscendC::DataCopyPad(dst, src, params);
    AscendC::SetAtomicNone();
    AscendC::PipeBarrier<PIPE_ALL>();
}

__aicore__ inline void FlushGmInt32(const AscendC::GlobalTensor<int32_t> &gm)
{
    AscendC::DataCacheCleanAndInvalid<int32_t, AscendC::CacheLine::ENTIRE_DATA_CACHE,
                                      AscendC::DcciDst::CACHELINE_OUT>(gm);
}

/** 单点写 GM（MTE3），多核并发安全；避免 GlobalTensor.SetValue 写回丢失 */
__aicore__ inline void StoreScalarInt32(const AscendC::GlobalTensor<int32_t> &dst, int64_t index, int32_t value,
                                        const AscendC::LocalTensor<int32_t> &tmp)
{
    tmp.SetValue(0, value);
    AscendC::PipeBarrier<PIPE_ALL>();
    AscendC::DataCopyExtParams params{1, static_cast<uint32_t>(sizeof(int32_t)), 0, 0, 0};
    AscendC::DataCopyPad(dst[index], tmp, params);
}

/**
 * 同 pos 写 q_ind + slot：一次 barrier + 两次 4B MTE3。
 * tmpQ/tmpS 须各自 32B 对齐（不可用 tmp[1] 作源）。
 */
```

## ITEM 19

### item 18

https://raw.githubusercontent.com/inclusionAI/AReno/main/areno/accel/csrc/npu/fused_experts_matmul_kernel.cpp
inclusionAI/AReno, last commit 2026-10-08 by sule
Cross-kernel (vector-launch -> cube-launch) metadata handoff: DataCacheCleanAndInvalid<int32_t, CacheLine::SINGLE_CACHE_LINE, DcciDst::CACHELINE_OUT>(total) immediately before `total.GetValue(0)`, repeated per-row for the expert id. The comment states scalar GM reads need explicit invalidation including during graph replay.
```cpp
template<uint32_t Storage>
__global__ __aicore__ void expert_matmul_kernel(GM_ADDR in, GM_ADDR w, GM_ADDR out,
    GM_ADDR expertIds, GM_ADDR paddedTotal, int64_t capacity, int64_t n, int64_t k, int64_t outputStride, GM_ADDR workspace) {
    using T = typename areno_npu::KernelDtype<Storage>::type;
    using namespace AscendC;
    using namespace areno_npu;
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIC_ONLY);
    using A = MatmulType<TPosition::GM, CubeFormat::ND, T>;
    using B = MatmulType<TPosition::GM, CubeFormat::ND, T, true>;
    using C = MatmulType<TPosition::GM, CubeFormat::ND, float>;
    constexpr static auto config = GetMatmulApiTiling<A, B, C, C>(expert_matmul_config());
    Matmul<A, B, C, C, config> mm;
    TPipe pipe;
    SetSysWorkspace(workspace);
    REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, (TCubeTiling*)nullptr);
    GlobalTensor<T> input, weight;
    GlobalTensor<float> output;
    GlobalTensor<int32_t> experts, total;
    input.SetGlobalBuffer(reinterpret_cast<__gm__ T*>(in));
    weight.SetGlobalBuffer(reinterpret_cast<__gm__ T*>(w));
    output.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(out));
    experts.SetGlobalBuffer(reinterpret_cast<__gm__ int32_t*>(expertIds));
    total.SetGlobalBuffer(reinterpret_cast<__gm__ int32_t*>(paddedTotal));
    // The preceding vector launches wrote this metadata. Scalar GM reads
    // need explicit cache invalidation, including during graph replay.
    DataCacheCleanAndInvalid<int32_t, CacheLine::SINGLE_CACHE_LINE, DcciDst::CACHELINE_OUT>(total);
    int64_t used = total.GetValue(0);
    int64_t columns = (n + kExpertN - 1) / kExpertN;
    for (int64_t task = GetBlockIdx(); task < capacity / kExpertM * columns; task += GetBlockNum()) {
        int64_t row = task / columns * kExpertM, col = task % columns * kExpertN;
        if (row >= used) continue;
        auto id = experts[row / kExpertM];
        DataCacheCleanAndInvalid<int32_t, CacheLine::SINGLE_CACHE_LINE, DcciDst::CACHELINE_OUT>(id);
        int64_t expert = id.GetValue(0);
        if (expert < 0) continue;
        int32_t tailN = n - col < kExpertN ? n - col : kExpertN;
        for (int64_t inner = 0; inner < k; inner += kExpertK) {
            int32_t tailK = k - inner < kExpertK ? k - inner : kExpertK;
            // Keep FP32 GM rows aligned for Fixpipe, including odd N tails.
            mm.SetOrgShape(kExpertM, n, k, k, outputStride);
            mm.SetTensorA(input[row * k + inner]);
```

## ITEM 20

### item 19

https://raw.githubusercontent.com/vllm-project/vllm-ascend/main/csrc/attention/fused_lightning_indexer_manage/op_kernel/fused_lightning_indexer_manage.cpp
vllm-project/vllm-ascend, last commit 2026-09-24 by xieqiang
A decode-path kernel that mixes `if ASCEND_IS_AIV { SyncAll(); }` grid barriers with a SINGLE_CACHE_LINE dcci placed between a scalar probe read and a DMA overwrite of the same line (the probe populated the DCache line; without the invalidate a later writeback would restore the stale value). Owner-per-AIV decomposition is chosen so owners publish disjoint chunks before the outer SyncAll.
```cpp
    slots.SetGlobalBuffer((__gm__ int32_t *)cacheSlotsAddr);
    queryEnds.SetGlobalBuffer((__gm__ int32_t *)actualSeqQueryAddr);
    keyLengths.SetGlobalBuffer((__gm__ int32_t *)actualSeqKeyAddr);
    offloadLengths.SetGlobalBuffer((__gm__ int32_t *)offloadSeqKeyAddr);
    cacheTokens.SetGlobalBuffer((__gm__ int32_t *)cacheTokensAddr);
    const uint32_t owner = GetBlockIdx() / LIMConfig::AIVS_PER_AIC;
    // KERNEL_TYPE_MIX_AIC_1_2 exposes 2 * GetBlockNum() AIV blocks.  Even
    // AIVs therefore provide exactly GetBlockNum() independent owners.
    const uint32_t owners = GetBlockNum();
    TBuf<TPosition::VECCALC> identityBaseBuf;
    TBuf<TPosition::VECCALC> identityValuesBuf;
    TBuf<TPosition::VECCALC> transitionInvalidBuf;
    bool identityBufferReady = false;
    bool transitionCleanupBufferReady = false;
    // Every owner participates in every standard row.  The previous
    // batch-strided assignment left all but one owner idle for BS=1, making a
    // large identity row a single-AIV GM write.  Standard LI does not consume
    // cacheSlots, so owners can publish disjoint chunks before the outer
    // SyncAll without introducing a data dependency.  Keep the transition
    // cleanup on its established one-owner-per-request assignment below.
    for (uint32_t batch = 0U; batch < batchSize; ++batch) {
        const int32_t state = states.GetValue(batch);
        if (state != LIMConfig::REQUEST_STATE_NON_OFFLOAD &&

/* ... */

            // the full-row cleanup.  Avoid scanning the row on every decode.
            if (static_cast<uint32_t>(cacheCount) >= sourceCapacity) {
                continue;
            }
            if (slots.GetValue(base + static_cast<uint32_t>(cacheCount)) <
                cacheCount) {
                continue;
            }
            // The scalar probe populated its DCache line with the identity
            // value.  Invalidate it before DMA overwrites the suffix, or a
            // later cache writeback could restore slot C and corrupt -1.
            const uint32_t probeLine = static_cast<uint32_t>(cacheCount) & ~31U;
            DataCacheCleanAndInvalid<int32_t, CacheLine::SINGLE_CACHE_LINE,
                                     DcciDst::CACHELINE_OUT>(
                slots[base + probeLine]);
            if (!transitionCleanupBufferReady) {
                pipe->InitBuffer(transitionInvalidBuf,

/* ... */

                              cacheSlots, tiling_data->bSize, tiling_data->tSize,                                      \
                              tiling_data->poolSize, tiling_data->cacheSlotsSize, &tPipe);                             \
        if ASCEND_IS_AIV { SyncAll(); }                                                                                \
        __gm__ uint8_t *unionPair0 =                                                                                    \
            user + MtpWorkspace::Pair0Offset(GetBlockNum(), tiling_data->n1Size);                                      \

/* ... */

        op.Process();                                                                                                   \
        if ASCEND_IS_AIV {                                                                                              \
            SyncAll();                                                                                                  \
            if (GetBlockIdx() % LIMConfig::AIVS_PER_AIC == 0U) {                                                       \
                tPipe.Reset();                                                                                          \
                const uint32_t unionOwner = GetBlockIdx() / LIMConfig::AIVS_PER_AIC;                                   \
```

## ITEM 21

### item 20

https://raw.githubusercontent.com/hicann/catlass/master/include/catlass/arch/cross_core_sync.hpp
hicann/catlass, last commit 2026-07-16 by yuantao_
CATLASS's grid barrier layer: reserved FlagIDs (AIV_INTER_BLOCK_BARRIER=8, AIC_INTER_BLOCK_BARRIER=9, AIV_INTER_SUBBLOCK_BARRIER=10, FFTS_MAX_FLAG=7), CrossCoreBarrier<MODE,PIPE>() = set-then-wait on one's own core-type flag, and MAX_REVERSE_DEPTH=15 with CrossCoreSetFlagWithReverse — the documented workaround for the 15-consecutive-set counter overflow freeze.
```cpp
namespace Catlass::Arch {

// A certain cross core flag can be continuously set up to 15 times without waiting. In scenarios where there is only
// one-way synchronization between cores and the synchronization operation is executed multiple times, if the core
// performing the set operation runs faster, it may result in the flag being set more than 15 times consecutively,
// leading to a system freeze. To prevent such a freeze, we need to wait for the waiting cores to perform a reverse
// synchronization operation after executing the set operation MAX_REVERSE_DEPTH times.
constexpr uint32_t MAX_REVERSE_DEPTH = 15;

using FlagID = uint16_t;
constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
constexpr FlagID AIC_INTER_BLOCK_BARRIER = 9;
constexpr FlagID AIV_INTER_SUBBLOCK_BARRIER = 10;
constexpr FlagID FFTS_MAX_FLAG = 7;

struct CrossCoreFlag {
    CATLASS_DEVICE
    CrossCoreFlag() : id(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlag(FlagID id) : id(id)
    {}

    FlagID id;
};

template <uint32_t REVERSE_DEPTH_ = MAX_REVERSE_DEPTH>
struct CrossCoreFlagWithReverse {
    CATLASS_DEVICE
    CrossCoreFlagWithReverse() : id(0), reverseId(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlagWithReverse(FlagID id, FlagID reverseId) : id(id), reverseId(reverseId)
    {}

    FlagID id;
    FlagID reverseId;
    uint32_t count{0};
};

template <uint8_t MODE, int32_t CORE_TYPE>
struct BarrierFlag {
    static_assert(MODE != 255 && MODE == 255, "Unsupported cross core barrier flag, can not find the specialization.");
};

template <>
struct BarrierFlag<0x0, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x0, AscendC::AIC> {
    static constexpr FlagID ID = AIC_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x1, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_SUBBLOCK_BARRIER;
};

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreBarrier()
{
    constexpr FlagID flagId = BarrierFlag<MODE, g_coreType>::ID;
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flagId);
    AscendC::CrossCoreWaitFlag(flagId);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreSetFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
}

CATLASS_DEVICE
void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag<MODE, PIPE>(flag.id);
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreSetFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreWaitFlag(flag.reverseId);
        flag.count = 0;
    }
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreWaitFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.reverseId);
        flag.count = 0;
    }
}

} // namespace Catlass::Arch

#endif // CATLASS_ARCH_CROSS_CORE_SYNC_HPP
```

## ITEM 22

### item 21

https://raw.githubusercontent.com/hicann/ops-nn/master/matmul/common/cmct/kernel/kernel_matmul_streamk.h
hicann/ops-nn, last commit 2026-09-18 by szhexin
Vendor Stream-K form of the grid barrier: AIC publishes its last partial drain with CrossCoreSetFlag<4, PIPE_FIX>(8) and (8+16) for the two AIV slots; every AIV does CrossCoreWaitFlag<4, PIPE_MTE3>(8) and only then SyncAll(). Cores with no work take the SAME path (set/wait + SyncAll) before returning, so nobody is missing from the barrier.
```cpp

    constexpr static uint16_t NUM_TWO = 2;
    constexpr static uint16_t AIC_SYNC_AIV_MODE_4 = 4;
    constexpr static uint16_t AIV_SYNC_AIC_FLAG = 6;
    constexpr static uint16_t AIC_SYNC_AIV_FLAG = 8;
    constexpr static uint16_t FLAG_ID_MAX = 16;
    constexpr static uint16_t BLOCK_BASE_M = 256;

/* ... */

        if ASCEND_IS_AIC {
            // Instantiate mmadOp
            BlockMmadOp blockMmadOp;
            int64_t curBlockIdx = AscendC::GetBlockIdx();

            TupleShape tileL0 = bs.GetTileL0Shape();
            int64_t isHf32 = bs.GetHf32Flag();

            if (curBlockIdx >= bs.GetBlockNum(usedCoreNum_)) {
                CrossCoreSetFlag<AIC_SYNC_AIV_MODE_4, PIPE_FIX>(AIC_SYNC_AIV_FLAG);
                CrossCoreSetFlag<AIC_SYNC_AIV_MODE_4, PIPE_FIX>(AIC_SYNC_AIV_FLAG + FLAG_ID_MAX);
                return;
            }
            if (isHf32) {

/* ... */

                        bs.splitSingleKIdx_ == (bs.splitSingleKRound_ - 1));
                }
                if (tmpTileIdx + usedCoreNum_ >= tileNum) {
                    CrossCoreSetFlag<AIC_SYNC_AIV_MODE_4, PIPE_FIX>(AIC_SYNC_AIV_FLAG);
                    CrossCoreSetFlag<AIC_SYNC_AIV_MODE_4, PIPE_FIX>(AIC_SYNC_AIV_FLAG + FLAG_ID_MAX);
                }
            }
            SetMMLayoutTransform(false);
            if (isHf32) {
                AscendC::SetHF32Mode(0);
                AscendC::SetHF32TransMode(0);
            }
        }

        if ASCEND_IS_AIV {
            uint64_t lastLoopTotalCnt = (mTileNum * nTileNum * batchNum % usedCoreNum_) * skKTileNum;
            uint64_t curBlockIdxInAiv = AscendC::GetBlockIdx();
            if (curBlockIdxInAiv >= lastLoopTotalCnt * AscendC::GetTaskRation()) {
                CrossCoreWaitFlag<AIC_SYNC_AIV_MODE_4, PIPE_MTE3>(AIC_SYNC_AIV_FLAG);
                SyncAll();
                return;
            }

            CrossCoreWaitFlag<AIC_SYNC_AIV_MODE_4, PIPE_MTE3>(AIC_SYNC_AIV_FLAG);
            SyncAll();
            BlockEpilogue epilogueOp;
```

## ITEM 23

### item 22

https://raw.githubusercontent.com/hicann/ops-nn/master/rnn/lstm_block_cell/op_kernel/arch35/sync_helper.h
hicann/ops-nn, last commit 2026-09-29 by wang-zhiyue2
In-tree engineering notes on the grid barrier contract: batch scheduling is required or the wait can be posted with nobody to answer (measured 3 hangs / 49 runs without it, 0 / 240 with); mode-4 flags are COUNTERS not one-shot barriers; and WHY an AIV must wait its own AIC on PIPE_MTE3 before SyncAll() — SyncAll's ARRIVE rides the MTE3 queue, so enqueuing the wait on the same queue orders the arrive behind the AIC drain.
```cpp
/* sync_helper.h -- ALL synchronization for the raw Ascend 950PR (dav_3510) kernels, in one place.
 *
 * WHY THIS IS ITS OWN HEADER, against the "split by who issues it" rule the other headers follow:
 *
 *   A HANDSHAKE IS A PROTOCOL, AND A PROTOCOL HAS TWO ENDS. The thing that goes wrong is not one
 *   side or the other -- it is the PAIRING. A dedicated cross-core measurement pins the pairing rule, because the three
 * plausible pairings do not all work (1 set : 1 consume deadlocks, 2 : 2 deadlocks, 2 : 1 runs). Putting the two ends
 * in two different files would separate exactly the thing that must be read together.
 *
 * So cube_helper.h and vec_helper.h are pure dataflow, and every ordering question lives here.
 *
 * TWO KINDS OF ORDERING, DO NOT CONFUSE THEM
 *   intra-core   between PIPES of one core (MTE2 / MTE1 / M / FIX / V / MTE3). Set+Wait on a
 *                typed HardEvent. Cheap, and purely local.
 *   cross-core   between the AIC and its two AIVs. CrossCoreSetFlag / CrossCoreWaitFlag.
 *                Semantics differ BY DIRECTION -- see below, this is the part that bites.
 */
#ifndef SYNC_HELPER_H
#define SYNC_HELPER_H

#include "kernel_operator.h"

namespace sh {

/* ---------------------------------------------------------------------------------------------
 * BATCH SCHEDULING (`__schedmode__` / `SetScheduleMode`) -- WHAT IT IS, AND WHY IT MATTERS
 *
 * A cross-core wait only holds if the AIC and its two AIVs are dispatched as a BATCH:
 * without batch scheduling the wait can be posted with nobody to answer it. A reference
 * recurrent-operator probe measured 3 hangs in 49 runs (~6%) without it, 0 in 240 with --
 * concentrated on SMALL shapes, where both AIVs reach the barrier at nearly the same moment.
 *
 * TWO SEPARATE LEVERS, AND ONLY ONE OF THEM EXISTS ON EACH PATH:
 *   op framework   `gert::TilingContext::SetScheduleMode(uint32_t)` -- an OUTPUT SLOT of
 *                  tiling, so it only exists when tiling runs. This kernel's TilingFunc
 *                  sets it (batch scheduling: AIC + 2 AIV dispatched together).
 *   raw <<<>>>     `__schedmode__(N)` -- there is no TilingContext on a raw launch, so
 *                  this attribute is the only lever there.
 * ------------------------------------------------------------------------------------------- */

/* ---------------------------------------------------------------------------------------------
 * Intra-core: order one pipe against another, within a single core.
 *
 * Each is a Set immediately followed by a Wait on the same event id -- a full stop rather than
 * true overlap. That is deliberate: correctness first, and the pipe pair stays legible at the
 * call site. Software-pipelining these (Set early, Wait late, multiple event ids) is a later
 * optimisation, not a cleanup.
 * ------------------------------------------------------------------------------------------- */
template <AscendC::HardEvent E>
__aicore__ inline void PipeWait(event_t id = EVENT_ID0)
{
    AscendC::SetFlag<E>(id);
    AscendC::WaitFlag<E>(id);
}

__aicore__ inline void WaitMte2ToMte1() { PipeWait<AscendC::HardEvent::MTE2_MTE1>(); } // GM->L1 before L1->L0
__aicore__ inline void WaitMte1ToM() { PipeWait<AscendC::HardEvent::MTE1_M>(); }       // L1->L0/BT before Mmad
__aicore__ inline void WaitMToFix() { PipeWait<AscendC::HardEvent::M_FIX>(); }         // Mmad before the drain
__aicore__ inline void WaitFixToM() { PipeWait<AscendC::HardEvent::FIX_M>(); }         // drain read before reusing L0C

/* ---------------------------------------------------------------------------------------------
 * Cross-core. Both ends of each protocol are adjacent ON PURPOSE.
 *
 * ⚠⚠ MODE 4 (intra-block) IS USED, NOT MODE 0x2. Mode 0x2 leaks across MIX blocks within
 * a group at blockDim > 1, and the "barrier, not counting semaphore" pairing (both AIVs
 * set, cube waits x1) breaks: a flag set by one block's AIV is consumed by another
 * block's AIC, deadlocking the producer. Mode 4 (`set_intra_block` /
 * `wait_intra_block`) is strictly intra-MIX-block (1 AIC + 2 AIV) and is what every
 * vendor MIX-1:2 op uses (quant_batch_matmul_v3, mat_mul_v3 arch35).
 *
 * Mode-4 pairing rules (measured by vendor + confirmed by dav_c310 impl):
 *   set_intra_block from AIC  → flag visible to BOTH AIVs (subBlock-scoped: AIV0 sees
 *                               flagId, AIV1 sees flagId + INTRA_NUM=16).
 *   set_intra_block from AIV  → flag visible to AIC only (subBlock-scoped: AIC distinguishes
 *                               AIV0 by flagId and AIV1 by flagId + INTRA_NUM).
 *   wait_intra_block from AIC → must wait for BOTH AIVs: flagId AND flagId + INTRA_NUM.
 *   wait_intra_block from AIV→ waits for its own flagId (hardware routes by subBlockId).
 *
 * So the AIC sets/waits TWO flags (one per AIV slot), each AIV sets/waits ONE.
 *
 * ⚠ MODE-4 FLAGS ARE COUNTERS, NOT ONE-SHOT BARRIERS. A set landing while an earlier
 * set on the same id is still unwaited ACCUMULATES -- it is neither lost nor
 * latched-as-edge (proven on real 3510 by count==0 fast paths pre-firing several
 * consumed slots ahead of their waits). The counter reading does NOT relax the
 * cross-launch pairing discipline: a set left unwaited at launch end stays armed
 * into the NEXT launch and makes its wait return early -- every protocol below
 * keeps one set + one wait per flag slot per launch.
 * ------------------------------------------------------------------------------------------- */
constexpr uint16_t INTRA_NUM = 16; // dav_c310 subBlock flag offset (AIV0: 0..15, AIV1: 16..31)

/* ---------------------------------------------------------------------------------------------
 * Bias prepass (AIV -> cube): the fp32 padded bias workspace is filled (AIV pre-pass).
 *
 * ⚠ ONE id per AIV: the hardware routes AIV1's set to id+16 by subBlockId; an
 * AIV setting its partner's slot directly corrupts the pairing the AIC's
 * double wait relies on.
 * ------------------------------------------------------------------------------------------- */
constexpr uint16_t V2C_PREPASS = 7;

__aicore__ inline void VecSignalPrepass() { AscendC::CrossCoreSetFlag<0x4, PIPE_MTE3>(V2C_PREPASS); }
__aicore__ inline void CubeWaitPrepass()
{
    /* ⚠ PIPE_MTE2, NOT PIPE_M. This wait guards the
     * bias workspace reads, which are MTE2 copies (GM->L1 CopyInFlat /
     * CopyInNd2Nz inside CubeProjectKS). On PIPE_M it stalled the M pipe and
     * left the MTE2 reads ungated -- the AIC could read the fp32 bias
     * workspace before the AIV pre-pass wrote it. Vendor pattern: wait on the
     * consuming pipe (same rule as every other cross-core wait here). */
    AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE2>(V2C_PREPASS);
    AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE2>(V2C_PREPASS + INTRA_NUM);
    AscendC::PipeBarrier<PIPE_ALL>();
}

/* ---------------------------------------------------------------------------------------------
 * K-SPLIT PHASE HANDOFF -- the K-split two-phase structure:
 * the AICs write their partials straight to GM (L0C->GM fixpipe), then every
 * AIV waits for its OWN AIC and only then joins the grid-wide
 * AscendC::SyncAll(). The ledger is one set + one wait per flag slot per
 * launch -- no ring, no reuse.
 *
 * ⚠ WHY THE AIV WAITS ON PIPE_MTE3: SyncAll() on 3510 is an AIV-only ffts
 * barrier whose ARRIVE instruction rides the MTE3 queue (dav_3510
 * kernel_operator_sync_impl.h: ffts_cross_core_sync(PIPE_MTE3, ...)). Enqueuing
 * this wait on the SAME queue makes the arrive queue-ordered behind the
 * own-AIC flag, so the barrier cannot pass while any AIC is still draining
 * (ops-nn kernel_matmul_streamk.h: CrossCoreWaitFlag<MODE_4, PIPE_MTE3> then
 * SyncAll -- the exact vendor form). After SyncAll() returns, EVERY cluster's
 * partials are GM-visible to every AIV.
 * ------------------------------------------------------------------------------------------- */
constexpr uint16_t KS_DONE = 8; // distinct from V2C_PREPASS; 16 logical ids total

/* AIC: my LAST partial drain is on the FIX queue -- this set rides PIPE_FIX,
 * so it is delivered only after every GM write of the phase is complete. */
__aicore__ inline void CubeSignalKsDone()
{
    AscendC::CrossCoreSetFlag<0x4, PIPE_FIX>(KS_DONE);
    AscendC::CrossCoreSetFlag<0x4, PIPE_FIX>(KS_DONE + INTRA_NUM);
}
/* AIV: my AIC's partials are in GM. Call BEFORE AscendC::SyncAll(). */
__aicore__ inline void VecWaitKsDone() { AscendC::CrossCoreWaitFlag<0x4, PIPE_MTE3>(KS_DONE); }

} // namespace sh
```

## ITEM 24

### item 23

https://raw.githubusercontent.com/hicann/ops-nn/master/index/inplace_add/op_kernel/arch35/inplace_add.cpp
hicann/ops-nn, last commit 2026-08-31 by raoliang_sac
A two-phase kernel whose phase boundary IS a SyncAll(). Three constraints stated in-source: (a) the published phase-1 traffic must be MTE DataCopy because SyncAll signals on PIPE_MTE3 and vf stores stayed outside the barrier's reach (~0.3-0.5% of destinations read stale values, and neither PipeBarrier<PIPE_ALL> nor DataCacheCleanAndInvalid nor DataSyncBarrier<ALL> closed the window); (b) host tiling must declare batch mode SetScheduleMode(1) or SyncAll returns immediately; (c) every core must take the same branch — cores that skip the work must skip the SyncAll too.
```cpp
// Phase one: y = x, over MTE, as one contiguous slice per core.
//
// The decomposition is flat rather than by rows on purpose. Splitting by rows
// ties thread occupancy to the row width and core occupancy to the row count,
// and both bind in practice: a rank-1 tensor has rowSize == 1, which left 1023
// of the 1024 threads idle, and an n = 16 tensor left 40 of the 56 cores idle
// whatever its row width. A flat range has neither property.
//
// The transport is DataCopy and not a SIMT vector store, and that is the part
// that took the longest to find. SyncAll raises its cross-core signal on
// PIPE_MTE3, so it publishes MTE traffic and only MTE traffic. Writing this
// phase with vf stores left them outside the barrier's reach, and no
// combination of PipeBarrier<PIPE_ALL>, DataCacheCleanAndInvalid and
// DataSyncBarrier<ALL> closed the window: peers kept reading rows this core had
// already written, at a steady ~0.3-0.5% of scattered destinations, every one
// of them holding the pristine x value. inplace_index_add_simt.h stages the
// same handoff through DataCopy for the same reason.
template <typename T>
__aicore__ inline void InplaceAddCopy(int64_t total, int64_t coreIdx, int64_t coreNum, __gm__ T* xGm, __gm__ T* yGm,

/* ... */

    }
}

// Phase two: y[indices[kIdx]] += v[kIdx], as one flat grid-stride pass over the
// k * rowSize elements of v.
//
// This is the split that needs the cross-core barrier: a core writes rows it
// does not own, so every core must have finished phase one first. Before that
// barrier worked, each core had to scan the whole index array and keep only the
// hits landing in its own rows, which made the kernel's cost a function of K
// alone -- a flat ~1.3ns per index that no amount of intra-block parallelism
// removed, because the scan itself was the work.
//
// No atomics: the operator's contract normalizes indices into [0, n) and
// requires them to be unique there, so two elements of v never target the same
// element of y. Duplicate indices are explicitly undefined by the operator
// contract and are only required to stay memory-safe, which plain stores
// are. Sibling operators that do allow duplicates pay for asc_atomic_add, which
// on GM covers only int32/uint32/int64/uint64/float and forces int8/int16 through
// a widened workspace; staying non-atomic keeps all 13 dtypes on one path.
template <typename T, typename COMP_T, bool ROW_SIZE_ONE>

/* ... */

    __gm__ T* xGm = reinterpret_cast<__gm__ T*>(x);
    __gm__ int32_t* indicesGm = reinterpret_cast<__gm__ int32_t*>(indices);
    __gm__ T* vGm = reinterpret_cast<__gm__ T*>(v);
    __gm__ T* yGm = reinterpret_cast<__gm__ T*>(y);

    const int64_t coreIdx = static_cast<int64_t>(GetBlockIdx());
    const int64_t coreNum = static_cast<int64_t>(tilingData->needCoreNum);
    const int64_t rowSize = tilingData->innerSize * ELEMENTS_PER_VALUE;
    const int64_t n = static_cast<int64_t>(tilingData->n);
    const int64_t k = static_cast<int64_t>(tilingData->k);
    const int64_t copyTotal = n * rowSize;
    const int64_t accTotal = k * rowSize;
    const int64_t widest = copyTotal > accTotal ? copyTotal : accTotal;

    TPipe pipe;
    InplaceAddCopy<T>(copyTotal, coreIdx, coreNum, xGm, yGm, pipe);

    // The cross-core barrier. Two things have to be true for it to hold:
    // the copy above must be MTE traffic (SyncAll signals on PIPE_MTE3), and the
    // host tiling must declare batch mode (SetScheduleMode(1)) so the cores are
    // co-resident -- without it SyncAll returns immediately and every core's
    // index chunk loses its head element to the peer that copied it.
    // Every core reaches this, including the ones with no accumulate work.
    SyncAll();

    if (accTotal <= 0) {
        return;
    }
    const int64_t uint32Max = static_cast<int64_t>(std::numeric_limits<uint32_t>::max());
    const int64_t accumulateStride = coreNum * static_cast<int64_t>(THREAD_NUM);
    const int64_t uint32SafeAccTotal = uint32Max - accumulateStride + 1;
    if (widest <= uint32Max && accTotal <= uint32SafeAccTotal) {
        LaunchAccumulate<T, uint32_t>(accTotal, rowSize, tilingData->n, coreIdx, coreNum, indicesGm, vGm, yGm);
    } else {
        LaunchAccumulate<T, uint64_t>(accTotal, rowSize, tilingData->n, coreIdx, coreNum, indicesGm, vGm, yGm);
    }
}

} // namespace

extern "C" __global__ __aicore__ void inplace_add(GM_ADDR x, GM_ADDR indices, GM_ADDR v, GM_ADDR y, GM_ADDR workspace,
                                                  GM_ADDR tiling)
{
    REGISTER_TILING_DEFAULT(InplaceAddTilingData);
    GET_TILING_DATA_WITH_STRUCT(InplaceAddTilingData, tilingData, tiling);
    // Every core must take the same branch here: the cores that skip the work
    // must also skip the SyncAll inside Process, or the ones that reach it wait
    // for peers that never arrive.
    if (tilingData.needCoreNum == 0 || tilingData.n <= 0 || tilingData.innerSize <= 0) {
        return;
    }
#if ORIG_DTYPE_X == DT_COMPLEX32
    Process<half, INPLACE_ADD_COMPLEX_COMPONENT_COUNT>(x, indices, v, y, &tilingData);
#elif ORIG_DTYPE_X == DT_COMPLEX64
    Process<float, INPLACE_ADD_COMPLEX_COMPONENT_COUNT>(x, indices, v, y, &tilingData);
#else
    Process<DTYPE_X>(x, indices, v, y, &tilingData);
#endif
}
```

## ITEM 25

### item 24

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/dynamic_quant/op_kernel/dynamic_quant_base.h
hicann/ops-nn, last commit 2026-07-06 by yang-di52
DynamicQuant's barrier-free decomposition and its row-max primitive. InitParams: each core owns rowPerHeadCore (head cores) or rowPerTailCore (tail cores) WHOLE rows, so the per-token max never crosses a core. ReduceMaxInplace is the intra-core row reduction: strided Max() repeats to fold the row into one 64-element (fp32) / 128-element (fp16) group, then a single WholeReduceMax. GetScale/GetScaleAndOffset turn that max into the scale.
```cpp

    __aicore__ inline void InitCommonParams()
    {
        lenHead = rowPerHeadCore * tilingData_.rowLen;
        lenTail = rowPerTailCore * tilingData_.rowLen;
        if (ORIG_DTYPE_Y == DT_INT4) {
            outLenHead = lenHead >> 1;
            outLenTail = lenTail >> 1;
        } else {
            outLenHead = lenHead;
            outLenTail = lenTail;
        }
    }

    __aicore__ inline void InitParams(GM_ADDR offset)
    {
        blockIdx = GetBlockIdx();
        if (offset != nullptr) {
            isAsymmetrical = true;
        }
        rowPerHeadCore = tilingData_.rowPerHeadCore;
        rowPerTailCore = tilingData_.rowPerTailCore;

        if (blockIdx < tilingData_.headCoreNum) {
            multiRowNum = tilingData_.multiRowNumHeadCore;
            loopCnt = rowPerHeadCore / multiRowNum;
            remainRow = rowPerHeadCore % multiRowNum;
        } else if (blockIdx >= tilingData_.headCoreNum && blockIdx < tilingData_.coreNum) {
            multiRowNum = tilingData_.multiRowNumTailCore;
            loopCnt = rowPerTailCore / multiRowNum;
            remainRow = rowPerTailCore % multiRowNum;
        }
        sizeHalfLen = (tilingData_.rowLen + FIFTEEN) / SIXTEEN * SIXTEEN;
        rightPadding = sizeHalfLen - tilingData_.rowLen;
        if (rightPadding > 0) {
            isPad = true;
        }
        if (ORIG_DTYPE_Y == DT_INT4) {
            outAlignLen = (tilingData_.rowLen + SIXTY_THREE) / SIXTY_FOUR * SIXTY_FOUR;
        } else {
            outAlignLen = (tilingData_.rowLen + THIRTY_ONE) / THIRTY_TWO * THIRTY_TWO;
        }
        sizeFloatLen = (multiRowNum + SEVEN) / EIGHT * EIGHT;
        lenMultiRow = multiRowNum * sizeHalfLen;
        lenGMMultiRow = multiRowNum * tilingData_.rowLen;
        outLen = multiRowNum * outAlignLen;
        InitCommonParams();
    }


/* ... */


    __aicore__ inline void GetScale(float max_value, float& scale)
    {
        if (ORIG_DTYPE_Y == DT_INT4) {
            scale = DYNAMIC_QUANT_INT4_SYM_SCALE / max_value;
        } else {
            scale = DYNAMIC_QUANT_INT8_SYM_SCALE / max_value;
        }
    }

    __aicore__ inline void GetScaleAndOffset(float max_value, float min_value, float& scale, float& offset)
    {
        if (ORIG_DTYPE_Y == DT_INT4) {
            scale = GetMax((max_value - min_value) / DYNAMIC_QUANT_INT4_SCALE, DYNAMIC_QUANT_EPSINON);
            offset = DYNAMIC_QUANT_INT4_OFFSET - max_value / scale;
        } else {
            scale = GetMax((max_value - min_value) / DYNAMIC_QUANT_INT8_SCALE, DYNAMIC_QUANT_EPSINON);
            offset = DYNAMIC_QUANT_INT8_OFFSET - max_value / scale;
        }
    }

    __aicore__ inline void ReduceMaxInplace(const LocalTensor<float>& src_local, uint32_t count)
    {
        uint64_t repsFp32 = count >> 6;       // 6 is cound / ELEM_PER_REP_FP32
        uint64_t offsetsFp32 = repsFp32 << 6; // 6 is repsFp32 * ELEM_PER_REP_FP32
        uint64_t remsFp32 = count & 0x3f;     // 0x3f 63, count % ELEM_PER_REP_FP32

        if (likely(repsFp32 > 1)) {
            // 8 is rep stride
            if (repsFp32 - 1 > MAX_REPEAT) {
                Max(src_local, src_local[ELEM_PER_REP_FP32], src_local, ELEM_PER_REP_FP32, MAX_REPEAT,
                    {1, 1, 1, 0, 8, 0});
                PipeBarrier<PIPE_V>();
                Max(src_local, src_local[ELEM_PER_REP_FP32 * MAX_REPEAT], src_local, ELEM_PER_REP_FP32,
                    repsFp32 - MAX_REPEAT - 1, {1, 1, 1, 0, 8, 0});
            } else {
                Max(src_local, src_local[ELEM_PER_REP_FP32], src_local, ELEM_PER_REP_FP32, repsFp32 - 1,
                    {1, 1, 1, 0, 8, 0});
            }
            PipeBarrier<PIPE_V>();
        }
        if (unlikely(remsFp32 > 0) && unlikely(offsetsFp32 > 0)) {
            Max(src_local, src_local[offsetsFp32], src_local, remsFp32, 1, {1, 1, 1, 0, 8, 0});
            PipeBarrier<PIPE_V>();
        }
        uint32_t mask = repsFp32 > 0 ? ELEM_PER_REP_FP32 : count;
        // 8 is rep stride
        WholeReduceMax(src_local, src_local, mask, 1, 8, 1, 8);
    }

    __aicore__ inline void ReduceMaxInplace(const LocalTensor<half>& src_local, uint32_t count)
    {
        uint64_t repsHalf = count >> 7;       // 7 is count / ELEM_PER_REP_HALF
        uint64_t offsetsHalf = repsHalf << 7; // 6 is repsHalf * ELEM_PER_REP_HALF
        uint64_t remsHalf = count & 0x7f;     // 0x7f 127, count % ELEM_PER_REP_HALF

        if (likely(repsHalf > 1)) {
            // 8 is rep stride
            Max(src_local, src_local[ELEM_PER_REP_HALF], src_local, ELEM_PER_REP_HALF, repsHalf - 1,
                {1, 1, 1, 0, 8, 0});
            PipeBarrier<PIPE_V>();
        }
```

## ITEM 26

### item 25

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/dynamic_quant/op_kernel/dynamic_quant.h
hicann/ops-nn, last commit 2026-07-06 by yang-di52
The DynamicQuant compute loop proper: per row -> Cast to fp32 -> optional smooth Mul -> Abs -> ReduceMaxInplace -> Div -> a V_S event pair -> temp.GetValue(0) scalar read -> Muls by the reciprocal -> Cast to int8. No SyncAll anywhere; the asymmetric variant uses ReduceMax/ReduceMin instead.
```cpp
    __aicore__ inline void Compute(const LocalTensor<float>& smoothLocal, int32_t multiRow)
    {
        uint32_t index = 0;
        LocalTensor<float> scaleLocal = scaleQueue.AllocTensor<float>();
        LocalTensor<xDtype> inLocal = inQueue.DeQue<xDtype>();
        LocalTensor<float> tempFp32 = tempCastUb.Get<float>();
        LocalTensor<yDtype> outLocal = outQueue.AllocTensor<yDtype>();
        AscendC::LocalTensor<float> temp = fp32_buf_.Get<float>();
        LocalTensor<int32_t> tempInt32 = fp32_buf_.Get<int32_t>();
        auto tempHalf = temp.ReinterpretCast<half>();

        for (int32_t i = 0; i < multiRow; i++) {
            index = i * sizeHalfLen;
            // x fp16->fp32
            Cast(tempFp32, inLocal[index], RoundMode::CAST_NONE, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            if (tilingData_.hasSmooth) {
                Mul(tempFp32, tempFp32, smoothLocal, tilingData_.rowLen);
                PipeBarrier<PIPE_V>();
            }
            Abs(temp, tempFp32, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            ReduceMaxInplace(temp, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            Div(temp, constScale, temp, 1);
            event_t event_v_s = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::V_S));
            SetFlag<HardEvent::V_S>(event_v_s);
            WaitFlag<HardEvent::V_S>(event_v_s);
            float scale = temp.GetValue(0);
            scaleLocal.SetValue(i, 1 / scale);
            Muls(tempFp32, tempFp32, scale, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            Cast(tempInt32, tempFp32, RoundMode::CAST_RINT, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            SetDeqScale(static_cast<half>(1.0));
            PipeBarrier<PIPE_V>();
            Cast(tempHalf, tempInt32, RoundMode::CAST_ROUND, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            Cast(outLocal[i * outAlignLen], tempHalf, RoundMode::CAST_TRUNC, tilingData_.rowLen);
        }
        outQueue.EnQue<yDtype>(outLocal);
        scaleQueue.EnQue<float>(scaleLocal);
        inQueue.FreeTensor(inLocal);
    }

    __aicore__ inline void ComputAsymmetric(const LocalTensor<float>& smoothLocal, int32_t multiRow)
    {
        uint32_t index = 0;
        float max_value, min_value;
        float scale, offset;
        float back_scale;
        LocalTensor<float> scaleLocal = scaleQueue.AllocTensor<float>();
        LocalTensor<float> offsetLocal = offsetQueue.AllocTensor<float>();
        LocalTensor<xDtype> inLocal = inQueue.DeQue<xDtype>();
        LocalTensor<float> tempFp32 = tempCastUb.Get<float>();
        LocalTensor<yDtype> outLocal = outQueue.AllocTensor<yDtype>();
        AscendC::LocalTensor<float> temp = fp32_buf_.Get<float>();
        LocalTensor<int32_t> tempInt32 = fp32_buf_.Get<int32_t>();
        auto tempHalf = temp.ReinterpretCast<half>();
        for (int32_t i = 0; i < multiRow; i++) {
            index = i * sizeHalfLen;
            // x fp16->fp32
            Cast(tempFp32, inLocal[index], RoundMode::CAST_NONE, tilingData_.rowLen);
            PipeBarrier<PIPE_V>();
            if (tilingData_.hasSmooth) {
                Mul(tempFp32, tempFp32, smoothLocal, tilingData_.rowLen);
                PipeBarrier<PIPE_V>();
            }
            ReduceMax(temp, tempFp32, temp, tilingData_.rowLen, false);
            PipeBarrier<PIPE_V>();
            max_value = temp.GetValue(0);
            ReduceMin(temp, tempFp32, temp, tilingData_.rowLen, false);
            PipeBarrier<PIPE_V>();
```

## ITEM 27

### item 26

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/dynamic_quant/op_kernel/dynamic_quant_single_row.h
hicann/ops-nn, last commit 2026-07-06 by yang-di52
The batched-rows variant: blkRows is derived from blockIdx_ (head vs tail core) so the ownership is again whole rows; ComputeReduceMax folds each row in place, then ONE WholeReduceMax(..., MASK_NUM_T32, ubRows, 1, 1, rowLen/MASK_NUM_T32*MASK_BLK_STRIDE, ReduceOrder::ORDER_ONLY_VALUE) produces all ubRows maxima at once; Brcb + strided Copy broadcast the reciprocal back across the row so the scaling is a Mul, not a Div.
```cpp
        }

        uint32_t blkRows = (blockIdx_ >= tilingD_->headCoreNum) ? tilingD_->rowPerTailCore : tilingD_->rowPerHeadCore;
        uint32_t loopCnt = (blkRows + tilingD_->multiRowNumHeadCore - 1) / tilingD_->multiRowNumHeadCore;
        uint32_t tailUbRows = blkRows - (loopCnt - 1) * tilingD_->multiRowNumHeadCore;

        DataCopyExtParams copyInParams{1, 1, 0, 0, 0};
        DataCopyPadExtParams<xDtype> padParams{false, 0, 0, 0};
        for (uint32_t idx = 0; idx < loopCnt; idx++) {
            uint32_t ubRows = (idx == loopCnt - 1) ? tailUbRows : tilingD_->multiRowNumHeadCore;
            uint32_t ubNums = ubRows * tilingD_->rowLen;

            LocalTensor<xDtype> inLocal = inQueue_.AllocTensor<xDtype>();
            copyInParams.blockLen = ubNums * sizeof(xDtype);
            DataCopyPad(inLocal[maxHandleNum_], inGm[idx * maxHandleNum_], copyInParams, padParams);

            inQueue_.EnQue(inLocal);
            inLocal = inQueue_.DeQue<xDtype>();
            LocalTensor<float> inLocalFp32 = inLocal.template ReinterpretCast<float>();

            Cast(inLocalFp32, inLocal[maxHandleNum_], RoundMode::CAST_NONE, ubNums);
            PipeBarrier<PIPE_V>();
            if (tilingD_->hasSmooth) {
                // [1, rowLen] -> [ubRows, rowLen]
                SetMaskCount();
                SetVectorMask<float, MaskMode::COUNTER>(tilingD_->rowLen);
                Copy<float, false>(inputCast, smoothLocalFp32, AscendC::MASK_PLACEHOLDER, ubRows,
                                   {1, 1, static_cast<uint16_t>(tilingD_->rowLen / BLOCK_ELEM_F32), 0});
                SetMaskNorm();
                ResetMask();
                PipeBarrier<PIPE_V>();
                Mul(inLocalFp32, inLocalFp32, inputCast, ubNums);
                PipeBarrier<PIPE_V>();
            }
            Abs(inputCast, inLocalFp32, ubNums);
            PipeBarrier<PIPE_V>();
            for (uint32_t i = 0; i < ubRows; ++i) {
                ComputeReduceMax(inputCast[i * tilingD_->rowLen], tilingD_->rowLen);
            }
            PipeBarrier<PIPE_V>();
            WholeReduceMax(inputCast, inputCast, MASK_NUM_T32, ubRows, 1, 1,
                           tilingD_->rowLen / MASK_NUM_T32 * MASK_BLK_STRIDE, ReduceOrder::ORDER_ONLY_VALUE);
            PipeBarrier<PIPE_V>();

            LocalTensor<yDtype> outLocal = outQueue_.AllocTensor<yDtype>();
            LocalTensor<float> outScaleLocal = outLocal[maxHandleNum_].template ReinterpretCast<float>();

            // max/127 = max*(1.0/127)
            Muls(outScaleLocal, inputCast, DYNAMIC_QUANT_FACTOR, ubRows);
            PipeBarrier<PIPE_V>();

            // 127/max
            Duplicate<float>(temp1, DYNAMIC_QUANT_MAX, ubRows);
            PipeBarrier<PIPE_V>();
            Div(temp1, temp1, inputCast, ubRows);
            PipeBarrier<PIPE_V>();

            // [ubRows] -> [ubRows, Block]
            int64_t blockCount = (ubRows + BLOCK_ELEM_F32 - 1) / BLOCK_ELEM_F32;
            Brcb(temp, temp1, blockCount, {1, MASK_BLK_STRIDE});
            PipeBarrier<PIPE_V>();
            // [ubRows, Block] -> [ubRows, tilingD_->rowLen]
            SetMaskCount();
            SetVectorMask<float, MaskMode::COUNTER>(tilingD_->rowLen);
            Copy<float, false>(inputCast, temp, AscendC::MASK_PLACEHOLDER, ubRows,
                               {1, 0, static_cast<uint16_t>(tilingD_->rowLen / BLOCK_ELEM_F32), 1});
            SetMaskNorm();
            ResetMask();
            PipeBarrier<PIPE_V>();
            // 改成乘法 Div(inputCast, inLocalFp32, inputCast, ubNums);
            Mul(inputCast, inLocalFp32, inputCast, ubNums);
            PipeBarrier<PIPE_V>();

            inQueue_.FreeTensor(inLocal);

            Cast(inputInt32, inputCast, RoundMode::CAST_RINT, ubNums);
            PipeBarrier<PIPE_V>();
            SetDeqScale(static_cast<half>(1.0));
            PipeBarrier<PIPE_V>();
            Cast(inputCast.ReinterpretCast<half>(), inputInt32, RoundMode::CAST_ROUND, ubNums);
            PipeBarrier<PIPE_V>();
            Cast(outLocal, inputCast.ReinterpretCast<half>(), RoundMode::CAST_TRUNC, ubNums);
            PipeBarrier<PIPE_V>();

            outQueue_.EnQue(outLocal);
            outLocal = outQueue_.DeQue<yDtype>();
            outScaleLocal = outLocal[maxHandleNum_].template ReinterpretCast<float>();

            DataCopyParams outScaleParams{1, static_cast<uint16_t>(ubRows * sizeof(float)), 0, 0};
            DataCopyPad(scaleGm[idx * tilingD_->multiRowNumHeadCore], outScaleLocal, outScaleParams);

            DataCopyParams copyOutParams{1, static_cast<uint16_t>(ubNums * sizeof(yDtype)), 0, 0};
```

## ITEM 28

### item 27

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/dynamic_quant/op_kernel/arch35/dynamic_quant_regbase_pertoken_large_multicore.h
hicann/ops-nn, last commit 2026-08-18 by cann-robot
The ONE DynamicQuant template that cannot avoid the grid barrier, and exactly how it pays for it. coreNumPerToken cores share one token: tokenIdx = blockIdx/coreNumPerToken, coreLocalIdx = blockIdx%coreNumPerToken. ProcessScale() = ProcessScaleRow() (partial max over this core's element slice, CopyUB2Workspace writes ONE float to workspaceTmp1[tokenIdx*coreNumPerToken + coreLocalIdx]) -> SyncAll() -> ProcessScaleCol() (every core re-reads the coreNumPerToken partials for its own token and max-reduces them). Then ProcessY() re-reads x a second time to apply the scale, and only coreLocalIdx==0 writes scaleGm[tokenIdx]. Note Duplicate(..., MIN_FLOAT_VALUE / MAX_FLOAT_VALUE, 64, ...) as the identity for the max/min partials.
```cpp
template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::Init(
    GM_ADDR x, GM_ADDR smooth_scales, GM_ADDR y, GM_ADDR scale, GM_ADDR offset, GM_ADDR workSpace,
    const DynamicQuantTilingDataArch35& tilingData)
{
    DynamicQuantNDOpt::SetFloatOverflowModeForRegbase<yDtype>();
    blockIdx = GetBlockIdx();

    ParseTilingData(tilingData);
    coreNumPerToken = tilingData_.headCoreNum;

    totalTokenNum = tilingData_.coreNum / coreNumPerToken;
    tokenIdx = blockIdx / coreNumPerToken;
    coreLocalIdx = blockIdx % coreNumPerToken;
    headSlices = tilingData_.multiRowNumHeadCore;

    elePerHeadCore = tilingData_.rowPerHeadCore;
    elePerTailCore = tilingData_.rowPerTailCore;
    eleCount = (coreLocalIdx < headSlices) ? elePerHeadCore : elePerTailCore;

    if (coreLocalIdx < headSlices) {
        coreStartOffset = static_cast<int64_t>(coreLocalIdx) * static_cast<int64_t>(elePerHeadCore);
    } else {
        coreStartOffset = static_cast<int64_t>(headSlices) * static_cast<int64_t>(elePerHeadCore) +
                          static_cast<int64_t>(coreLocalIdx - headSlices) * static_cast<int64_t>(elePerTailCore);
    }

    innerLoopCnt = (eleCount + tilingData_.innerLoopEle - 1) / tilingData_.innerLoopEle;
    innerLoopRem = (eleCount % tilingData_.innerLoopEle == 0) ? tilingData_.innerLoopEle :
                                                                eleCount % tilingData_.innerLoopEle;
    innerLoopFull = (eleCount == innerLoopRem) ? 0 : (eleCount - innerLoopRem) / tilingData_.innerLoopEle;

    uint32_t sizeTailLen = (innerLoopRem + FIFTEEN) / SIXTEEN * SIXTEEN;
    rightPadding = sizeTailLen - innerLoopRem;


/* ... */

    outGm.SetGlobalBuffer((__gm__ yCopyDtype*)y, outLenHead);
    scaleGm.SetGlobalBuffer((__gm__ float*)scale, totalTokenNum);

    if constexpr (isSymmetrical == false) {
        workspaceTmp1.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace), tilingData_.coreNum);
        workspaceTmp2.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace + tilingData_.coreNum * sizeof(float)),
                                      tilingData_.coreNum);
    } else {
        workspaceTmp1.SetGlobalBuffer(reinterpret_cast<__gm__ float*>(workSpace), tilingData_.coreNum);
    }

    if constexpr (hasSmooth == 1) {
        smoothGm.SetGlobalBuffer((__gm__ T*)smooth_scales);

/* ... */


template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::Process()
{
    if (blockIdx >= tilingData_.coreNum) {
        return;
    }
    ProcessScale();
    ProcessY();
}

template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::ProcessScale()
{
    ProcessScaleRow();
    SyncAll();
    ProcessScaleCol();
}

template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::ProcessY()
{
    LocalTensor<float> scaleOutLocal = scaleOutQueue.DeQue<float>();
    __ubuf__ float* scaleOutLocalAddr = (__ubuf__ float*)scaleOutLocal.GetPhyAddr();

    LocalTensor<float> offsetLocal;
    __ubuf__ float* offsetLocalAddr;

    if constexpr (isSymmetrical == false) {
        offsetLocal = offsetQueue.DeQue<float>();
        offsetLocalAddr = (__ubuf__ float*)offsetLocal.GetPhyAddr();
    }

    ProcessYRow(0, 0, scaleOutLocalAddr, offsetLocalAddr);

    if (coreLocalIdx == 0) {
        DataCopyParams copyParams{1, (uint16_t)(sizeof(float)), 0, 0};
        DataCopyPad(scaleGm[tokenIdx], scaleOutLocal, copyParams);
        if constexpr (isSymmetrical == false) {
            DataCopyPad(offsetGm[tokenIdx], offsetLocal, copyParams);
        }
    }
    scaleOutQueue.FreeTensor(scaleOutLocal);
    if constexpr (isSymmetrical == false) {
        offsetQueue.FreeTensor(offsetLocal);
    }
}


/* ... */

__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::ProcessScaleRow()
{
    LocalTensor<float> MaxToWorkSpaceLocal;
    LocalTensor<float> MinToWorkSpaceLocal;
    LocalTensor<float> scaleToWorkSpaceLocal;

    if constexpr (isSymmetrical == false) {
        MaxToWorkSpaceLocal = MaxToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(MaxToWorkSpaceLocal, MIN_FLOAT_VALUE, 64, 1, 1, 8);
        MaxToWorkSpaceQueue.EnQue(MaxToWorkSpaceLocal);

        MinToWorkSpaceLocal = MinToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(MinToWorkSpaceLocal, MAX_FLOAT_VALUE, 64, 1, 1, 8);
        MinToWorkSpaceQueue.EnQue(MinToWorkSpaceLocal);
    } else {
        scaleToWorkSpaceLocal = scaleToWorkSpaceQueue.AllocTensor<float>();
        AscendC::Duplicate(scaleToWorkSpaceLocal, (float)0.0, 64, 1, 1, 8);
        scaleToWorkSpaceQueue.EnQue(scaleToWorkSpaceLocal);
    }

    ProcessScaleRowLoop(0, 0);

    CopyUB2Workspace(1);
}

/* ... */

template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::CopyInScaleByEle(
    int64_t offset, uint32_t elementNum)
{
    DataCopyParams copyParams{1, (uint16_t)(elementNum * sizeof(float)), 0, 0};
    if constexpr (isSymmetrical == false) {
        LocalTensor<float> MaxFromWorkSpaceLocal = MaxFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(MaxFromWorkSpaceLocal, workspaceTmp1[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        MaxFromWorkSpaceQueue.EnQue(MaxFromWorkSpaceLocal);

        LocalTensor<float> MinFromWorkSpaceLocal = MinFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(MinFromWorkSpaceLocal, workspaceTmp2[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        MinFromWorkSpaceQueue.EnQue(MinFromWorkSpaceLocal);
    } else {
        LocalTensor<float> scaleFromWorkSpaceLocal = scaleFromWorkSpaceQueue.AllocTensor<float>();
        DataCopyPad(scaleFromWorkSpaceLocal, workspaceTmp1[offset], {1, (uint16_t)(elementNum * sizeof(float)), 0, 0},
                    {false, 0, 0, 0});
        scaleFromWorkSpaceQueue.EnQue(scaleFromWorkSpaceLocal);
    }
}

template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
__aicore__ inline void DynamicQuantPertenLargeMulticore<T, yDtype, hasSmooth, isSymmetrical>::CopyUB2Workspace(
    int64_t size)
{
    if constexpr (isSymmetrical == false) {
        auto tmp1 = MaxToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp1[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp1, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        MaxToWorkSpaceQueue.FreeTensor(tmp1);

        auto tmp2 = MinToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp2[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp2, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        MinToWorkSpaceQueue.FreeTensor(tmp2);
    } else {
        auto tmp = scaleToWorkSpaceQueue.DeQue<float>();
        DataCopyPad(workspaceTmp1[static_cast<int64_t>(tokenIdx) * static_cast<int64_t>(coreNumPerToken) +
                                  static_cast<int64_t>(coreLocalIdx)],
                    tmp, {1, (uint16_t)(size * sizeof(float)), 0, 0});
        scaleToWorkSpaceQueue.FreeTensor(tmp);
    }
}

template <typename T, typename yDtype, int64_t hasSmooth, bool isSymmetrical>
```

## ITEM 29

### item 28

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/grouped_quant_max/op_kernel/grouped_quant_max.cpp
hicann/ops-nn, last commit 2026-07-06 by yang-di52
GroupedQuantMax entry point: the whole grid-wide amax reduction is three statements — op.Process(); SyncAll(); op.MergeAmax(); — under KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIV_1_0), which is the kernel type the SyncAll hard-sync constraint demands for a pure-Vector operator.
```cpp
#include "arch35/grouped_quant_max_regbase.h"
#include "arch35/grouped_quant_max_tiling_data.h"
#include "arch35/grouped_quant_max_struct.h"

#define FLOAT_OVERFLOW_MODE_CTRL 60

using namespace AscendC;
using namespace GroupedQuantMax;

template <uint64_t RoundMode>
__global__ __aicore__ void grouped_quant_max(GM_ADDR x, GM_ADDR scale, GM_ADDR groupList, GM_ADDR y, GM_ADDR amax,
                                             GM_ADDR workspace, GM_ADDR tiling)
{
    int64_t oriOverflowMode = GetCtrlSpr<FLOAT_OVERFLOW_MODE_CTRL, FLOAT_OVERFLOW_MODE_CTRL>();
    REGISTER_TILING_DEFAULT(GroupedQuantMaxTilingData);
    GET_TILING_DATA_WITH_STRUCT(GroupedQuantMaxTilingData, tilingData, tiling);
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIV_1_0);
    GroupedQuantMaxRegbase<DTYPE_X, DTYPE_Y, RoundMode> op(&tilingData);
    GM_ADDR usrWorkspace = GetUserWorkspace(workspace);
    op.Init(x, scale, groupList, y, amax, usrWorkspace);
    op.Process();
    SyncAll();
    op.MergeAmax();
    SetCtrlSpr<FLOAT_OVERFLOW_MODE_CTRL, FLOAT_OVERFLOW_MODE_CTRL>(oriOverflowMode);
}
```

## ITEM 30

### item 29

https://raw.githubusercontent.com/hicann/ops-nn/master/quant/grouped_quant_max/op_kernel/arch35/grouped_quant_max_regbase.h
hicann/ops-nn, last commit 2026-07-06 by yin-peng
The matching two-stage reduction body. Stage 1 (inside Process): Reg::Reduce<ReduceType::MAX> folds a tile and StoreAlign<DIST_FIRST_ELEMENT_B32> writes one float per group into the core's own slice of coreGroupMaxGm_. Stage 2 (MergeAmax, after SyncAll): `if (coreIdx_ >= 1) return;` — core 0 alone DataCopyPads the whole [totalCoreNum_, numGroups_] partial matrix in and loops j over actualCoreNum_ with Reg::Max<float, MaskMergeMode::ZEROING> to get the final amax. Partials are seeded with Duplicate(vregFloatMax, 0.0f).
```cpp
        }

        AscendC::Reg::Reduce<Reg::ReduceType::MAX>(vregTileMaxFp32, vregTileMaxFp32, maskAll);
        AscendC::Reg::StoreAlign<float, Reg::StoreDist::DIST_FIRST_ELEMENT_B32>(
            ((__local_mem__ float*)maxAddr + groupIndex), vregTileMaxFp32, maskOne);
    }

/* ... */

__aicore__ inline void GroupedQuantMaxRegbase<T, U, RoundMode>::MergeAmax()
{
    if (coreIdx_ >= 1) {
        return;
    }

    LocalTensor<float> groupMaxLocal = inQueueGroupMax_.AllocTensor<float>();
    LocalTensor<T> amaxLocal = outQueueAmax_.AllocTensor<T>();

    uint8_t padNum = (numGroups_ % FLOAT_ALIGN_ELEM == 0) ? 0 : FLOAT_ALIGN_ELEM - (numGroups_ % FLOAT_ALIGN_ELEM);
    DataCopyExtParams copyParams{static_cast<uint16_t>(totalCoreNum_),
                                 static_cast<uint32_t>(numGroups_ * sizeof(float)), 0, 0, 0};
    DataCopyPad(groupMaxLocal, coreGroupMaxGm_, copyParams, {true, 0, padNum, 0});

    inQueueGroupMax_.EnQue(groupMaxLocal);
    groupMaxLocal = inQueueGroupMax_.DeQue<float>();

    __local_mem__ float* groupMaxLocalAddr = (__local_mem__ float*)groupMaxLocal.GetPhyAddr();
    __local_mem__ T* amaxLocalAddr = (__local_mem__ T*)amaxLocal.GetPhyAddr();

    __VEC_SCOPE__
    {
        AscendC::Reg::RegTensor<float> vregFloatMax;
        AscendC::Reg::RegTensor<float> vregFloatTmp;
        AscendC::Reg::RegTensor<T> vregFloatOutAmax;

        AscendC::Reg::MaskReg mask = AscendC::Reg::CreateMask<float>();
        AscendC::Reg::MaskReg maskU8 = AscendC::Reg::CreateMask<uint8_t>();

        uint32_t count = numGroups_;
        uint16_t vfLoopNum = (numGroups_ + ALIGN_64 - 1) / ALIGN_64;
        uint32_t numGroupsAlign32_ = (numGroups_ + FLOAT_ALIGN_ELEM - 1) / FLOAT_ALIGN_ELEM * FLOAT_ALIGN_ELEM;
        uint16_t totalCoreNumLoop_ = static_cast<uint16_t>(actualCoreNum_);

        for (uint16_t i = 0; i < vfLoopNum; ++i) {
            mask = AscendC::Reg::UpdateMask<float>(count);
            AscendC::Reg::Duplicate<float>(vregFloatMax, 0.0f, mask);
            for (uint16_t j = 0; j < totalCoreNumLoop_; ++j) {
                AscendC::Reg::LoadAlign<float, AscendC::Reg::LoadDist::DIST_NORM>(
                    vregFloatTmp, groupMaxLocalAddr + i * VL_ + j * numGroupsAlign32_);
                AscendC::Reg::Max<float, AscendC::Reg::MaskMergeMode::ZEROING>(vregFloatMax, vregFloatMax, vregFloatTmp,
                                                                               mask);
            }

            if constexpr (IsSameType<T, half>::value || IsSameType<T, bfloat16_t>::value) {
                AscendC::Reg::Cast<T, float, GroupedQuantMaxBase<T, U, RoundMode>::CAST_TRAIT_FP32_TO_X_DETYPE>(
                    vregFloatOutAmax, vregFloatMax, maskU8);
                AscendC::Reg::StoreAlign<T, Reg::StoreDist::DIST_PACK_B32>(amaxLocalAddr + i * VL_, vregFloatOutAmax,
                                                                           mask);
            } else if constexpr (IsSameType<T, float>::value) {
                AscendC::Reg::StoreAlign<T>(amaxLocalAddr + i * VL_, vregFloatMax, mask);
            }
        }
    }
    outQueueAmax_.EnQue(amaxLocal);
    amaxLocal = outQueueAmax_.DeQue<T>();

    DataCopyExtParams copyParamsOut{1, static_cast<uint32_t>(numGroups_ * sizeof(T)), 0, 0, 0};
    DataCopyPad(amaxGm_, amaxLocal, copyParamsOut);

    inQueueGroupMax_.FreeTensor(groupMaxLocal);
    outQueueAmax_.FreeTensor(amaxLocal);
}
```

## ITEM 31

### item 30

https://raw.githubusercontent.com/hicann/ops-nn/master/norm/lp_norm_reduce/op_kernel/arch35/lp_norm_reduce_tiling_key.h
hicann/ops-nn, last commit 2026-10-10 by tangweiwei2
How the SyncAll kernel-type constraint is expressed in a real tiling key: the group template (tilingKey=1, the A x R 2D-split branch that writes partials to workspace and then SyncAlls) is declared ASCENDC_TPL_MIX_AIV_1_0 'to guarantee the participating cores are co-resident', while the base/empty branches with no cross-core dependency stay ASCENDC_TPL_AIV_ONLY.
```cpp
// =============================================================================
// LpNormReduce_package/op_kernel/arch35/lp_norm_reduce_tiling_key.h
// =============================================================================
//
// ROLE: LpNormReduce TPL（模板化 TilingKey）声明 —— reduction 范式双 bool 轴。
//   据 docs/LpNormReduce/design/TilingKey.md §1：
//   - 声明序 isGroup 占 bit0、isEmptyTensor 占 bit1（BOOL 各 1 bit）；
//   - GET_TPL_TILING_KEY 实际位编码：base=0、group=1、empty=2；
//   - (isGroup=1, isEmptyTensor=1) 互斥不实例化（tilingKey=3 为设计性空位）；
//   - dtype 不进 key（框架按输入名 x 以 DTYPE_X 编译期实例化 fp16/fp32/bf16 三档）、
//     p / axisNum / keepdim / epsilon 等纯参数差异不拆 key。
//   模板参数与 op_kernel/lp_norm_reduce.cpp 的 kernel 入口签名
//   template <bool isGroup, bool isEmptyTensor> 一一对应、顺序一致。
//
// =============================================================================

#ifndef LP_NORM_REDUCE_TILING_KEY_H_
#define LP_NORM_REDUCE_TILING_KEY_H_

#include "ascendc/host_api/tiling/template_argument.h" // ASCENDC_TPL macros

// ---------------------------------------------------------------------------
// ASCENDC_TPL_ARGS_DECL — 声明编译期模板参数（host 侧供 GET_TPL_TILING_KEY 编码，
// kernel 侧经 ASCENDC_TPL_PRE 预处理导出 @@ 标记供 codegen 实例化）
// ---------------------------------------------------------------------------
ASCENDC_TPL_ARGS_DECL(LpNormReduce, ASCENDC_TPL_BOOL_DECL(isGroup, 0, 1), // 0=base/empty, 1=group（A×R 2D 分核）
                      ASCENDC_TPL_BOOL_DECL(isEmptyTensor, 0, 1) // 0=非空, 1=空 tensor（EMPTY_A/EMPTY_R 共用）
);

// ---------------------------------------------------------------------------
// ASCENDC_TPL_SEL — 实例化组合表（3 组合 × 2 档 dtype = 6 份 binary，见 TilingKey.md）
// SEL 块顺序（base→empty→group）只影响 codegen 实例化遍历顺序，runtime 永远按
// tilingKey 位编码值直接选符号。
//
// 每条 SEL 携带 ASCENDC_TPL_KERNEL_TYPE_SEL（kernel 任务类型，atvoss reduce 框架
// reduce_tiling_key_decl.h 同款机制）：group（tilingKey=1）为 SyncAll 硬同步分支，
// 须 MIX_AIV_1_0（纯 AIV 计算、1:0 任务比——保证 SyncAll 参与核同时驻留，
// bn3d_training_reduce split-reduce / reduce_mean_variance / atvoss reduce
// *_GROUP SEL 同款）；base / empty 无核间依赖保持 AIV_ONLY。
// ---------------------------------------------------------------------------
ASCENDC_TPL_SEL(
    // tilingKey=0：base（isGroup=0, isEmptyTensor=0）
    ASCENDC_TPL_ARGS_SEL(ASCENDC_TPL_KERNEL_TYPE_SEL(ASCENDC_TPL_AIV_ONLY), ASCENDC_TPL_BOOL_SEL(isGroup, 0),
                         ASCENDC_TPL_BOOL_SEL(isEmptyTensor, 0)),
    // tilingKey=2：empty（isGroup=0, isEmptyTensor=1；EMPTY_A/EMPTY_R 共用同一 binary）
    ASCENDC_TPL_ARGS_SEL(ASCENDC_TPL_KERNEL_TYPE_SEL(ASCENDC_TPL_AIV_ONLY), ASCENDC_TPL_BOOL_SEL(isGroup, 0),
                         ASCENDC_TPL_BOOL_SEL(isEmptyTensor, 1)),
    // tilingKey=1：group（isGroup=1, isEmptyTensor=0）——SyncAll 硬同步 → MIX_AIV_1_0
    // （isGroup=1 与 isEmptyTensor=1 互斥：(1,1) 无 SEL 块，tilingKey=3 为设计性空位）
    ASCENDC_TPL_ARGS_SEL(ASCENDC_TPL_KERNEL_TYPE_SEL(ASCENDC_TPL_MIX_AIV_1_0), ASCENDC_TPL_BOOL_SEL(isGroup, 1),
                         ASCENDC_TPL_BOOL_SEL(isEmptyTensor, 0)));

#endif // LP_NORM_REDUCE_TILING_KEY_H_
```

## ITEM 32

### item 31

https://raw.githubusercontent.com/hicann/ops-nn/master/norm/l2_normalize/op_kernel/l2_normalize.cpp
hicann/ops-nn, last commit 2026-09-23 by raoliang_sac
The same partial-write / SyncAll / second-reduce shape stated as a design contract in the kernel header comment, including the explicit note that phase 3 reuses the phase-2 slot so NO second SyncAll is needed, and that SetScheduleMode(1) is the required companion.
```cpp
//
// ROLE: Ascend C kernel entry point for L2Normalize (Ascend 950 / arch35 only).
//   核函数签名：
//     template <bool isGroup, bool isEmptyTensor>
//     __global__ __aicore__ void l2_normalize(GM_ADDR x, GM_ADDR y, GM_ADDR workspace, GM_ADDR tiling);
//   - 形参顺序 = 算子原型 tensor 定义顺序（x, y）+ 末尾固定 workspace + tiling；
//     axis / eps 均为 attr，非 tensor 输入，无对应 GM 形参。
//   - 模板参数为 TilingKey 双 bool 轴（isGroup / isEmptyTensor）；
//     dtype 走编译期 DTYPE_X 实例化（每 dtype 组合一个 binary），不走 TilingKey 运行时分支。
//   - base 模板处理通用非空输入；empty 模板对空 tensor 全核早退；group 模板以
//     A×R 二维分核执行三阶段计算：partial 写 workspace → SyncAll → RA 二次归约
//     得 denom → keepdims 广播除法。
// =============================================================================

#include "kernel_operator.h"                   // Ascend C kernel framework (AscendC:: namespace)
#include "arch35/l2_normalize_tiling_struct.h" // L2NormalizeTilingData / L2NormalizeEmptyTilingData
#include "arch35/l2_normalize_struct.h"        // TPL 声明（isGroup / isEmptyTensor 双 bool 轴）
#include "arch35/l2_normalize_base.h"          // Base 模板 kernel 类（TPL_SEL_0）
#include "arch35/l2_normalize_empty.h"         // Empty 模板 kernel 类（TPL_SEL_1）
#include "arch35/l2_normalize_group.h"         // Group 模板 kernel 类（TPL_SEL_2）

// ===========================================================================
// __global__ __aicore__ void l2_normalize(x, y, workspace, tiling)
//
// This is the main NPU kernel function. Each AIV core executes this once.
//
// Template parameters (TilingKey 双 bool 轴):
//   isGroup       — group 模板（A 用不满核且 R 有并行度 → A×R 2D 分核 + workspace 二次归约）
//   isEmptyTensor — 空 tensor 模板（某维为 0 → 全核早退，零计算零 IO）
//
// Parameters (all GM_ADDR = global memory pointers on device):
//   x         — input data tensor
//   y         — output tensor（shape/dtype 与 x 一致）
//   workspace — workspace buffer（base R 切分两遍 denom 中转 / group 二次归约用）
//   tiling    — tiling data buffer（empty → L2NormalizeEmptyTilingData；其余 → L2NormalizeTilingData）
// ===========================================================================
template <bool isGroup, bool isEmptyTensor>
__global__ __aicore__ void l2_normalize(GM_ADDR x, GM_ADDR y, GM_ADDR workspace, GM_ADDR tiling)
{
    // REGISTER_NONE_TILING: Registers the kernel with the AICore runtime.
    // The tiling data is read manually via GET_TILING_DATA_WITH_STRUCT.
    REGISTER_NONE_TILING;

    // KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIV_ONLY):
    //   Sets this kernel to run on AIV (AI Vector) cores only.
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIV_ONLY);

    // TPipe 统一在入口申请，经 Init 指针传入各模板。
    AscendC::TPipe pipe;

    if constexpr (isEmptyTensor) {
        // 空 tensor 模板（TPL_SEL_1）：EMPTY_A / EMPTY_R 合一全核早退——
        // 零计算零 IO（不绑 x/y GM）、零 TBuf、零同步。
        GET_TILING_DATA_WITH_STRUCT(L2NormalizeEmptyTilingData, tilingData, tiling);
        NsL2Normalize::L2NormalizeEmptyKernel<DTYPE_X> op;
        op.Init(&tilingData, &pipe); // 仅缓存 TilingData/TPipe（零 IO：不传 GM 形参）
        op.Process();                // usedCoreNum=0 → 进入即 return（全核早退）
    } else if constexpr (isGroup) {
        // group 模板（TPL_SEL_2）：A×R 2D 分核三阶段——
        // Phase 1 各核 [1 A chunk × 1 段 R 分组] 局部平方和写 ws partial 区
        // [rGroupCnt, aTotal] → SyncAll 全核同步（SetScheduleMode(1) 配套）→
        // Phase 2 RA mini-kernel 二次归约 + eps 钳制 + sqrt 得 denom 写 ws
        // denom 区本核槽位 → Phase 3 keepdims 广播除法（A 切分沿用 Phase 2
        // 槽位自产自销，无第二次 SyncAll；tail-R / tail-A 运行时子路径）。
        GET_TILING_DATA_WITH_STRUCT(L2NormalizeTilingData, tilingData, tiling);
        NsL2Normalize::L2NormalizeGroupKernel<DTYPE_X> op;
        op.InitGroup(x, y, workspace, &tilingData, &pipe);
        op.ProcessGroup();
    } else {
        // base 模板（TPL_SEL_0）：非空输入兜底分支——A 方向分核、核间零依赖
        GET_TILING_DATA_WITH_STRUCT(L2NormalizeTilingData, tilingData, tiling);
        NsL2Normalize::L2NormalizeBaseKernel<DTYPE_X> op;
        op.Init(x, y, workspace, &tilingData, &pipe);
        op.Process();
    }
}
```

---

### TOPIC B — additional items (PTO ISA SYNCALL contract, flash-linear-attention-npu, tilelang-ascend)

### item 0

https://pto-isa.gitcode.com/docs/isa/SYNCALL/
cann/pto-isa (PTO Virtual ISA Architectural Manual), retrieved 2026-10-20; page date not stated. Markdown source: https://gitcode.com/cann/pto-isa/blob/master/docs/isa/SYNCALL.md
The ISA-level contract for SYNCALL, text-extracted verbatim. States the two orthogonal template axes (SyncCoreType x SyncAllMode), the soft-mode workspace being only ONE int32 counter that must be zeroed, usedCores inference and the rule that non-participating cores MUST NOT call it, and -- critically -- that SYNCALL guarantees arrival ONLY: it takes no WaitEvents, does not wait for a preceding TSTORE to land, and flushes no cache, so cross-core GM traffic around the barrier needs explicit dcci/dsb. Also: Hard AIC-only on A2/A3 cannot be built as pure dav-c220-cube (no FFTS context -> hang); build MIX dav-c220 instead.
```text
PTO Virtual ISA Architectural Manual
SYNCALL
SYNCALL
¶
Instruction Diagram
¶
No
SYNCALL.svg
is provided.
SYNCALL
is a
cross-core control-plane
primitive; it does not describe a data transform on a single Tile. Its meaning is "all participants rendezvous at this point before any may proceed".
flowchart TB
subgraph hard [Hard Mode / FFTS]
H1[Each participant reaches the call site] --> H2[ffts_cross_core_sync]
H2 --> H3[wait_flag_dev]
H3 --> H4[Barrier complete]
end
subgraph soft [Soft Mode / Shared GM Counter]
S1[Each core arrives: increment the shared counter] --> S2[Derive this round's release condition]
S2 --> S3[Wait until the counter meets that condition]
S3 --> S4[Barrier complete]
end
Summary
¶
SYNCALL
is a cross-core synchronization barrier. Its two template parameters are independent:
SyncCoreType
selects the participant set:
AIVOnly
(default),
AICOnly
,
Mix
(AIC+AIV).
SyncAllMode
selects the implementation path:
Hard
(FFTS hardware flags, workspace-free overload),
Soft
(shared GM atomic counter, workspace-bearing overload).
Mathematical Semantics
¶
Not applicable as an elementwise arithmetic operation.
SYNCALL
expresses a
barrier arrival
relation: once every core in the current participant set has executed this
SYNCALL
, any core may proceed. Hard and Soft have identical semantics and differ only in implementation path.
C++ Built-in Interface
¶
Public header
<pto/pto-inst.hpp>
; declarations live in
include/pto/common/pto_instr.hpp
:
// Hardware mode (all CoreType variants)
template <SyncCoreType CoreType = SyncCoreType::AIVOnly>
PTO_INST void SYNCALL();
// Software mode — shared GM atomic counter
template <SyncAllMode Mode, SyncCoreType CoreType = SyncCoreType::AIVOnly, typename GlobalData,
std::enable_if_t<is_global_data_v<GlobalData>, int> = 0>
PTO_INST void SYNCALL(GlobalData &gmWorkspace, int32_t usedCores = 0);
Parameters
¶
gmWorkspace
: a GM buffer used by Soft mode, of type
GlobalTensor<int32_t, pto::Shape<>, pto::Stride<>>
. The instruction uses only its
first int32
as the arrival counter shared by all participants, so one cache line is enough to allocate, and it
must be zeroed before first use
.
usedCores
: the number of cores participating in the barrier.
When 0, the instruction infers it: AIV-only and AIC-only take the core count of this launch; MIX takes all AIC cores plus their paired AIV cores.
When specified explicitly it
may be smaller than the launched core count
, letting only some cores synchronize; cores that do not participate
must not
call
SYNCALL
.
When
Mode
is
Hard
,
gmWorkspace
and
usedCores
are ignored and the behavior is identical to the argument-free
SYNCALL()
.
Constraints
¶
SYNCALL
guarantees barrier
arrival
and nothing else; ordering and visibility of business data are the caller's responsibility. It does not participate in PTO's automatic Event dependency scheduling (it accepts no
WaitEvents
and returns no
RecordEvent
), so it does not wait for preceding data instructions on the same core (e.g.
TSTORE
) to land. Neither hard nor soft mode
flushes the cache for business data
, so cross-core GM accesses around the barrier need explicit
dcci
/
dsb
.
Soft mode requires every participating core to enter the same barrier group
in the same order and the same number of times
. The instruction derives the current round from the arrival count, so a core that enters one time too many or too few falls out of step with the others and the barrier deadlocks.
The participant set is determined by how the kernel is compiled and launched, not by
SYNCALL
. The template parameters only declare
which kind of cores
to synchronize; how many cores actually come up and how AIC and AIV are paired depends on the compile arch and the launch method. If the two disagree, some core waits forever.
Hard AIC-only on A2/A3 cannot be compiled as a pure cube kernel: plain
dav-c220-cube
fails to establish the FFTS context that AIC-only hard sync needs, and hangs in practice. Compile it as MIX (
dav-c220
) instead, with the AIC side calling
SYNCALL<AICOnly>()
and the AIV side left empty. On A5,
dav-c310-cube
works.
When compiling a kernel by hand (not through chevron auto-split), the kernel meta must be declared explicitly, otherwise the runtime schedules the wrong core type and hard sync hangs for lack of an FFTS context. Declare it with the macros in
include/pto/common/kernel_meta.hpp
(
PTO_SYNCALL_AIV_KERNEL_META
/
PTO_SYNCALL_AIC_KERNEL_META
/
PTO_SYNCALL_MIX_AIC_KERNEL_META
); the macro argument must exactly match the
__global__
entry symbol. Currently only Hard AIV-only and Soft AIC-only on A2/A3 need a hand-written meta; the compiler generates it for all other cases.
In the auto build path (
__PTO_AUTO__
),
SYNCALL
is a no-op; real synchronization happens only in manual kernels.
In CPU_SIM, every
SYNCALL
overload is currently a compatibility no-op, including Soft mode. It does not synchronize
workers launched by
LaunchKernelMultiCore
.
Examples
¶
Hardware Mode
¶
#include <pto/pto-inst.hpp>
using namespace pto;
void example_hard_aiv() { SYNCALL(); }                        // all AIV cores
void example_hard_aic() { SYNCALL<SyncCoreType::AICOnly>(); } // all AIC cores
void example_hard_mix() { SYNCALL<SyncCoreType::Mix>(); }     // AIC + AIV
For compilation and launch requirements, see "Constraints".
Software Mode
¶
#include <pto/pto-inst.hpp>
using namespace pto;
// AIV-only: usedCores=0 falls back to get_block_num()
void example_soft_aiv(__gm__ int32_t *gmPtr) {
GlobalTensor<int32_t, pto::Shape<>, pto::Stride<>> gmWs(gmPtr);
SYNCALL<SyncAllMode::Soft, SyncCoreType::AIVOnly>(gmWs, 0);
}
// MIX: AIC and AIV participants arrive on the same counter
void example_soft_mix(__gm__ int32_t *gmPtr) {
GlobalTensor<int32_t, pto::Shape<>, pto::Stride<>> gmWs(gmPtr);
SYNCALL<SyncAllMode::Soft, SyncCoreType::Mix>(gmWs, 0);
}
// Partial participation: all cores are launched but only the first syncBlocks
// synchronize; the rest must not call SYNCALL.
void example_soft_partial(__gm__ int32_t *gmPtr, int32_t syncBlocks) {
if (static_cast<int32_t>(get_block_idx()) >= syncBlocks) {
return;
}
GlobalTensor<int32_t, pto::Shape<>, pto::Stride<>> gmWs(gmPtr);
SYNCALL<SyncAllMode::Soft, SyncCoreType::AIVOnly>(gmWs, syncBlocks);
}
```

## ITEM 34

### item 1

https://raw.githubusercontent.com/flashserve/flash-linear-attention-npu/main/fla/ops/ascendc/kda/chunk_kda_bwd_finalize/op_kernel/chunk_kda_bwd_finalize.cpp
flashserve/flash-linear-attention-npu, last commit 2026-10-19 by wuyushu
A hand-written MIX kernel that reduces per-core partials from workspace after a grid barrier, and picks SyncAll<true> over SyncAll<false> *specifically* to avoid the flagId collision documented in key_features.md: AIV-only SyncAll burns flag 14, which no earlier AIC->AIV handoff uses, while MIX SyncAll burns 12/13 and would consume unspent ZB_FREE credits. KERNEL_TYPE_MIX_AIC_1_2 is the declared kernel type.
```cpp

extern "C" __global__ __aicore__ void chunk_kda_bwd_finalize(
    GM_ADDR q, GM_ADDR k, GM_ADDR v, GM_ADDR gk,
    GM_ADDR rawG, GM_ADDR beta, GM_ADDR aLog, GM_ADDR dtBias,
    GM_ADDR akk, GM_ADDR vNew, GM_ADDR h, GM_ADDR dh,
    GM_ADDR dvScan, GM_ADDR dAqk, GM_ADDR dqRaw,
    GM_ADDR qRstd, GM_ADDR kRstd,
    GM_ADDR cuSeqlens, GM_ADDR chunkIndices,
    GM_ADDR dq, GM_ADDR dk, GM_ADDR dv, GM_ADDR dBeta,
    GM_ADDR dG, GM_ADDR dALog, GM_ADDR dDtBias,
    GM_ADDR workspace, GM_ADDR tiling)
{
    REGISTER_TILING_DEFAULT(KDA::ChunkKdaBwdFinalizeTilingData);
    GET_TILING_DATA_WITH_STRUCT(KDA::ChunkKdaBwdFinalizeTilingData, tilingData, tiling);
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);
    if (TILING_KEY_IS(1) || TILING_KEY_IS(2) ||
        TILING_KEY_IS(3) || TILING_KEY_IS(4)) {
        KERNEL_TASK_TYPE(1, KERNEL_TYPE_MIX_AIC_1_2);
        GM_ADDR userWorkspace = AscendC::GetUserWorkspace(workspace);
        KDA::ChunkKdaBwdFinalizeImpl(
            q, k, v, gk, beta, akk, vNew, h, dh, dvScan,
            dAqk, dqRaw, qRstd, dq, dv, kRstd, dk, dBeta,
            rawG, aLog, dtBias, dG,
            cuSeqlens, chunkIndices, userWorkspace, &tilingData);
        // Only AIVs produce the partials. AIV-only SyncAll uses flag 14,
        // which no earlier AIC->AIV handoff uses. MIX SyncAll uses 12/13
        // and would consume the final, unspent ZB_FREE credits instead.
        AscendC::SyncAll<true>();
        if ASCEND_IS_AIV {
            KDA::FinalizeStage12(userWorkspace, dALog, dDtBias, tilingData);
        }
    }
}

#endif
```

## ITEM 35

### item 2

https://raw.githubusercontent.com/flashserve/flash-linear-attention-npu/main/fla/ops/ascendc/kda/chunk_kda_bwd/op_kernel/chunk_kda_bwd_finalize.h
flashserve/flash-linear-attention-npu, last commit 2026-09-07 by weinachuan
Three SyncAll<false>() phase boundaries in one fused MIX kernel, every one of them placed OUTSIDE the `if (active)` guard so inactive cores still arrive. Each barrier carries its reason in-source: WY stores must land before Intra reads them back; Intra's half-row dg writes must finish before Gate remaps the work to whole heads; and the final barrier exists so a queued dg/dA/dbias store cannot leak into the next invocation's reuse of the same output allocation.
```cpp
            process.Process();
        }
    }

    // WY materializes the base gradients in GM and Intra immediately reads
    // them back for the local correction.  Complete every WY store before
    // remapping the same buffers to the Intra owner.
    AscendC::SyncAll<false>();


/* ... */

    }

    // Intra writes dg by half rows on both AIV sub-blocks, whereas Gate
    // remaps the work to complete heads and updates dg in place.  Finish the
    // whole Intra phase before any core starts the Gate read/scan/write phase.
    AscendC::SyncAll<false>();

    if ASCEND_IS_AIV {
        if (active) {
            AscendC::TPipe pipe;
            ChunkKdaBwdCGateProcess<SAFE_GATE, DTYPE_RAW_G> process(
                dg, rawG, aLog, dtBias, dA, dBias,
                cuSeqlens, chunkIndices);
            if (tiling->deferGatePost == 0) {
                process.Init(*tiling, &pipe);
                process.Process();
            }
        }
    }

    // Gate is the final phase of the fused MIX kernel.  Do not return while
    // either AIV sub-block still has a queued dg/dA/dbias store: a following
    // invocation can reuse the same output allocation and observe that late
    // write as a stale cross-shape generation.
    bool needsFinalSync =
        tiling->seqlen < static_cast<int32_t>(kA5SharedGateMinSeqlen);
#if defined(__CCE_AICORE__) && __CCE_AICORE__ == 310
    needsFinalSync = needsFinalSync ||
        (tiling->useGateInKernel != 0 &&
         !CanUseA5SharedGateAnchor(*tiling));
#endif
    if (needsFinalSync) {
        AscendC::SyncAll<false>();
    }
```

## ITEM 36

### item 3

https://raw.githubusercontent.com/tile-ai/tilelang-ascend/ascendc_pto/src/tl_templates/pto/common.h
tile-ai/tilelang-ascend, branch ascendc_pto, last commit 2026-09-02 by baixinran
A compiler backend's view: the three grid-barrier wrappers it emits (pto::SYNCALL<SyncCoreType::Mix / AICOnly / AIVOnly>) sitting right next to its atomic GM accumulate helpers (TSTORE with pto::AtomicType::AtomicAdd, from UB and from L0C). The AscendC path of the same backend emits `AscendC::SyncAll<false>` (src/target/codegen_ascend.cc).
```cpp
AICORE PTO_INLINE void atomic_add_ub_to_gm_dynamic(
    __gm__ T1 *handle,
    const pto::Shape<shape1, shape2, shape3, shape4, shape5> &shape,
    const pto::Stride<stride1, stride2, stride3, stride4, stride5> &stride,
    int32_t ub_shape_addr, int32_t ub_offset, int32_t valid_row,
    int32_t valid_col) {
  pto::Shape<shape1, shape2, shape3, pto::DYNAMIC, pto::DYNAMIC> dynamic_shape;
  dynamic_shape.shape[3] = valid_row;
  dynamic_shape.shape[4] = valid_col;
  pto::GlobalTensor<
      T1, pto::Shape<shape1, shape2, shape3, pto::DYNAMIC, pto::DYNAMIC>,
      pto::Stride<stride1, stride2, stride3, stride4, stride5>>
      global_tensor(handle, dynamic_shape, stride);
  constexpr uint8_t len = sizeof(T2);
  constexpr bool use_nd = (static_cast<uint64_t>(ub_shape2) * len) >= 32;

  if constexpr (use_nd) {
    TileUbDataND<T2, ub_shape1, ub_shape2, pto::DYNAMIC, pto::DYNAMIC> temp_ub(
        valid_row, valid_col);
    pto::TASSIGN(temp_ub, ub_shape_addr + ub_offset * len);
    pto::TSTORE<decltype(temp_ub), decltype(global_tensor),
                pto::AtomicType::AtomicAdd>(global_tensor, temp_ub);
  } else {
    TileUbDataDN<T2, ub_shape1, ub_shape2, pto::DYNAMIC, pto::DYNAMIC> temp_ub(
        valid_row, valid_col);
    pto::TASSIGN(temp_ub, ub_shape_addr + ub_offset * len);
    pto::TSTORE<decltype(temp_ub), decltype(global_tensor),
                pto::AtomicType::AtomicAdd>(global_tensor, temp_ub);
  }
}

template <typename T1, typename T2, int32_t shape1, int32_t shape2,
          int32_t shape3, int32_t shape4, int32_t shape5, int32_t stride1,
          int32_t stride2, int32_t stride3, int32_t stride4, int32_t stride5,
          uint32_t l0c_shape1, uint32_t l0c_shape2, bool enRelu = false>
AICORE PTO_INLINE void atomic_add_l0c_to_gm_dynamic(
    __gm__ T1 *handle,
    const pto::Shape<shape1, shape2, shape3, shape4, shape5> &shape,
    const pto::Stride<stride1, stride2, stride3, stride4, stride5> &stride,
    int32_t l0c_shape_addr, int32_t l0c_offset, int32_t valid_row,
    int32_t valid_col) {
  pto::Shape<shape1, shape2, shape3, pto::DYNAMIC, pto::DYNAMIC> dynamic_shape;
  dynamic_shape.shape[3] = valid_row;
  dynamic_shape.shape[4] = valid_col;
  pto::GlobalTensor<
      T1, pto::Shape<shape1, shape2, shape3, pto::DYNAMIC, pto::DYNAMIC>,
      pto::Stride<stride1, stride2, stride3, stride4, stride5>>
      global_tensor(handle, dynamic_shape, stride);
  constexpr uint8_t len = sizeof(T2);

  pto::TileAcc<T2, l0c_shape1, l0c_shape2, pto::DYNAMIC, pto::DYNAMIC> temp_l0c(
      valid_row, valid_col);
  pto::TASSIGN(temp_l0c, l0c_shape_addr + l0c_offset * len);

  constexpr auto reluMode =
      enRelu ? pto::ReluPreMode::NormalRelu : pto::ReluPreMode::NoRelu;
  pto::TSTORE<decltype(temp_l0c), decltype(global_tensor),
              pto::AtomicType::AtomicAdd, reluMode>(global_tensor, temp_l0c);
}

AICORE PTO_INLINE void sync_all() { pto::SYNCALL<pto::SyncCoreType::Mix>(); }

AICORE PTO_INLINE void sync_all_aic() {
  pto::SYNCALL<pto::SyncCoreType::AICOnly>();
}

AICORE PTO_INLINE void sync_all_aiv() {
  pto::SYNCALL<pto::SyncCoreType::AIVOnly>();
}
```

### TOPIC B — negative findings (sources checked that yielded nothing)
NOTHING: https://github.com/hicann/cann-ops-adv — repo does not exist on GitHub (404); so does github.com/Ascend/cann-ops-adv and github.com/hicann/ascendc-api-adv. The adv-API/ops-adv content now lives under hicann/asc-devkit (docs/zh/api/SIMD-API/adv_api/...) and hicann/ops-nn, both of which are quoted above.
NOTHING: https://github.com/Ascend/samples — `gh search code "SyncAll" --repo Ascend/samples` returns zero hits and the recursive tree has no sync_all/syncall path; the SyncAll sample moved into hicann/asc-devkit/examples (quoted above).
NOTHING: https://raw.gitcode.com/cann/ops-nn/raw/master/quant/dynamic_quant/op_kernel/dynamic_quant.h — gitcode raw refuses unregistered traffic with `429 ... Limited account:unregisteredUser`; the same files were taken from the hicann/ops-nn GitHub mirror instead.
NOTHING: https://github.com/hicann/ops-nn — no kernel in the tree builds a per-token quant row max with SetAtomicMax into GM. Every cross-core max in the repo is done as partials-in-workspace + SyncAll + a second reduce pass (ITEM 28, 30, 31). `gh search code "SetAtomicMax" --limit 30` finds the API only in asc-devkit headers/docs and in sgl-kernel-npu / unified-cache-management / AReno wrappers, never as a row-max reduction.
NOTHING: https://github.com/hicann/catlass — no dcci polling loop; catlass synchronises purely through CrossCoreSetFlag/CrossCoreWaitFlag (ITEM 21). Its tla_dsl subtree lowers flag barriers in MLIR, not in AscendC kernel source.


---

# Provenance / verification log

Items marked "verified first-hand" (A20, A21, B0a-B0d) and all of sections A1-A19 were fetched
directly, not via the delegated sweeps. In addition I independently re-fetched four claims that
the sweeps reported and that would change a design decision. All four matched byte-for-byte:

1. `hicann/asc-devkit` `include/basic_api/kernel_operator_block_sync_intf.h` — the arch gate on
   the `SyncAllConfig` overload. Confirmed: `__NPU_ARCH__` must be one of
   `3510, 5102, 5162, 9201, 9202`; `2201` is not in that set.
   (quoted verbatim in B0a)

2. `hicann/asc-devkit` `impl/basic_api/kernel_macros.h` — `2201` is a live arch id in the same
   tree, in the V200/V210 group. Confirmed. There is no `impl/basic_api/dav_2201/` directory;
   the directories present are exactly
   `dav_3510, dav_5161, dav_5162, dav_9201, dav_c100, dav_c220, dav_l300, dav_l311, dav_m200,
   dav_m300, dav_m310, dav_m510` (plus `reg_compute`, `utils`), so `2201` is served by `dav_c220`.
   `2201` otherwise appears only under `tests/api/c_api/npu_arch_2201/` and in
   `docs/.../deprecated_interface/*_arch_2201_deprecated.md`.
   (quoted verbatim in B0a)

3. `hicann/asc-devkit` `docs/zh/api/SIMD-API/basic_api/atomic_operations/SetAtomicMax_ISASI.md` —
   A3 支持, data path `UB/L0C Buffer/L1 Buffer->GM`, dtypes
   `int8_t、int16_t、half、bfloat16_t、int32_t、float`, does not auto-zero GM, and on
   `NPU架构版本2201` integer and `bfloat16_t` are non-saturating by default with saturation
   settable only via `npu-smi` at device level. Confirmed.
   (quoted verbatim in the TOPIC B official-docs section)

4. `Zhangyq-1999/shmem-doc` `_sources/api/atomic_api_sync_async_comparison.md.txt` — the MTE-backend
   AMO support matrix. Confirmed: on A2/A3 the only MTE-backend atomic is
   `aclshmemx_mte_atomic_add`; `atomic_fetch`, `atomic_set`, `atomic_swap`,
   `atomic_compare_swap`, `atomic_inc`, `atomic_fetch_inc`, `atomic_fetch_add` are all marked
   `950` only.
   (quoted verbatim in the TOPIC A, continued section)

Also independently fetched and converted to text (HTML→text, so the quoted blocks in the
visibility section are the agent's extraction; I confirmed the pages exist and carry the same
content):
- `https://asc.gitcode.com/guide/programming_guide/advanced_programming/memory_model/cache_coherence.html`
  (HTTP 200, 86 828 bytes) — names `NPU架构版本2201` in its opening sentence and gives the 2201
  cache-unit table: `L2 Cache` line 512 B / 192 MB; `AIC ICache` 128 B / 32 KB;
  `AIV ICache` 128 B / 16 KB; `AIC DCache` 64 B / 16 KB; `AIV DCache` 64 B / 32 KB.
- `https://asc.gitcode.com/guide/programming_guide/advanced_programming/memory_model/memory_consistency.html`
  (HTTP 200, 102 805 bytes).

Fetch-access notes for anyone re-running this:
- `raw.gitcode.com/<owner>/<repo>/raw/<branch>/<path>` works for `cann/shmem` but returns
  `429 ... Limited account:unregisteredUser` for `cann/ops-nn`, and
  `{"code":"CH.00402000","title":"Project not found"}` for `cann/ops-hccl` (no such repo) and
  `Ascend/ascend-transformer-boost`.
- `gitcode.com/<owner>/<repo>/raw/...` returns the JS shell, not the file.
- The GitHub mirrors used instead: `immengzi/shmem` and `Zhangyq-1999/shmem-doc` and
  `mkbk-with-circle/ascend_inc_dispatch_combine` for `cann/shmem`; `hicann/ops-nn`,
  `hicann/asc-devkit`, `hicann/catlass`, `hicann/cann-recipes-infer`, `hicann/cannbot-skills`
  are first-party GitHub orgs; `egretwAlker/cpl-ascend-transformer-boost` for ATB/LCCL.


---

## 37. The constraint that breaks a multi-block MIX brick: `CrossCoreSetFlag` is intra-core-group only, so the cube's tiling and the vector's tiling must be the *same* partition

### 37.1 The statement, from the team that shipped the first MIX operator into `cann/ops-transformer`

https://zhuanlan.zhihu.com/p/2000250579956540357
Title 「端到端打通transformer仓experimental路径首个开源MIX算子」. Authorship stated in the article itself,
verbatim: 「本文原创作者为**华为2012实验室中央媒体技术院 AI 加速团队**，文中的RoPE_Matrix算子由该团队自主开发，且作为
ops-transformer开源算子仓experimental路径首个贡献的融合算子成功落地。」 Contributors named via the issue tracker,
verbatim: 「我们专门以issue(`https://gitcode.com/cann/ops-transformer/issues`搜索作者xuyun15和jimmy_lin)的方式记录了
对应问题」. Retrieved 2026-10-20 (the page is 403 to a plain fetcher; read through a reader proxy).

The constraint, verbatim, embedded in their performance-optimisation section:

```
由于 `CrossCoreSetFlag`仅支持核内同步（比如说20个Cube和40个Vector，Cube0仅能和Vector0和Vector1同步），所以我们需要同步的将matmul的tiling修改为切S轴的方式。
```

Translated for the record: *because `CrossCoreSetFlag` only supports intra-core synchronisation (say 20 Cube and 40
Vector cores — Cube0 can only synchronise with Vector0 and Vector1), we had to correspondingly change the matmul's
tiling to split along the S axis.*

The worked example they give, verbatim — note how the cube's per-core work is deliberately made the union of exactly
the two AIVs it can signal:

```
以[B,N,S,D]=[1,24,28799,128]， Cube20核，Vector40核为例： 则我们可以将S=28799切分为40份： 720*39 + 719； 如此非尾块的Cube执行720*2， Vector执行720，尾块的Vector执行719， 尾块的Cube执行(720+719)。
```

The surrounding reasoning, verbatim — including the explicit statement of the 910-series CV data path:

```
实现流程设计：由于910系列 CV分离(Cube上的数据传入Vector必须经过L2或高带宽内存)的特性，我们分析发现matmul计算和Vector计算理论上都是memory bound， 所以我们决策采用先计算matmul后再计算Vector的方式完成编程。

参考样例的实现，我们使用`ASCEND_IS_AIC, ASCEND_IS_AIV`去区分Cube和Vector部分，按照官网说法，这个好处是Cube和Vector解耦，无需关心Cube和Vector数量问题(C/V=1/2)，再通过`CrossCoreSetFlag， CrossCoreWaitFlag`去控制C和V之间的通信关系。
```

and their kernel skeleton, verbatim — `flagId` 0x8, mode 0x2, bare wait, `KERNEL_TASK_TYPE_DEFAULT` declared at the
top of the kernel body:

```cpp
KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);  // dry kernel type: KERNEL_TYPE_MIX_xxx
TPipe tpipe;
TCubeTiling tilingLocal;
RopeMatrix::CopyTiling(&tilingLocal, tiling);
if ASCEND_IS_AIC {
    ...
    AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8); // set flag after matmul
}
if ASCEND_IS_AIV {
    AscendC::CrossCoreWaitFlag(0x8); // wait matmul outputs
    ...
}
```

The article also records the tiling bug that motivated the change, verbatim — useful as a worked example of reading
a MIX profile:

```
通过注释掉matmul组件代码，仅执行Vector的profiling，可发现 `Vector memory copy in`的开销比预期的要高1倍有余，通过对比我们的实现和原版的RoPE融合算子（`https://gitcode.com/cann/ops-transformer/blob/master/posembedding/rotary_position_embedding/rotate_half_bf16.h`），我们发现tiling的差异：由于x的维度`[B,N,S,D]`, sin/cos维度`[1,1,S,D]`，本方案第一个版本切核方式是BNS方向均分，导致sin和cos需重复拷贝，实际拷贝量不是`S*D`而是约等于x的`B*N*S*D`，因此Vector部分的`memory copy in`开销翻倍。
```

### 37.2 The shipped operator's own README

https://gitcode.com/cann/ops-transformer/blob/master/experimental/posembedding/rope_matrix/README.md
raw: https://raw.gitcode.com/cann/ops-transformer/raw/master/experimental/posembedding/rope_matrix/README.md
Repo `cann/ops-transformer`, branch `master`. Retrieved 2026-10-20. Verbatim:

```
Designing detail：
By profiling, we find memory bound for both C and V on 910B. Thus, no need CV pipeline, we just simplify run V after C.
Using ```AscendC::CrossCoreSetFlag``` and ```AscendC::CrossCoreWaitFlag``` to control pipeline.
```
```
we simplify the code from origin rope-fused operator to fit our cases.
Then use ```ASCEND_IS_AIC, ASCEND_IS_AIV``` to isolation cube/vector process and ```CrossCoreSetFlag, CrossCoreWaitFlag``` to control communication between cube and vector.
```
```bash
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);  // dry kernel type: KERNEL_TYPE_MIX_xxx
    TPipe tpipe;
    TCubeTiling tilingLocal;
    RopeMatrix::CopyTiling(&tilingLocal, tiling);
    if ASCEND_IS_AIC {
        ...
        AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8); // set flag after matmul
    }
    if ASCEND_IS_AIV {
        AscendC::CrossCoreWaitFlag(0x8); // wait matmul outputs
        ...
    }
```

Its directory layout, verbatim — the cube half is a separate header, which is the shape a per-layer kernel wants:

```bash
  ${op_class}                                          # class
  ├── ${op_name}                                       # name
  │   ├── inc                                          # define aRopeMatrixTiling like TCubeTiling, which can be call by both op_device and op_host
  │   │   └── ${op_name}_extern.h
  │   ├── op_host                                      # Tiling、InferShape(If needed, custom operator may not need)...
  │   │   └── ${op_name}_tiling.h                      # Tiling
  │   ├── op_kernel                                    # kernel
  │   │   ├── ${op_name}.h                             # fused vector part
  │   │   └── ${op_name}_cube.h                        # matrix part
  │   ├── tests                                        # tests
  │   │   └── test_rope.py                             # test file: contain how to gen the [d, d] rope-matrix,
  │   ├── CMakeLists.txt                               # makefile
  │   ├── torch_interface.cpp                          # for torch calling
  │   └── README.md                                    # readme
```

and its build flags, verbatim from the same article — the exact flag set for a MIX kernel on `dav-2201`:

```
8. **CMakeLists文件重写：** 请参考库上代码，COMPILE_FLAGS "--npu-arch=dav-2201 -xasc -ltiling_api -lplatform -lregister" 是为了MIX融合算子编译通过，如果Vector算子可参考ops-math仓的编译工程；
```

plus two engineering traps the same article records, verbatim:

```
4. **目录结构调整：** tiling和kernel实现都调整到h文件中，当前官网编译工程如果声明在h文件，实现在cpp文件中可以编译通过但是无法执行的；
```
```
7. **namespace显式调用:**由于kernel和host不同的namespace内有重名的结构，而新的编译方式不区分kernel和host侧，所以using namespace matmul_tiling; using namespace matmul; using namespace AscendC; 不能同时使用，否则会编译工程报错。 为此代码需要调整为显示的调用命名空间中类和结构，如：TPosition修改为matmul_tiling::TPosition；
```

## Relevance
This is the most likely cause of `mix_expert_kernel.cpp`'s non-determinism, and it is a design constraint rather
than a missing barrier. Stated as a rule: **under mode 2, AIC[i] can raise the flag only for AIV[2i] and AIV[2i+1].
A flag therefore says nothing about any tile produced by a different block's AIC.**
- Our brick launches `<<<blocks>>>` with blocks > 1 and the AIV half `DataCopy`s "slices of `partial`". If any AIV
  reads a slice its own AIC did not produce, no amount of `DataSyncBarrier` or `DataCacheCleanAndInvalid` will help:
  the flag it waited on was raised by the wrong producer. The signature of that failure is exactly what we measured —
  the slices your own AIC wrote are correct, the rest hold whatever has landed so far, and the count varies with
  scheduling: 0, 0, 416, 672, 896, 896 of 1024 across six runs of one binary, wrong values being 0 or 0x8000. It also
  explains why the full `partial` buffer downloaded after the kernel is always bit-correct: every AIC does finish, it
  just finishes after some AIV already read.
- The fix is structural and is the one the vendor team used: make the cube's per-core output tile the exact union of
  the two AIVs' input tiles, so the only data an AIV ever reads is data its own AIC wrote. Their arithmetic for
  `[B,N,S,D] = [1,24,28799,128]` on 20 Cube / 40 Vector cores is the template — split the consumer axis into
  `2 × cubeCores` parts, give each AIV one part and each AIC the two parts belonging to its pair, and absorb the
  ragged tail on both sides (tail AIV does 719, tail AIC does 720 + 719). For our W4A8 routed experts with
  `moe_intermediate` 128 per rank, the consumer axis is the N direction of the expert GEMM, and the partition must be
  `2 × blocks` wide, not `blocks` wide.
- Diagnostic, cheap and decisive: rerun the brick with `<<<1>>>`. If the error count goes to 0 of 1024 every time,
  this is the cause and §31's cache protocol is not needed. That also reconciles §32 — the vendor's
  `matmul_fused_manual` sample is correct with no cache maintenance at all precisely because it launches
  `numBlocks = 1`, so the intra-core-group constraint is trivially satisfied.
- 「由于910系列 CV分离(Cube上的数据传入Vector必须经过L2或高带宽内存)」 is independent third-party confirmation of
  README finding 3b and §35.4: on 910-series, cube→vector must pass through L2 or HBM. Their design conclusion —
  「matmul计算和Vector计算理论上都是memory bound， 所以我们决策采用先计算matmul后再计算Vector」 — is that at
  memory-bound shapes a CV *pipeline* is not worth building and plain sequencing is enough. Our decode families are
  memory-bound by the same test (GroupedMatmulSwigluQuantV2 6.793 ms spent against 2.272 ms of bytes;
  GroupedMatmul 5.596 against 1.212), which argues the per-layer kernel should sequence cube and vector rather than
  overlap them, and spend its effort on deleting the 505 MIX_AIC launches instead.
- `KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);` declared as the first statement of the kernel body is the
  form a shipping operator uses, and the build flags are
  `--npu-arch=dav-2201 -xasc -ltiling_api -lplatform -lregister`.
- The two engineering traps are worth encoding before the brick grows: a kernel declared in a `.h` with its
  implementation in a `.cpp` 「可以编译通过但是无法执行」, and `using namespace matmul_tiling;` together with
  `using namespace matmul;` and `using namespace AscendC;` collides, so names like `TPosition` must be qualified.


---

## 38. The authoritative `CrossCoreSetFlag` semantics (newer than §34/§31.7) — pairing arity, counter residue, the unsupported `PIPE_S` default, and why an unpaired wait alternates

Two pages, both newer and far more detailed than the CANN 8.0 copies in §31.7 and the architecture page in §34.
Retrieved 2026-10-20 from the static mirror described in §35.0. Where they disagree with §34, prefer these.

https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E5%90%8C%E6%AD%A5%E6%8E%A7%E5%88%B6/%E6%A0%B8%E9%97%B4%E5%90%8C%E6%AD%A5/CrossCoreSetFlag_ISASI.html
https://asc.gitcode.com/api/SIMD-API/%E5%9F%BA%E7%A1%80API/%E5%90%8C%E6%AD%A5%E6%8E%A7%E5%88%B6/%E6%A0%B8%E9%97%B4%E5%90%8C%E6%AD%A5/%E5%85%B3%E9%94%AE%E7%89%B9%E6%80%A7%E8%AF%B4%E6%98%8E.html
(the second is 「核间同步 / 关键特性说明」, which the first references as 「每个模式的具体执行逻辑与细节可以参考关键特性说明」)

### 38.1 What the flag actually is: a scheduling-module event, not a memory operation

Verbatim:

```
在核间同步场景中，CrossCoreSetFlag接口和CrossCoreWaitFlag接口配对工作，使用时需传入核间同步的标记ID（flagId），每个ID对应一个用于控制同步的计数器。
CrossCoreSetFlag：AI Core中的AIC/AIV在完成本核前置位的pipe流水任务后，调用该接口，向调度模块上报本核任务已完成。调度模块收集所有参与核的上报信息，作为全局完成标志。
CrossCoreWaitFlag：用于阻塞本核后续指令的下发（已下发指令可正常执行），直至调度模块确认所有应调用CrossCoreSetFlag的核均已上报完成，随即解除阻塞，允许该核继续下发指令。
```

and the constraint that follows from it, verbatim — **if the kernel type is AIC-only or AIV-only the scheduling
module is not even turned on**:

```
由于当Kernel类型为KERNEL_TYPE_AIC_ONLY或KERNEL_TYPE_AIV_ONLY时，硬件不会开启调度模块，也就无法正常进行核间同步，因此不同的同步模式配置Kernel类型或函数修饰符的情况如下： 在纯Vector/Cube场景下（模式0或模式1），建议设置Kernel类型为KERNEL_TYPE_MIX_AIV_1_0或KERNEL_TYPE_MIX_AIC_1_0，其它支持的Kernel类型请参考表3。
对于Vector和Cube混合场景（模式2和模式4），需根据AI Core中AIC和AIV的比例灵活配置Kernel类型，不同模式支持的函数修饰符和Kernel类型请参照表3。
表3 模式与支持的Kernel类型配置
模式
支持的函数修饰符
支持的Kernel类型配置
0
__mix__(0, 1)、__mix__(1, 0)、__mix__(1, 1)、__mix__(1, 2)
KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2
1
__mix__(1, 1)、__mix__(1, 2)
KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2
2
__mix__(1, 1)、__mix__(1, 2)
KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2
4
__mix__(1, 2)
KERNEL_TYPE_MIX_AIC_1_2
```

### 38.2 The pairing arity of mode 2 — one Set, **M** Waits, and each AIV has its own counter

This is the paragraph that matters most. Verbatim from 「关键特性说明」, 「单AI Core中AIC与AIV全核同步」:

```
单AI Core中AIC与AIV全核同步需要配套使用模式2的CrossCoreSetFlag和CrossCoreWaitFlag接口。该场景可细分为两类：
1个AI Core中的AIC执行CrossCoreSetFlag，对应的M个AIV都执行CrossCoreWaitFlag。
当AIC执行完CrossCoreSetFlag时，M个AIV对应flagId的计数器增加1。若AIV该flagId的计数器为非0，则解除AIV的阻塞，CrossCoreWaitFlag后的指令继续发射，该flagId的计数器减去1。
总计AIC 1次调用CrossCoreSetFlag，对应M个AIV各1次CrossCoreWaitFlag才算配对使用。
1个AI Core中的M个AIV都执行CrossCoreSetFlag，对应的AIC执行CrossCoreWaitFlag。
当M个AIV全都执行完CrossCoreSetFlag时，AIC对应flagId的计数器增加1。若AIC该flagId的计数器为非0，则解除AIC的阻塞，CrossCoreWaitFlag后的指令继续发射，该flagId的计数器减去1。
总计M个AIV各1次CrossCoreSetFlag，对应AIC 1次调用CrossCoreWaitFlag才算配对使用。
```

and the canonical code for mode 2, verbatim — note 「必须要所有AIV都执行」 and 「pipe要一致」:

```cpp
// AIC和AIV都应该有类似如下的成对调用CrossCoreSetFlag和CrossCoreWaitFlag
// modeId必须配置为2, pipe要一致，flagId要一致
if ASCEND_IS_AIV {
 AscendC::CrossCoreSetFlag<2, PIPE_MTE3>(0); // 待前置PIPE_MTE3流水任务完成后，通知调度模块。必须要所有AIV都执行。
}
if ASCEND_IS_AIC {
 AscendC::CrossCoreWaitFlag(0); // 直到该AI Core中的所有AIV都完成前置PIPE_MTE3流水，调度模块更新flagId=0的计数器后，AIC解除阻塞。
}
```

The per-core counter ownership, verbatim from the `CrossCoreSetFlag` page's 约束说明:

```
flagId相关的约束：
对于模式0、1、2，每个AIC和每个AIV都各自有16个flagId，支持的取值范围为0-15。如果flagId的值超出该范围，则会取截取最低位4bit为准。
每个flagId都对应一个计数器，当调用CrossCoreWaitFlag时，若计数器值为0则会阻塞后续指令下发，已下发指令可正常执行；当调度模块感知到所有参与同步的核（具体包含哪些核与设置的核间同步模式有关）完成（调用了CrossCoreSetFlag）同步后，会将与设置的flagId对应的计数器的值增加1。此时，计数器值为非0，阻塞解除，并且将对应计数器的值减去1进行还原。具体执行逻辑与细节可以参考关键特性说明。每一个计数器计数范围为0-15。如果调用CrossCoreWaitFlag的次数过多，计数器的值超出该范围，则会异常报错，中断流程。
```

and the explicit statement on unpaired use, verbatim:

```
用户需要确保配套使用CrossCoreSetFlag和CrossCoreWaitFlag，否则会出现未定义行为。
```
```
CrossCoreSetFlag和CrossCoreWaitFlag必须成对使用，否则可能导致算子超时问题。
```

### 38.3 `PIPE_S` and `PIPE_ALL` are **not supported** pipes for modes 0/1/2

Verbatim:

```
pipe
设置这条指令所在的流水类型。支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX，不支持PIPE_S和PIPE_ALL。不同产品对流水类型的支持情况请参见pipe支持的流水类型说明。
```
```
pipe支持的流水类型说明​
核间同步的模式为模式0、1、2时， 支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX。
不支持的流水类型为PIPE_ALL、PIPE_S。
针对Ascend 950PR/Ascend 950DT，核间同步的模式为模式4时， 支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX、PIPE_S。
不支持的流水类型为PIPE_ALL。
```
```
核间同步的模式为模式0、1、2时，模板参数pipe不支持设置为PIPE_ALL，PIPE_S。
```

Set against the declared default in the public header (§1):

```cpp
template <uint8_t modeId = 0, pipe_t pipe = PIPE_S>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId);
```

So on A3 the **default** `pipe` of `CrossCoreWaitFlag` is a value the same documentation set lists as unsupported for
every mode A3 has. Note that this page's own mode-0/1/2 examples nevertheless use the bare form, while its mode-4
example spells the pipe out (`CrossCoreWaitFlag<4, PIPE_FIX>(0)`), and §34 separately claims the `pipe` argument is
inert on 2201 — the documentation set is not self-consistent here. What **is** consistent and repeated three times is
「pipe要一致」, the pipe must match between the Set and the Wait.

### 38.4 flagId range is 0-15 on A3, not 0-10; mode 4 is confirmed absent

Verbatim:

```
flagId取值范围说明​
核间同步的模式为模式0、1、2时，支持的取值范围为0-15。
```
```
modeId支持的取值说明​
不同产品对同步模式的支持情况如下：
针对Ascend 950PR/Ascend 950DT，支持的同步模式为：模式0、模式1、模式2、模式4。
针对如下产品，支持的同步模式为：模式0、模式1、模式2。 Atlas A3 训练系列产品/Atlas A3 推理系列产品
Atlas A2 训练系列产品/Atlas A2 推理系列产品
```

and the occupancy list, verbatim:

```
以下接口内部实现中使用了CrossCoreSetFlag和CrossCoreWaitFlag会占用一部分flagId，开发者同时使用CrossCoreSetFlag/CrossCoreWaitFlag与以下接口时，需注意避免flagId使用冲突：
Matmul高阶API占用的flagId范围与定义的Matmul对象数目相关，假设定义了N个Matmul对象，Matmul高阶API内部占用的flagId范围为[0, 2 * N - 1]。Matmul最多支持定义4个对象，此时flagId占用范围为[0,7]。
SyncAll硬件同步接口占用的flagId情况请参考flagId占用情况。
```

### 38.5 Consecutive Sets from one core have no guaranteed order

Verbatim — this is new and matters for a multi-stage megakernel:

```
一个核连续发出的CrossCoreSetFlag，硬件不保证执行顺序。例如AIV依次发射CrossCoreSetFlag<0, PIPE_V>(0)，CrossCoreSetFlag<0, PIPE_V>(1)，实际的执行顺序可能是flagId=1的先执行。
```

### 38.6 Reusing one flagId across modes

Verbatim:

```
核间同步的模式为模式0、1、2时，同一个flagId用于不同核间同步模式的约束：
同一核上，若同一个flagId需用于不同核间同步模式，须在模式切换前完成前一个模式的所有同步操作——即确保该flagId关联的所有CrossCoreSetFlag与配套CrossCoreWaitFlag调用均已执行完毕。
对于不同的核，可以直接将同一flagId用于不同的核间同步模式，具体包括以下2种场景： 多个AI Core之间，使用flagId=0同步所有的AIC（模式0）；单个AI Core内，使用flagId=0同步所有AIV（模式1）。
单个AI Core内，使用flagId=0同步所有AIV（模式1）；另一个AI Core内，使用flagId=0同步AIC与所有AIV（模式2）。
```

### 38.7 Mode 0 and 4 for completeness

Mode 0, verbatim — note that the counter is raised on **every** participating core simultaneously:

```
N个AI Core中的N个AIC进行全核同步。
当N个AIC都执行完CrossCoreSetFlag时，每个AIC对应flagId的计数器增加1。若AIC该flagId的计数器为非0，被CrossCoreWaitFlag所阻塞的所有指令才会执行下去，该flagId的计数器减去1。
对于每个AIC，CrossCoreSetFlag和CrossCoreWaitFlag都必须配对使用。
```
```cpp
// 每个核都应该有类似如下的成对调用CrossCoreSetFlag和CrossCoreWaitFlag
// modeId必须配置为0, pipe要一致，flagId要一致
AscendC::CrossCoreSetFlag<0, PIPE_M>(0); // 待前置PIPE_M流水任务完成后，通知调度模块
AscendC::CrossCoreWaitFlag(0); // 直到所有AIC都完成前置PIPE_M流水，调度模块更新flagId=0的计数器后，解除阻塞。
```

Mode 4 (950 only), verbatim, for the port — note the flagId remapping that makes it a point-to-point channel:

```cpp
// AIC和AIV都应该有类似如下的成对调用CrossCoreSetFlag和CrossCoreWaitFlag 
// modeId必须配置为4，flagId要一致 
if ASCEND_IS_AIV { 
 if (blockIdx % 2 == 0) { 
 AscendC::CrossCoreSetFlag<4, PIPE_MTE3>(0); // 待AIV0上前置PIPE_MTE3流水任务完成后，通知调度器。对于flagId，AIV0上的0-15对应AIC上的0-15。 
 } 
 if (blockIdx % 2 == 1) { 
 AscendC::CrossCoreSetFlag<4, PIPE_MTE3>(0); // 待AIV1上前置PIPE_MTE3流水任务完成后，通知调度器。对于flagId，AIV1上的0-15对应AIC上的16-31。 
 } 
} 
if ASCEND_IS_AIC { 
 AscendC::CrossCoreWaitFlag<4, PIPE_FIX>(0); // 阻塞后续PIPE_FIX流水指令，直到该AI Core中的AIV0都完成前置PIPE_MTE3流水，调度器更新flagId=0的计数器后，AIC解除阻塞 
 ... 
 AscendC::CrossCoreWaitFlag<4, PIPE_FIX>(16); // 阻塞后续PIPE_FIX流水指令，直到该AI Core中的AIV1都完成前置PIPE_MTE3流水，调度器更新flagId=16的计数器后，AIC解除阻塞 
 ... 
}
```
```
flagId取值范围说明 ... 针对Ascend 950PR/Ascend 950DT，核间同步的模式为模式4时，支持的取值范围情况如下： AIV0发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-15的操作。
AIV1发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-31的操作。
AIC发起的flagId 0-15的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-15的操作。
AIC发起的flagId 16-31的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-31的操作。
```

## Relevance
This is the page that explains an alternating failure, and the mechanism is arithmetic, not a race.
- **Mode 2 AIC→AIV requires exactly M waits per set, and each AIV owns its own counter.** Verbatim:
  「当AIC执行完CrossCoreSetFlag时，M个AIV对应flagId的计数器增加1 ... 总计AIC 1次调用CrossCoreSetFlag，对应M个AIV各
  1次CrossCoreWaitFlag才算配对使用。」 Under `__mix__(1, 2)`, M = 2. One `CrossCoreSetFlag` from the AIC raises
  **both** AIVs' counters by 1. If only one AIV reaches its `CrossCoreWaitFlag` — because the vector half is guarded
  by `GetSubBlockIdx()`, because a `taskRation` skip (`if (vecCount % taskRation != subBlockIdx) continue;`, §15) or
  an early `return` jumps over it, or because the two AIVs take different branches — then the other AIV's counter is
  left at 1. Nothing in either page says the runtime zeroes these counters at kernel load, and unpaired use is
  explicitly 「会出现未定义行为」. A leftover 1 makes the **next** launch's wait on that counter return immediately,
  before the cube has written anything, which produces wrong data and consumes the residue — and then the launch
  after that is correct again. That is a period-two alternation across launches and, if the counter is device state
  rather than context state, across processes. It is the only mechanism found in any source that produces period two
  rather than a random rate.
  **Checks that distinguish it, cheapest first.** (a) Make the AIV-side `CrossCoreWaitFlag` unconditional and
  textually outside every branch, loop, skip and early return, so both subblocks execute it exactly once per set —
  then confirm the alternation disappears. (b) Count it: instrument both subblocks to write `GetSubBlockIdx()` to
  distinct GM slots immediately after the wait, and check both slots are written on every run. (c) If the brick's
  vector work is split between the two AIVs, note that the split must not gate the wait — split the *work*, never
  the *handshake*. (d) Run the same binary twice in one process: if run 1 is wrong and run 2 right within a single
  process, the residue is per-launch and a self-inflicted pairing bug; if the parity follows the process, it is
  device state and every protocol in this project needs an opening drain.
  **The documented discipline, since no reset API was found.** There is none. The sanctioned approach is exact
  pairing plus an explicit tail drain: §31.3's PPFM kernel ends each chain with
  `CrossCoreWaitFlag<...>(kFlagDhFree)` purely to 「把本链 dH 槽与 T2 槽的归还信用收干净」 — drain the leftover
  credits — and counts them 「每链 AIV prime 1 次、每 chunk set 1 次、这里 wait 1 次 ⇒ 逐链平衡」. Copy that
  bookkeeping: for every flagId, write down sets and waits per core and show they are equal.
- **`PIPE_S` is listed as an unsupported pipe for every mode A3 has, and it is the header default.** Our brick's
  `CrossCoreWaitFlag<0x02>(4)` takes `pipe = PIPE_S`. Combined with 「pipe要一致」 and with §31.3's measured
  observation that a `PIPE_S` wait on A2 lets the following MTE2 issue early and read 「半新半旧」 C, the conflict
  recorded in §34 now resolves in PPFM's favour: write the consumer as
  `CrossCoreWaitFlag<0x02, PIPE_MTE2>(flag)`. That is the pipe the consumer actually blocks (it is about to MTE2 the
  cube's result out of GM), it is a supported value, and it is what the one shipping A2/A3 kernel we have measured
  evidence for uses.
- **flagId on A3 is 0-15, not 0-10**, and each AIC and each AIV has its own 16. This supersedes README finding 3 and
  §20/§34. Out-of-range values are silently truncated to the low 4 bits — so a hand-rolled scheme that lets an id
  reach 16 aliases onto 0, which on A3 is inside `Matmul`'s `[0, 2N-1]`. With Matmul's N objects taking `[0, 2N-1]`
  and `SyncAll` taking 11/12/13/14 (§35.5), one Matmul object leaves 2-10 and 15 free.
- **Consecutive Sets from one core are unordered**: 「一个核连续发出的CrossCoreSetFlag，硬件不保证执行顺序」, with
  the vendor's own example of `(0)` then `(1)` executing as `(1)` then `(0)`. A 78-layer kernel that raises stage
  flags back to back cannot rely on their order; it needs one flag per stage with a wait between, or a GM counter.
- **If the kernel type ever resolves to `KERNEL_TYPE_AIC_ONLY` or `KERNEL_TYPE_AIV_ONLY`, the hardware does not turn
  the scheduling module on and cross-core sync silently does not work** —
  「硬件不会开启调度模块，也就无法正常进行核间同步」. That is the one documented way every barrier in a kernel
  becomes a no-op at once. It is worth verifying from the built binary rather than the source that the type is
  `KERNEL_TYPE_MIX_AIC_1_2`, particularly given the measured finding that `--cce-aicore-arch=dav-c220` silently drops
  `__schedmode__` where `--npu-arch=dav-2201` keeps it: a toolchain that drops one kernel attribute may drop another.
- The flag is a **scheduling-module event**, not a memory operation: the Set 「向调度模块上报本核任务已完成」 and the
  Wait blocks 「本核后续指令的下发」 until 「调度模块确认」. That is the clean statement of why it carries no memory
  ordering, which is the §34/§35 story, and also why its state lives outside the kernel's address space.


---

## 39. Two complete vendor MIX kernels: a shipped multi-block `ASCENDC_CUBE_ONLY` + flag handoff, and the KFC route where the AIV drives the cube and waits on a `TQue`

§32's `matmul_fused_manual` is `numBlocks = 1` on one tile, which proves nothing about a multi-block handoff. These
two do better: `rope_matrix` is a shipped, multi-block, `KERNEL_TYPE_MIX_AIC_1_2` operator whose AIV consumes an AIC
matmul result out of GM, and `matmul_fused` is the alternative structure in which the AIV *drives* the cube and never
touches a cross-core flag at all.

### 39.1 `rope_matrix` — the shipped multi-block kernel, complete

https://github.com/hicann/ops-transformer/tree/master/experimental/posembedding/rope_matrix/op_kernel
(mirror of `cann/ops-transformer`; the entry point with the `ASCEND_IS_AIC` / `ASCEND_IS_AIV` split and the flag is
quoted in §37.1 from the authors' own write-up.) Copyright 2025 Huawei, CANN Open Software License Agreement
Version 2.0. Retrieved 2026-10-20. Two files: `rope_matrix.h` (266 lines, vector half + `ASCENDC_CUBE_ONLY`) and
`rope_matrix_cube.h` (114 lines, matrix half).

First: **`ASCENDC_CUBE_ONLY` together with a populated AIV half in the same translation unit is the shipped shape.**
`rope_matrix.h` opens with it and then defines the whole vector class below, verbatim:

```cpp
#pragma once
#ifndef ASCENDC_CUBE_ONLY
#define ASCENDC_CUBE_ONLY
#endif
#include "kernel_operator.h"
#include "lib/matmul_intf.h"
#include "rope_matrix_cube.h"

namespace npu_ops_transformer_ext {
namespace RopeMatrix {

constexpr int32_t DOUBLE_BUFFER = 2;

using AscendC::GetBlockIdx;
using AscendC::TBuf;
using AscendC::TPipe;
using AscendC::LocalTensor;
using AscendC::SetFlag;
using AscendC::WaitFlag;
using AscendC::DataCopy;
using AscendC::Add;
using AscendC::Mul;
using AscendC::Cast;
using AscendC::HardEvent;
using AscendC::PipeBarrier; // <PIPE_V>();
```

The cube half, verbatim and complete — note `IterateAll` called `B*H` times in a loop with **one** `End()` at the
very end, `SetTail` per iteration, and a `Matmul` whose B operand has IBShare enabled (sixth template argument
`true`):

```cpp
template <typename A_T, typename B_T, typename C_T>
class MatmulBatchKernel {
public:
    __aicore__ inline MatmulBatchKernel(){};
    __aicore__ inline void Init(GM_ADDR a, GM_ADDR b, GM_ADDR c, GM_ADDR workspace,
                                const TCubeTiling &tiling, AscendC::TPipe *pipe);
    __aicore__ inline void Process(AscendC::TPipe *pipe, RopeMatrixTiling *ropeTiling);
    
    typedef MatmulType<AscendC::TPosition::GM, CubeFormat::ND, A_T> aType;
    typedef MatmulType<AscendC::TPosition::GM, CubeFormat::ND, B_T, false, LayoutMode::NONE, true> bType;
    typedef MatmulType<AscendC::TPosition::GM, CubeFormat::ND, C_T> cType;
    typedef MatmulType<AscendC::TPosition::GM, CubeFormat::ND, C_T> biasType;
    Matmul<aType, bType, cType, biasType> matmulObj;

    AscendC::GlobalTensor<A_T> aGlobal;
    AscendC::GlobalTensor<B_T> bGlobal;
    AscendC::GlobalTensor<C_T> cGlobal;
    TCubeTiling tiling;

private:
    __aicore__ inline void CalcGMOffset(int blockIdx, int &offsetA, int &offsetB, int &offsetC,
                                        int &tailM, int &tailN, int B, int H, int M, int N,
                                        int K, int Nindex);
};

template <typename A_T, typename B_T, typename C_T>
__aicore__ inline void MatmulBatchKernel<A_T, B_T, C_T>::Init(GM_ADDR a, GM_ADDR b, GM_ADDR c,
                                                                GM_ADDR workspace, const TCubeTiling &tiling,
                                                                AscendC::TPipe *pipe)
{
    this->tiling = tiling;
    aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ A_T *>(a), tiling.M * tiling.Ka);
    bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ B_T *>(b), tiling.Ka * tiling.N);
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ C_T *>(c), tiling.M * tiling.N);
}

template <typename A_T, typename B_T, typename C_T>
__aicore__ inline void MatmulBatchKernel<A_T, B_T, C_T>::Process(AscendC::TPipe *pipe, RopeMatrixTiling *ropeTiling)
{
    REGIST_MATMUL_OBJ(pipe, GetSysWorkSpacePtr(), matmulObj, &tiling);

    auto B = ropeTiling->b;
    auto H = ropeTiling->n;
    auto M = ropeTiling->s;
    auto N = ropeTiling->d;
    auto K = ropeTiling->d;

    int total_N = B * H;
    for (int Nindex = 0; Nindex < total_N; ++Nindex) {
        int offsetA = 0, offsetB = 0, offsetC = 0;
        int tailM = 0, tailN = 0;
        bool isTransA = false, isTransB = false;

        CalcGMOffset(AscendC::GetBlockIdx(), offsetA, offsetB, offsetC,
                    tailM, tailN, B, H, M, N, K, Nindex);

        matmulObj.SetTensorA(aGlobal[offsetA], isTransA);
        matmulObj.SetTensorB(bGlobal[offsetB], isTransB);
        matmulObj.SetTail(tailM, tailN);
        matmulObj.IterateAll(cGlobal[offsetC]);
    }
    matmulObj.End();
}

template <typename A_T, typename B_T, typename C_T>
__aicore__ inline void MatmulBatchKernel<A_T, B_T, C_T>::CalcGMOffset(int blockIdx,
                                                                        int &offsetA, int &offsetB, int &offsetC,
                                                                        int &tailM, int &tailN, int B, int H,
                                                                        int M, int N, int K, int Nindex)
{
    uint32_t aCoreInaS = tiling.singleCoreM;
    uint32_t aCoreMBlock = Ceiling(M, aCoreInaS);
    uint32_t mCoreIndx = blockIdx % aCoreMBlock;
    uint32_t nCoreIndx = blockIdx / aCoreMBlock;

    offsetA = mCoreIndx * tiling.Ka * aCoreInaS + Nindex * M * tiling.Ka;
    offsetB = nCoreIndx * tiling.singleCoreN;
    offsetC = mCoreIndx * tiling.N * aCoreInaS + nCoreIndx * tiling.singleCoreN + Nindex * M * tiling.N;

    tailM = M - mCoreIndx * aCoreInaS;
    tailM = tailM < aCoreInaS ? tailM : aCoreInaS;

    tailN = N - nCoreIndx * tiling.singleCoreN;
    tailN = tailN < tiling.singleCoreN ? tailN : tiling.singleCoreN;
}
```

### 39.2 The index asymmetry between the two halves, as a comment in shipped code

This is the vector half's `Init`, verbatim. The comment is the finding:

```cpp
    __aicore__ inline void Init(GM_ADDR x, GM_ADDR xNew, GM_ADDR sin, GM_ADDR cos, GM_ADDR out,
                                RopeMatrixTiling *ropeTiling, TPipe *tpipe)
    {
        this->aivIdx = GetBlockIdx();
        this->aivNum = GetBlockNum();
        this->subIdx = GetSubBlockIdx();
        this->subNum = GetSubBlockNum();
        // doc say aivNum has already mul subNum, by we test are not, thus need this
        this->aivNum *= this->subNum;
```

and the partition it drives, verbatim — `aivIdx` is used directly as the **global** AIV index:

```cpp
        this->sSize = this->CeilDiv(this->seqLen, this->aivNum);
        this->sdSize = this->sSize * this->d;

        uint32_t remainSize = this->seqLen - this->sSize * this->aivIdx;
        this->startSize = this->sSize * this->aivIdx;
        // update sSize for last core, need after this->startSize set
        this->sSize = (this->sSize < remainSize) ? (this->sSize) : (remainSize);
        this->sBlockNum = this->CeilDiv(sSize, this->sBlockSize);
        this->sLastBlockSize = this->sSize % this->sBlockSize;
        this->sLastBlockSize = (this->sLastBlockSize == 0) ? this->sBlockSize : this->sLastBlockSize;
        this->sdLastBlockSize = this->sLastBlockSize * this->d;

        uint32_t startNumel = this->startSize * this->d;
        xGm.SetGlobalBuffer((__gm__ T*) x + startNumel);
        xNewGm.SetGlobalBuffer((__gm__ T*) xNew + startNumel);
        yGm.SetGlobalBuffer((__gm__ T*) out + startNumel);
        cosGm.SetGlobalBuffer((__gm__ T*) cos + startNumel);
        sinGm.SetGlobalBuffer((__gm__ T*) sin + startNumel);
```

So in a `__mix__(1, 2)` kernel on A3, as measured by the team that shipped it: on the AIV side `GetBlockIdx()`
returns the **global AIV index** (range `[0, 2N)`), while `GetBlockNum()` returns the **AIC** count `N`, so the AIV
count has to be formed by hand as `GetBlockNum() * GetSubBlockNum()`. The comment records that the documentation
claims otherwise.

The vector half's consumption of the cube result — `xNewGm` is the matmul's `C` — verbatim:

```cpp
    __aicore__ inline void Process() {
        uint32_t ubLoop = this->sBlockNum - 1;
        for (uint32_t progress = 0; progress < ubLoop; progress++) {
            SingleStepProcess(progress, this->sdBlockSize, this->sdBlockSize);
        }
        // last block
        SingleStepProcess(ubLoop, this->sdLastBlockSize, this->sdLastBlockSize);
    }
```
```cpp
    __aicore__ inline void CopyInX(uint64_t xStartOffset, uint32_t copyLength) {
        LocalTensor<T> xLocal = inQueueX.AllocTensor<T>();
        LocalTensor<T> xNewLocal = inQueueXnew.AllocTensor<T>();
        DataCopy(xLocal, xGm[xStartOffset], copyLength);
        DataCopy(xNewLocal, xNewGm[xStartOffset], copyLength);
        inQueueX.EnQue(xLocal);
        inQueueXnew.EnQue(xNewLocal);
    }
```

No `DataCacheCleanAndInvalid`, no `DataSyncBarrier`, no `PipeBarrier` guards this read: the whole protocol is the
entry point's `CrossCoreSetFlag<0x2, PIPE_FIX>(0x8)` / `CrossCoreWaitFlag(0x8)` pair from §37.1.

### 39.3 `matmul_fused` — the KFC route, complete: the AIV drives the cube and waits on a `TQue`

https://gitcode.com/cann/asc-devkit/blob/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_fused/README.md
raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_fused/matmul_fused.asc
Repo `cann/asc-devkit`, branch `master`. Copyright 2025 Huawei. A3 from CANN 9.0.0, acceptance 「test pass!」,
`cmake -DCMAKE_ASC_ARCHITECTURES=dav-2201`. Retrieved 2026-10-20.

Its self-description, verbatim — note what provides the synchronisation:

```
## 概述

分核AIC、AIV融合编程实现，主要介绍了Matmul高阶API的MIX模式，Matmul API内部会自动控制AIC、AIV的核间同步。

## 样例描述

- 样例功能：  
  本样例创建MIX模式的Matmul对象，在AIC核实现Matmul计算，中间结果输出至VECIN(Unified Buffer)。AIC核计算完成后，通过TQue的EnQue/DeQue接口控制同步，继续在AIV核对Unified Buffer上的中间结果进行LeakyRelu的计算。

- 样例规格：  
  本样例中：M = 1024, N = 640, K = 256
```

The include block, verbatim — **no `ASCENDC_CUBE_ONLY`**:

```cpp
#include "kernel_operator.h"
#include "lib/matmul_intf.h"
#include "tiling/tiling_api.h"
#include "tiling/platform/platform_ascendc.h"
#include "data_utils.h"
#include "kernel_tiling/kernel_tiling.h"
#include "acl/acl.h"

using namespace matmul;
using namespace std;
```

The entry point, verbatim — **`__global__ __aicore__`, not `__mix__`; one function body; no
`ASCEND_IS_AIC`/`ASCEND_IS_AIV` split; `__kfc_workspace__` on the workspace argument**:

```cpp
extern "C" __global__ __aicore__ void matmul_fused_custom(
    __gm__ uint8_t* a, __gm__ uint8_t* b, __gm__ uint8_t* bias, __gm__ uint8_t* c,
    __gm__ uint8_t* __kfc_workspace__ workspace, __gm__ uint8_t* tilingGm)
{
    AscendC::TPipe pipe;
    TCubeTiling tiling;
    CopyTiling(&tiling, tilingGm);

    MatmulLeakyKernel<half, half, float, float> matmulLeakyKernel;
    matmulLeakyKernel.Init(a, b, bias, c, workspace, tiling, &pipe);
    REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), matmulLeakyKernel.matmulObj, &matmulLeakyKernel.tiling);
    matmulLeakyKernel.Process();
}
```

The member declarations, verbatim — C at `TPosition::VECIN`, plus a `workspaceGlobal` and two `TQue`s:

```cpp
    Matmul<
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, AType>,
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BType>,
        MatmulType<AscendC::TPosition::VECIN, CubeFormat::ND, CType>,
        MatmulType<AscendC::TPosition::GM, CubeFormat::ND, BiasType>>
        matmulObj;

    AscendC::GlobalTensor<AType> aGlobal;
    AscendC::GlobalTensor<BType> bGlobal;
    AscendC::GlobalTensor<CType> cGlobal;
    AscendC::GlobalTensor<BiasType> biasGlobal;
    AscendC::GlobalTensor<CType> workspaceGlobal;
    AscendC::LocalTensor<CType> reluInLocal;
    TCubeTiling tiling;
    AscendC::TQue<AscendC::TPosition::VECIN, 1> reluInQueue;
    AscendC::TQue<AscendC::TPosition::VECOUT, 1> reluOutQueue;
    uint32_t splitRowNums = 0;
    uint32_t splitRowSize = 0;
```

`Init`, verbatim — note `GetUserWorkspace(workspace)` and the **per-block** staging offset:

```cpp
template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::Init(
    __gm__ uint8_t* a, __gm__ uint8_t* b, __gm__ uint8_t* bias, __gm__ uint8_t* c, __gm__ uint8_t* workspace,
    const TCubeTiling& tiling, AscendC::TPipe* pipe)
{
    this->tiling = tiling;
    splitRowNums = 4;
    splitRowSize = tiling.baseM / splitRowNums;
    aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ AType*>(a), tiling.M * tiling.Ka);
    bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ BType*>(b), tiling.Kb * tiling.N);
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ CType*>(c), tiling.M * tiling.N);
    biasGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ BiasType*>(bias), tiling.N);
    workspaceGlobal.SetGlobalBuffer(
        reinterpret_cast<__gm__ CType*>(AscendC::GetUserWorkspace(workspace)), tiling.M * tiling.N);

    int32_t offsetA, offsetB, offsetC, offsetBias;
    CalcOffset(
        AscendC::GetBlockIdx(), tiling, offsetA, offsetB, offsetC,
        offsetBias); // Calculate the gm offset based on the blockidx.
    aGlobal = aGlobal[offsetA];
    bGlobal = bGlobal[offsetB];
    cGlobal = cGlobal[offsetC];
    biasGlobal = biasGlobal[offsetBias];
    workspaceGlobal = workspaceGlobal[GetBlockIdx() * tiling.singleCoreM * tiling.singleCoreN];
    pipe->InitBuffer(reluInQueue, 1, tiling.baseM * tiling.baseN * sizeof(CType));  // Init relu input queue.
    pipe->InitBuffer(reluOutQueue, 1, splitRowSize * tiling.baseN * sizeof(CType)); // Init relu output queue.
}
```

`Process` and the handoff, verbatim and complete — **the `DeQue` is the wait**:

```cpp
template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::Process()
{
    matmulObj.SetWorkspace(workspaceGlobal);
    matmulObj.SetTensorA(aGlobal);
    matmulObj.SetTensorB(bGlobal);
    matmulObj.SetBias(biasGlobal);
    matmulObj.template Iterate<false>(); // Sync is set false means async, this scene will run while(Iterate).
    for (int i = 0; i < tiling.singleCoreM * tiling.singleCoreN / (tiling.baseM * tiling.baseN); ++i) {
        MatmulCompute();                          // Get matmul compute result.
        reluInLocal = reluInQueue.DeQue<CType>(); // wait matmul compute result finish.
        for (int j = 0; j < splitRowNums; ++j) {
            LeakyReluCompute(j);           // Compute leakyRelu.
            CopyOut(i * splitRowNums + j); // Copy leakyRelu out result to GM.
        }
        reluInQueue.FreeTensor(reluInLocal);
    }
    matmulObj.End();
}

template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::MatmulCompute()
{
    reluInLocal = reluInQueue.AllocTensor<CType>();
    matmulObj.template GetTensorC<false>(reluInLocal, false, true);
    reluInQueue.EnQue(reluInLocal);
}

template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::LeakyReluCompute(uint32_t count)
{
    auto reluOutLocal = reluOutQueue.AllocTensor<CType>();
    LeakyRelu(
        reluOutLocal, reluInLocal[count * splitRowSize * tiling.baseN], (CType)0.001, splitRowSize * tiling.baseN);
    reluOutQueue.EnQue(reluOutLocal);
}

template <typename AType, typename BType, typename CType, typename BiasType>
__aicore__ inline void MatmulLeakyKernel<AType, BType, CType, BiasType>::CopyOut(uint32_t count)
{
    auto reluOutLocal = reluOutQueue.DeQue<CType>(); // wait relu compute result finish.
    const uint32_t roundM = tiling.singleCoreM / splitRowSize;
    uint32_t startOffset = (count % roundM * splitRowSize * tiling.N + count / roundM * tiling.baseN);
    AscendC::DataCopyParams copyParam = {
        (uint16_t)splitRowSize, (uint16_t)(tiling.baseN * sizeof(CType) / AscendC::DEFAULT_C0_SIZE), 0,
        (uint16_t)((tiling.N - tiling.baseN) * sizeof(CType) / AscendC::DEFAULT_C0_SIZE)};
    DataCopy(cGlobal[startOffset], reluOutLocal, copyParam);
    reluOutQueue.FreeTensor(reluOutLocal);
}
```

and the host side, verbatim — `SetDim` is in **AIV** units while the `<<<>>>` argument is in **AIC** units:

```cpp
    int usedCoreNum = 2;
```
```cpp
    tilingApi.SetDim(usedCoreNum); // Set the number of cores that participate in multi-core computation is 2.
```
```cpp
    uint32_t numBlocks = 1;
```
```cpp
    matmul_fused_custom<<<numBlocks, 0, stream>>>(
```
```cpp
    ICPU_RUN_KF(matmul_fused_custom, numBlocks, a, b, bias, c, workspace, tiling);
```

## Relevance
- **§39.1 settles that `ASCENDC_CUBE_ONLY` plus a populated AIV half is supported and shipped.** `rope_matrix.h`
  `#define`s it and defines the entire vector class in the same header, and the operator is in
  `cann/ops-transformer` with a torch binding. So the brick's structure is legal. What it is *not* is the only
  option — §39.3 is the other one, and in that one the AIV never waits on a flag, which is on its own a complete
  explanation for "every barrier I add is a no-op" if a build ever resolves to that route.
- **§39.1 is also the multi-block existence proof asked for**, with the whole function rather than the protocol
  lines. The cube half loops `IterateAll` over `B*H` batches with a single trailing `End()`, re-pointing A, B and C
  per iteration and calling `SetTail` each time; the AIV half reads the cube's `C` (`xNewGm`) with a bare `DataCopy`
  and no cache operation at all. The only synchronisation in the whole operator is the entry point's
  `CrossCoreSetFlag<0x2, PIPE_FIX>(0x8)` / `CrossCoreWaitFlag(0x8)` from §37.1. Two consequences. First, a bare
  default-pipe wait is what a shipped multi-block operator uses, which weakens §38.3's `PIPE_S` argument from
  "certainly a bug" to "contradicts the spec but is current practice" — worth trying `PIPE_MTE2` as a cheap
  experiment, not worth believing in. Second, the handoff is correct here only because the two tilings are
  deliberately aligned pairwise (§37): `tiling.singleCoreM` on the cube side is exactly `2 ×` the vector side's
  `sSize = CeilDiv(seqLen, aivNum)`.
- **§39.2 is the index trap, confirmed in shipped code against the documentation.** Verbatim:
  `// doc say aivNum has already mul subNum, by we test are not, thus need this` followed by
  `this->aivNum *= this->subNum;`. So in a `__mix__(1, 2)` kernel on A3: the AIV's `GetBlockIdx()` is the **global
  AIV index** in `[0, 2N)` and is used directly as such, while `GetBlockNum()` returns the **AIC** count `N`. The
  AIC's `GetBlockIdx()` is in `[0, N)`. Any buffer indexed by `GetBlockIdx()` on both sides is therefore indexed
  with two different strides, and at `numBlocks = 1` the AIV with `GetBlockIdx() == 1` reads a slice no AIC ever
  wrote. Since the brick's index fix was made before this was known, the check is: print
  `GetBlockIdx(), GetBlockNum(), GetSubBlockIdx(), GetSubBlockNum()` from both halves on A3 and confirm which of the
  four the fix assumed. `AscendC::printf` is the documented debug route — `rope_matrix.h` ships a `Debug()` stub for
  exactly this, verbatim:
  `// AscendC::printf("... debug %d, %d, %d, %d\n", this->aivIdx, this->aivNum, this->subIdx, this->subNum);`
- **§39.3 gives the KFC route in full, and it is the structure to consider if the flag protocol stays unreliable.**
  `__kfc_workspace__` on the workspace parameter plus `REGIST_MATMUL_OBJ` plus a MIX-mode Matmul with
  `C` at `TPosition::VECIN` means the AIV issues `Iterate<false>()`, the API dispatches the cube work, and
  `GetTensorC<false>(localTensor, false, true)` plus `reluInQueue.EnQue` / `DeQue` is the entire synchronisation —
  intra-core pipe sync on the AIV's own queue, because from the AIV's point of view the result lands in its own UB.
  No `CrossCoreSetFlag`, no flagId budget, no counter residue, no intra-core-group pairing constraint. Given §38's
  finding that the flag is scheduler state with no documented reset and undefined behaviour when unpaired, this
  route removes the entire failure class. The cost is that the API owns the pipelining, which is the 13.58 us MIX
  head overhead we are trying to delete — so the honest reading is: use the KFC route to get a correct baseline and
  a reference output, then move to the hand-written flag route with a known-good comparison in hand.
- Two mechanical facts from §39.3 worth keeping regardless. The cube→vector staging buffer is explicit and
  per-block: `GetUserWorkspace(workspace)` offset by `GetBlockIdx() * singleCoreM * singleCoreN`, which is the same
  ring-slot arithmetic as §15's `workSpaceOffset` and is what `SetWorkspace()` consumes. And `SetDim(usedCoreNum)`
  with `usedCoreNum = 2` alongside `numBlocks = 1` confirms that `SetDim` counts AIV while the `<<<>>>` argument
  counts AIC — a factor of two between the tiling's core count and the launch's.
- For our numbers: `rope_matrix` is the only shipped A3 MIX operator found whose published motivation is ours in
  miniature — a vector-heavy op turned into `x @ mat` to put work on the cube, measured at 10% of a network, with
  the conclusion 「matmul计算和Vector计算理论上都是memory bound」 (§37). Our `Cast` family at 2.300 ms against
  0.076 ms of bytes is the same disease; §34's Fixpipe `S322S8` / `S322FP16` / `FP322BF16` list is the cure that
  does not need a vector instruction at all.


---

## 40. Flag exhaustion and rotation across many sequential stages — what real megakernels do, and the confirmation that there is no reset

Collected 2026-10-20 for question 2.1, "how a single kernel stages 78 sequential layers' worth of cross-core
handshakes". Everything below is verbatim. Collector's provenance note, verbatim:

> 319 fenced blocks. 250 were machine-checked as exact literal substrings of source files cached
> locally at fetch time. The checker parses this file with a real CommonMark parser
> (`markdown-it-py`), so nested fences and info strings are handled correctly.

## Relevance
This answers question 2.1 and independently corroborates §38's two load-bearing claims.
- **flagId is 0-15, not 0-10** — arrived at independently here, and with the explanation for the discrepancy:
  the usable range only *looks* like 0-10 because AscendC reserves 11/12/13 for `SyncAll<false>` and 14 for
  `SyncAll<true>` (§35.5). Out-of-range truncates to the low 4 bits; overflow is a hard error. This supersedes
  README finding 3 and `ascend-launch-overhead-and-sync.md` §4.7 for a second time.
- **There is no reset primitive. A counter only falls by executing matching Waits.** That is the independent
  confirmation of §38's conclusion, and it is why the brick's alternation is a pairing ledger problem rather than
  something a reset call can fix.
- Real code does exactly one of three things, and all three are quoted below.
  1. **Drain at a barrier.** `huawei-csl/megagdn-pto`'s seven-stage megakernel touches only flagIds 0-4 ever,
     ping-ponged on `slot = ci & 1`, with three explicit drain blocks in `mega_kernel.cpp` that consume the Sets the
     last loop iteration left outstanding. This is the shape to copy first: it is a working public Ascend
     megakernel, and the drain blocks are the literal answer to "what do I do with the residue".
  2. **Credit window.** CATLASS `cross_core_sync.hpp` `CrossCoreSetFlagWithReverse` with
     `MAX_REVERSE_DEPTH = 15` (already quoted in §31.8) costs **2 flagIds regardless of stage count**, which is the
     cheapest fit for 78 layers. The hazard is proven rather than theoretical: MR !325, merged 2025-12-18, changed
     the default from 16 because 16 「会导致卡死」.
  3. **flagId rotation.** Huawei's own MegaMoE computes
     `flagId = syncgmmIdx / CROSS_CORE_FLAG_MAX_SET_COUNT` with the constant `= 15`, zeroing the counter each round,
     and its header states the entire budget verbatim: 「syncgmm 流 0-8、C2V=9、V2C=10 ... 不落入 ...
     SyncAll<false> 的 11-13」. That is a shipped operator's flagId allocation table for A3.
- **The unbounded alternative avoids the hardware counter entirely.** `cann/pto-isa` PR 878's
  `TSYNCALL<TSyncAllMode::Soft>` is a GM-counter barrier — monotonic `curValue = prev + 1`, one cache-line-isolated
  8 × int32 slot per core, poll until all are `>= curValue` — with no flag and no depth limit; its ST exercises
  three back to back. SuperKernel's `SkMemoryWaitFlag::GEQ` plus `NotifyFunc` / `WaitFunc` / `ResetFunc` is the same
  idea, and critically **its RESET is of the GM word, never of a hardware flag**. Combined with §35.3's
  `WriteGmByPassDCache` / `ReadGmByPassDCache`, that is a 78-layer-safe barrier that touches no flagId at all.
- `graph-autofusion`'s `sk_flag_diag.h` is the authoritative proof of both limits: it deliberately saturates with
  `for (i = 0; i <= 10)` × `for (j = 0; j < 15)`.
- `IBSet` / `IBWait` / soft `SyncAll` are GM polling loops and do **not** share the 16-deep hardware counter — so
  they are immune to the residue failure class in §38.

# TOPIC A — cross-core flag exhaustion and rotation across many sequential stages

## A1. `huawei-csl/megagdn-pto` — the barrier: `SyncAllMegaKernel`

https://github.com/huawei-csl/megagdn-pto/blob/main/kernels/pto/include/kernel_utils.h

Author: Huawei Technologies Co., Ltd. (repo `huawei-csl/megagdn-pto`, branch `main`,
copyright header 2026). Fetched 2026-10-20.

This is the WHOLE file. It contains the barrier (`SyncAllMegaKernel`), the FFTS message
encoder (`GetffstMsg`), the A2/A3 path (`SyncAllA2A3`), the A5 path (`SyncAllMixA5`), and the
cross-core set/wait helpers (`SetCrossFlag`, `SignalBothVecOnA5`, `WaitBothVecOnA5`).
Note the hard-coded reserved flag ids 11/12/13/14 and `SYNC_FLAG_ID_MAX` usage on A5.

```cpp
/**
Copyright (c) 2026 Huawei Technologies Co., Ltd.
All rights reserved.

See LICENSE in the root of the software repository:
https://github.com/huawei-csl/pto-kernels/
for the full License text.
*/
#pragma once

#include <pto/pto-inst.hpp>
#include <type_traits>

namespace kernel_utils {
/**
 * @brief Do a sync step (set-wait flag) between two pipes.
 *
 * @tparam SrcPipe The pipe that sets the flag.
 * @tparam DstPipe The pipe that waits for the flag.
 * @param [in] id The event id to sync for.
 */
template <pipe_t SrcPipe, pipe_t DstPipe>
AICORE inline void SetWaitFlag(uint32_t id) {
  set_flag(SrcPipe, DstPipe, static_cast<event_t>(id));
  wait_flag(SrcPipe, DstPipe, static_cast<event_t>(id));
}

/**
 * @brief Performs a division on two integral numbers and rounds the result up
 * to the nearest integer.
 *
 * @tparam T1 Data type of dividend.
 * @tparam T2 Data type of divisor.
 * @param [in] value Dividend.
 * @param [in] divisor Divisor.
 * @return Result of division.
 */
template <typename T1, typename T2,
          typename std::enable_if<std::is_integral<T1>::value &&
                                      std::is_integral<T2>::value,
                                  int>::type = 0>
AICORE inline T1 CeilDiv(T1 value, T2 divisor) {
  return (value + divisor - 1) / divisor;
}

template <pipe_t Pipe, uint8_t VEC_NUM = 2>
AICORE inline void SetCrossFlag(int32_t flag) {
  ffts_cross_core_sync(Pipe, 1 | (VEC_NUM << 4) | (flag << 8));
}

template <pipe_t Pipe>
AICORE inline void SignalBothVecOnA5(uint16_t flag) {
  // A5: the flag offset is 16 on new core.
  constexpr uint16_t VEC_FLAG_OFFSET = 16;

  set_intra_block(Pipe, flag);
  set_intra_block(Pipe, flag + VEC_FLAG_OFFSET);
}

template <pipe_t Pipe>
AICORE inline void WaitBothVecOnA5(uint16_t flag) {
  // A5: the flag offset is 16 on new core.
  constexpr uint16_t VEC_FLAG_OFFSET = 16;

  wait_intra_block(Pipe, flag);
  wait_intra_block(Pipe, flag + VEC_FLAG_OFFSET);
}

/**
 * @brief Returns the outer matrix layout based on the target architecture and
 * matrix orientation.
 *
 * On DAV C310 targets, the layout depends on whether the matrix is "left-sided"
 * (L0A). DAV C310: L0A is NZ, L0B is ZN. Older: L0A is ZZ, L0B is ZN.
 *
 * Link:
 * https://pto-isa.github.io/docs/isa/cube/nz-fractal-layout/#per-buffer-nz-layouts
 *
 * @param is_left Whether the matrix is on the left side (L0A) or not (L0B).
 * @return The appropriate @c BLayout for the target architecture.
 */
constexpr inline pto::BLayout GetOuterLayout(bool is_left) {
#ifdef __DAV_C310__
  return is_left ? pto::BLayout::ColMajor : pto::BLayout::RowMajor;
#else
  return pto::BLayout::RowMajor;
#endif
}

/**
 * @brief Pipe in-core barrier for vector core that is a no-op for A5.
 *
 */
AICORE inline void PipeBarrierVec() {
#if __CCE_AICORE__ == 220
  pipe_barrier(PIPE_V);
#endif
}

AICORE inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId) {
  constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
  constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;
  return (0x1 + ((mode & 0x3) << SYNC_MODE_SHIFT_VALUE) +
          ((flagId & 0xf) << SYNC_FLAG_SHIFT_VALUE));
}

template <bool isAIVOnly = true>
AICORE inline void SyncAllA2A3() {
// These constants are defined on A5
#if __CCE_AICORE__ == 220
  constexpr uint16_t SYNC_AIV_FLAG = 12;
  constexpr uint16_t SYNC_AIC_FLAG = 11;
  constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
  constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
  pipe_barrier(PIPE_ALL);
  if constexpr (isAIVOnly) {
    ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x0, SYNC_AIV_ONLY_ALL));
    wait_flag_dev(SYNC_AIV_ONLY_ALL);
    return;
  }
#if defined(__DAV_CUBE__)
  wait_flag_dev(SYNC_AIV_FLAG);
  ffts_cross_core_sync(PIPE_FIX, GetffstMsg(0x0, SYNC_AIC_FLAG));
  wait_flag_dev(SYNC_AIC_FLAG);
  ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIC_AIV_FLAG));
#elif defined(__DAV_VEC__)
  ffts_cross_core_sync(PIPE_MTE3, GetffstMsg(0x02, SYNC_AIV_FLAG));
  wait_flag_dev(SYNC_AIC_AIV_FLAG);
#endif
#endif
}

// ── A5 ── mirrors include/pto/npu/a5/SyncAll.hpp:101-111
// Requires: getFFTSMsg from <pto/npu/a5/SyncAll.hpp> (A5 defines its own)
AICORE inline void SyncAllMixA5() {
#if __CCE_AICORE__ != 220
  pipe_barrier(PIPE_ALL);
#if defined(__DAV_CUBE__)
  // 1. Wait for both paired AIVs: one flag ID per subblock (base, base +
  // SYNC_FLAG_ID_MAX).
  wait_intra_block(PIPE_S, SYNC_AIV_FLAG);
  wait_intra_block(PIPE_S, SYNC_AIV_FLAG + SYNC_FLAG_ID_MAX);
  // 2. Global all-AIC barrier.
  ffts_cross_core_sync(PIPE_FIX, getFFTSMsg(0x0, SYNC_AIC_FLAG));
  wait_flag_dev(PIPE_S, SYNC_AIC_FLAG);
  // 3. Release both paired AIVs.
  set_intra_block(PIPE_S, SYNC_AIC_AIV_FLAG);
  set_intra_block(PIPE_S, SYNC_AIC_AIV_FLAG + SYNC_FLAG_ID_MAX);
#elif defined(__DAV_VEC__)
  // Set on MTE3 so prior stores drain; wait on PIPE_S.
  set_intra_block(PIPE_MTE3, SYNC_AIV_FLAG);
  wait_intra_block(PIPE_S, SYNC_AIC_AIV_FLAG);
#endif
#endif
}

template <bool isAIVOnly = true>
AICORE inline void SyncAllMegaKernel() {
#if __CCE_AICORE__ == 220
  SyncAllA2A3<isAIVOnly>();
#else
  static_assert(isAIVOnly == false, "No support for AIV only global sync");
  SyncAllMixA5();
#endif
}

}  // namespace kernel_utils
```

Key arithmetic, isolated: the FFTS config word is `1 | (mode << 4) | (flagId << 8)` and the
flagId field is masked to **4 bits** (`flagId & 0xf`), i.e. 0-15 encodable, of which 11-14 are
taken by the barrier itself:

```cpp
AICORE inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId) {
  constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
  constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;
  return (0x1 + ((mode & 0x3) << SYNC_MODE_SHIFT_VALUE) +
          ((flagId & 0xf) << SYNC_FLAG_SHIFT_VALUE));
}
```

```cpp
template <pipe_t Pipe, uint8_t VEC_NUM = 2>
AICORE inline void SetCrossFlag(int32_t flag) {
  ffts_cross_core_sync(Pipe, 1 | (VEC_NUM << 4) | (flag << 8));
}
```

## A2. `huawei-csl/megagdn-pto` — how `mega_kernel.cpp` sequences many stages

https://github.com/huawei-csl/megagdn-pto/blob/main/kernels/pto/mega_kernel.cpp

Author: Huawei Technologies Co., Ltd. (repo `huawei-csl/megagdn-pto`, branch `main`). Fetched 2026-10-20.

Stage list declared at the top of the file:

```cpp
// mega_kernel.cpp — GDN Mega-Kernel (group-value / GQA): all PTO stages in one
// launch
//
// Same pipeline as pto_mega_kernel, but scaled_dot_kkt / wy_fast / chunk_h /
// chunk_o use runtime H/Hg dispatch from dynamic_bsnd_groupvalue; cumsum still
// uses H (value heads) like dynamic_bsnd.
//
// Stages:
//   1. cumsum      (Vec)
//   2. transpose   (Vec)
//   3. kkt         (Cube+Vec)  — K has Hg heads; β,g,A use H value heads
//   4. solve_tril  (Cube)
//   5. wy_fast     (Vec+Cube)
//   6. chunk_h     (Cube+Vec)
//   7. chunk_o     (Cube+Vec)
```

The body of `mega_kernel_impl` — this is the ANSWER to "how does real code sequence many
stages". The answer has two halves: (1) `SyncAllMegaKernel<false>()` between every pair of
stages, and (2) an explicit per-stage DRAIN of the leftover cross-core flag Sets, so the flag
counters return to zero before the next stage runs. Flag ids are NOT rotated across stages —
they are re-zeroed. Note the three drain blocks and their comments, which say exactly which
flag was left outstanding by which engine:

```cpp
AICORE inline void mega_kernel_impl(
    __gm__ uint8_t* q_ptr, __gm__ uint8_t* k_ptr, __gm__ uint8_t* v_ptr,
    __gm__ uint8_t* g_in_ptr, __gm__ uint8_t* beta_ptr,
    __gm__ uint8_t* msk_lower_ptr, __gm__ uint8_t* msk_full_ptr,
    __gm__ uint8_t* minus_id_ptr, __gm__ uint8_t* cu_seqlens_ptr,
    __gm__ uint8_t* o_ptr, __gm__ uint8_t* g_sum_ptr, __gm__ uint8_t* g_t_ptr,
    __gm__ uint8_t* beta_t_ptr, __gm__ uint8_t* A_ptr,
    __gm__ uint8_t* A_inv_f32_ptr, __gm__ uint8_t* A_inv_ptr,
    __gm__ uint8_t* w_ptr, __gm__ uint8_t* u_ptr, __gm__ uint8_t* s_ptr,
    __gm__ uint8_t* v_new_ptr, __gm__ uint8_t* fs_ptr, __gm__ uint8_t* h0_ptr,
    int64_t has_initial_state, __gm__ uint8_t* kkt_ws_ptr,
    __gm__ uint8_t* wy_ws_a1_ptr, __gm__ uint8_t* wy_ws_a2_ptr,
    __gm__ uint8_t* h_ws_ptr, __gm__ uint8_t* o_ws_qk_ptr,
    __gm__ uint8_t* o_ws_qs_ptr, __gm__ uint8_t* o_ws_gated_ptr, int32_t H,
    uint32_t num_key_heads, int64_t batch_size, int64_t seq_len,
    int64_t total_tokens, uint32_t num_matrices, uint64_t ffts_addr) {
  set_ffts_base_addr(ffts_addr);

  constexpr int32_t D = GDN_D;
  constexpr int32_t C = GDN_C;

  if (num_key_heads == 0 || (static_cast<uint32_t>(H) % num_key_heads) != 0) {
    return;
  }

  mk_cumsum::cumsum_kernel<C>(reinterpret_cast<__gm__ float*>(g_in_ptr),
                              reinterpret_cast<__gm__ float*>(g_sum_ptr),
                              reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr),
                              batch_size, seq_len, H, ffts_addr);

#ifdef MEGA_STOP_AFTER_CUMSUM
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

#ifdef MEGA_STOP_AFTER_SYNC1
  return;
#endif

  mega_transpose_TH_to_HT<float>(reinterpret_cast<__gm__ float*>(g_sum_ptr),
                                 reinterpret_cast<__gm__ float*>(g_t_ptr),
                                 total_tokens, H);
  mega_transpose_TH_to_HT<half>(reinterpret_cast<__gm__ half*>(beta_ptr),
                                reinterpret_cast<__gm__ half*>(beta_t_ptr),
                                total_tokens, H);

#ifdef MEGA_STOP_AFTER_TRANSPOSE
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

  mk_kkt::kkt_kernel<D, C>(reinterpret_cast<__gm__ half*>(k_ptr),
                           reinterpret_cast<__gm__ half*>(beta_t_ptr),
                           reinterpret_cast<__gm__ float*>(g_t_ptr),
                           reinterpret_cast<__gm__ float*>(msk_lower_ptr),
                           reinterpret_cast<__gm__ half*>(kkt_ws_ptr),
                           reinterpret_cast<__gm__ half*>(A_ptr),
                           reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr),
                           batch_size, seq_len, total_tokens,
                           static_cast<uint32_t>(H), num_key_heads, ffts_addr);

// Drain the kkt handshake: Vec released both workspace slots (flags 2/3) one
// last time after Cube's final iteration, so consume them before the next
// stage. A2: Vec is a separate core → FFTS cross-core flag. A5: both Vec
// sub-blocks share Cube's core → each signals its own intra-block
//     flag (base, base + 16).
#if defined(__DAV_CUBE__)
  pipe_barrier(PIPE_ALL);
#if __CCE_AICORE__ == 220
  wait_flag_dev(2);
  wait_flag_dev(3);
#else
  WaitBothVecOnA5<PIPE_MTE2>(2);
  WaitBothVecOnA5<PIPE_MTE2>(3);
  pipe_barrier(PIPE_ALL);
#endif
#endif

#ifdef MEGA_STOP_AFTER_KKT
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

  mega_solve_tril(reinterpret_cast<__gm__ half*>(A_inv_ptr),
                  reinterpret_cast<__gm__ half*>(A_ptr),
                  reinterpret_cast<__gm__ half*>(minus_id_ptr), C, num_matrices,
                  H, reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr), 1);

#ifdef MEGA_STOP_AFTER_SOLVE
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

#ifdef MEGA_STOP_AFTER_CAST
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

#ifdef MEGA_STOP_AFTER_SYNC_BEFORE_WY
  return;
#endif

  mk_wy::wy_fast_kernel<D, C>(
      reinterpret_cast<__gm__ half*>(k_ptr),
      reinterpret_cast<__gm__ half*>(v_ptr),
      reinterpret_cast<__gm__ half*>(beta_t_ptr),
      reinterpret_cast<__gm__ float*>(g_t_ptr),
      reinterpret_cast<__gm__ half*>(A_inv_ptr),
      reinterpret_cast<__gm__ half*>(wy_ws_a1_ptr),
      reinterpret_cast<__gm__ half*>(wy_ws_a2_ptr),
      reinterpret_cast<__gm__ half*>(w_ptr),
      reinterpret_cast<__gm__ half*>(u_ptr),
      reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr), batch_size, seq_len,
      total_tokens, static_cast<uint32_t>(H), num_key_heads, ffts_addr);

// Drain the wy_fast handshake: Cube freed the A2/A1 slots (flags 3/4) one last
// time after Vec's final iteration.
// A5: Cube signalled both sub-blocks (base, base + 16); each sub-block waits on
//     its own flag, so a plain intra-block wait is what mirrors the signal.
#if defined(__DAV_VEC__)
  if (get_block_idx() < num_matrices) {
    pipe_barrier(PIPE_ALL);
#if __CCE_AICORE__ == 220
    wait_flag_dev(3);
    wait_flag_dev(4);
#else
    wait_intra_block(PIPE_MTE3, 3);
    wait_intra_block(PIPE_MTE3, 4);
    pipe_barrier(PIPE_ALL);
#endif
  }
#endif

#ifdef MEGA_STOP_AFTER_WY
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

  mk_h::chunk_h_kernel<D, C>(
      reinterpret_cast<__gm__ half*>(k_ptr),
      reinterpret_cast<__gm__ half*>(w_ptr),
      reinterpret_cast<__gm__ half*>(u_ptr),
      reinterpret_cast<__gm__ float*>(g_t_ptr),
      reinterpret_cast<__gm__ half*>(s_ptr),
      reinterpret_cast<__gm__ half*>(v_new_ptr),
      reinterpret_cast<__gm__ half*>(fs_ptr),
      reinterpret_cast<__gm__ half*>(h0_ptr), has_initial_state, 1,
      reinterpret_cast<__gm__ half*>(h_ws_ptr),
      reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr), batch_size, seq_len,
      total_tokens, static_cast<uint32_t>(H), num_key_heads, ffts_addr);

#ifdef MEGA_STOP_AFTER_H
  pipe_barrier(PIPE_ALL);
  return;
#endif

  SyncAllMegaKernel<false>();

  mk_o::chunk_o_kernel<D, C>(
      reinterpret_cast<__gm__ half*>(q_ptr),
      reinterpret_cast<__gm__ half*>(k_ptr),
      reinterpret_cast<__gm__ half*>(v_new_ptr),
      reinterpret_cast<__gm__ half*>(s_ptr),
      reinterpret_cast<__gm__ float*>(g_t_ptr),
      reinterpret_cast<__gm__ float*>(msk_full_ptr),
      reinterpret_cast<__gm__ half*>(o_ws_qk_ptr),
      reinterpret_cast<__gm__ half*>(o_ws_qs_ptr),
      reinterpret_cast<__gm__ half*>(o_ws_gated_ptr),
      reinterpret_cast<__gm__ half*>(o_ptr),
      reinterpret_cast<__gm__ int32_t*>(cu_seqlens_ptr), batch_size, seq_len,
      total_tokens, static_cast<uint32_t>(H), num_key_heads, ffts_addr);

// Drain the chunk_o handshake: Vec's final "workspace free" (flag 3) is never
// consumed by Cube's loop, so consume it here.
#if defined(__DAV_CUBE__)
  if (get_block_idx() < num_matrices) {
    pipe_barrier(PIPE_ALL);
#if __CCE_AICORE__ == 220
    wait_flag_dev(3);
#else
    WaitBothVecOnA5<PIPE_MTE2>(3);
    pipe_barrier(PIPE_ALL);
#endif
  }
#endif
}

```

Mechanism, stated plainly (this is the finding, not a quote): megagdn-pto does **not** rotate
flagIds. It uses only flag ids 0,1,2,3,4 inside a stage (strict ping-pong on a double-buffer
`slot = ci & 1`), and ids 11-14 reserved for the barrier. Between stages it calls
`SyncAllMegaKernel<false>()` and then explicitly **consumes the leftover Sets** so every
counter returns to zero. That is why 7 stages (and by extension 78 layers) do not exhaust
anything: the number of *live* flags is bounded by the stage, not by the kernel.

The per-stage ping-pong, verbatim, from the kkt stage. Cube waits on `2+slot`, sets `slot`;
Vec waits on `slot`, sets `2+slot`; Vec primes both `2` and `3` before the loop so Cube does
not deadlock on the first iteration:

https://github.com/huawei-csl/megagdn-pto/blob/main/kernels/pto/scaled_dot_kkt.cpp

Author: Huawei Technologies Co., Ltd. (repo `huawei-csl/megagdn-pto`, branch `main`). Fetched 2026-10-20.

```cpp
    // ── Double-buffering via workspace slots ──────────────────────────
    // slot = ci & 1: alternates between 0 and 1 each chunk iteration.
    // Cube writes KK^T to workspace[slot], then signals Vec.
    // While Vec processes slot[0], Cube can write slot[1] (next chunk).
    // This overlaps Cube computation with Vec computation for pipelining.
    for (int64_t ci = 0; ci < num_chunks; ++ci) {
      int32_t slot = static_cast<int32_t>(ci & 1);
      // Wait for Vec to finish reading the previous KK^T from this slot.
      // A2: Cube and Vec are separate cores → FFTS cross-core flag.
      // A5: Cube and both Vec sub-blocks live in ONE core → intra-block flags,
      //     and each Vec sub-block signals its own flag (base and base+16).
#if __CCE_AICORE__ == 220
      wait_flag_dev(2 + slot);
#else
      WaitBothVecOnA5<PIPE_MTE2>(2 + slot);
#endif
      pipe_barrier(PIPE_ALL);
```

```cpp
      // ── Cross-core synchronization (Cube → Vec) ──────────────────────
      // ffts_cross_core_sync(pipe, config): Signal across physical cores.
      // Unlike set_flag/wait_flag (which sync pipes within ONE core), this
      // syncs between the Cube core and Vec core (they are separate hardware
      // units).
      //
      // Config encoding: 1 | (mode << 4) | (flag_id << 8)
      //   mode=2: broadcast to all cores on same block
      //   flag_id: which flag to set (0,1,2,3...)
      //
      // The receiving side calls wait_flag_dev(flag_id) to wait for this
      // signal.
      //
      // In this kernel:
      //   Cube sets flag 0/1 → Vec waits on wait_flag_dev(0/1) (KK^T ready)
      //   Vec sets flag 2/3 → Cube waits on wait_flag_dev(2/3) (workspace free)
      //
      // Signal Vec that this slot's KK^T is ready
      // ffts_cross_core_sync(PIPE_FIX, 1 | (2 << 4) | (slot << 8));
#if __CCE_AICORE__ == 220
      SetCrossFlag<PIPE_FIX>(slot);
#else
      pipe_barrier(PIPE_ALL);
      SignalBothVecOnA5<PIPE_FIX>(slot);
#endif
    }
```

```cpp
  // Initial cross-core sync: release both workspace slots so Cube can start.
  // Vec tells Cube "slots 0 and 1 are free" by setting flags 2 and 3.
  // Without this, Cube would hang on wait_flag_dev(2/3) at the first iteration.
  // ffts_cross_core_sync(PIPE_MTE3, 1 | (2 << 4) | (2 << 8));
  // ffts_cross_core_sync(PIPE_MTE3, 1 | (2 << 4) | (3 << 8));
#if __CCE_AICORE__ == 220
  SetCrossFlag<PIPE_MTE3>(2);
  SetCrossFlag<PIPE_MTE3>(3);
#else
  set_intra_block(PIPE_MTE3, 2);
  set_intra_block(PIPE_MTE3, 3);
#endif
```

```cpp
      pipe_barrier(PIPE_ALL);
      // Signal Cube that this workspace slot is free for reuse.
      // Flag (2+slot): slot 0 → flag 2, slot 1 → flag 3.
      // Cube is waiting on wait_flag_dev(2+slot) before writing the next chunk.
      // ffts_cross_core_sync(PIPE_MTE3, 1 | (2 << 4) | ((2 + slot) << 8));
#if __CCE_AICORE__ == 220
      SetCrossFlag<PIPE_MTE3>(2 + slot);
#else
      set_intra_block(PIPE_MTE3, 2 + slot);
#endif
```

## A3. `huawei-csl/megagdn-pto` — repo file listing (code + docs, archival output trees elided)

https://github.com/huawei-csl/megagdn-pto (branch `main`), listed via
`gh api repos/huawei-csl/megagdn-pto/git/trees/main?recursive=1` on 2026-10-20.

```
.clang-format
.github/skills/pre-commit-validation/SKILL.md
.github/skills/pto-kernel-compilation/SKILL.md
.github/workflows/build-single-kernels-on-a2a3.yml
.github/workflows/build-single-kernels-on-a5.yml
.github/workflows/pre-commit-check.yml
.gitignore
.gitlab-ci.yml
.gitmodules
.pre-commit-config.yaml
README.md
benchmarks/eval_acc/run_eval_suite.sh
benchmarks/eval_acc/run_lm_eval.py
benchmarks/kernel/bench_gdn_kernels.py
benchmarks/kernel/bench_kda_vs_gdn.py
benchmarks/kernel/bench_pto_pipeline_latency.py
benchmarks/vllm_prefill/benchmark_prefill.py
benchmarks/vllm_prefill/run_prefill_sweep.sh
blog/fig/eval_accuracy.png
blog/fig/kernel_stages_N16_L8192_H16.png
blog/fig/prefill_qwen36_35b_a3b_w8a8.png
blog/fig/prefill_qwen36_35b_a3b_w8a8_v019.png
blog/fig/torch_profiling.png
blog/mega_gdn_en.md
blog/mega_gdn_zh.md
docker/overrides/kv_cache_utils.py
docker/overrides/model_runner_v1.py
docker/overrides/worker_init.py
docker/overrides/worker_init_v19.py
docker/run_kimi_docker.sh
docker/start_sglang_ascend.sh
docker/start_vllm_ascend.sh
kernels/pto/chunk_cumsum.cpp
kernels/pto/chunk_h.cpp
kernels/pto/chunk_h_kda.cpp
kernels/pto/chunk_o.cpp
kernels/pto/chunk_o_kda.cpp
kernels/pto/gate_cumsum_kda.cpp
kernels/pto/include/kernel_utils.h
kernels/pto/kkt_kda.cpp
kernels/pto/mega_kernel.cpp
kernels/pto/mega_kernel_kda.cpp
kernels/pto/scaled_dot_kkt.cpp
kernels/pto/tri_inverse.cpp
kernels/pto/wy_fast.cpp
kernels/pto/wy_kda.cpp
kernels/triton_baseline/__init__.py
kernels/triton_baseline/fla_vendor/SOURCES.md
kernels/triton_baseline/fla_vendor/__init__.py
kernels/triton_baseline/fla_vendor/ascend_triton_utils.py
kernels/triton_baseline/fla_vendor/chunk.py
kernels/triton_baseline/fla_vendor/chunk_delta_h.py
kernels/triton_baseline/fla_vendor/chunk_o.py
kernels/triton_baseline/fla_vendor/chunk_scaled_dot_kkt.py
kernels/triton_baseline/fla_vendor/cumsum.py
kernels/triton_baseline/fla_vendor/solve_tril.py
kernels/triton_baseline/fla_vendor/utils.py
kernels/triton_baseline/fla_vendor/wy_fast.py
megagdn_pto/__init__.py
megagdn_pto/compile.py
megagdn_pto/fast_inverse.py
megagdn_pto/kda_kernel_libs.py
megagdn_pto/kda_mega_kernel.py
megagdn_pto/kernel_libs.py
megagdn_pto/mega_kernel.py
outputs/data/archive/...        (eval.json / *.jsonl result trees, many dirs — not source)
```

The Chinese blog states which primitive the megakernel relies on for the inter-stage barrier,
and points at the upstream PR:

https://github.com/huawei-csl/megagdn-pto/blob/main/blog/mega_gdn_zh.md

Author: Huawei Technologies Co., Ltd. Fetched 2026-10-20.

```
## 简单粗暴实现Megakernel

本文不去硬啃Prefill图模式的坑，改用更简单粗暴的方案：GDN 各阶段的源码只有几百行C++，把源码直接合并成一个NPU kernel函数，用熟悉的 `<<< >>>` 语法只 **launch 一次**。

跨阶段之间需要对所有核做同步，保证读写次序。这里用**PTO-ISA**新加的`TSyncAll`（见 [pto-isa PR](https://gitcode.com/cann/pto-isa/pull/878)）。

融合算子代码在 `megagdn-pto/kernels/pto/mega_kernel.cpp`。Megakernel的源码依然保持简短可读，并不复杂。`launch_mega_kernel` 入口只有几百行量级的代码。各阶段**复用**单算子的源文件，不需要复制黏贴。这是编译器支持的写法：一个 AICORE 函数可以调用另一个 AICORE 函数，类似 CUDA 的 `__forceinline__ __device__`。
```

---

## A4. `cann/pto-isa` PR 878 — `TSYNCALL`, the SOFTWARE (GM-counter) barrier

This is the single most load-bearing find for Topic A. It is an unbounded-depth barrier that
does not consume a hardware flagId at all, and it is the primitive megagdn-pto's blog points at.

https://gitcode.com/cann/pto-isa/pull/878

Title: `[WIP][Feature] TSYNCALL`. State: closed. Repo `cann/pto-isa`.
Assignees include WenboCodes, csjlchen, syfeng (Siyuan Feng), ChanKaLok, qukelin, Zhanghaijian,
linjiashu, bluesky901, zhoubotcam, SherwinBai. Fetched via
`https://gitcode.com/api/v5/repos/cann/pto-isa/pulls/878` on 2026-10-20.

PR body, verbatim:

```
## 描述

仿照asc 实现 TSYNCALL() 全核同步指令

支持：
1. 硬件FFTS实现同步，限制kernel 类型
2. 软件实现同步，不限制kernel 类型

## 关联的Issue
<!-- 如果这个PR是为了解决特定的Issue，请在这里提供Issue链接。-->
<!-- 如果这个PR是为了解决特定的问题单，请在这里描述问题单单号。-->

## 测试
<!--描述进行了哪些测试来验证你的改动。包括但不限于二级冒烟、算子泛化等。-->

## 文档更新
<!--如果这个PR包含文档的更新，请在这里指出。例如：更新了README.md文件。-->

## 类型标签
<!--  [x] 表示选中 -->
- [ ] Bug修复
- [x] 新特性
- [ ] 性能优化
- [ ] 文档更新
- [ ] 其他，请描述：
```

Files touched by the PR (from `https://gitcode.com/cann/pto-isa/pull/878.diff`):

```
docs/PTOISA_zh.md
docs/isa/README_zh.md
docs/isa/TSYNCALL_zh.md
docs/menu_apis.md
include/pto/common/cpu_stub.hpp
include/pto/common/kernel_meta.hpp
include/pto/common/pto_instr.hpp
include/pto/common/type.hpp
include/pto/npu/a2a3/TSync.hpp
include/pto/pto-inst.hpp
tests/npu/a2a3/src/st/CMakeLists.txt
tests/npu/a2a3/src/st/testcase/CMakeLists.txt
tests/npu/a2a3/src/st/testcase/tsyncall/CMakeLists.txt
tests/npu/a2a3/src/st/testcase/tsyncall/gen_data.py
tests/npu/a2a3/src/st/testcase/tsyncall/main.cpp
tests/npu/a2a3/src/st/testcase/tsyncall/make_mix_register_elf.py
tests/npu/a2a3/src/st/testcase/tsyncall/tsyncall_kernel.cpp
tests/npu/a2a3/src/st/testcase/tsyncall/tsyncall_mix_1_1_kernel.cpp
tests/npu/a2a3/src/st/testcase/tsyncall/tsyncall_mix_1_2_kernel.cpp
tests/npu/a2a3/src/st/testcase/tsyncall/tsyncall_mix_common.hpp
tests/npu/a2a3/src/st/testcase/tsyncall/tsyncall_soft_kernel.cpp
```

### A4.1 `docs/isa/TSYNCALL_zh.md` — the whole new doc file, verbatim

https://gitcode.com/cann/pto-isa/blob/master/docs/isa/TSYNCALL_zh.md (added by PR 878)

Author: Huawei Technologies Co., Ltd. / cann/pto-isa contributors. Fetched 2026-10-20.

````markdown
# TSYNCALL

## 简介

`TSYNCALL` 是 A2/A3 NPU 后端的跨核同步屏障，默认硬件路径语义对齐 AscendC `dav_c220` 的无参硬件 `SyncAll()`。

默认形式 `TSYNCALL()` 同步当前 kernel 内的 AIV cores。`TSYNCALL<false>()` 预留给 AIC/AIV 混合同步场景。软件形式 `TSYNCALL<TSyncAllMode::Soft>(...)` 使用 GM workspace 轮询实现 AIV-only barrier，不依赖 FFTS 调度。

## C++ 内建接口

声明于 `include/pto/common/pto_instr.hpp`：

```cpp
template <bool IsAIVOnly = true>
PTO_INST void TSYNCALL();

template <TSyncAllMode Mode, bool IsAIVOnly = true>
PTO_INST void TSYNCALL(__gm__ int32_t *gmWorkspace, __ubuf__ int32_t *ubWorkspace, int32_t usedCores = 0);
```

## 参数

- `gmWorkspace`: 软件模式使用的 GM workspace。调用前需要初始化为 0。
- `ubWorkspace`: 软件模式使用的 UB scratch，容量至少为 `usedCores * 8 * sizeof(int32_t)`。
- `usedCores`: 参与软件 barrier 的 AIV core 数。为 0 时使用 `get_block_num()`。

## 约束

- 当前实现仅覆盖 A2/A3 后端。
- 软件模式当前仅支持 AIV-only kernel。
- 软件模式要求所有参与 core 以相同顺序进入同一组 barrier；每个参与 core 在 `gmWorkspace` 中占用 8 个 `int32_t`，用于按 cache line 隔离同步计数。
- 软件模式只提供 barrier 到达语义。若 barrier 前后还需要观察其他 GM 数据，调用方仍需保证对应数据的 cache 可见性。
- 硬件 AIV-only `TSYNCALL()` 需要 kernel ELF 中带 `.ascend.meta.<kernel>_mix_aiv` metadata，使 runtime 按 `KERNEL_TYPE_MIX_AIV_1_0` 调度。
- `TSYNCALL` 不返回 `RecordEvent`，也不作为 `Event<SrcOp, DstOp>` 的依赖操作使用。
- 在 auto 模式下与现有同步指令保持一致，不直接发射硬件同步。
````

### A4.2 `include/pto/npu/a2a3/TSync.hpp` — the implementation, verbatim (the `+` side of the diff)

https://gitcode.com/cann/pto-isa/blob/master/include/pto/npu/a2a3/TSync.hpp (as changed by PR 878)

Author: Huawei Technologies Co., Ltd. / cann/pto-isa contributors. Fetched 2026-10-20 from
`https://gitcode.com/cann/pto-isa/pull/878.diff`.

First: the reserved flag-id constants. Note `SYNC_FLAG_ID_MAX = 16` and that 11-14 are the
barrier's own ids, so a user kernel on A2/A3 only has 0-10 free:

```cpp
constexpr uint16_t SYNC_AIC_FLAG = 11;
constexpr uint16_t SYNC_AIV_FLAG = 12;
constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
constexpr uint16_t SYNC_FLAG_ID_MAX = 16;
constexpr int32_t SYNCALL_SOFT_SLOT_INT32 = 8;
```

The hardware path (one FFTS flag per direction, exactly one Set + one Wait per call):

```cpp
template <bool IsAIVOnly = true>
PTO_INTERNAL void TSYNCALL_IMPL()
{
#ifndef __PTO_AUTO__
    pipe_barrier(PIPE_ALL);
    if constexpr (IsAIVOnly) {
#if defined(__DAV_VEC__)
        ffts_cross_core_sync(PIPE_MTE3, getFFTSMsg(0x0, SYNC_AIV_ONLY_ALL));
        wait_flag_dev(SYNC_AIV_ONLY_ALL);
#endif
        return;
    }

#if defined(__DAV_CUBE__)
    wait_flag_dev(SYNC_AIV_FLAG);
    ffts_cross_core_sync(PIPE_FIX, getFFTSMsg(0x0, SYNC_AIC_FLAG));
    wait_flag_dev(SYNC_AIC_FLAG);
    ffts_cross_core_sync(PIPE_MTE3, getFFTSMsg(0x2, SYNC_AIC_AIV_FLAG));
#elif defined(__DAV_VEC__)
    ffts_cross_core_sync(PIPE_MTE3, getFFTSMsg(0x2, SYNC_AIV_FLAG));
    wait_flag_dev(SYNC_AIC_AIV_FLAG);
#endif
#endif
}
```

The software path's GM/cache helpers — `dcci` + `dsb(DSB_DDR)` per cache line, one 8-int32
slot per participant:

```cpp
PTO_INTERNAL void TSYNCALL_SOFT_DCCI(__gm__ void *ptr)
{
    __asm__ __volatile__("");
    dcci(ptr, SINGLE_CACHE_LINE);
    __asm__ __volatile__("");
}

PTO_INTERNAL void TSYNCALL_SOFT_DCCI_RANGE(__gm__ int32_t *ptr, int32_t lines)
{
    for (int32_t i = 0; i < lines; ++i) {
        TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(ptr + i * SYNCALL_SOFT_SLOT_INT32));
    }
    dsb(DSB_DDR);
}

PTO_INTERNAL int32_t TSYNCALL_SOFT_GM_LOAD(__gm__ int32_t *src)
{
    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(src));
    dsb(DSB_DDR);
    return src[0];
}
```

Participant indexing for mix (AIC+AIV) kernels. AIC blocks occupy `[0, aicBlocks)`, AIV
sub-blocks occupy `[aicBlocks, aicBlocks + aicBlocks*aivRatio)`:

```cpp
PTO_INTERNAL int32_t TSYNCALL_GET_MIX_AIV_RATIO()
{
#if defined(__MIX_CORE_AIV_RATION__)
    return static_cast<int32_t>(__MIX_CORE_AIV_RATION__);
#elif defined(__DAV_VEC__)
    return static_cast<int32_t>(get_subblockdim());
#else
    return 1;
#endif
}

PTO_INTERNAL int32_t TSYNCALL_GET_MIX_AIC_BLOCKS()
{
#if defined(__MIX_CORE_AIC_BLOCKS__)
    return static_cast<int32_t>(__MIX_CORE_AIC_BLOCKS__);
#else
    return static_cast<int32_t>(get_block_num());
#endif
}

PTO_INTERNAL int32_t TSYNCALL_GET_MIX_PARTICIPANT_COUNT()
{
    return static_cast<int32_t>(TSYNCALL_GET_MIX_AIC_BLOCKS() * (1 + TSYNCALL_GET_MIX_AIV_RATIO()));
}

PTO_INTERNAL int32_t TSYNCALL_GET_MIX_PARTICIPANT_IDX()
{
#if defined(__DAV_VEC__)
    return static_cast<int32_t>(TSYNCALL_GET_MIX_AIC_BLOCKS() + get_block_idx() * get_subblockdim() +
                                get_subblockid());
#else
    return static_cast<int32_t>(get_block_idx());
#endif
}
```

The AIV-only software barrier. THIS IS THE ROTATION-FREE ANSWER: the per-core counter is
monotonically incremented (`curValue = ubWorkspace[0] + 1`) and every core spins until all
counters are `>= curValue`. There is no 15-deep limit and no flagId to run out of; the counter
is an `int32_t` in GM:

```cpp
template <bool IsAIVOnly = true>
PTO_INTERNAL void TSYNCALL_SOFT_IMPL(__gm__ int32_t *gmWorkspace, __ubuf__ int32_t *ubWorkspace,
                                     int32_t usedCores = 0)
{
#ifndef __PTO_AUTO__
    PTO_STATIC_ASSERT(IsAIVOnly, "Software TSYNCALL currently only supports AIV-only kernels.");
    pipe_barrier(PIPE_ALL);

#if defined(__DAV_VEC__)
    const int32_t totalBlocks = (usedCores != 0) ? usedCores : static_cast<int32_t>(get_block_num());
    const int32_t blockIdx = static_cast<int32_t>(get_block_idx());
    __gm__ int32_t *localSyncGM = gmWorkspace + blockIdx * SYNCALL_SOFT_SLOT_INT32;

    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(localSyncGM));
    copy_gm_to_ubuf(static_cast<__ubuf__ void *>(ubWorkspace), static_cast<__gm__ void *>(localSyncGM), 0, 1, 1, 0,
                    0);
    set_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);
    wait_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);

    const int32_t curValue = ubWorkspace[0] + 1;
    ubWorkspace[0] = curValue;

    set_flag(PIPE_S, PIPE_MTE3, EVENT_ID0);
    wait_flag(PIPE_S, PIPE_MTE3, EVENT_ID0);
    copy_ubuf_to_gm(static_cast<__gm__ void *>(localSyncGM), static_cast<__ubuf__ void *>(ubWorkspace), 0, 1, 1, 0,
                    0);
    set_flag(PIPE_MTE3, PIPE_MTE2, EVENT_ID0);
    wait_flag(PIPE_MTE3, PIPE_MTE2, EVENT_ID0);
    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(localSyncGM));
    dsb(DSB_DDR);

    while (true) {
        TSYNCALL_SOFT_DCCI_RANGE(gmWorkspace, totalBlocks);
        copy_gm_to_ubuf(static_cast<__ubuf__ void *>(ubWorkspace), static_cast<__gm__ void *>(gmWorkspace), 0, 1,
                        totalBlocks, 0, 0);
        set_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);
        wait_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);

        int32_t readyCount = 0;
        for (int32_t i = 0; i < totalBlocks; ++i) {
            if (ubWorkspace[i * SYNCALL_SOFT_SLOT_INT32] >= curValue) {
                ++readyCount;
            }
        }
        pipe_barrier(PIPE_ALL);
        if (readyCount >= totalBlocks) {
            break;
        }
    }
#endif
    pipe_barrier(PIPE_ALL);
#endif
}
```

The mix (AIC+AIV) software barrier. The AIC side cannot use UB, so it writes its counter via
L1 (`create_cbuf_matrix` + `copy_cbuf_to_gm`) and polls GM scalar-wise:

```cpp
PTO_INTERNAL void TSYNCALL_SOFT_AIC_STORE_SLOT(__gm__ int32_t *dst, __cbuf__ int32_t *l1Workspace, int32_t value)
{
    constexpr int64_t repeatConfig = (static_cast<int64_t>(1) << 16) | 1;
    create_cbuf_matrix(l1Workspace, repeatConfig, static_cast<uint32_t>(value));
    pipe_barrier(PIPE_ALL);
    copy_cbuf_to_gm(static_cast<__gm__ void *>(dst), static_cast<__cbuf__ void *>(l1Workspace), 0, 1, 1, 0, 0);
    pipe_barrier(PIPE_ALL);
    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(dst));
    dsb(DSB_DDR);
}

template <bool IsAIVOnly = false>
PTO_INTERNAL void TSYNCALL_SOFT_MIX_IMPL(__gm__ int32_t *gmWorkspace, __ubuf__ int32_t *ubWorkspace,
                                         __cbuf__ int32_t *l1Workspace, int32_t usedCores = 0)
{
#ifndef __PTO_AUTO__
    PTO_STATIC_ASSERT(!IsAIVOnly, "Software TSYNCALL mix overload is for AIC/AIV kernels.");
    pipe_barrier(PIPE_ALL);

#if defined(__DAV_CUBE__)
    (void)ubWorkspace;
    const int32_t totalBlocks = (usedCores != 0) ? usedCores : TSYNCALL_GET_MIX_PARTICIPANT_COUNT();
    const int32_t blockIdx = TSYNCALL_GET_MIX_PARTICIPANT_IDX();
    __gm__ int32_t *localSyncGM = gmWorkspace + blockIdx * SYNCALL_SOFT_SLOT_INT32;

    const int32_t curValue = TSYNCALL_SOFT_GM_LOAD(localSyncGM) + 1;
    TSYNCALL_SOFT_AIC_STORE_SLOT(localSyncGM, l1Workspace, curValue);

    while (true) {
        int32_t readyCount = 0;
        for (int32_t i = 0; i < totalBlocks; ++i) {
            __gm__ int32_t *syncGM = gmWorkspace + i * SYNCALL_SOFT_SLOT_INT32;
            if (TSYNCALL_SOFT_GM_LOAD(syncGM) >= curValue) {
                ++readyCount;
            }
        }
        pipe_barrier(PIPE_ALL);
        if (readyCount >= totalBlocks) {
            break;
        }
    }
#elif defined(__DAV_VEC__)
    (void)l1Workspace;
    const int32_t totalBlocks = (usedCores != 0) ? usedCores : TSYNCALL_GET_MIX_PARTICIPANT_COUNT();
    const int32_t blockIdx = TSYNCALL_GET_MIX_PARTICIPANT_IDX();
    __gm__ int32_t *localSyncGM = gmWorkspace + blockIdx * SYNCALL_SOFT_SLOT_INT32;

    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(localSyncGM));
    dsb(DSB_DDR);
    copy_gm_to_ubuf(static_cast<__ubuf__ void *>(ubWorkspace), static_cast<__gm__ void *>(localSyncGM), 0, 1, 1, 0,
                    0);
    set_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);
    wait_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);

    const int32_t curValue = ubWorkspace[0] + 1;
    ubWorkspace[0] = curValue;

    set_flag(PIPE_S, PIPE_MTE3, EVENT_ID0);
    wait_flag(PIPE_S, PIPE_MTE3, EVENT_ID0);
    copy_ubuf_to_gm(static_cast<__gm__ void *>(localSyncGM), static_cast<__ubuf__ void *>(ubWorkspace), 0, 1, 1, 0,
                    0);
    set_flag(PIPE_MTE3, PIPE_MTE2, EVENT_ID0);
    wait_flag(PIPE_MTE3, PIPE_MTE2, EVENT_ID0);
    TSYNCALL_SOFT_DCCI(static_cast<__gm__ void *>(localSyncGM));
    dsb(DSB_DDR);

    while (true) {
        TSYNCALL_SOFT_DCCI_RANGE(gmWorkspace, totalBlocks);
        copy_gm_to_ubuf(static_cast<__ubuf__ void *>(ubWorkspace), static_cast<__gm__ void *>(gmWorkspace), 0, 1,
                        totalBlocks, 0, 0);
        set_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);
        wait_flag(PIPE_MTE2, PIPE_S, EVENT_ID0);

        int32_t readyCount = 0;
        for (int32_t i = 0; i < totalBlocks; ++i) {
            if (ubWorkspace[i * SYNCALL_SOFT_SLOT_INT32] >= curValue) {
                ++readyCount;
            }
        }
        pipe_barrier(PIPE_ALL);
        if (readyCount >= totalBlocks) {
            break;
        }
    }
#endif
    pipe_barrier(PIPE_ALL);
#endif
}
```

### A4.3 `include/pto/common/type.hpp` and `pto_instr.hpp` — the public surface

```cpp
enum class TSyncAllMode : uint8_t
{
    Hard = 0,
    Soft = 1,
};
```

```cpp
template <bool IsAIVOnly = true>
PTO_INST void TSYNCALL()
{
#if defined(PTO_NPU_ARCH_A2A3) || defined(__CPU_SIM)
    TSYNCALL_IMPL<IsAIVOnly>();
#else
    PTO_STATIC_ASSERT(IsAIVOnly != IsAIVOnly, "TSYNCALL currently only supports the A2/A3 backend.");
#endif
}

template <TSyncAllMode Mode, bool IsAIVOnly = true>
PTO_INST void TSYNCALL(__gm__ int32_t *gmWorkspace, __ubuf__ int32_t *ubWorkspace, int32_t usedCores = 0)
{
#if defined(PTO_NPU_ARCH_A2A3) || defined(__CPU_SIM)
    if constexpr (Mode == TSyncAllMode::Hard) {
        (void)gmWorkspace;
        (void)ubWorkspace;
        (void)usedCores;
        TSYNCALL_IMPL<IsAIVOnly>();
    } else {
        TSYNCALL_SOFT_IMPL<IsAIVOnly>(gmWorkspace, ubWorkspace, usedCores);
    }
#else
    PTO_STATIC_ASSERT(Mode != Mode, "TSYNCALL currently only supports the A2/A3 backend.");
#endif
}

template <TSyncAllMode Mode, bool IsAIVOnly = false>
PTO_INST void TSYNCALL(__gm__ int32_t *gmWorkspace, __ubuf__ int32_t *ubWorkspace, __cbuf__ int32_t *l1Workspace,
                       int32_t usedCores = 0)
{
#if defined(PTO_NPU_ARCH_A2A3) || defined(__CPU_SIM)
    if constexpr (Mode == TSyncAllMode::Hard) {
        (void)gmWorkspace;
        (void)ubWorkspace;
        (void)l1Workspace;
        (void)usedCores;
        TSYNCALL_IMPL<IsAIVOnly>();
    } else {
        TSYNCALL_SOFT_MIX_IMPL<IsAIVOnly>(gmWorkspace, ubWorkspace, l1Workspace, usedCores);
    }
#else
    PTO_STATIC_ASSERT(Mode != Mode, "TSYNCALL currently only supports the A2/A3 backend.");
#endif
}
```

### A4.4 `include/pto/common/kernel_meta.hpp` — the ELF metadata the hardware barrier requires

The hardware AIV-only `TSYNCALL()` only works if the kernel ELF carries
`.ascend.meta.<kernel>_mix_aiv`. This is the whole new file:

```cpp
#ifndef PTO_COMMON_KERNEL_META_HPP
#define PTO_COMMON_KERNEL_META_HPP

#include <stdint.h>

namespace pto {
namespace detail {
constexpr uint16_t PTO_META_F_TYPE_KTYPE = 1;
constexpr uint16_t PTO_META_F_TYPE_MIX_TASK_RATION = 3;
constexpr uint32_t PTO_META_K_TYPE_MIX_AIC_MAIN = 4;
constexpr uint32_t PTO_META_K_TYPE_MIX_AIV_MAIN = 5;

struct PtoMetaBaseTlv {
    uint16_t type;
    uint16_t len;
};

struct PtoMetaKType {
    PtoMetaBaseTlv head;
    uint32_t ktype;
};

struct PtoMetaMixCoreType {
    PtoMetaBaseTlv head;
    uint16_t taskRation0;
    uint16_t taskRation1;
};

struct PtoMetaFunLevelMixCoreType {
    PtoMetaKType ktypeMeta;
    PtoMetaMixCoreType mixCoreType;
};
} // namespace detail
} // namespace pto

#define PTO_DETAIL_CONCAT_INNER(a, b) a##b
#define PTO_DETAIL_CONCAT(a, b) PTO_DETAIL_CONCAT_INNER(a, b)
#define PTO_A2A3_TSYNCALL_AIV_KERNEL_META(kernelName)                                                              \
    static const ::pto::detail::PtoMetaFunLevelMixCoreType                                                          \
        PTO_DETAIL_CONCAT(g_pto_tsyncall_aiv_meta_, __COUNTER__)                                                    \
            __attribute__((used, section(".ascend.meta." #kernelName))) =                                           \
                {{{::pto::detail::PTO_META_F_TYPE_KTYPE, sizeof(uint32_t)},                                         \
                  ::pto::detail::PTO_META_K_TYPE_MIX_AIV_MAIN},                                                     \
                 {{::pto::detail::PTO_META_F_TYPE_MIX_TASK_RATION, sizeof(uint32_t)}, 0, 1}}

#define PTO_A2A3_TSYNCALL_MIX_AIC_KERNEL_META(kernelName, aicRatio, aivRatio)                                      \
    static const ::pto::detail::PtoMetaFunLevelMixCoreType                                                          \
        PTO_DETAIL_CONCAT(g_pto_tsyncall_mix_aic_meta_, __COUNTER__)                                                \
            __attribute__((used, section(".ascend.meta." #kernelName))) =                                           \
                {{{::pto::detail::PTO_META_F_TYPE_KTYPE, sizeof(uint32_t)},                                         \
                  ::pto::detail::PTO_META_K_TYPE_MIX_AIC_MAIN},                                                     \
                 {{::pto::detail::PTO_META_F_TYPE_MIX_TASK_RATION, sizeof(uint32_t)}, aicRatio, aivRatio}}

#endif
```

### A4.5 `tests/.../tsyncall_soft_kernel.cpp` — THREE barriers back-to-back in one kernel

Proof that the software barrier is re-entrant with no reset and no flag bookkeeping. Note
`kBlockCount = 48`, `kInt32PerCacheLine = 8`, and that `syncWorkspace` is passed unchanged
across all three calls:

```cpp
#include <pto/pto-inst.hpp>
#include "acl/acl.h"

using namespace pto;

constexpr int32_t kBlockCount = 48;
constexpr int32_t kInt32PerCacheLine = 8;
constexpr uint64_t kFlagUbAddr = 0x0;
constexpr uint64_t kReadUbAddr = 0x1000;
constexpr uint64_t kOutUbAddr = 0x2000;
constexpr uint64_t kSoftSyncUbAddr = 0x3000;

PTO_INTERNAL void StoreInt32Line(__gm__ int32_t *dst, int32_t value, uint64_t ubAddr)
{
    __ubuf__ int32_t *ub = reinterpret_cast<__ubuf__ int32_t *>(ubAddr);
    ub[0] = value;
    pipe_barrier(PIPE_ALL);
    copy_ubuf_to_gm(static_cast<__gm__ void *>(dst), static_cast<__ubuf__ void *>(ub), 0, 1, 1, 0, 0);
    pipe_barrier(PIPE_ALL);
}

PTO_INTERNAL void InvalidateInt32Lines(__gm__ int32_t *addr, int32_t lines)
{
    for (int32_t i = 0; i < lines; ++i) {
        __asm__ __volatile__("");
        dcci(static_cast<__gm__ void *>(addr + i * kInt32PerCacheLine), SINGLE_CACHE_LINE);
        __asm__ __volatile__("");
    }
    dsb(DSB_DDR);
}

extern "C" __global__ AICORE void RunSoftTSyncAll(__gm__ int32_t __out__ *out, __gm__ int32_t __out__ *flags,
                                                  __gm__ int32_t __out__ *syncWorkspace)
{
    const int32_t idx = block_idx;
    StoreInt32Line(flags + idx * kInt32PerCacheLine, idx + 1, kFlagUbAddr);

    __ubuf__ int32_t *syncUb = reinterpret_cast<__ubuf__ int32_t *>(kSoftSyncUbAddr);
    TSYNCALL<TSyncAllMode::Soft>(syncWorkspace, syncUb, kBlockCount);

    __ubuf__ int32_t *readUb = reinterpret_cast<__ubuf__ int32_t *>(kReadUbAddr);
    InvalidateInt32Lines(flags, kBlockCount);
    copy_gm_to_ubuf(static_cast<__ubuf__ void *>(readUb), static_cast<__gm__ void *>(flags), 0, 1, kBlockCount, 0, 0);
    pipe_barrier(PIPE_ALL);

    int32_t allFirstVisible = 1;
    for (int32_t i = 0; i < kBlockCount; ++i) {
        if (readUb[i * kInt32PerCacheLine] != i + 1) {
            allFirstVisible = 0;
        }
    }

    TSYNCALL<TSyncAllMode::Soft>(syncWorkspace, syncUb, kBlockCount);

    StoreInt32Line(flags + idx * kInt32PerCacheLine, (idx + 1) * 2, kFlagUbAddr);
    TSYNCALL<TSyncAllMode::Soft>(syncWorkspace, syncUb, kBlockCount);

    InvalidateInt32Lines(flags, kBlockCount);
    copy_gm_to_ubuf(static_cast<__ubuf__ void *>(readUb), static_cast<__gm__ void *>(flags), 0, 1, kBlockCount, 0, 0);
    pipe_barrier(PIPE_ALL);

    int32_t allSecondVisible = 1;
    for (int32_t i = 0; i < kBlockCount; ++i) {
        if (readUb[i * kInt32PerCacheLine] != (i + 1) * 2) {
            allSecondVisible = 0;
        }
    }

    StoreInt32Line(out + idx * kInt32PerCacheLine, allFirstVisible & allSecondVisible, kOutUbAddr);
}

void LaunchSoftTSyncAll(int32_t *out, int32_t *flags, int32_t *syncWorkspace, void *stream)
{
    RunSoftTSyncAll<<<48, nullptr, stream>>>(out, flags, syncWorkspace);
}
```

The hardware-path equivalent, showing the `PTO_A2A3_TSYNCALL_AIV_KERNEL_META` requirement and
the `_mix_aiv` name suffix on the kernel symbol:

```cpp
PTO_A2A3_TSYNCALL_AIV_KERNEL_META(RunTSyncAll_mix_aiv);

extern "C" __global__ AICORE void RunTSyncAll_mix_aiv(__gm__ uint64_t __in__ *fftsAddr, __gm__ int32_t __out__ *out,
                                                      __gm__ int32_t __out__ *flags)
{
    set_ffts_base_addr(reinterpret_cast<uint64_t>(fftsAddr));

    const int32_t idx = block_idx;
    StoreInt32Line(flags + idx * kInt32PerCacheLine, idx + 1, kFlagUbAddr);

    TSYNCALL();
```

And the mix test body, which alternates hard and soft at compile time and runs THREE barriers:

```cpp
template <int32_t TotalParticipants, bool UseSoft>
PTO_INTERNAL void RunMixSyncAllBody(__gm__ uint64_t *fftsAddr, __gm__ int32_t *out, __gm__ int32_t *flags,
                                    __gm__ int32_t *syncWorkspace)
{
    set_ffts_base_addr(reinterpret_cast<uint64_t>(fftsAddr));

    const int32_t idx = GetMixLogicalIdx();
    StoreMixInt32Line(flags + idx * kInt32PerCacheLine, idx + 1, kMixFlagUbAddr, kMixFlagL1Addr);

    if constexpr (UseSoft) {
        __ubuf__ int32_t *syncUb = reinterpret_cast<__ubuf__ int32_t *>(kMixSoftUbAddr);
        __cbuf__ int32_t *syncL1 = reinterpret_cast<__cbuf__ int32_t *>(kMixSoftL1Addr);
        TSYNCALL<TSyncAllMode::Soft, false>(syncWorkspace, syncUb, syncL1, TotalParticipants);
    } else {
        TSYNCALL<false>();
    }

    const int32_t allFirstVisible = CheckMixFlags(flags, TotalParticipants, kMixReadUbAddr, kMixReadL1Addr, 1);

    if constexpr (UseSoft) {
        __ubuf__ int32_t *syncUb = reinterpret_cast<__ubuf__ int32_t *>(kMixSoftUbAddr);
        __cbuf__ int32_t *syncL1 = reinterpret_cast<__cbuf__ int32_t *>(kMixSoftL1Addr);
        TSYNCALL<TSyncAllMode::Soft, false>(syncWorkspace, syncUb, syncL1, TotalParticipants);
    } else {
        TSYNCALL<false>();
    }

    StoreMixInt32Line(flags + idx * kInt32PerCacheLine, (idx + 1) * 2, kMixFlagUbAddr, kMixFlagL1Addr);

    if constexpr (UseSoft) {
        __ubuf__ int32_t *syncUb = reinterpret_cast<__ubuf__ int32_t *>(kMixSoftUbAddr);
        __cbuf__ int32_t *syncL1 = reinterpret_cast<__cbuf__ int32_t *>(kMixSoftL1Addr);
        TSYNCALL<TSyncAllMode::Soft, false>(syncWorkspace, syncUb, syncL1, TotalParticipants);
    } else {
        TSYNCALL<false>();
    }

    const int32_t allSecondVisible = CheckMixFlags(flags, TotalParticipants, kMixReadUbAddr, kMixReadL1Addr, 2);
    StoreMixInt32Line(out + idx * kInt32PerCacheLine, allFirstVisible & allSecondVisible, kMixOutUbAddr, kMixOutL1Addr);
}
```

---

## A5. `cann/graph-autofusion` SuperKernel — device-side source

Repo tree walked via `https://gitcode.com/api/v5/repos/cann/graph-autofusion/git/trees/<sha>`
on 2026-10-20. Top level is: `.claude`, `.gitcode`, `.opencode`, `autofuse`, `cmake`, `docs`,
`model_specialization`, `multistream`, `scripts`, `super_kernel`.

The device-side sources live in `super_kernel/kernel/`:

```
super_kernel/cmake/aot_host.cmake
super_kernel/docs/developer_guide.md
super_kernel/docs/images/ICachePreload优化.excalidraw
super_kernel/docs/images/ICachePreload优化.svg
super_kernel/docs/images/super_kernel示意图.svg
super_kernel/docs/images/superkernel示意图.excalidraw
super_kernel/docs/images/同步事件.excalidraw
super_kernel/docs/images/同步事件.svg
super_kernel/docs/images/子kernel拆分.excalidraw
super_kernel/docs/images/子kernel拆分.svg
super_kernel/include/super_kernel/super_kernel.h
super_kernel/kernel/CMakeLists.txt
super_kernel/kernel/ascendc_compat/bits/floatn.h
super_kernel/kernel/sk_entry.asc
super_kernel/kernel/sk_flag_diag.h
super_kernel/kernel/sk_scope_kernel.asc
super_kernel/scripts/gen_sk_entry_stub.py
super_kernel/src/aot/sk_candidate_heap.{cpp,h}
super_kernel/src/aot/sk_common.{cpp,h}
super_kernel/src/aot/sk_dfx_exception_handler.{cpp,h}
super_kernel/src/aot/sk_dump_json.{cpp,h}
super_kernel/src/aot/sk_event_recorder.{cpp,h}
super_kernel/src/aot/sk_file_guard.h
super_kernel/src/aot/sk_graph.{cpp,h}
super_kernel/src/aot/sk_lock_detector.{cpp,h}
super_kernel/src/aot/sk_log.{cpp,h}
super_kernel/src/aot/sk_node.{cpp,h}
super_kernel/src/aot/common/pattern_common.{cpp,h}
super_kernel/src/jit/superkernel/*.py
super_kernel/tests/st/data/test_sk_*/expect_sk_code.cc     (golden generated device code)
```

### A5.1 `super_kernel/kernel/sk_flag_diag.h` — AUTHORITATIVE on the 15-deep counter; sweeps flagIds 0..10

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/kernel/sk_flag_diag.h

Author: Huawei Technologies Co., Ltd., copyright header 2025. Repo `cann/graph-autofusion`,
branch `master`. Fetched 2026-10-20.

This file is a hardware diagnostic that deliberately drives every flagId to saturation. The
loop bounds ARE the documentation: `for (int i = 0; i <= 10; i++)` over flagIds, and
`for (int j = 0; j < 15; j++)` over outstanding Sets of one flagId. Whole file, verbatim:

```cpp
/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Source Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, EITHER EXPRESS OR
 * IMPLIED, INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE. See
 * LICENSE in the root of the software repository for the full text of the License.
 */

#ifndef SK_FLAG_DIAG_H_
#define SK_FLAG_DIAG_H_

#include "kernel_operator.h"

inline __aicore__ void send_all_flag_aic_aiv(void) {
  if ASCEND_IS_AIC {
    for (int i = 0; i <= 10; i++) {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(i);
      }
    }
  }
}

inline __aicore__ void wait_all_flag_aic_aiv(void) {
  if ASCEND_IS_AIV {
    for (int i = 0; i <= 10; i++) {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreWaitFlag(i);
      }
    }
  }
}

inline __aicore__ void send_all_flag_aiv_aic(void) {
  if ASCEND_IS_AIV {
    for (int i = 0; i <= 10; i++) {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreSetFlag<0x2, PIPE_MTE3>(i);
      }
    }
  }
}

inline __aicore__ void wait_all_flag_aiv_aic(void) {
  if ASCEND_IS_AIC {
    for (int i = 0; i <= 10; i++) {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreWaitFlag(i);
      }
    }
  }
}

#if defined(__NPU_ARCH__) && __NPU_ARCH__ == 3510
constexpr int INTRA_FLAG_ID_OFFSET = 16;

template <pipe_t aic_pipe, pipe_t aiv_pipe>
inline __aicore__ void test_intra_core_sync_flag_pair(int flag_id) {
  // AIC -> AIV0/AIV1: AIC flag_id and flag_id + 16 map to the same
  // flag_id on AIV0 and AIV1 respectively.
  AscendC::SyncAll<false>();
  if ASCEND_IS_AIC {
    for (int j = 0; j < 15; j++) {
      AscendC::CrossCoreSetFlag<0x4, aic_pipe>(flag_id);
      AscendC::CrossCoreSetFlag<0x4, aic_pipe>(flag_id + INTRA_FLAG_ID_OFFSET);
    }
  }
  AscendC::SyncAll<false>();
  if ASCEND_IS_AIV {
    for (int j = 0; j < 15; j++) {
      AscendC::CrossCoreWaitFlag<0x4, aiv_pipe>(flag_id);
    }
  }

  // AIV0/AIV1 -> AIC: each AIV sets flag_id, which maps to the AIC
  // flag_id and flag_id + 16 wait slots respectively.
  AscendC::SyncAll<false>();
  if ASCEND_IS_AIV {
    for (int j = 0; j < 15; j++) {
      AscendC::CrossCoreSetFlag<0x4, aiv_pipe>(flag_id);
    }
  }
  AscendC::SyncAll<false>();
  if ASCEND_IS_AIC {
    for (int j = 0; j < 15; j++) {
      AscendC::CrossCoreWaitFlag<0x4, aic_pipe>(flag_id);
      AscendC::CrossCoreWaitFlag<0x4, aic_pipe>(flag_id + INTRA_FLAG_ID_OFFSET);
    }
  }
}

inline __aicore__ void test_intra_core_sync_flag(int flag_id) {
  // The eight pairs cover every valid AIC and AIV pipe once as both a
  // producer and consumer without enumerating redundant pipe pairs.
  test_intra_core_sync_flag_pair<PIPE_S, PIPE_S>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_M, PIPE_S>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_MTE1, PIPE_S>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_MTE2, PIPE_S>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_FIX, PIPE_S>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_FIX, PIPE_MTE2>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_FIX, PIPE_MTE3>(flag_id);
  test_intra_core_sync_flag_pair<PIPE_FIX, PIPE_V>(flag_id);
}

inline __aicore__ void test_intra_core_sync_flags(int flag_id = -1) {
  if (flag_id >= 0) {
    if (flag_id <= 10) {
      test_intra_core_sync_flag(flag_id);
    }
    return;
  }

  for (int i = 0; i <= 10; i++) {
    test_intra_core_sync_flag(i);
  }
}
#endif

inline __aicore__ void test_cross_core_sync_flags(int flag_id = -1) {
  if (flag_id >= 0 && flag_id <= 15) {
    // only diag one single event id
    // AIC -> AIV diag
    AscendC::SyncAll<false>();
    if ASCEND_IS_AIC {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(flag_id);
      }
    }
    AscendC::SyncAll<false>();
    if ASCEND_IS_AIV {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreWaitFlag(flag_id);
      }
    }

    // AIV -> AIC diag
    AscendC::SyncAll<false>();
    if ASCEND_IS_AIV {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreSetFlag<0x2, PIPE_MTE3>(flag_id);
      }
    }
    AscendC::SyncAll<false>();
    if ASCEND_IS_AIC {
      for (int j = 0; j < 15; j++) {
        AscendC::CrossCoreWaitFlag(flag_id);
      }
    }
  } else {
    // AIC -> AIV
    AscendC::SyncAll<false>();
    send_all_flag_aic_aiv();
    AscendC::SyncAll<false>();
    wait_all_flag_aic_aiv();

    // AIV -> AIC
    AscendC::SyncAll<false>();
    send_all_flag_aiv_aic();
    AscendC::SyncAll<false>();
    wait_all_flag_aiv_aic();
  }
#if defined(__NPU_ARCH__) && __NPU_ARCH__ == 3510
  test_intra_core_sync_flags(flag_id);
#endif
}

#endif  // SK_FLAG_DIAG_H_
```

Four things to take from this file:
1. flagId domain is `0 <= i <= 10` on both A2/A3 and A5 for cross-core Sets.
2. Exactly 15 Sets per flagId are legal before a Wait must drain them; the diag saturates the
   counter and then drains it with exactly 15 Waits.
3. **A `SyncAll<false>()` is placed between the Set burst and the Wait burst.** The Sets and the
   Waits are on different cores, so without the barrier the diagnostic would race; this is the
   same discipline the megakernel uses at stage boundaries.
4. On A5 (`__NPU_ARCH__ == 3510`) there is a second, *intra*-core flag space with
   `INTRA_FLAG_ID_OFFSET = 16`: AIC's `flag_id` and `flag_id + 16` map onto AIV0's and AIV1's
   `flag_id` respectively. That offset-16 trick is exactly what megagdn-pto's
   `SignalBothVecOnA5` / `WaitBothVecOnA5` implement.

### A5.2 `super_kernel/kernel/sk_entry.asc` — how flags are NOT rotated between fused sub-kernels

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/kernel/sk_entry.asc

Author: Huawei Technologies Co., Ltd. Repo `cann/graph-autofusion`, branch `master`. Fetched 2026-10-20.

The barrier the SuperKernel runs between fused sub-kernels. It uses ONLY the four reserved
AscendC flag ids — `AscendC::SYNC_AIC_FLAG`, `SYNC_AIV_FLAG`, `SYNC_AIC_AIV_FLAG`,
`SYNC_AIV_ONLY_ALL` — in strict one-Set/one-Wait pairs. There is no rotation and no modulo:

```cpp
template <uint8_t aic, uint8_t aiv>
__aicore__ inline void FullCoreSyncImpl() {
  if constexpr (aic == 1 && aiv == 0) {
    AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(AscendC::SYNC_AIC_FLAG);
    AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_FLAG);
  } else if constexpr (aic == 0 && aiv == 1) {
    AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(AscendC::SYNC_AIV_ONLY_ALL);
    AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_ONLY_ALL);
  } else {
    if ASCEND_IS_AIC {
      AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(AscendC::SYNC_AIC_FLAG);
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_FLAG);
      AscendC::CrossCoreSetFlag<0x02, PIPE_FIX>(AscendC::SYNC_AIC_AIV_FLAG);
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_FLAG);
    }
    if ASCEND_IS_AIV {
      AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(AscendC::SYNC_AIV_ONLY_ALL);
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_ONLY_ALL);
      AscendC::CrossCoreSetFlag<0x02, PIPE_MTE3>(AscendC::SYNC_AIV_FLAG);
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_AIV_FLAG);
    }
  }
}
```

The finer-grained variant, selected per-task from a GM task descriptor. `SkCoreSyncType`
decomposes the barrier into separate Set and Wait halves so a producer sub-kernel can Set and
a later consumer sub-kernel can Wait — the Set and the Wait live in *different* fused stages,
yet still on the same four reserved flagIds:

```cpp
template <uint8_t aic, uint8_t aiv>
__aicore__ inline void AutoCoreSyncImpl(SkCoreSyncType syncType) {
  switch (syncType) {
    case SkCoreSyncType::CROSS_SYNC_AIC_TO_AIC:
      if ASCEND_IS_AIC {
        AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(AscendC::SYNC_AIC_FLAG);
        AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_FLAG);
      }
      return;
    case SkCoreSyncType::CROSS_SYNC_AIV_TO_AIV:
      if ASCEND_IS_AIV {
        AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(AscendC::SYNC_AIV_ONLY_ALL);
        AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_ONLY_ALL);
      }
      return;
    case SkCoreSyncType::INTER_SYNC_SET_AIC_TO_AIV:
      if ASCEND_IS_AIC {
        AscendC::CrossCoreSetFlag<0x02, PIPE_FIX>(AscendC::SYNC_AIC_AIV_FLAG);
      }
      return;
    case SkCoreSyncType::INTER_SYNC_SET_AIV_TO_AIC:
      if ASCEND_IS_AIV {
        AscendC::CrossCoreSetFlag<0x02, PIPE_MTE3>(AscendC::SYNC_AIV_FLAG);
      }
      return;
    case SkCoreSyncType::INTER_SYNC_WAIT_AIC_TO_AIV:
      if ASCEND_IS_AIV {
        AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_AIV_FLAG);
      }
      return;
    case SkCoreSyncType::INTER_SYNC_WAIT_AIV_TO_AIC:
      if ASCEND_IS_AIC {
        AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_FLAG);
      }
      return;
    case SkCoreSyncType::ALL_SYNC:
      FullCoreSyncImpl<aic, aiv>();
      return;
    default:
      AscendC::Trap();
      return;
  }
}
```

The "early start" overload, which lets a bitmask select which halves to emit. Note
`SkEarlyStartMask` gives 8 independent Set/Wait halves over the same four flagIds:

```cpp
template <uint8_t aic, uint8_t aiv>
__aicore__ inline void AutoCoreSyncImpl(SkCoreSyncType syncType, uint8_t numBlocks, uint64_t syncConfig) {
  if (syncConfig == 0) {
    AutoCoreSyncImpl<aic, aiv>(syncType);
    return;
  }

  if (AscendC::GetBlockIdx() < numBlocks) {
    return;
  }

  if ASCEND_IS_AIC {
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIC_TO_AIC_SET)) != 0) {
      AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(AscendC::SYNC_AIC_FLAG);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIC_TO_AIC_WAIT)) != 0) {
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_FLAG);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIC_TO_AIV_SET)) != 0) {
      AscendC::CrossCoreSetFlag<0x02, PIPE_FIX>(AscendC::SYNC_AIC_AIV_FLAG);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIV_TO_AIC_WAIT)) != 0) {
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_FLAG);
    }
  }

  if ASCEND_IS_AIV {
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIV_TO_AIV_SET)) != 0) {
      AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(AscendC::SYNC_AIV_ONLY_ALL);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIV_TO_AIV_WAIT)) != 0) {
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIV_ONLY_ALL);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIV_TO_AIC_SET)) != 0) {
      AscendC::CrossCoreSetFlag<0x02, PIPE_MTE3>(AscendC::SYNC_AIV_FLAG);
    }
    if ((syncConfig & static_cast<uint64_t>(SkEarlyStartMask::AIC_TO_AIV_WAIT)) != 0) {
      AscendC::CrossCoreWaitFlag(AscendC::SYNC_AIC_AIV_FLAG);
    }
  }
}
```

### A5.3 `sk_entry.asc` — `SkMemoryWaitFlag` / GM-counter waits (Notify / Wait / RESET)

This is the second, flag-free synchronisation channel in the SuperKernel: a 64-bit GM word per
event, written by `NotifyFunc`, spun on by `WaitFunc`, and — crucially for the question of
"how are flags reset between fused sub-kernels" — **reset by `ResetFunc`**. The reset is of the
GM counter, not of a hardware flag; the hardware flags are never reset, only balanced.

```cpp
template <bool aic_flag>
__aicore__ inline void NotifyFunc(GM_ADDR param, uint64_t value) {
  if constexpr (aic_flag) {
    if (get_block_idx() == 0) {
      __gm__ uint64_t *notifyLock = reinterpret_cast<__gm__ uint64_t *>(param);
      *notifyLock = value;
      dcci(notifyLock, 0, 2);
    }
  } else {
    if (AscendC::GetBlockIdx() == 0) {
      __gm__ uint64_t *notifyLock = reinterpret_cast<__gm__ uint64_t *>(param);
      *notifyLock = value;
      dcci(notifyLock, 0, 2);
    }
  }
}

template <bool aic_flag>
__aicore__ inline void WaitFunc(GM_ADDR param, uint64_t value, uint32_t flag) {
  if constexpr (aic_flag) {
    if (get_block_idx() == 0) {
      __gm__ volatile uint64_t *waitLock = reinterpret_cast<__gm__ uint64_t *>(param);
      if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::GEQ)) {
        dcci(waitLock, 0, 2);
        while (*waitLock < value) {
          dcci(waitLock, 0, 2);
        }
      } else if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::EQ)) {
        dcci(waitLock, 0, 2);
        while (*waitLock != value) {
          dcci(waitLock, 0, 2);
        }
      } else if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::AND)) {
        dcci(waitLock, 0, 2);
        while ((*waitLock & value) == 0) {
          dcci(waitLock, 0, 2);
        }
      } else {
        dcci(waitLock, 0, 2);
        while ((~(*waitLock | value)) == 0) {
          dcci(waitLock, 0, 2);
        }
      }
    }
  } else {
    if (AscendC::GetBlockIdx() == 0) {
      __gm__ volatile uint64_t *waitLock = reinterpret_cast<__gm__ uint64_t *>(param);
      if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::GEQ)) {
        dcci(waitLock, 0, 2);
        while (*waitLock < value) {
          dcci(waitLock, 0, 2);
        }
      } else if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::EQ)) {
        dcci(waitLock, 0, 2);
        while (*waitLock != value) {
          dcci(waitLock, 0, 2);
        }
      } else if (flag == static_cast<uint32_t>(SkMemoryWaitFlag::AND)) {
        dcci(waitLock, 0, 2);
        while ((*waitLock & value) == 0) {
          dcci(waitLock, 0, 2);
        }
      } else {
        dcci(waitLock, 0, 2);
        while ((~(*waitLock | value)) == 0) {
          dcci(waitLock, 0, 2);
        }
      }
    }
  }
}

template <bool aic_flag>
__aicore__ inline void ResetFunc(GM_ADDR param, uint64_t value) {
  if constexpr (aic_flag) {
    if (get_block_idx() == 0) {
      __gm__ uint64_t *resetLock = reinterpret_cast<__gm__ uint64_t *>(param);
      *resetLock = value;
      dcci(resetLock, 0, 2);
    }
  } else {
    if (AscendC::GetBlockIdx() == 0) {
      __gm__ uint64_t *resetLock = reinterpret_cast<__gm__ uint64_t *>(param);
      *resetLock = value;
      dcci(resetLock, 0, 2);
    }
  }
}
```

### A5.4 `super_kernel/src/aot/sk_common.h` — the task/sync/flag enums

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/src/aot/sk_common.h

Author: Huawei Technologies Co., Ltd. Repo `cann/graph-autofusion`, branch `master`. Fetched 2026-10-20.

```cpp
enum class SkKernelType : uint8_t {
  AIC_ONLY = 1,
  AIV_ONLY = 2,
  MIX_AIV_1_0 = 3,
  MIX_AIC_1_0 = 4,
  MIX_AIC_1_1 = 5,
  MIX_AIC_1_2 = 6,
  DEFAULT = 0xFF,
};
```

```cpp
enum class SkTaskType : uint8_t {
  TYPE_FUNC,
  TYPE_SYNC,
  TYPE_PRELOAD,
  TYPE_EVENT_NOTIFY,
  TYPE_EVENT_WAIT,
  TYPE_EVENT_RESET,
  TYPE_MAX,
};
```

```cpp
enum class SkCoreSyncType : uint8_t {
  ALL_SYNC = 0,
  CROSS_SYNC_AIC_TO_AIC,
  CROSS_SYNC_AIV_TO_AIV,
  INTER_SYNC_SET_AIC_TO_AIV,
  INTER_SYNC_SET_AIV_TO_AIC,
  INTER_SYNC_WAIT_AIC_TO_AIV,
  INTER_SYNC_WAIT_AIV_TO_AIC,
  SYNC_NONE,
};
```

The `SkMemoryWaitFlag` enum, with the comment that pins its numeric values to the host runtime's
`aclrtValueWait`:

```cpp
// Memory wait rule for VALUE_WAIT tasks.
// The numeric values must stay aligned with runtime's aclrtValueWait flag definition.
enum class SkMemoryWaitFlag : uint32_t {
  GEQ = 0x0,  // Wait until *addr >= value
  EQ = 0x1,   // Wait until *addr == value
  AND = 0x2,  // Wait until (*addr & value) != 0
  NOR = 0x3,  // Wait until ~(*addr | value) != 0
};
```

```cpp
constexpr uint64_t SK_DEFAULT_NOTIFY_VALUE = 1;
constexpr uint64_t SK_DEFAULT_WAIT_VALUE = 1;
constexpr uint64_t SK_DEFAULT_RESET_VALUE = 0;
constexpr uint32_t SK_DEFAULT_WRITE_FLAG = 0;
```

The per-task descriptor, including the `debugOptions` bit map. Bit 16 (`0x10`) is
`debug_cross_core_sync_check`, which is what triggers `test_cross_core_sync_flags()`:

```cpp
struct TaskInfo {
  uint32_t index;
  SkTaskType type;
  SkKernelType relatedType = SkKernelType::DEFAULT;
  uint8_t numBlocks;
  uint8_t entryCnt;
  uint64_t entry[4];
  // 根据bit位确定option选项
  // 1： dcci_disable_on_kernel
  // 2： debug_sync_all
  // 4： dcci_before_kernel_start
  // 8： dcci_after_kernel_end
  // 16： debug_cross_core_sync_check
  // 32： enable_dcci_after_func - 直接指示kernel是否需要在func执行后插入dcci
  //      该bit由host端根据disableDcci和afterKernelEnd综合计算得出
  //      kernel侧只需检查此bit即可，无需组合判断
  uint64_t debugOptions;
  uint64_t extraInfo;
  uint64_t args;
  uint32_t argsSize;
  uint8_t isSimtKernel;
  uint8_t reservedList[3];
};

inline void SetEventTaskArgs(TaskInfo &taskInfo, uint64_t addr, uint64_t value, uint32_t flag) {
  taskInfo.args = addr;
  taskInfo.entry[0] = value;
  taskInfo.extraInfo = static_cast<uint64_t>(flag);
}

inline uint64_t GetEventTaskAddr(const TaskInfo &taskInfo) {
  return taskInfo.args;
}

enum class SkEarlyStartMask : uint32_t {
  NONE = 0U,
  AIC_TO_AIC_SET = 1U << 0,
  AIC_TO_AIC_WAIT = 1U << 1,
  AIC_TO_AIV_SET = 1U << 2,
  AIV_TO_AIC_WAIT = 1U << 3,
  AIV_TO_AIV_SET = 1U << 4,
  AIV_TO_AIV_WAIT = 1U << 5,
  AIV_TO_AIC_SET = 1U << 6,
  AIC_TO_AIV_WAIT = 1U << 7,
  SPLIT_CORE_CTRL = 1U << 15,
};
```

### A5.5 `sk_entry.asc` — the stage-sequencing loop (how hundreds of sub-kernels are driven)

This is the SuperKernel's answer to "sequencing many stages": a GM-resident task queue, walked
by every core, with four task kinds — FUNC (call a sub-kernel through a function pointer),
SYNC (emit a barrier), PRELOAD (ICache prefetch of the next sub-kernel), and
EVENT_NOTIFY/WAIT/RESET (the GM counter channel). The flag usage per task is constant, so the
queue length is unbounded:

```cpp
  uint32_t que_offset = 0;
  if ASCEND_IS_AIC {
    que_offset = sk_header->aicQueOffset + (((uint8_t)get_coreid()) % 4) * sk_header->aicQueSize;
    if constexpr (enable_profiling) {
      if (aic != 0) {
        skBlockNum = AscendC::GetBlockNum() * aic;
      }
    }
  }
  if ASCEND_IS_AIV {
    que_offset = sk_header->aivQueOffset + (((uint8_t)get_coreid()) % 4) * sk_header->aivQueSize;
    if constexpr (enable_profiling) {
      if (aiv != 0) {
        skBlockNum = AscendC::GetBlockNum() * aiv;
      }
    }
  }
  const __gm__ TaskQue *taskQue = (const __gm__ TaskQue *)((const __gm__ uint8_t *)sk_header + que_offset);
  for (auto i = 0; i < taskQue->taskCnt; i++) {
    const __gm__ TaskInfo *task = taskQue->taskInfos + i;
    if (task->type == SkTaskType::TYPE_PRELOAD) {
      auto blockId = AscendC::GetBlockIdx();
      if (blockId < task->numBlocks) {
        preload((const void *)(task->entry[((uint8_t)get_coreid()) % task->entryCnt]), task->args);
        dc_preload((__gm__ uint64_t *)(task->extraInfo), 0);
        dc_preload((__gm__ uint64_t *)(task->extraInfo) + 8, 0);
        dc_preload((__gm__ uint64_t *)(task + 1), 0);
      }
    } else if (task->type == SkTaskType::TYPE_FUNC) {
      auto blockId = AscendC::GetBlockIdx();
      if (blockId < task->numBlocks) {
```

```cpp
        if ((task->debugOptions & 0x4) != 0) {
          dcci(nullptr, 1, 2);
        }

        ((sk_sub_func)(task->entry[((uint8_t)get_coreid()) % task->entryCnt]))((const __gm__ void *)task->args,
                                                                               &sysArgs);
```

```cpp
      if constexpr (enable_op_trace) {
        constexpr bool is_aic_or_aiv_only = (aic == 1 && aiv == 0) || (aic == 0 && aiv == 1);
        if constexpr (!is_aic_or_aiv_only) {
          bool is_mix_kernel =
              (task->relatedType == SkKernelType::MIX_AIC_1_1) || (task->relatedType == SkKernelType::MIX_AIC_1_2);
          if (((task->debugOptions & 0x10) != 0) && is_mix_kernel) {
            test_cross_core_sync_flags();
          }
        }
      }
    } else if (task->type == SkTaskType::TYPE_SYNC) {
      if constexpr (enable_debug) {
        if ((task->debugOptions & 0x2) != 0) {
          sk::FullCoreSyncImpl<aic, aiv>();
        } else {
          if constexpr (enable_early_start) {
            sk::AutoCoreSyncImpl<aic, aiv>((SkCoreSyncType)task->args, task->numBlocks, task->extraInfo);
          } else {
            sk::AutoCoreSyncImpl<aic, aiv>((SkCoreSyncType)task->args);
          }
        }
      } else {
        if constexpr (enable_early_start) {
          sk::AutoCoreSyncImpl<aic, aiv>((SkCoreSyncType)task->args, task->numBlocks, task->extraInfo);
        } else {
          sk::AutoCoreSyncImpl<aic, aiv>((SkCoreSyncType)task->args);
        }
      }
    } else if (task->type == SkTaskType::TYPE_EVENT_NOTIFY) {
      GM_ADDR eventAddr = reinterpret_cast<GM_ADDR>(task->args);
      const uint64_t eventValue = task->entry[0];
      if ASCEND_IS_AIC {
        sk::NotifyFunc<true>(eventAddr, eventValue);
      }
      if ASCEND_IS_AIV {
        sk::NotifyFunc<false>(eventAddr, eventValue);
      }
    } else if (task->type == SkTaskType::TYPE_EVENT_WAIT) {
      GM_ADDR eventAddr = reinterpret_cast<GM_ADDR>(task->args);
      const uint64_t eventValue = task->entry[0];
      const uint32_t waitFlag = static_cast<uint32_t>(task->extraInfo);
      if ASCEND_IS_AIC {
        sk::WaitFunc<true>(eventAddr, eventValue, waitFlag);
      }
      if ASCEND_IS_AIV {
        sk::WaitFunc<false>(eventAddr, eventValue, waitFlag);
      }
    } else if (task->type == SkTaskType::TYPE_EVENT_RESET) {
      GM_ADDR eventAddr = reinterpret_cast<GM_ADDR>(task->args);
      const uint64_t eventValue = task->entry[0];
      if ASCEND_IS_AIC {
        sk::ResetFunc<true>(eventAddr, eventValue);
      }
      if ASCEND_IS_AIV {
        sk::ResetFunc<false>(eventAddr, eventValue);
      }
    }
  }
```

### A5.6 Golden generated SuperKernel device code (the AOT codegen output)

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/tests/st/data/test_sk_1_stream_2_ops_debug_sync_all_1_aic_only/expect_sk_code.cc

Author: Huawei Technologies Co., Ltd. Repo `cann/graph-autofusion`, branch `master`. Fetched 2026-10-20.

Note that the emitted inter-op barrier for 2 fused ops uses the SAME flagId
(`AscendC::SYNC_AIC_FLAG`) both times, and that the separate "inter ops barrier" uses a
different primitive pair entirely: `AscendC::SetNextTaskStart()` / `AscendC::WaitPreTaskEndImpl<0>()`:

```cpp
    // op end debug sync all.

    ffts_cross_core_sync(PIPE_FIX, AscendC::GetffstMsg(0x0, AscendC::SYNC_AIC_FLAG));
    wait_flag_dev(AscendC::SYNC_AIC_FLAG);
    //begin func call of sub operator pows__kernel0
    // begin inter ops barrier
    if ASCEND_IS_AIC {
        if (true) {
            AscendC::SetNextTaskStart();
        }
    }

    if ASCEND_IS_AIV {
        if (true) {
            // AIC only, no complement early start set flag.
        }
    }

    g_super_kernel_early_start_config = 0;
    if ASCEND_IS_AIC {
        if (true) {
            AscendC::WaitPreTaskEndImpl<0>();
        }
    }

    if ASCEND_IS_AIV {
        if (true) {
            AscendC::WaitPreTaskEndImpl<0>();
        }
    }
```

```cpp
    // op end debug sync all.

    ffts_cross_core_sync(PIPE_FIX, AscendC::GetffstMsg(0x0, AscendC::SYNC_AIC_FLAG));
    wait_flag_dev(AscendC::SYNC_AIC_FLAG);
}
```

Also from the 2-stream mix golden file, the generated entry showing the `_mix_aic`/`_mix_aiv`
ELF metadata emitted for `__NPU_ARCH__ == 2201` (i.e. A2/A3 `dav-2201`):

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/tests/st/data/test_sk_2_stream_2_ops_default_aic_1_1/expect_sk_code.cc

```cpp
extern "C"  __global__ __attribute__((aligned(512))) __aicore__ void auto_gen_te_superkernel_2_stream_2_ops_kernel(void) {
    GM_ADDR *param_base = (GM_ADDR *)get_para_base();
    GM_ADDR ffts_addr = param_base[0];
    if (ffts_addr != nullptr) {
        set_ffts_base_addr((uint64_t)ffts_addr);
    }

    if ASCEND_IS_AIC {
        auto_gen_te_superkernel_2_stream_2_ops_kernel_aic();
    }
    if ASCEND_IS_AIV {
        auto_gen_te_superkernel_2_stream_2_ops_kernel_aiv();
    }
}

#if TILING_KEY_VAR == 0UL
#if (defined(__DAV_CUBE__) && __NPU_ARCH__ == 2201)
static const struct FunLevelMixCoreType te_superkernel_2_stream_2_ops_mix_aic_section __attribute__ ((used, section (".ascend.meta.te_superkernel_2_stream_2_ops_mix_aic"))) = { {{F_TYPE_KTYPE, sizeof(unsigned int)}, K_TYPE_MIX_AIC_MAIN},    {{F_TYPE_MIX_TASK_RATION, sizeof(unsigned int)}, 1, 1} };
#endif
#endif

#if TILING_KEY_VAR == 0UL
#if (defined(__DAV_VEC__) && __NPU_ARCH__ == 2201)
static const struct FunLevelMixCoreType te_superkernel_2_stream_2_ops_mix_aiv_section __attribute__ ((used, section (".ascend.meta.te_superkernel_2_stream_2_ops_mix_aiv"))) = { {{F_TYPE_KTYPE, sizeof(unsigned int)}, K_TYPE_MIX_AIC_MAIN},    {{F_TYPE_MIX_TASK_RATION, sizeof(unsigned int)}, 1, 1} };
#endif
#endif
```

### A5.7 Negative result — `super_kernel/docs/developer_guide.md` has nothing on synchronisation

https://raw.gitcode.com/cann/graph-autofusion/raw/master/super_kernel/docs/developer_guide.md

Author: Huawei Technologies Co., Ltd. Repo `cann/graph-autofusion`, branch `master`, 6283 bytes.
Fetched 2026-10-20. Grepped for `同步` / `sync` / `flag` / `barrier` / `dcci` / `事件`: zero hits.
The file is about the System Test harness (fixtures, golden files, dependency management), not
kernel design. The one datum worth keeping is the default SoC the SuperKernel tests target:

```
- `soc_version`（`fixtures/config.py`）：指定默认 SoC 信息，当前默认值为 `Ascend910_9391`；如需使用其他版本，可在场景内覆盖或增加新的 fixture。
```

The sync design is instead documented only as diagrams — `super_kernel/docs/images/同步事件.svg`
and `.excalidraw`, plus `子kernel拆分.svg` and `ICachePreload优化.svg` — which are not quotable text.

Negative result for this repo: there is **no** `SkMemoryWaitFlag`-style rotation of
`CrossCoreSetFlag` flagIds anywhere in `cann/graph-autofusion`, and no per-sub-kernel flagId
allocator. Searched `super_kernel/kernel/*.asc`, `super_kernel/kernel/*.h`,
`super_kernel/src/aot/*`, and the golden `expect_sk_code.cc` files: every `CrossCoreSetFlag`
call site uses one of the four `AscendC::SYNC_*` constants, except `sk_flag_diag.h`, which
sweeps 0..10 purely as a hardware self-test.

---

## A6. The complete flagId budget of a real 7-stage megakernel (derived, with the grep that proves it)

Every cross-core Set/Wait site in all five stage files of `huawei-csl/megagdn-pto`, extracted on
2026-10-20 with
`grep -n 'SetCrossFlag<[^>]*>([^)]*)\|wait_flag_dev([^)]*)\|set_intra_block([^)]*)\|wait_intra_block([^)]*)\|SignalBothVecOnA5<[^>]*>([^)]*)\|WaitBothVecOnA5<[^>]*>([^)]*)\|SyncAll'`
over the files fetched from `https://raw.githubusercontent.com/huawei-csl/megagdn-pto/main/kernels/pto/`:

```
##### scaled_dot_kkt.cpp
316: wait_flag_dev(2 + slot);          # slot = ci & 1  -> flags 2,3
318: WaitBothVecOnA5<PIPE_MTE2>(2 + slot);
427: SetCrossFlag<PIPE_FIX>(slot);     # -> flags 0,1
430: SignalBothVecOnA5<PIPE_FIX>(slot);
490: SetCrossFlag<PIPE_MTE3>(2);       # prime
491: SetCrossFlag<PIPE_MTE3>(3);       # prime
493: set_intra_block(PIPE_MTE3, 2);
494: set_intra_block(PIPE_MTE3, 3);
579: wait_flag_dev(slot);              # -> flags 0,1
581: wait_intra_block(PIPE_MTE3, slot);
699: SetCrossFlag<PIPE_MTE3>(2 + slot);# -> flags 2,3
701: set_intra_block(PIPE_MTE3, 2 + slot);

##### wy_fast.cpp
476: wait_flag_dev(3);
478: wait_intra_block(PIPE_MTE3, 3);
496: SetCrossFlag<PIPE_MTE3>(2);
498: set_intra_block(PIPE_MTE3, 2);
540: wait_flag_dev(4);
542: wait_intra_block(PIPE_MTE3, 4);
560: SetCrossFlag<PIPE_MTE3>(1);
562: set_intra_block(PIPE_MTE3, 1);
664: wait_flag_dev(3);
666: wait_intra_block(PIPE_MTE3, 3);
684: SetCrossFlag<PIPE_MTE3>(2);
686: set_intra_block(PIPE_MTE3, 2);
724: wait_flag_dev(4);
726: wait_intra_block(PIPE_MTE3, 4);
744: SetCrossFlag<PIPE_MTE3>(1);
746: set_intra_block(PIPE_MTE3, 1);
813: wait_flag_dev(2);
815: WaitBothVecOnA5<PIPE_MTE2>(2);
851: SetCrossFlag<PIPE_FIX>(3);
853: SignalBothVecOnA5<PIPE_FIX>(3);
859: wait_flag_dev(1);
861: WaitBothVecOnA5<PIPE_MTE2>(1);
895: SetCrossFlag<PIPE_FIX>(4);
897: SignalBothVecOnA5<PIPE_FIX>(4);
959: wait_flag_dev(2);
961: WaitBothVecOnA5<PIPE_MTE2>(2);
993: SetCrossFlag<PIPE_FIX>(3);
995: SignalBothVecOnA5<PIPE_FIX>(3);
1001: wait_flag_dev(1);
1003: WaitBothVecOnA5<PIPE_MTE2>(1);
1035: SetCrossFlag<PIPE_FIX>(4);
1037: SignalBothVecOnA5<PIPE_FIX>(4);

##### chunk_h.cpp
444: wait_flag_dev(3);
446: WaitBothVecOnA5<PIPE_MTE2>(3);
497: SetCrossFlag<PIPE_FIX>(0);
500: SignalBothVecOnA5<PIPE_FIX>(0);
505: wait_flag_dev(1);
507: WaitBothVecOnA5<PIPE_MTE2>(1);
555: SetCrossFlag<PIPE_FIX>(2);
558: SignalBothVecOnA5<PIPE_FIX>(2);
643: SetCrossFlag<PIPE_MTE3>(3);
646: set_intra_block(PIPE_MTE3, 3);
768: wait_flag_dev(0);
770: wait_intra_block(PIPE_MTE3, 0);
824: SetCrossFlag<PIPE_MTE3>(1);
827: set_intra_block(PIPE_MTE3, 1);
886: wait_flag_dev(2);
888: wait_intra_block(PIPE_MTE3, 2);
943: SetCrossFlag<PIPE_MTE3>(3);
946: set_intra_block(PIPE_MTE3, 3);

##### chunk_o.cpp
306: wait_flag_dev(3);
308: WaitBothVecOnA5<PIPE_MTE2>(3);
492: SetCrossFlag<PIPE_FIX>(0);
495: SignalBothVecOnA5<PIPE_FIX>(0);
500: wait_flag_dev(1);
502: WaitBothVecOnA5<PIPE_MTE2>(1);
583: SetCrossFlag<PIPE_FIX>(2);
586: SignalBothVecOnA5<PIPE_FIX>(2);
608: wait_flag_dev(3);
610: WaitBothVecOnA5<PIPE_MTE2>(3);
752: SetCrossFlag<PIPE_FIX>(0);
755: SignalBothVecOnA5<PIPE_FIX>(0);
760: wait_flag_dev(1);
762: WaitBothVecOnA5<PIPE_MTE2>(1);
837: SetCrossFlag<PIPE_FIX>(2);
840: SignalBothVecOnA5<PIPE_FIX>(2);
976: wait_flag_dev(0);
978: wait_intra_block(PIPE_MTE3, 0);
987: SetCrossFlag<PIPE_MTE3>(1);
988: wait_flag_dev(2);
989: SetCrossFlag<PIPE_MTE3>(3);
992: set_intra_block(PIPE_MTE3, 1);
993: wait_intra_block(PIPE_MTE3, 2);
994: set_intra_block(PIPE_MTE3, 3);
1066: SetCrossFlag<PIPE_MTE3>(1);
1069: set_intra_block(PIPE_MTE3, 1);
1091: wait_flag_dev(2);
1093: wait_intra_block(PIPE_MTE3, 2);
1152: SetCrossFlag<PIPE_MTE3>(3);
1155: set_intra_block(PIPE_MTE3, 3);
1232: wait_flag_dev(0);
1234: wait_intra_block(PIPE_MTE3, 0);

##### chunk_cumsum.cpp   (no cross-core sites at all — Vec only)
##### tri_inverse.cpp    (no cross-core sites at all — Cube only)
```

The whole 7-stage megakernel touches flagIds **0, 1, 2, 3, 4** and nothing else. No stage uses
a flagId above 4; the barrier uses 11-14. Every stage re-uses the same low ids. That is legal
only because of the three invariants the source enforces:
1. inside a stage, each flagId alternates Set / Wait strictly (a double-buffer `slot = ci & 1`),
   so the outstanding count never exceeds 1 — nowhere near 15;
2. a `SyncAllMegaKernel<false>()` separates every pair of stages;
3. any Set left outstanding by the last loop iteration is explicitly consumed by a drain block
   in `mega_kernel.cpp` (the three `wait_flag_dev(2); wait_flag_dev(3);` / `(3); (4);` / `(3);`
   blocks quoted in A2 above).

For a kernel fusing 78 layers, the implication from this source is: do not look for a rotation
scheme. Make each layer's flag use balanced and bracketed by a barrier, and the same 11 flagIds
serve an arbitrary number of layers. Where a dependency must cross a barrier (producer in layer
*i*, consumer in layer *j*), use the GM-counter channel (A4's `TSYNCALL<Soft>` or A5.3's
`NotifyFunc`/`WaitFunc`/`ResetFunc` with `SkMemoryWaitFlag::GEQ`), which has no counter limit.


---

## A7. Official docs, CATLASS, field reports and real rotation code (Topic A, breadth pass)

Verification note for this section: 102 fenced blocks. 64 were machine-checked as exact literal
substrings of the locally cached source files. The other 38 come from issue/PR/code-search APIs
that were not cached to disk; I independently re-fetched and re-confirmed the two most
load-bearing of those (gitcode `cann/catlass` MR !325 body and `cann/ops-solver` issue #13 body)
character-for-character, and re-fetched `catlass/include/catlass/arch/cross_core_sync.hpp` whole
(reproduced at the end of this section). Treat any remaining uncached quote as high-confidence
but single-sourced.

### A7.1 OFFICIAL CANN DOC — `CrossCoreSetFlag(ISASI)`, older master snapshot (flagId 0-10, "最多设置15次")

This is the CANN `asc-devkit` repo copy of the official hiascend API page. The topic id `ZH-CN_TOPIC_0000001834069637` is the hiascend doc id. Note the A2/A3 range is **0-10** here, and the counter clause.

https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/CrossCoreSetFlag(ISASI).md
(raw mirror used to fetch: https://raw.githubusercontent.com/ckorikov/asc-devkit/master/docs/api/context/CrossCoreSetFlag(ISASI).md )
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit) / doc topic ZH-CN_TOPIC_0000001834069637; file header "Copyright (c) 2026"

````
## 功能说明<a name="section618mcpsimp"></a>

面向分离模式的核间同步控制接口。

该接口和[CrossCoreWaitFlag](CrossCoreWaitFlag(ISASI).md)接口配合使用。使用时需传入核间同步的标记ID\(flagId\)，每个ID对应一个用于控制同步的计数器。

同步控制分为以下几种模式，如[图1](#fig37581010773)所示：

-   模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。
-   模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。
-   模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后， 两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
-   模式4：AI Core内部，AIC与AIV之间的同步控制。AIV0与AIV1可单独触发AIC等待。比如，在AIC核执行CrossCoreSetFlag之后， AIV0上CrossCoreWaitFlag后续的指令才会继续执行；AIV0执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。

其中，模式4仅支持Ascend 950PR/Ascend 950DT。

## 函数原型<a name="section620mcpsimp"></a>

```
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
```
````

flagId range table rows (same file, 表 2, HTML tags stripped for legibility — the Chinese text is verbatim):

```
flagId
输入
核间同步的标记。
Atlas A2 训练系列产品/Atlas A2 推理系列产品，取值范围是0-10。
Atlas A3 训练系列产品/Atlas A3 推理系列产品，取值范围是0-10。
Ascend 950PR/Ascend 950DT，取值范围如下：
AIV0发起的flagId 0-10的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-10的操作。
AIV1发起的flagId 0-10的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-26的操作。
AIC发起的flagId 0-10的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-10的操作。
AIC发起的flagId 16-26的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-10的操作。
```

Constraint section of the same file, verbatim:

```
## 约束说明<a name="section633mcpsimp"></a>

-   使用该同步接口时，需要按照如下规则[设置Kernel类型](设置Kernel类型.md)：
    -   在纯Vector/Cube场景下，需设置Kernel类型为KERNEL\_TYPE\_MIX\_AIV\_1\_0或KERNEL\_TYPE\_MIX\_AIC\_1\_0。
    -   对于Vector和Cube混合场景，需根据实际情况灵活配置Kernel类型。

-   因为[Matmul高阶API](矩阵计算-85.md)内部实现中使用了本接口进行核间同步控制，所以不建议开发者同时使用该接口和Matmul高阶API，否则会有flagID冲突的风险。
-   同一flagId的计数器最多设置15次。
-   使用该接口模式0时，必须通过[SetScheduleMode](https://www.hiascend.com/document/detail/zh/canncommercial/850/API/basicdataapi/atlasopapi_07_00248.html)使能batchmode模式，使算子独占全部所需核资源，否则可能因满足以下条件导致死锁：
    -   多流并发场景（≥2条执行流）。
    -   ≥2个算子并发执行。
    -   所有并发算子的核数总和超过物理核数。
    -   ≥2个并发算子使用了核间同步功能。
```

Call example (same file), verbatim:

```
// 使用模式0的方式同步所有的AIV核
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(0x8);
    AscendC::CrossCoreWaitFlag(0x8);
}

// 使用模式1的方式同步当前AICore内的所有AIV子核
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreSetFlag<0x1, PIPE_MTE3>(0x8);
    AscendC::CrossCoreWaitFlag(0x8);
}

// 注意：如果调用高阶API,无需开发者处理AIC和AIV的同步
// 以Matmul为例：AIC侧做完Matmul计算后通知AIV进行后处理
if (g_coreType == AscendC::AIC) {
    // Matmul处理
    AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(0x8);
}

// AIV侧等待AIC Set消息, 进行Vector后处理
if (g_coreType == AscendC::AIV) {
    AscendC::CrossCoreWaitFlag(0x8);
    // Vector后处理
}
```

---

### A7.2 OFFICIAL CANN DOC — `CrossCoreWaitFlag(ISASI)`, older master snapshot (blocking + 15-count)

https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/CrossCoreWaitFlag(ISASI).md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit) / unknown date, same snapshot as item 1

```
-   CrossCoreWaitFlag必须与[CrossCoreSetFlag](CrossCoreSetFlag(ISASI).md)接口配合使用，避免计算核一直处于阻塞阶段。
-   如果执行CrossCoreWaitFlag时该flagId的计数器的值为0，则CrossCoreWaitFlag之后的所有指令都将被阻塞，直到该flagId的计数器的值不为0。同一个flagId的计数器最多设置15次。
```

---

### A7.3 OFFICIAL CANN DOC (CURRENT, docs/zh tree) — `CrossCoreSetFlag_ISASI.md`: flagId 0-15, 4-bit truncation, counter overflow is a HARD ERROR, Set order not guaranteed, and the ONLY documented "reset" (drain)

This is the newest official wording. It supersedes the 0-10 range of item 1: range is now 0-15 for modes 0/1/2 on all products, with the 11-14 reservations documented separately (item 5).

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreSetFlag_ISASI.md
(raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreSetFlag_ISASI.md )
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
## 功能说明<a id="section618mcpsimp"></a>

头文件路径为：`"basic_api/kernel_operator_block_sync_intf.h"`。

在核间同步场景中，CrossCoreSetFlag接口和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)接口配对工作，使用时需传入核间同步的标记ID（flagId），每个ID对应一个用于控制同步的计数器。

- CrossCoreSetFlag：AI Core中的AIC/AIV在完成本核前置位的pipe流水任务后，调用该接口，向调度模块上报本核任务已完成。调度模块收集所有参与核的上报信息，作为全局完成标志。
- CrossCoreWaitFlag：用于阻塞本核后续指令的下发（已下发指令可正常执行），直至调度模块确认所有应调用CrossCoreSetFlag的核均已上报完成，随即解除阻塞，允许该核继续下发指令。
```

```
### flagId取值范围说明<a id="flagId取值范围说明"></a>

- 核间同步的模式为模式0、1、2时，支持的取值范围为0-15。
<!-- npu="950" id13 -->
- 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，支持的取值范围情况如下：
    - AIV0发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 0-15的操作。
    - AIV1发起的flagId 0-15的CrossCoreSetFlag操作对应AIC CrossCoreWaitFlag中flagId 16-31的操作。
    - AIC发起的flagId 0-15的CrossCoreSetFlag操作对应AIV0 CrossCoreWaitFlag中flagId 0-15的操作。
    - AIC发起的flagId 16-31的CrossCoreSetFlag操作对应AIV1 CrossCoreWaitFlag中flagId 0-15的操作。
<!-- end id13 -->

此外，当本接口与Matmul高阶API或SyncAll接口同时使用时，开发者自行使用的flagId还需注意避免与这些接口内部已占用的flagId冲突，详见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。
```

```
- 一个核连续发出的CrossCoreSetFlag，硬件不保证执行顺序。例如AIV依次发射CrossCoreSetFlag<0, PIPE\_V\>\(0\)，CrossCoreSetFlag<0, PIPE\_V\>\(1\)，实际的执行顺序可能是flagId=1的先执行。
- flagId相关的约束：
    - 对于模式0、1、2，每个AIC和每个AIV都各自有16个flagId，支持的取值范围为0-15。如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- npu="950" id15 -->
    - 针对Ascend 950PR&950DT系列产品，核间同步的模式为模式4时，AIC有32个flagId，支持的取值范围为0-31，如果flagId的值超出该范围，则截取低5bit（例如，flagId=35时，截取后为3）；AIV有16个flagId，支持的取值范围为0-15，如果flagId的值超出该范围，则截取低4bit（例如，flagId=17时，截取后为1）。
    <!-- end id15 -->
    - 每个flagId都对应一个计数器，当调用[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)时，若计数器值为0则会阻塞后续指令下发，已下发指令可正常执行；当调度模块感知到所有参与同步的核（具体包含哪些核与设置的核间同步模式有关）完成（调用了CrossCoreSetFlag）同步后，会将与设置的flagId对应的计数器的值增加1。此时，计数器值为非0，阻塞解除，并且将对应计数器的值减去1进行还原。具体执行逻辑与细节可以参考[关键特性说明](key_features.md)。每一个计数器计数范围为0-15。如果调用CrossCoreSetFlag的次数超过15次，计数器的值超出该范围，则会异常报错，中断流程。
- 核间同步的模式为模式0、1、2时，同一个flagId用于不同核间同步模式的约束：
    - 同一核上，若同一个flagId需用于不同核间同步模式，须在模式切换前完成前一个模式的所有同步操作——即确保该flagId关联的所有CrossCoreSetFlag与配套CrossCoreWaitFlag调用均已执行完毕。
    - 对于不同的核，可以直接将同一flagId用于不同的核间同步模式，具体包括以下2种场景：
        - 多个AI Core之间，使用flagId=0同步所有的AIC（模式0）；单个AI Core内，使用flagId=0同步所有AIV（模式1）。
        - 单个AI Core内，使用flagId=0同步所有AIV（模式1）；另一个AI Core内，使用flagId=0同步AIC与所有AIV（模式2）。
```

Kernel-type table from the same file (modes vs required `__mix__` qualifier) — needed because a megakernel must pick one:

```
        | 模式 | 支持的函数执行空间限定符 | 支持的核函数（Kernel）类型配置 |
        | --- | --- | --- |
        | 0 | \_\_mix\_\_(0, 1)、\_\_mix\_\_(1, 0)、\_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIV\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_0、KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 1 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 2 | \_\_mix\_\_(1, 1)、\_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_1、KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
        | 4 | \_\_mix\_\_(1, 2) | KERNEL\_TYPE\_MIX\_AIC\_1\_2 |
```

Also, pipe constraint (a `PIPE_S` Set is illegal on A3):

```
| pipe | 标识在哪条流水的前序指令完成后，CrossCoreSetFlag才向调度模块发送通知。支持的流水类型为PIPE_V、PIPE_M、PIPE_MTE1、PIPE_MTE2、PIPE_MTE3、PIPE_FIX，不支持PIPE_S和PIPE_ALL。不同产品对流水类型的支持情况请参见[pipe支持的流水类型说明](#pipe支持的流水类型说明)。 |
```

---

### A7.4 OFFICIAL CANN DOC (CURRENT) — `CrossCoreWaitFlag_ISASI.md`: on A3 the `pipe` template param of Wait is INEFFECTIVE (blocks all pipes)

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreWaitFlag_ISASI.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
- CrossCoreWaitFlag必须与[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)接口配合使用，避免计算核一直处于阻塞阶段。建议显式配置与配对CrossCoreSetFlag相同的modeId，以便确认Set与Wait使用相同的同步模式。
```

```
    - 每个flagId都对应一个计数器，当调用[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)时，若计数器值为0则会阻塞后续指令下发，已下发指令可正常执行；当调度模块感知到核间同步（CrossCoreSetFlag）全部完成后，会将对应CrossCoreWaitFlag的计数器的值增加1。此时，计数器值为非0，阻塞解除，并且将对应计数器的值减去1进行还原。具体执行逻辑与细节可以参考[关键特性说明](key_features.md)。flagId对应的计数器计数范围为0-15。如果计数器的值超出该范围，则会异常报错，中断流程。
```

From the same doc tree, `key_features.md` note on pipe semantics per arch:

```
> [!NOTE]说明
> 模式0、1、2下`CrossCoreWaitFlag`阻塞的流水类型因NPU架构而异：
> - 在[NPU架构版本2201](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)上，`CrossCoreWaitFlag`传入的`pipe`参数无效，无论取值为何都默认阻塞全部流水的后续指令，建议省略`pipe`参数并使用默认值。
> - 在[NPU架构版本3510](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)上，`CrossCoreWaitFlag`传入的`pipe`参数生效，阻塞由模板参数`pipe`指定的流水的后续指令。
```

---

### A7.5 OFFICIAL CANN DOC — `核间同步flagId占用说明` (which flagIds each API eats, per NPU arch). THE answer to "how many flags does each mode consume".

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/key_features.md
(anchor `#inter_core_sync_flagid_usage`)
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
## 核间同步flagId占用说明<a id="inter_core_sync_flagid_usage"></a>

### 概述

开发者使用[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)接口进行核间同步时，需要传入核间同步标记**flagId**，每个flagId对应一个用于控制同步的计数器。

部分接口的内部实现也会占用一部分flagId。当开发者同时使用这些接口与CrossCoreSetFlag/CrossCoreWaitFlag时，若flagId发生冲突（即相互独立的同步操作复用了同一个flagId），其对应的计数器会被错误地共享和修改，导致核间同步行为异常：可能出现阻塞无法解除而使程序卡死，或同步提前完成、阻塞提前解除而导致计算结果错误。

因此，当开发者同时调用CrossCoreSetFlag/CrossCoreWaitFlag与这些占用flagId的接口时，应**避开各接口内部已占用的flagId**，选用未被占用的flagId。

核间同步分为**模式0、1、2**与**模式4**，两者的底层硬件指令不同，flagId相互独立，因此各接口flagId的占用情况按**所属模式**和**NPU架构版本**分别参见[模式0、1、2的flagId占用](#inter_core_sync_flagid_mode012)和[模式4的flagId占用](#inter_core_sync_flagid_mode4)。

### 模式0、1、2的flagId占用<a id="inter_core_sync_flagid_mode012"></a>

**表1**  模式0、1、2flagId占用情况

| 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
| :--- | :--- | :--- | :--- | :--- |
| [SyncAll](SyncAll.md) | `isAIVOnly=true` | 14 | AIV：14 | 2201、3510 |
| [SyncAll](SyncAll.md) | `isAIVOnly=false` | 11、12、13 | AIC：11、12、13；AIV：12、13 | 2201、3510 |
| [SetNextTaskStart](../inter_task_sync/SetNextTaskStart.md) | SuperKernel子核函数（Kernel）中调用 | 11、14 | AIC：11；AIV：14 | 2201、3510 |
| [WaitPreTaskEnd](../inter_task_sync/WaitPreTaskEnd.md) | SuperKernel子核函数（Kernel）中调用 | 11、12、13、14 | AIC：11、12、13；AIV：12、13、14 | 2201、3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | 定义N个Matmul对象 | `[0, 2N-1]` | AIV/AIC按对象与subBlock分配 | 2201 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | SuperKernel融合场景（[GetTaskRatio](../../tool_interface/system_resources_and_variables/GetTaskRatio.md)返回2，即1:2配比） | 15 | AIV：15 | 2201 |

### 模式4的flagId占用<a id="inter_core_sync_flagid_mode4"></a>

**表2**  模式4flagId占用情况

| 接口 | 限定条件 | 占用flagId | 各计算核占用情况 | NPU架构版本 |
| :--- | :--- | :--- | :--- | :--- |
| [SyncAll](SyncAll.md) | `isAIVOnly=false`（核函数（Kernel）使用`__mix__(1, 2)`修饰时） | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
| [WaitPreTaskEnd](../inter_task_sync/WaitPreTaskEnd.md) | SuperKernel子核函数（Kernel）中调用 | 12、13、28、29 | AIC：12、13、28、29；AIV：12、13 | 3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | 定义N个[Matmul对象](../../../adv_api/cube_compute/Matmul_Kernel/REGIST_MATMUL_OBJ.md) | `[0, N+17]` | AIC/AIV按对象、eventType、subBlock分配 | 3510 |
| [Matmul](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_Kernel.md) | A矩阵和B矩阵同时开启[IBSHARE](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_usage.md#p84551411817)的场景 | 15 | AIV：15 | 3510 |
| [TSCM](../../resource_management/TSCM/TSCM.md) | 从UB发起的L1 Buffer（TSCM）队列 | 0~11（从11向下逐个分配） | AIV | 3510 |
| [DataCopy（GM→L1）](../../cube_compute_ISASI/cube_compute_load/DataCopy_GMToL1_continuous.md) | 无 | 1、17 | AIC：1、17；AIV：1 | 3510 |
```

Per-interface explanation from the same file (2201 = A3):

```
#### SyncAll

- **isAIVOnly=true**：纯Vector算子的全核同步，占用模式0、1、2的flagId为14（AIV）。
- **isAIVOnly=false**：Mix（包含Cube和Vector计算）算子的全核同步，占用情况随NPU架构与核函数（Kernel）类型不同：
    - **2201架构**：占用模式0、1、2的flagId为11、12、13。
```

```
#### Matmul

- 占用flagId的范围与定义的**Matmul对象数目N**相关（N最大为4），并且随NPU架构不同而不同，参见[REGIST_MATMUL_OBJ](../../../adv_api/cube_compute/Matmul_Kernel/REGIST_MATMUL_OBJ.md#约束说明)。
- **2201架构**：占用模式0、1、2的flagId为[0, 2N-1]（N=4时占用`[0,7]`）；SuperKernel融合（1:2配比，即[GetTaskRatio](../../tool_interface/system_resources_and_variables/GetTaskRatio.md)返回2）场景下还占用flagId为15。
- **3510架构**：占用模式4的flagId为[0, N+17]（N=4时占用`[0,21]`）；A矩阵和B矩阵同时开启[IBSHARE](../../../adv_api/cube_compute/Matmul_Kernel/Matmul_usage.md#p84551411817)的场景下还占用flagId为15。
```

Mode-4 semantics from the same file (notably "AIC与单个AIV"):

```
- 模式4：AI Core内部，AIC与单个AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后，单个AIV上CrossCoreWaitFlag后续的由模板参数pipe指定的流水中的指令才会继续执行；单个AIV执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的由模板参数pipe指定的流水中的指令才能执行。该模式仅在[NPU架构版本3510](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md)上支持。
```

---

### A7.6 OFFICIAL CANN DOC — NPU arch spec 2201 (i.e. A2/A3, dav_c220): "不允许连续设置同一个flagId" and "同一flagId的计数器最多可以设置15次"

This is the arch-specific page for exactly the target chip generation. Rendered at https://asc.gitcode.com/guide/programming_guide/advanced_programming/hardware_implementation/architecture_spec/npu_arch_2201.html

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/guide/programming_guide/advanced_programming/hardware_implementation/architecture_spec/npu_arch_2201.md
(raw: https://raw.gitcode.com/cann/asc-devkit/raw/master/docs/zh/guide/programming_guide/advanced_programming/hardware_implementation/architecture_spec/npu_arch_2201.md )
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
    [CrossCoreSetFlag](../../../../../api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreSetFlag_ISASI.md)和[CrossCoreWaitFlag](../../../../../api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreWaitFlag_ISASI.md)接口配合使用。使用时需传入核间同步的标记ID\(flagId\)，即上图中的ID1，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。flagId取值范围请参考[flagId取值范围说明](../../../../../api/SIMD-API/basic_api/sync_control/inter_core_sync/CrossCoreSetFlag_ISASI.md#flagId取值范围说明)。

    需要注意以下几点：

    -   **成对使用与一致性要求**

        CrossCoreSetFlag和CrossCoreWaitFlag必须成对使用，否则可能导致算子超时问题。两个接口的参数一致性要求如下：

        - modeId：本架构版本的硬件指令不使用CrossCoreWaitFlag的modeId，但建议显式配置与CrossCoreSetFlag相同的modeId，以便确认两个接口的同步模式匹配。
        - pipe：CrossCoreWaitFlag的pipe不生效，无需与CrossCoreSetFlag的pipe保持一致。
        - flagId：CrossCoreSetFlag与CrossCoreWaitFlag必须使用相同的flagId。

    -   **避免连续设置**

        不允许连续设置同一个flagId，以防止计数器状态混乱。

    -   **与其它接口的flagId冲突**

        部分接口内部实现中使用了CrossCoreSetFlag和CrossCoreWaitFlag，会占用一部分flagId，开发者同时使用这些接口与CrossCoreSetFlag/CrossCoreWaitFlag时，需注意避免flagId使用冲突，各接口flagId占用的完整说明（含各NPU架构版本的差异）参考[核间同步flagId占用说明](../../../../../api/SIMD-API/basic_api/sync_control/inter_core_sync/key_features.md#inter_core_sync_flagid_usage)。

    -   **计数器限制**

        同一flagId的计数器最多可以设置15次。

    -   **默认值**<a id="cross_core_wait_flag_default_values"></a>

        - modeId：默认值为0。建议显式配置与CrossCoreSetFlag相同的modeId。
        - pipe：默认值为PIPE\_S。CrossCoreWaitFlag接口提供pipe模板参数，但本架构版本的硬件指令不区分等待的流水，因此pipe取值不影响实际执行效果，CrossCoreWaitFlag会阻塞全部流水的后续指令。
```

Adjacent intra-core rule in the same file (the SetFlag/WaitFlag EventID analogue, and the reserved 6/7):

```
    -   不允许连续设置同一个EventID，因为这可能导致事件状态混乱或未被正确处理。
    -   不建议手动插入TEventID，不能手动插入6和7的TEventID，因为它们可能被系统预留或用于特殊用途。
```

---

### A7.7 CANN SOURCE — `dav_c220` (== `__NPU_ARCH__ 2201`, the A3 target) cross-core sync implementation: `ffts_cross_core_sync` / `wait_flag_dev`, 4-bit flagId mask, 2-bit mode mask, and the four flagIds AscendC reserves for itself (11/12/13/14)

https://gitcode.com/cann/asc-devkit/blob/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h
(raw mirror used: https://raw.githubusercontent.com/ckorikov/asc-devkit/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h )
author/date: Huawei Technologies Co., Ltd. / file header "Copyright (c) 2025 Huawei Technologies Co., Ltd."

```
constexpr uint16_t SYNC_AIV_FLAG = 12;
constexpr uint16_t SYNC_AIC_FLAG = 11;
constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;


__aicore__ inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId)
{
    return (0x1 + ((mode & 0x3) << SYNC_MODE_SHIFT_VALUE) + ((flagId & 0xf) << SYNC_FLAG_SHIFT_VALUE));
}
```

The whole `CrossCoreSetFlag`/`CrossCoreWaitFlag` pair on 2201 reduces to exactly two intrinsics — there is no reset/clear intrinsic in this file:

```
__aicore__ inline void NotifyEventImpl(uint16_t flagId)
{
    ffts_cross_core_sync(pipe, GetffstMsg(modeId, flagId));
}

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void WaitEventImpl(uint16_t flagId)
{
    (void)modeId;
    wait_flag_dev(flagId);
}
```

Hard `SyncAll` on 2201 is itself built out of those reserved flagIds (so a megakernel calling `SyncAll<false>()` burns 11/12/13):

```
template<pipe_t AIV_PIPE = PIPE_MTE3, pipe_t AIC_PIPE = PIPE_FIX>
__aicore__ inline void SetNextTaskStartImpl()
{
    if ASCEND_IS_AIC {
        ffts_cross_core_sync(AIC_PIPE, AscendC::GetffstMsg(0x0, AscendC::SYNC_AIC_FLAG));
    }
    if ASCEND_IS_AIV {
        ffts_cross_core_sync(AIV_PIPE, AscendC::GetffstMsg(0x0, AscendC::SYNC_AIV_ONLY_ALL));
    }
    return;
}
```

```
            wait_flag_dev(AscendC::SYNC_AIC_FLAG);
            ffts_cross_core_sync(PIPE_MTE3, AscendC::GetffstMsg(0x02, AscendC::SYNC_AIC_AIV_FLAG));
```

Also present (the only "base address" style config knob in the file):

```
__aicore__ inline void SetSyncBaseAddrImpl(uint64_t config)
{
    set_ffts_base_addr(config);
}
```

---

### A7.8 CANN SOURCE — `kernel_operator_block_sync_intf_impl.h`: the arch dispatch (2201 -> dav_c220), and proof that `IBSet`/`IBWait`/soft `SyncAll` do NOT touch the 16-deep hardware counter (they are GM polling loops)

https://gitcode.com/cann/asc-devkit/blob/master/impl/basic_api/kernel_operator_block_sync_intf_impl.h
author/date: Huawei Technologies Co., Ltd. / file header "Copyright (c) 2026 Huawei Technologies Co., Ltd."

```
#if __NPU_ARCH__ == 1001
#include "dav_c100/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 2002
#include "dav_m200/kernel_operator_sync_impl.h"
#elif __NPU_ARCH__ == 2201
#include "dav_c220/kernel_operator_sync_impl.h"
```

```
template<uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreSetFlag(uint16_t flagId)
{
    NotifyEventImpl<modeId, pipe>(flagId);    
}

template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void CrossCoreWaitFlag(uint16_t flagId)
{
    WaitEventImpl<modeId, pipe>(flagId);
}
```

`IBSet` is a GM spin on a 32-byte slot, i.e. a different resource entirely:

```
template <bool isAIVOnly>
__aicore__ inline void IBSet(const GlobalTensor<int32_t> &gmWorkspace,
    const LocalTensor<int32_t> &ubWorkspace, int32_t blockIdx, int32_t eventID)
{
    int32_t blockNum = GetBlockNum();
...
    auto localSyncGM = gmWorkspace[blockNum * 8 * eventID + blockIdx * 8];
    pipe_barrier(PIPE_ALL);

    while (true) {
        DataCopy(ubWorkspace, localSyncGM, ONE_BLK_SIZE / sizeof(int32_t));
        event_t eventIdMte2ToS = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE2_S));
        SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
        if (ubWorkspace.GetValue(0) == 0) {
            ubWorkspace.SetValue(0, 1);
```

Note `NotifyEvent`/`WaitEvent` are thin aliases that silently pick mode 0x02 / mode 0 on 2201:

```
template <pipe_t pipe>
__aicore__ inline void NotifyEvent(uint16_t flagId)
{
    constexpr uint8_t subBlockSyncMode = 0x02;
    NotifyEventImpl<subBlockSyncMode, pipe>(flagId);
}

template <pipe_t pipe=PIPE_S>
__aicore__ inline void WaitEvent(uint16_t flagId)
{
    constexpr uint8_t mode = 0;
    WaitEventImpl<mode, pipe>(flagId);
}
```

---

### A7.9 CANN SOURCE — `dav_c310` for contrast: `SYNC_FLAG_ID_MAX = 16`, `INTRA_NUM = 16`, and mode 4 lowered to `set_intra_block`/`wait_intra_block` instead of FFTS

Shows the 16 constant explicitly, and that mode 4 is a *different hardware mechanism* (so its flag pool is independent, matching item 5's "两者的底层硬件指令不同，flagId相互独立").

https://gitcode.com/cann/asc-devkit/blob/master/impl/basic_api/dav_c310/kernel_operator_sync_impl.h
author/date: Huawei Technologies Co., Ltd. / "Copyright (c) 2025"

```
constexpr uint16_t SYNC_AIV_FLAG = 12;
constexpr uint16_t SYNC_AIC_FLAG = 11;
constexpr uint16_t SYNC_AIC_AIV_FLAG = 13;
constexpr uint16_t SYNC_AIV_ONLY_ALL = 14;
constexpr uint16_t SYNC_MODE_SHIFT_VALUE = 4;
constexpr uint16_t SYNC_FLAG_SHIFT_VALUE = 8;
constexpr uint16_t SYNC_FLAG_ID_MAX = 16;
constexpr uint16_t INTRA_NUM = 16;

__aicore__ inline uint16_t GetffstMsg(uint16_t mode, uint16_t flagId)
{
    return (0x1 + ((mode & 0x3) << SYNC_MODE_SHIFT_VALUE) + ((flagId & 0xf) << SYNC_FLAG_SHIFT_VALUE));
}

__aicore__ inline uint8_t GetIntraFlagId(uint8_t instID, uint8_t eventType, uint8_t subBlockId)
{
    return (instID + eventType + subBlockId * INTRA_NUM);
}
```

```
template <uint8_t modeId, pipe_t pipe>
__aicore__ inline void NotifyEventImpl(uint16_t flagId)
{
    if constexpr(modeId == 4) {
        if constexpr (IsSplitVectorPipe<pipe>()) {
            if ASCEND_IS_AIV {
                set_intra_block(pipe, flagId);
            }
        }
        if constexpr (IsSplitCubePipe<pipe>()){
            if ASCEND_IS_AIC {
                set_intra_block(pipe, flagId);
            }
        }
    } else {
        if constexpr (IsSplitVectorPipe<pipe>()) {
            if ASCEND_IS_AIV {
                ffts_cross_core_sync(pipe, GetffstMsg(modeId, flagId));
            }
        }
```

And the "software sync converted to hardware sync" path showing the `+ SYNC_FLAG_ID_MAX` stride for AIV1:

```
    // trans software sync to hardware sync
    if ASCEND_IS_AIC {
        wait_intra_block(PIPE_S, AscendC::SYNC_AIV_FLAG);
        wait_intra_block(PIPE_S, AscendC::SYNC_AIV_FLAG + AscendC::SYNC_FLAG_ID_MAX);
        ffts_cross_core_sync(PIPE_FIX, GetffstMsg(0x0, AscendC::SYNC_AIC_FLAG));
        wait_flag_dev(PIPE_S, AscendC::SYNC_AIC_FLAG);
        set_intra_block(PIPE_S, AscendC::SYNC_AIC_AIV_FLAG);
        set_intra_block(PIPE_S, AscendC::SYNC_AIC_AIV_FLAG + AscendC::SYNC_FLAG_ID_MAX);
        return;
    }
```

---

### A7.10 ★ MOST LOAD-BEARING: CATLASS `cross_core_sync.hpp` — the official CANN library's answer to counter saturation: a reverse-flag credit scheme with `MAX_REVERSE_DEPTH = 15`

This is the canonical rotation/reset mechanism for long sequential chains. Note it does NOT rotate flagIds; it *drains* one flagId by forcing a reverse handshake every 15 Sets.

https://gitcode.com/cann/catlass/blob/master/include/catlass/arch/cross_core_sync.hpp
(raw: https://raw.gitcode.com/cann/catlass/raw/master/include/catlass/arch/cross_core_sync.hpp ; GitHub mirror https://github.com/hicann/catlass/blob/master/include/catlass/arch/cross_core_sync.hpp )
author/date: Huawei Technologies Co., Ltd. / "Copyright (c) 2025"; `MAX_REVERSE_DEPTH = 15` landed 2025-12-18 (see item 11)

```
namespace Catlass::Arch {

// A certain cross core flag can be continuously set up to 15 times without waiting. In scenarios where there is only
// one-way synchronization between cores and the synchronization operation is executed multiple times, if the core
// performing the set operation runs faster, it may result in the flag being set more than 15 times consecutively,
// leading to a system freeze. To prevent such a freeze, we need to wait for the waiting cores to perform a reverse
// synchronization operation after executing the set operation MAX_REVERSE_DEPTH times.
constexpr uint32_t MAX_REVERSE_DEPTH = 15;

using FlagID = uint16_t;
constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
constexpr FlagID AIC_INTER_BLOCK_BARRIER = 9;
constexpr FlagID AIV_INTER_SUBBLOCK_BARRIER = 10;
constexpr FlagID FFTS_MAX_FLAG = 7;

struct CrossCoreFlag {
    CATLASS_DEVICE
    CrossCoreFlag() : id(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlag(FlagID id) : id(id)
    {}

    FlagID id;
};

template <uint32_t REVERSE_DEPTH_ = MAX_REVERSE_DEPTH>
struct CrossCoreFlagWithReverse {
    CATLASS_DEVICE
    CrossCoreFlagWithReverse() : id(0), reverseId(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlagWithReverse(FlagID id, FlagID reverseId) : id(id), reverseId(reverseId)
    {}

    FlagID id;
    FlagID reverseId;
    uint32_t count{0};
};
```

The barrier flag allocation (modes 0x0/0x1 get dedicated ids 8/9/10, leaving 0-7 for users — hence `FFTS_MAX_FLAG = 7`):

```
template <>
struct BarrierFlag<0x0, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x0, AscendC::AIC> {
    static constexpr FlagID ID = AIC_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x1, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_SUBBLOCK_BARRIER;
};

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreBarrier()
{
    constexpr FlagID flagId = BarrierFlag<MODE, g_coreType>::ID;
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flagId);
    AscendC::CrossCoreWaitFlag(flagId);
}
```

The actual counter-drain primitives:

```
template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreSetFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreWaitFlag(flag.reverseId);
        flag.count = 0;
    }
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreWaitFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.reverseId);
        flag.count = 0;
    }
}
```

---

### A7.11 ★ THE OFFICIAL BUGFIX — CANN catlass MR !325 "fix: 更改默认的MAX_REVERSE_DEPTH": the original 16 "会导致卡死"

The off-by-one proof: depth 16 means the 16th Set lands before any Wait, which hangs. Merged 2025-12-18.

https://gitcode.com/cann/catlass/merge_requests/325
(API: https://api.gitcode.com/api/v5/repos/cann/catlass/pulls/325 ; GitHub mirror commit https://github.com/hicann/catlass/commit/f457683a841c )
author/date: triwooder <zhangyunsong3@huawei.com>, created 2025-10-23, merged 2025-12-18 by cann-robot

```
## 描述
更改默认的MAX_REVERSE_DEPTH为15，原设置会导致卡死

## 类型标签
- [x] Bug修复
- [ ] 新特性
- [ ] 性能优化
- [ ] 文档更新
```

The diff itself:

```
@@ -15,7 +15,12 @@
 
 namespace Catlass::Arch {
 
-constexpr uint32_t MAX_REVERSE_DEPTH = 16;
+// A certain cross core flag can be continuously set up to 15 times without waiting. In scenarios where there is only
+// one-way synchronization between cores and the synchronization operation is executed multiple times, if the core 
+// performing the set operation runs faster, it may result in the flag being set more than 15 times consecutively,
+// leading to a system freeze. To prevent such a freeze, we need to wait for the waiting cores to perform a reverse 
+// synchronization operation after executing the set operation MAX_REVERSE_DEPTH times.
+constexpr uint32_t MAX_REVERSE_DEPTH = 15;
 
 using FlagID = uint16_t;
 constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
```

Commit list for that file (shows how rarely it is touched):

```
5f10a480a107 2026-07-16T06:36:36Z yuantao_ :: 用pre-commit刷新主要文件的格式
376fc7caec04 2026-06-09T07:29:40Z li_wei21 :: add a declarative post-processing framework, EVG.
f457683a841c 2025-12-18T12:44:02Z triwooder :: fix: 更改默认的MAX_REVERSE_DEPTH
83e7d141b8a5 2025-12-18T09:38:45Z yuantao_ :: 【task】更新license
8ceefb5c735d 2025-11-06T11:46:44Z init__zhb__ :: Safety check. 
2cdcd3ad71d1 2025-09-30T02:38:14Z init__zhb__ :: 更新许可证到CANN2.0版本
ef8be58db449 2025-05-16T09:39:12Z 黄鑫 :: !96 change name to catlass
```

---

### A7.12 PRE-FIX FORM STILL IN THE WILD — vendored ACT/catlass copies with the unsafe `MAX_REVERSE_DEPTH = 16` and no comment

Anyone copy-pasting a vendored `act/arch/cross_core_sync.hpp` inherits the hang. These are live as of fetch date.

https://github.com/sgl-project/sgl-kernel-npu/blob/main/csrc/deepep/ops/utils/op_kernel/operator/catlass/act/arch/cross_core_sync.hpp
author/date: vendored Huawei ACT header inside sgl-kernel-npu / fetched 2026-10-20

```
namespace Act::Arch {

constexpr uint32_t MAX_REVERSE_DEPTH = 16;

using FlagID = uint16_t;
constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
constexpr FlagID AIC_INTER_BLOCK_BARRIER = 9;
constexpr FlagID AIV_INTER_SUBBLOCK_BARRIER = 10;
constexpr FlagID FFTS_MAX_FLAG = 7;
```

Other repos carrying `MAX_REVERSE_DEPTH = 16` (same unsafe value), from `gh search code 'MAX_REVERSE_DEPTH'`:

```
vllm-project/vllm-ascend:csrc/attention/sparse_attention_score/op_kernel/attn_infra/arch/cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
sgl-project/sgl-kernel-npu:csrc/sparse_attention_score/op_kernel/attn_infra/arch/cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
Ascend/AscendNPU-IR:bishengir/lib/Template/lib/RegBase/Cube/include/catlass/arch/cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
vllm-project/afd-plugin:csrc/npu/ascend_kernels/grouped_matmul_layered/op_kernel/gmm_infra/arch/cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
hicann/ops-transformer:gmm/grouped_matmul/op_kernel/gmm_infra/arch/gmm_cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
Ascend/MindIE-SD:csrc/ops/eagle_block_sparse_attention/op_kernel/attn_infra/arch/bsa_cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
repo-mirror-test/catlass:include/catlass/arch/cross_core_sync.hpp: constexpr uint32_t MAX_REVERSE_DEPTH = 16;
```

---

### A7.13 REAL CALL SITE — catlass `matmul_epilogue.hpp`: an unbounded `coreLoops` producer/consumer chain carried by ONE flagId + ONE reverse flagId

This is the shape a megakernel wants: 2 flagIds total regardless of how many stages, because the reverse handshake drains the counter.

https://gitcode.com/cann/catlass/blob/master/include/catlass/gemm/kernel/matmul_epilogue.hpp
(raw mirror: https://raw.githubusercontent.com/hicann/catlass/master/include/catlass/gemm/kernel/matmul_epilogue.hpp )
author/date: Huawei Technologies Co., Ltd. (CANN catlass) / fetched 2026-10-20

```
        for (uint32_t loopIdx = AscendC::GetBlockIdx(); loopIdx < coreLoops; loopIdx += AscendC::GetBlockNum()) {
            ...
            // Compute block-scoped matrix multiply-add
            blockMmad(
                gmA[gmOffsetA], params.layoutA, gmB[gmOffsetB], params.layoutB, gmC[gmOffsetC], layoutC,
                actualBlockShape);

            Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagAicFinishStore);
        }

        AscendC::PipeBarrier<PIPE_ALL>();
```

```
        for (uint32_t loopIdx = aicoreIndex; loopIdx < coreLoops; loopIdx += aicoreNum) {
            ...
            // Synchronize cross core
            Arch::CrossCoreWaitFlagWithReverse<0x2, PIPE_MTE3>(flagAicFinishStore);
            // Actual calculatioin logic for performing block-scoped epilogue
            blockEpilogue(blockShape, blockCoord, actualBlockShape, gmBlockC, layoutBlockC);
        }

        AscendC::PipeBarrier<PIPE_ALL>();
    }

private:
    // ID used for inter-core synchronization
    static constexpr Arch::FlagID FLAG_AIC_FINISH_STORE = 0;
    static constexpr Arch::FlagID RV_FLAG_AIC_FINISH_STORE = 1;
    Arch::CrossCoreFlagWithReverse<> flagAicFinishStore{FLAG_AIC_FINISH_STORE, RV_FLAG_AIC_FINISH_STORE};
    Arch::Resource<ArchTag> resource;
```

Other real call sites of the same pattern (from `gh search code 'Arch::CrossCoreSetFlagWithReverse'`), showing it is the standard across CANN libraries:

```
Ascend/AscendNPU-IR:bishengir/lib/Template/lib/RegBase/Cube/include/catlass/gemm/kernel/gemm.hpp: Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagAicFinishStore);
Ascend/AscendNPU-IR:bishengir/lib/Template/lib/RegBase/Cube/include/catlass/gemm/kernel/quant_matmul.hpp: Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(ptr->flagAicFinishStore);
Ascend/AscendNPU-IR:bishengir/lib/Template/lib/RegBase/Cube/include/catlass/gemm/kernel/group_gemm.hpp: Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagAicFinishStore);
Ascend/AscendNPU-IR:bishengir/lib/Template/lib/RegBase/Cube/include/catlass/gemv/kernel/kernel_gemv_aic.hpp: Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagAicFinishStore);
vllm-project/vllm-ascend:csrc/attention/msa_index_score/op_kernel/arch35/msa_index_score_kernel.h: Catlass::Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagSReady);
vllm-project/vllm-ascend:csrc/attention/msa_index_score/op_kernel/arch22/msa_index_score_kernel.h: Catlass::Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(flagSReady);
sgl-project/sgl-kernel-npu:csrc/chunk_kda_fwd/op_kernel/chunk_kda_fwd_prepare.h: Catlass::Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(mchSyncDoneFlag_);
flashserve/flash-linear-attention-npu:fla/ops/ascendc/gdn/chunk_gdn_fwd/solve_tri/op_kernel/solve_tri_fp32.h: Catlass::Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_FIX>(aicToAiv_);
flashserve/flash-linear-attention-npu:fla/ops/ascendc/gdn/chunk_gdn_fwd/solve_tri/op_kernel/solve_tri_fp32.h: Catlass::Arch::CrossCoreSetFlagWithReverse<0x2, PIPE_MTE3>(aivToAic_);
```

---

### A7.14 ★ ACTUAL flagId ROTATION IN PRODUCTION CODE — `#define MAKE_ID ((++idCounterNum) % 11)` plus the documented A3 AIV0/AIV1 +16 stride

This is the only real "rotate the id across many sequential stages" scheme I found: a `__BLOCK_LOCAL__` monotone counter taken mod 11, with 16 as the sentinel "invalid id".

https://github.com/sgl-project/sgl-kernel-npu/blob/main/csrc/sparse_flash_attention/op_kernel/common/buffer.h
author/date: sgl-project / sgl-kernel-npu (namespace `fa_base_matmul`) / fetched 2026-10-20. The same file also exists at https://github.com/Ascend/MindIE-SD/blob/master/csrc/ops/common/op_kernel/buffer.h

```
using namespace AscendC;
namespace fa_base_matmul {
__BLOCK_LOCAL__ __inline__ uint32_t idCounterNum;
#define MAKE_ID ((++idCounterNum) % 11)

// 核间同步中，AIC(flagId 0-10)对应AIV0(flagId 0-10)，对应AIV1(flagId 16-26)
#define AIV0_AIV1_OFFSET 16
```

```
constexpr uint32_t INVALID_CROSS_CORE_EVENT_ID = 16;
static constexpr uint64_t CROSS_CORE_SYNC_MODE = 4;
```

```
            id0_ = MAKE_ID;
            id1_ = INVALID_CROSS_CORE_EVENT_ID;
...
            id0_ = INVALID_CROSS_CORE_EVENT_ID;
            id1_ = MAKE_ID;
...
            id0_ = MAKE_ID;
            id1_ = MAKE_ID;
...
            id0_ = INVALID_CROSS_CORE_EVENT_ID;
            id1_ = INVALID_CROSS_CORE_EVENT_ID;
```

How the rotated ids are consumed (note the mirrored `+ AIV0_AIV1_OFFSET` set/wait for the two AIVs):

```
    __aicore__ inline void WaitCrossCore()
    {
...
                CrossCoreWaitFlag<CROSS_CORE_SYNC_MODE, PIPE_MTE2>(id1_);
                CrossCoreWaitFlag<CROSS_CORE_SYNC_MODE, PIPE_MTE2>(id1_ + AIV0_AIV1_OFFSET);
...
                CrossCoreWaitFlag<CROSS_CORE_SYNC_MODE, PIPE_FIX>(id1_);
                CrossCoreWaitFlag<CROSS_CORE_SYNC_MODE, PIPE_FIX>(id1_ + AIV0_AIV1_OFFSET);
...
    __aicore__ inline void SetCrossCore()
    {
...
                CrossCoreSetFlag<CROSS_CORE_SYNC_MODE, PIPE_FIX>(id0_);
                CrossCoreSetFlag<CROSS_CORE_SYNC_MODE, PIPE_FIX>(id0_ + AIV0_AIV1_OFFSET);
```

---

### A7.15 ★ REAL-WORLD ANALYSIS of the freeze, with per-AIV id segmentation and the A2 `0x2` broadcast trap — flash-linear-attention-npu design doc

Long engineering log from a kernel that hit exactly the failure mode in question (sets accumulating on a flag nobody waits on). Quotes the catlass comment as the root cause.

https://github.com/flashserve/flash-linear-attention-npu/blob/main/fla/ops/ascendc/cp/pre_process_bwd_kernel_merged/docs/design.md
author/date: flashserve / flash-linear-attention-npu contributors / fetched 2026-10-20

```
1. A2 的 `mode 0x2` 是"AIC : 2*AIV 集合同步"，**没有 subblock 选择语义** ⇒ AIC 的一次 set 会同时落到
   **两个** AIV 的同一 id 上；而 AIV→AIC 方向是点对点（这也是 fwd_h 能按 `vec1Done[0]/[1]` 分别寻址
   AIC 侧寄存器的原因）。
2. 由此得到三条推论：
   * **共享 id + 每个 AIV 一条独立链**（§17 尝试 1）：AIC 服务 head A 时 set 的 `T1_READY` 会
     **同时放行**正在等 head B 的另一个 AIV ⇒ 事件与链错配（实测死锁）。
   * **per-AIV id 段 + 独立链**（§17 尝试 2、§21 尝试 3）：AIC 给 AIV1 的 set 会**顺带**落在 AIV0 的
     同一 id 寄存器上，而 AIV0 永远不 wait 它 ⇒ 该寄存器上"未被消费的 set"持续累积。catlass 明确写了
     *"a cross core flag can be continuously set up to 15 times without waiting, leading to a system
     freeze"*（`MAX_REVERSE_DEPTH = 15`，见 `third_party/catlass/include/catlass/arch/cross_core_sync.hpp:22`）
     ⇒ 长序列必然冻结。这类"跑一阵子才挂"的症状与之完全吻合。
   * 只有**两个 AIV 在同一个逻辑点 wait 同一个 id**（集合语义的正确用法，也是 fwd_h 的做法）时，
     broadcast 才自洽：AIC 一次 set 给两个 AIV 各自 +1，两个 AIV 各 wait 一次 ⇒ 账本平衡；
     AIV→AIC 方向则由两个 AIV 各 set 一次、AIC 连续 wait 两次构成 rendezvous。
```

The per-AIV flagId segmentation table they actually used (and the explicit "setter may lead by at most 15" reasoning for dropping a dimension):

```
* **尝试 2（按 `fwd_h` 的写法给每个 AIV 一段独立 id）**：先确认 910B 的 flag 上限只有 8 个
  （catlass `FFTS_MAX_FLAG = 7`），因此把 `T1_READY`/`T1BF_READY` 合并成一个 base（方向相反、
  落在不同核的寄存器上，可共用 id），并**去掉 window 维度**，得到 AIV0 = 0..3、AIV1 = 4..7：

  | base | 方向 | AIV0 id | AIV1 id |
  | --- | --- | --- | --- |
  | V0_READY | AIV→AIC | 0 | 4 |
  | T1_READY / T1BF_READY | AIC→AIV / AIV→AIC | 1 | 5 |
  | Z_READY | AIC→AIV | 2 | 6 |
  | STATE_READY | AIV→AIC | 3 | 7 |

  结果：`gva` 档（Hv=32，1 轮）**通过**；`kda` 档（Hv=64，2 轮）仍挂住，原因未定。
  （`window` 维度去掉是安全的：flag 是计数器、允许 setter 领先最多 15 次，只要两侧按同一
  chunk 顺序推进，一个 base 一个 id 就够；双 window 只省一次跨核往返，不是正确性前提。）
```

The A5 id-space convention they adopted (relevant to how to budget ids):

```
| 4 | ready/free 双向 credit：每个 local slot × 每类数据用**同一个 ID 双向计数**，ready 由真实生产 pipe 发布、free 由最后消费者发布，复用前必须完成上一代 wait；A5 的 AIV 本地 ID 0..10，AIC 侧用 16-ID 步长区分 AIV0/AIV1 | 替换我现在 5 条单向 ready 链（`V0/T1/T1BF/Z/STATE`）；双向 credit 才能让"生产者领先消费者"真正成立 |
```

Operational warning in the same doc (what happens after a flag deadlock):

```
**运维注意**：两次挂死后 `run_case` 进程被 `kill -9`，device 停在 AICore 100% 且无进程占用，
`npu-smi set -t reset -i 0 -c 0` 被拒（AMP + HCCS 模式下会要求重启全部设备且执行失败），
**必须重启该主机才能恢复**；期间同一台机器上的任何用例都会同样挂住（实测：原本通过的
`gva_cp64` 在设备卡住后也变成 10 分钟不返回）。因此排查 A2 的 1:2 之前要先确认设备已恢复。
```

---

### A7.16 ★ REAL DEADLOCK + FIX — flash-linear-attention-npu PR #825: one flagId shared by three consumer stages on different pipes steals credits; 42 runs → 8 hangs, fixed by splitting into three flagIds

Directly on the "flag credit carries no label" problem that bites a many-stage megakernel.

https://github.com/flashserve/flash-linear-attention-npu/pull/825
author/date: wzzll123 (wzz) / 2026-09-30

```
## 为什么还要拆分 flag

只做“等待后移”会间歇性死锁。原来 `free[slot]` 被 V0、V3、V6 三个阶段轮流等待；V0/V6 后移并改成 `PIPE_MTE3` 后，同一计数器上同时可能有 `PIPE_MTE3` 和 `PIPE_V` 的阻塞等待。flag 的一次信用不携带“应交给哪个阶段”的标签，跨 pipe 消费顺序不再受原来的 MTE2→V→MTE3 mutex 链保证。例如 V3 抢走本应让 V0 继续的信用，V0 的 workspace 写被卡住，V1 发不出 `ready`；AIC 等不到 `ready`，也就做不了 C2、发不出下一次信用。

修复提交 `8f96f635` 把这三种依赖拆成独立通道：`C7→V0` 用 `free`，`C2→V3` 用 `scoreReady`，`C4→V6` 用 `payloadRepurpose`。每条通道只由预定的阶段和 pipe 消费；末尾清账的 `free` wait 也改为 `PIPE_MTE3`。这保留了提交 `7a88bf27` 的等待后移与重叠计算。
```

The flagId map before and after (A5 / mode 0x4, with the AIC-side +16 stride for AIV1):

```
# AIV 本地每个 slot 的 flag 编号；AIV0、AIV1 各自使用一套本地编号。
ready             = [0, 1] # V1/V3/V6 -> C2/C4/C7
score_ready       = [2, 3] # C2 -> V3
free              = [4, 5] # 初始许可或上一轮 C7 -> 下一轮 V0
payload_repurpose = [6, 7] # C4 -> V6
```

```
def aic_one_group(chunk, group_begin, active_heads):
    # AIC 视角：AIV1 的本地 ID 映射到另一组核间 flag 编号。
    ready             = [0, 1, 16, 17]
    score_ready       = [2, 3, 18, 19]
    free              = [4, 5, 20, 21]
    payload_repurpose = [6, 7, 22, 23]
```

The reproduction statistics (so the failure is probabilistic, not deterministic — important for a 78-layer kernel):

```
| 快速直调复现(修复前) | 42 次挂 8 次(AIC+双 AIV 跨核停等,aicore timeout) |
| 快速直调复现(修复后,PR 最终树) | **70 次全清**(d4×30+d5×10 + 最终树 d4×20+d5×10;作者场景 BNSD+recompute 另查 10/10) |
```

Also, the "initial credit" trick worth noting — AIC pre-seeds one Set per slot before the loop:

```
    for local_head in range(active_heads):
        if first_use_of_this_local_head(local_head):
            SET(PIPE_FIX, free[local_head])  # 初始只发一次；后续由 C7 归还
```

---

### A7.17 PTOAS issue #985 — full functional spec of the three parameters, including the A5 0-31 flag_id address space and per-mode table

Useful as an independent restatement of the contract, and because it quotes the hiascend doc URL for `CrossCoreSetFlag`.

https://github.com/hw-native-sys/PTOAS/issues/985
author/date: bingmeiyou / 2026-07-23 (comment by W4termy 2026-08-11)

```
| 参数 | 类型 | 说明 |
|------|------|------|
| `mode_id` | int | 同步模式，取值 0/1/2/4，控制信号传播范围（跨 block 全核同步 / AIV 间同步 / CV 广播汇聚 / CV 逐子核 1:1） |
| `pipe` | str | 流水线类型，如 PIPE_FIX / PIPE_MTE3 / PIPE_V / PIPE_M 等，指定信号发射或等待的流水线 |
| `flag_id` | int 或 PrimExpr | 信号量编号，A5 平台范围 0-31（0-15 对应 AIV0，16-31 对应 AIV1） |
```

```
| mode_id | 含义 | 典型场景 |
|---------|------|---------|
| 0 | 跨 block 同类型核同步（所有 AIC↔AIC 或所有 AIV↔AIV） | 多个 block 分担计算，需要所有同类型核到达屏障 |
| 1 | block 内 AIV 子核间同步（AIV0 ↔ AIV1） | 两个 AIV 子核协作处理数据，需要互相通知 |
| 2 | block 内 AIC↔AIV 同步，广播+汇聚（一次 set 到达两个 AIV，一次 wait 等到两个 AIV 都完成） | AIC 算完 GEMM 一次性通知两个 AIV 来搬数据 |
| 4 | block 内 AIC↔AIV 同步，1:1 逐子核（AIV0 和 AIV1 可单独触发） | AIC 分别通知 AIV0 和 AIV1，用不同 flag_id 区分目标子核 |
```

```
### flag_id 参数

A5 平台上 flag_id 地址空间为 0-31：0-15 对应 AIV0，16-31 对应 AIV1（+16 偏移）。mode 4 场景中，AIC 需要用不同的 flag_id 分别通知两个 AIV 子核。
```

```
如果 wait 端 stall 了错误的流水线，需要同步的流水线不会被阻塞，导致读到未就绪数据。
```

The `SyncAll` lowering request in the comment, confirming SyncAll ≡ mode 0:

```
该算子运行在 AIV kernel 中，需要所有参与执行的 AIV core 到达同步点后再继续，
语义上对应本 issue 描述的 mode_id=0 跨 block 同类型核同步。
```

---

### A7.18 triton-ascend official docs — `al.sync_block_set` / `sync_block_wait`: counter semantics in one paragraph, event_id range `[0,15]`

https://github.com/Ascend/triton-ascend/blob/main/docs/zh/triton_api_extention/al/sync_block_set.md
author/date: Ascend / triton-ascend / fetched 2026-10-20

```
# al.sync_block_set 接口文档

## 1. 硬件背景

面向分离模式的核间同步控制接口。

该接口和 sync_block_wait 接口配合使用。使用时需传入核间同步的标记ID(flagId)，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。
```

```
    <td>event_id</td>
    <td>int</td>
    <td>同步标记ID，取值范围 [0,15]</td>
```

```
## 5. 约束说明

- sender != receiver
```

And the companion overview doc which states "共16个独立事件":

https://github.com/Ascend/triton-ascend/blob/main/docs/zh/triton_api/Extension_Ops/sync_block.md
author/date: Ascend / triton-ascend / fetched 2026-10-20

```
#### 2.2.2 特殊限制说明

1. `sender` 和 `receiver` 不能相同，不能自己给自己发信号
2. `event_id` 必须在 0-15 范围内（共16个独立事件）
```

```
#### 3.2.2 特殊限制说明

1. `sender` 和 `receiver` 不能相同
2. `event_id` 必须与对应 `sync_block_set` 使用的 ID 一致
```

---

### A7.19 OFFICIAL CANN DOC ISSUE — `asc-devkit` #22 "CrossCoreSetFlag接口描述矛盾": an external developer reports the +1/-1 counter wording contradicts the "all cores must arrive" wording

Confirms the counter is NOT a plain per-core semaphore under mode 0/1/2: the scheduler aggregates. Current master doc was edited to drop the +1/-1 sentence (compare item 1's 功能说明 with the text quoted inside this issue).

https://gitcode.com/cann/asc-devkit/issues/22
author/date: munanhw / 2025-12-19, state closed

```
### Document Link（文档链接）
            
https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/CrossCoreSetFlag(ISASI).md
### Issues Section（问题文档片段）
            
![image.png](https://raw.gitcode.com/user-images/assets/8547062/a39f6ddc-2e1d-45fe-a263-e41c89222986/image.png 'image.png')
### Existing Issues（存在的问题）
            
来自外部开发者工单：

这两段话很矛盾
到了set变1，wait-1，那核心岂不是自顾自走了？ 下面说全部到才会继续，这样才显得合理

该接口和CrossCoreWaitFlag接口配合使用。使用时需传入核间同步的标记ID(flagId)，每个ID对应一个初始值为0的计数器。执行CrossCoreSetFlag后ID对应的计数器增加1；执行CrossCoreWaitFlag时如果对应的计数器数值为0则阻塞不执行；如果对应的计数器大于0，则计数器减一，同时后续指令开始执行。 同步控制分为以下几种模式，如图1所示： 模式0：AI Core核间的同步控制。对于AIC场景，同步所有的AIC核，直到所有的AIC核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行；对于AIV场景，同步所有的AIV核，直到所有的AIV核都执行到CrossCoreSetFlag时，CrossCoreWaitFlag后续的指令才会执行。 模式1：AI Core内部，AIV核之间的同步控制。如果两个AIV核都运行了CrossCoreSetFlag，CrossCoreWaitFlag后续的指令才会执行。 模式2：AI Core内部，AIC与AIV之间的同步控制。在AIC核执行CrossCoreSetFlag之后， 两个AIV上CrossCoreWaitFlag后续的指令才会继续执行；两个AIV都执行CrossCoreSetFlag后，AIC上CrossCoreWaitFlag后续的指令才能执行。
```

---

### A7.20 ★ REAL "two consecutive Sets of the same flagId" BUG REPORT in shipped CANN code — `cann/ops-solver` #13

Exactly the illegal pattern described in item 6 ("不允许连续设置同一个flagId"), found in `cgetrf_kernel.cpp`.

https://gitcode.com/cann/ops-solver/issues/13
author/date: zhanghua145 / 2026-06-29, state closed

```
## 问题描述

src/cgetrf/cgetrf_kernel.cpp:304-305 连续两次调用 `CrossCoreSetFlag<0x0, PIPE_MTE3>(0x6)` 设置完全相同的标志。同样在第439-440行连续两次 `CrossCoreWaitFlag(0x6)` 等待相同标志。这可能是意图设置/等待两个不同标志但代码错误地使用了相同的0x6，导致同步语义错误。

## 环境信息

- 芯片型号：Ascend 910B3
- CANN 版本：8.0.0
- 操作系统：Ubuntu 22.04

## 重现步骤

1. 分析 blockIdx>=8 且 blockM>512 时的核心同步行为

## 预期结果

若需设置两个独立标志，应分别使用不同的 flag 值

## 日志 / 截图

文件：src/cgetrf/cgetrf_kernel.cpp:304

## 备注

严重等级：medium
```

---

### A7.21 ★ HARDWARE BEHAVIOUR CONFIRMED BY TOOLING — `Ascend/mssanitizer` #166: when an AIV flagId exceeds 15 the HARDWARE TRUNCATES it, so synccheck's deadlock report is a false positive

Independent confirmation of item 3's "截取低4bit".

https://gitcode.com/Ascend/mssanitizer/issues/166
author/date: gong-siwei / 2026-07-28, state closed

```
### 🐛 问题描述
            
 synccheck检测核间同步mode4场景时，当AIV上flag id超过15时，属于非法范围，synccheck会报告死锁，但是算子实际不会死锁，硬件会截断AIV的flag id，因此建议synccheck不要报告死锁
```

Title (verbatim):

```
[Bug]: synccheck检测核间同步mode4场景时，当AIV上flag id超过15时，属于非法范围，synccheck会报告死锁，但是算子实际不会死锁
```

---

### A7.22 ★ SIMULATOR MODEL EVIDENCE for the 16-ID / 4-bit encoding, and a high-frequency set/wait overflow — `Ascend/msopprof` #175

The reporter disassembled `libpem_davinci.so` and found the ID bound check `cmp $0xf; ja <error>`. Also quotes the `GetffstMsg` 4-bit encoding. Note: the kernel runs FINE on real silicon with 4 fixed ids reused at high frequency — only the simulator's internal pairing pool overflows.

https://gitcode.com/Ascend/msopprof/issues/175
author/date: chenjiayi_ / 2026-10-19, state open

```
AscendC Kernel 使用**固定合法 flag ID** 的 `CrossCoreSetFlag` / `CrossCoreWaitFlag` 跨核同步时，在多核（32 AIC）× 高频（kstep 流水反复收发同一 ID）× 长时间仿真的场景下，仿真器报 `set_cross_core flag ID overflows` 错误。**msopprof simulator 与 npusim两个工具均复现**（共用同一仿真模型库 libpem_davinci.so）。

关键事实：

1. **溢出时 kernel 传入的 flagId 恒为 10/11**（npusim 报错自带 `coreId/subcoreId/flagId` 上下文证实），远小于硬件编码的 16 ID 上限（`GetffstMsg` 按 `flagId & 0xf` 编码，4 bit / mode），ID 本身完全合法；
2. **溢出条数远超 kernel 逻辑 flag 操作数**（10 倍以上）且随仿真周期线性增长——溢出的是仿真器内部为 (core, flag) 维护的状态/配对记录池，而非用户可见的 flag ID 值；
3. 溢出后 `wait` 立即失败返回，跨核同步语义损坏，流水时序数据不可信；错误累积至约 4.6 万条时仿真器直接崩溃退出，无 trace 落盘；
4. **同一 kernel 真机上板运行完全正常**（精度 PASS、无死锁），仅仿真受影响。
```

The kernel's own flag budget (a 2-slot ready/free credit scheme on ids 8..11):

```cpp
// include/block/quant_matmul_mxfp8_block_mmad_swat_ub.h
// readyFlag_ = 8, freeFlag_ = 10, slot ∈ {0, 1}
AscendC::CrossCoreWaitFlag<2, PIPE_FIX>(freeFlag_ + slot);   // ID {10, 11}
AscendC::CrossCoreSetFlag<2, PIPE_FIX>(readyFlag_ + slot);   // ID {8, 9}
```

The disassembly note and expected behaviour:

```
- **定位分析**（供参考）：对 `libpem_davinci.so` 反汇编可见 `Pem::set_flag(unsigned, unsigned)` 入口处含 `cmp $0xf; ja <error>` 检查（拦截 ID>15），但用户 ID 恒为 8-11，不可能触发该分支——报错实际来自内部状态管理路径。库内另有 `Isa::update_flag_id()`、`flag_info` 等符号，推测为 set/wait 配对记录结构，容量固定或未回收，在大规模高频场景下耗尽；
- **触发条件归纳**：跨核 flag 高频反复收发（32 核 × kstep 流水重叠 × 仿真百万周期级）。小规模（kSteps ≤ 3）不触发；
```

```
- 硬件 flag 池每 mode 支持 16 个 ID（`GetffstMsg` 按 `flagId & 0xf` 编码），kernel 固定使用 4 个合法 ID 反复 set/wait 属于正常使用模式，仿真器应正确建模并**正常完成仿真**；
```

Error text seen (with the legal flagId in context):

```
[ERROR] pem.cc:1009 set_flag set_cross_core flag ID overflows!
coreId: 29
subcoreId: 0
flagId: 11        ← 用户传入的合法 ID（< 16）
[ERROR] pem_issque.cc:1029 exec_wait_flag_dev flag ID overflows
```

---

### A7.23 flagId COLLISION causing intermittent WRONG RESULTS (not a hang) — `cann/ops-transformer` #4882

Short but it is the failure mode that item 5 warns about ("同步提前完成、阻塞提前解除而导致计算结果错误").

https://gitcode.com/cann/ops-transformer/issues/4882
author/date: wangss21 / 2026-09-02, state closed

```
### Describe the current behavior / 问题描述 (Mandatory / 必填)
            
Mlaprolog 存在核间同步flagId冲突问题，导致OOM版本偶现精度失败
### Environment / 环境信息 (Mandatory / 必填)
            
Ascend950
### Steps to reproduce the issue / 重现步骤 (Mandatory / 必填)
            
OOM版本会出现2/3路输出偶现精度失败
```

---

### A7.24 flagId SCOPE established as per-combo, but the MEMORY-ORDER contract of CrossCoreSetFlag on A3/mode 2 is UNDEFINED in public docs — `Kurtnirvana/cannbot-knowledge` #9

Relevant because a megakernel handing data between AIC and AIV through GM cannot assume the flag flushes anything.

https://gitcode.com/Kurtnirvana/cannbot-knowledge/issues/9
author/date: Kurtnirvana / 2026-09-30, state open

```
## 问题

在 Atlas A3（modeId=2，AI Core 内 AIC↔AIV 同步）下用 CrossCoreSetFlag/WaitFlag 做跨核 GM 数据交接时，两点契约在知识仓中无法查到：

1. **内存序语义**：CrossCoreSetFlag/WaitFlag 是否隐含 GM 写可见性 / 写回（冲刷）保证，还是仅保证「前置 pipe 指令完成 → 后续指令下发」这一指令序？
2. **正确的跨核 GM 交接方式**：若只是指令序，跨核经 GM 交接 P/S 数据是否需要额外同步原语（DCCI / Scalar.DSB / MEMBAR）或 GM→GM 中转约束？

同族的 flagId 作用域问题（per-AIC / per-AI-Core 分域 vs 全局）已有明确出处，不在本 Issue 范围。
```

```
- 知识仓 `cross_core_set_flag_isasi.md` 对 flag 的唯一顺序承诺是「pipe：标识在哪条流水的前序指令完成后，CrossCoreSetFlag 才向调度模块发送通知」，`cross_core_wait_flag_isasi.md` 为「阻塞本核后续指令的下发」；两页均未声明 GM 可见性/写回语义。
- 知识仓 `memory_consistency.md`「核间内存一致性」给出的通用规则是：硬件不会自动为多个 AI Core 建立全局读写顺序；跨核生产者-消费者流程需 `DCCI data → Scalar.DSB → ARRIVE / WAIT → DCCI → Scalar.DSB → LOAD`；并明确「arrive/wait 类接口只传递同步信号……使用这些接口后，仍需要根据数据访问路径判断是否需要 DCCI 和 DSB」。但该页只点名 `asc_sync_block_arrive/wait`、`asc_sync_inter_arrive/wait`，未把规则落到 CrossCoreSetFlag/WaitFlag。
```

```
2. 给出跨核经 GM 交接数据的推荐序列（写端 `DCCI + Scalar.DSB` → `CrossCoreSetFlag`，读端 `CrossCoreWaitFlag` → `DCCI` 失效旧副本后再读），并说明 MTE3 非 DCache 路径下可省略哪些步骤。
```

Verdict recorded in the same issue (flag domain resolved, memory order not):

```
已得到的答案：(1) 已回答——flag 域=per-combo，本地文档有出处（inter_core_sync/key_features），且实验 A 用错位 set/wait 探针双向实证（候选①关闭、预案 β 排除）；(2) 未回答——架构师回传「内存序公开契约未定义」，QA 复审还要求核实该「未定义」结论的文档出处真实性。
```

---

### A7.25 `CrossCoreWaitFlag` mode coverage request in catlass — `cann/catlass` #153 (confirms catlass's wrapper hard-wired `(0x1, PIPE_S)` defaults)

https://gitcode.com/cann/catlass/issues/153
author/date: lihao_huawei / 2026-04-14, state closed

```
### Backgroud / 背景信息 (Mandatory / 必填)
            
1、CrossCoreWaitFlag AscendC是支持0x4 ,0x2 0x1模式，并且支持插入在不同流水线后面，当前已经实现的CrossCoreWaitFlag使用的默认值(0x1, PIPE_S)
### Origin / 信息来源 (Mandatory / 必填)
            
RecSDK CATLASS HSTU
```

---

### A7.26 OFFICIAL DOC — `SyncAll`: hard sync is built on CrossCoreSetFlag internally; soft sync is a GM algorithm; and `numBlocks > physical cores` ⇒ "卡死"

Older snapshot:
https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/SyncAll.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit) / unknown date

```
## 功能说明
当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用该函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬件同步是利用硬件自带的全核同步指令由硬件保证多核同步，软件同步是使用软件算法模拟实现。
```

```
-   使用该接口进行多核控制时，算子调用时指定的逻辑numBlocks必须保证不大于实际运行该算子的AI处理器核数，否则框架进行多轮调度时会插入异常同步，导致Kernel“卡死”现象。
-   在分离模式下，建议使用硬同步接口而非软同步接口。软同步接口仅适用于纯Vector场景，且性能较低。使用硬同步接口时，需根据场景设置Kernel类型：
```

Current `docs/zh` snapshot (explicit statement that hard SyncAll consumes flagIds via CrossCoreSetFlag, and the 3-step decomposition):

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/SyncAll.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
    - 纯Vector算子的全核同步，可参考[CrossCoreSetFlag的模式0](key_features.md)。
    - 融合算子的全核同步，一次性实现三个核间同步能力（参考[CrossCoreSetFlag的关键特性说明](key_features.md)）：首先完成单个AI Core内，AIC与所有AIV同步（AIC等AIV）；接着完成多个AI Core间，所有AIC的同步；最后完成单个AI Core内，所有AIV与AIC同步（AIV等AIC）。
```

```
    - SyncAll硬件同步接口内部实现中使用了[CrossCoreSetFlag](CrossCoreSetFlag_ISASI.md)和[CrossCoreWaitFlag](CrossCoreWaitFlag_ISASI.md)进行核间同步控制，因此开发者同时使用CrossCoreSetFlag（或CrossCoreWaitFlag）和SyncAll硬件同步接口时，需注意避免flagId冲突，各接口flagId占用的完整说明参见[核间同步flagId占用说明](key_features.md#inter_core_sync_flagid_usage)。
```

---

### A7.27 OFFICIAL DOC — `IBSet`: its `eventID` is a GM-slot index, explicitly NOT the hardware event/flag resource. So IBSet/IBWait do NOT share the 16-deep cross-core counter.

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_core_sync/IBSet.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
| eventID | 输入 | 同步事件的逻辑编号，与`blockIdx`共同确定`gmWorkspace`中的同步标志，用于区分同一对生产者和消费者之间的不同软件同步事件。<br>该参数与[SetFlag/WaitFlag](../intra_core_sync/SetFlag_WaitFlag_ISASI.md)的入参名称相同，但含义不同：本接口的`eventID`用于定位软件同步标志，SetFlag/WaitFlag的`eventID`用于硬件指令中的核内流水同步事件。<br>因此，本接口的`eventID`不适用SetFlag/WaitFlag中0-7的取值限制。取值为非负整数，建议从0开始连续编号。 |
```

```
    \text{gmWorkspace空间大小} \geq (\mathrm{eventStride} \times \mathrm{eventID\_max} + \mathrm{blockIdx\_max} + 1) \times 32\text{字节}
```

```
    AIVOnly模式下`GetBlockNum() = 4`，核0作为生产者分别通过`IBSet(sync_gm, sync_buf, 0, 0)`和`IBSet(sync_gm, sync_buf, 0, 1)`通知两个不同同步事件，核2作为生产者通过`IBSet(sync_gm, sync_buf, 2, 0)`通知另一个同步事件。对应的IBWait必须分别传入相同的`blockIdx`和`eventID`，例如`IBWait(sync_gm, sync_buf, 0, 1)`只能等待`IBSet(sync_gm, sync_buf, 0, 1)`设置的同步标志；如果误传为`blockIdx = 1`或`eventID = 0`，会访问另一处同步标志并可能卡死。该场景中`blockIdx_max = 2`、`eventID_max = 1`、`eventStride = 4`，因此`gmWorkspace`至少需要`(4 × 1 + 2 + 1) × 32 = 224`字节。
```

---

### A7.28 OFFICIAL DOC — `同步控制简介` (sync control overview): the SetFlag/WaitFlag intra-core flag is a single BIT (set to 1 / cleared to 0), in contrast to the cross-core COUNTER

Useful contrast: intra-core hardware events are 1-bit, which is why "two consecutive Sets" is also illegal there but for a different reason.

https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/同步控制简介.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit) / unknown date

```
-   多流水同步：通过[TQueSync](TQueSync.md)的SetFlag/WaitFlag或者[SetFlag/WaitFlag\(ISASI\)](SetFlag-WaitFlag(ISASI).md)接口进行不同流水线间的同步控制。
    -   SetFlag：当前序指令的所有读写操作都完成之后，当前指令开始执行，并将硬件中的对应标志位设置为1。
    -   WaitFlag：当执行到该指令时，如果发现对应标志位为0，该队列的后续指令将一直被阻塞；如果发现对应标志位为1，则将对应标志位设置为0，同时后续指令开始执行。
```

Pipe table from the same doc (needed to pick the `pipe` template arg):

```
PIPE_S
标量流水线，使用Tensor GetValue函数时为此流水
PIPE_V
矢量计算流水及部分硬件架构下的L0C Buffer-&gt;UB数据搬运流水
PIPE_M
矩阵计算流水
PIPE_MTE1
L1 Buffer -&gt;L0A Buffer、L1 Buffer-&gt;L0B Buffer数据搬运流水
PIPE_MTE2
GM-&gt;L1 Buffer、GM-&gt;UB等数据搬运流水
PIPE_MTE3
UB-&gt;GM等数据搬运流水
PIPE_FIX
L0C Buffer-&gt;GM、L0C Buffer -&gt;L1等数据搬运流水
```

The `核间同步` chapter index, which enumerates the complete set of inter-core sync APIs (so nothing with "reset" or "clear" exists):

https://gitcode.com/cann/asc-devkit/blob/master/docs/api/context/核间同步.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit) / unknown date

```
# 核间同步<a name="ZH-CN_TOPIC_0000001871607660"></a>

-   **[IBSet](IBSet.md)**  

-   **[IBWait](IBWait.md)**  

-   **[SyncAll](SyncAll.md)**  

-   **[CrossCoreSetFlag\(ISASI\)](CrossCoreSetFlag(ISASI).md)**  

-   **[CrossCoreWaitFlag\(ISASI\)](CrossCoreWaitFlag(ISASI).md)**  

-   **[InitDetermineComputeWorkspace](InitDetermineComputeWorkspace.md)**  

-   **[NotifyNextBlock](NotifyNextBlock.md)**  

-   **[WaitPreBlock](WaitPreBlock.md)**  
```

---

### A7.29 mssanitizer soft-sync classification doc — explicitly marks `CrossCoreSetFlag`/`CrossCoreWaitFlag` as HARDWARE inter-core sync, not reportable soft sync

Relevant for tooling: racecheck/synccheck already models them; you do not report them via `sanitizer_report.h`.

https://github.com/kali20gakki/msAgent/blob/master/skills/operator/mstx-report-soft-sync/SKILL.md
author/date: kali20gakki / msAgent skill (mirrors Ascend mssanitizer guidance) / fetched 2026-10-20

```
- 硬件同步（非软同步）：`SetFlag`/`WaitFlag`/`PipeBarrier`（核内事件同步）、`CrossCoreSetFlag`/`CrossCoreWaitFlag`（硬件核间同步）。
```

```
| 核间 barrier | 同卡多个核到达同步点后一起继续 | `MstxCrossCoreBarrier` |
| 核间 set/wait | 核 A 发信号，核 B 等待后才继续 | `MstxCrossCoreSetFlag` / `MstxCrossCoreWaitFlag` |
```

https://github.com/kali20gakki/msAgent/blob/master/skills/operator/mstx-report-soft-sync/references/recognition-examples.md
author/date: kali20gakki / msAgent / fetched 2026-10-20

```
| `CrossCoreSetFlag` / `CrossCoreWaitFlag` | 否（硬件核间同步） | 不处理 |
```

---

### A7.30 Community quick-reference (secondary, corroborating) — `FinResect/CANN` Ascend C 核心速查

https://github.com/FinResect/CANN/blob/main/docs/Ascend%20C%E7%AE%97%E5%AD%90%E5%BC%80%E5%8F%91%E6%8C%87%E5%8D%97-%E6%A0%B8%E5%BF%83%E9%80%9F%E6%9F%A5.md
author/date: FinResect (community compilation of the CANN guide) / fetched 2026-10-20

```
### 10.3 核间同步优化

- 避免多核同时访问同一 GM 地址（被串行化，性能下降 10-20%）
- 错峰访问；首次加载到 L2 Cache 后后续访问反而性能提升
- CrossCoreSetFlag 同一 flagId 计数器上限 15 次
```

---

### A7.31 OTHER REAL FLAG-BUDGET PATTERNS seen in public kernels (no rotation, fixed small sets) — for comparison

These are the macro-wrapper style: a fixed handful of named ids per direction, re-used every iteration, relying on strict alternation rather than rotation.

https://github.com/sgl-project/sgl-kernel-npu/blob/main/csrc/recurrent_gated_delta_rule/op_kernel/tensorutils.h
author/date: sgl-project / sgl-kernel-npu / fetched 2026-10-20

```
#define ALLCUBE_READY(iiii, append_to_pipe) CrossCoreSetFlag<0x0, append_to_pipe>(iiii)
#define ALLCUBE_WAIT(iiii) CrossCoreWaitFlag(iiii)
#define ALLVEC_READY(iiii, append_to_pipe) CrossCoreSetFlag<0x0, append_to_pipe>(iiii)
#define ALLVEC_WAIT(iiii) CrossCoreWaitFlag(iiii)
#define CUBE_READY(iiii, append_to_pipe) CrossCoreSetFlag<0x2, append_to_pipe>(iiii)
#define WAIT_CUBE(iiii) CrossCoreWaitFlag(iiii)
#define VEC_READY(iiii, append_to_pipe) CrossCoreSetFlag<0x2, append_to_pipe>(iiii)
#define WAIT_VEC(iiii) CrossCoreWaitFlag(iiii)
```

Further examples found by `gh search code 'CrossCoreSetFlag'` (fixed ids, often a base + db index — a 2-deep rotation):

```
sgl-project/sgl-kernel-npu:csrc/compressor/op_kernel/arch35/compressor_kernel.h: CrossCoreSetFlag<SYNC_MODE0, PIPE_FIX>(SYNC_C1_FLAG);
sgl-project/sgl-kernel-npu:csrc/compressor/op_kernel/arch35/compressor_kernel.h: CrossCoreSetFlag<SYNC_MODE2, PIPE_FIX>(SYNC_C1_V1_FLAG + info.cubeDbIdx);
sgl-project/sgl-kernel-npu:csrc/compressor/op_kernel/arch22/compressor_kernel_perf.h: CrossCoreSetFlag<SYNC_MODE0, PIPE_FIX>(SYNC_C1_FLAG);
sgl-project/sgl-kernel-npu:csrc/compressor/op_kernel/arch22/compressor_kernel_perf.h: CrossCoreSetFlag<SYNC_MODE2, PIPE_FIX>(SYNC_C1_V1_FLAG + info.cubeDbIdx);
sgl-project/sgl-kernel-npu:csrc/deepep/ops/op_kernel/dispatch_ffn_combine_kernel/utils/hccl_shmem.hpp: AscendC::CrossCoreSetFlag<0x0, PIPE_FIX>(8);
sgl-project/sgl-kernel-npu:csrc/deepep/ops/op_kernel/dispatch_ffn_combine_kernel/utils/hccl_shmem.hpp: AscendC::CrossCoreSetFlag<0x0, PIPE_MTE3>(RECV_SYNC_EVENT_ID);
sgl-project/sgl-kernel-npu:csrc/deepep/ops/op_kernel/fused_deep_moe.h: Arch::CrossCoreSetFlag<0x2, PIPE_MTE3>(gmm1AivFinished);
XPU-Forces/mojo_opset:native/src/npu_a5/sku_950pr/swa/kernel/runtime.cpp: AscendC::CrossCoreSetFlag<4, PIPE_KIND>(event_id);
XPU-Forces/mojo_opset:native/src/npu_a5/sku_950pr/swa/kernel/runtime.cpp: AscendC::CrossCoreSetFlag<4, PIPE_KIND>(static_cast<uint16_t>(event_id + 16));
Just-it/AscendOpGenAgent:archive_tasks/quant_matmul/kernel/workspace_queue.h: AscendC::CrossCoreSetFlag<0x2, PIPE_MTE2>(vecNotifyCubeId_);
Just-it/AscendOpGenAgent:archive_tasks/quant_matmul/kernel/workspace_queue.h: AscendC::CrossCoreSetFlag<0x2, PIPE_FIX>(cubeNotifyVecId_);
hw-native-sys/pto-isa:kernels/manual/a2a3/dispatch_mega_combine/overview.md: - 每个 localExpert group 全部 srcRank 搬完后 `SYNCALL<AIVOnly>`，再 `CrossCoreSetFlag` 通知 GMM1 该 expert ready。
```

---

### A7.32 ★ THE ONE PLAUSIBLE "RE-POINT THE FLAG BANK" LEVER — `AscendC::SetSyncBaseAddr(uint64_t)` / `set_ffts_base_addr`: present in the 2201 impl, NO public doc page

Found in the A3 implementation file (item 7). Searching the whole `asc-devkit` doc tree (`docs/api/context/*` and `docs/zh/api/**`) returns no page for `SetSyncBaseAddr`, so it is a non-public interface. Source:

https://gitcode.com/cann/asc-devkit/blob/master/impl/basic_api/dav_c220/kernel_operator_sync_impl.h
author/date: Huawei Technologies Co., Ltd. / "Copyright (c) 2025"

```
__aicore__ inline void SetSyncBaseAddrImpl(uint64_t config)
{
    set_ffts_base_addr(config);
}

__aicore__ inline void SetSyncBaseAddr(uint64_t config)
{
    SetSyncBaseAddrImpl(config);
}
```

Its real host-side pairing — `kernelInfo_.SetHwsyncIdx(0)` + `rtGetC2cCtrlAddr` — is documented only incidentally in this bug report, which also shows the facility is NOT available on Ascend 950 (chip type 15), i.e. it is an A2/A3-era mechanism:

https://gitcode.com/cann/ascend-boost-comm/issues/65
author/date: demoauguste / 2026-04-20, state closed

```
### Describe the current behavior / 问题描述 (Mandatory / 必填)
            
相关日志打印如下，提示rtGetC2cCtrlAddr不支持Ascend 950芯片：
[2026-04-20 17:28:38.540372] [debug] [1652661] [kernel_base.cpp:341] kernel param: 5 in/out, 0 const in, 1 workspaces, 1 hwsync
[WARNING] RUNTIME(1652661,Sample):2026-04-20-17:28:38.540.380 [api_c.cc:2602] 1652661 rtGetC2cCtrlAddr: chip type(15) does not support.
[WARNING] RUNTIME(1652661,Sample):2026-04-20-17:28:38.540.383 [api_c.cc:2602] 1652661 rtGetC2cCtrlAddr: chip type(15) does not support.
[2026-04-20 17:28:38.540383] [error] [1652661] [rt_backend_module.cpp:223] rt Get C2cCtrl Addr fail, error:118554637
[WARNING] RUNTIME(1652661,Sample):2026-04-20-17:28:38.540.387 [api_c.cc:2602] 1652661 rtGetC2cCtrlAddr: chip type(15) does not support.
[2026-04-20 17:28:38.540390] [error] [1652661] [kernel_base.cpp:123] Mki Get RtC2cCtrlAddr fail
[2026-04-20 17:28:38.540393] [error] [1652661] [kernel_base.cpp:58] failed to update hwsync args
[2026-04-20 17:28:38.540397] [error] [1652661] [kernel_base.cpp:349] build args failed, abort running
```

`````
在算子InitImpl处，设置：
```c++
kernelInfo_.SetHwsyncIdx(0);
```

算子kernel处设置：
```
AscendC::SetSyncBaseAddr((uint64_t)ffts_addr);
```

执行时日志出现报错。
`````

---

### A7.33 OFFICIAL DOC — `SetNextTaskStart` (SuperKernel Early-Start): the only CANN-sanctioned "many fused sub-kernels in sequence" mechanism, and it too eats flagIds; a TilingKey branch that skips it "卡住"

Directly relevant: a 78-layer megakernel is the hand-written alternative to SuperKernel, and this page states the per-core call-exactly-once discipline that the counter requires.

https://gitcode.com/cann/asc-devkit/blob/master/docs/zh/api/SIMD-API/basic_api/sync_control/inter_task_sync/SetNextTaskStart.md
author/date: Huawei Technologies Co., Ltd. (CANN asc-devkit, master) / fetched 2026-10-20

```
## 约束说明<a name="section633mcpsimp"></a>

- 该接口适用于TorchAir图模式开发场景，且需在启用SuperKernel特性后方可生效。具体内容请参考[图内标定SuperKernel范围](https://gitcode.com/Ascend/torchair/blob/master/docs/zh/ascend_ir/features/advanced/super_kernel_scope.md)。
- 在算子运行过程中，需要保证此接口在每个核上都被调用，且每个核上仅被调用一次。
- 若子核函数（Kernel）某个TilingKey分支调用了此接口，则开发者需要保证当前算子可能会运行的所有TilingKey均调用了此接口，否则会出现因同步指令数量不匹配而卡住的现象。
- 本接口内部实现会占用核间同步flagId，若与CrossCoreSetFlag/CrossCoreWaitFlag同时使用需注意避免flagId冲突，详见[核间同步flagId占用说明](../inter_core_sync/key_features.md#inter_core_sync_flagid_usage)。
```

```cpp
    template<pipe_t AIV_PIPE = PIPE_MTE3, pipe_t AIC_PIPE = PIPE_FIX, bool FORCE = false>
    __aicore__ inline void SetNextTaskStart()
```

```
| FORCE | 离线编译时是否强制启用Early-Start能力，不影响在线编译。<br>false：离线编译时不强制启用Early-Start能力；<br>true：离线编译时启用Early-Start能力，适用于无在线编译流程的算子（如<<<>>>开发的算子）。 |
```

And its implementation on 2201 (already quoted in item 7) shows it burns `SYNC_AIC_FLAG = 11` on AIC and `SYNC_AIV_ONLY_ALL = 14` on AIV — matching the occupancy table in item 5.

---

### A7.34 ADDITIONAL NEGATIVE / LEADS

- `SetSyncBaseAddr` / `set_ffts_base_addr`: no page exists under `cann/asc-devkit` `docs/api/context/` or `docs/zh/api/**`. Grepping the full recursive tree for `SetSyncBaseAddr|ffts|SetNextTask|WaitPreTask|super_kernel` returns only `docs/api/context/SetNextTaskStart.md`, `docs/api/context/WaitPreTaskEnd.md`, test files (`tests/api/basic_api/ascendc_case_ascend910b1/ascendc_case_ascend910b1_aiv/test_ffts_debug.cpp`, `tests/api/basic_api/ascendc_case_ascend950pr_9599/.../test_ffts_debug.cpp`), `tests/tools/utils/stub/rt_ffts_stub.cpp`, and the SuperKernel build tooling. So: `nothing relevant` in the public API docs — only the impl header (item 32) and the bug report. The two `test_ffts_debug.cpp` files are a lead for exercising the base-address path per chip.
- `gitcode` issue search for 「flagId 清零」 returns only unrelated OpenHarmony "告警清零" issues. `nothing relevant` — no public discussion of clearing a cross-core flag counter exists, consistent with there being no such primitive.
- `gitcode` issue search for `SetSyncBaseAddr` returns only `cann/ascend-boost-comm#65` (item 32) and auto-generated per-file issues in a mirror repo `WinstonSmith/CATCoC_mm_dq_rs` (#27/#28/#30/#13/#46). The latter are file-listing placeholders. `nothing relevant` for those five.

---

## NEGATIVE RESULTS (pages fetched, nothing extractable or nothing relevant)

- https://www.hiascend.com/document/detail/zh/canncommercial/83RC1/opdevg/Ascendcopdevg/atlas_ascendc_10_0011.html — returns a 51 KB SPA shell with zero occurrences of "CrossCore"; content is client-rendered. `nothing relevant` as fetched. The identical content is available as markdown in `cann/asc-devkit` (items 1-6), which is what the SPA renders.
- https://www.hiascend.com/document/detail/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0273.html — same SPA shell, zero "CrossCore" matches. `nothing relevant` as fetched. (This is the URL cited by PTOAS #985 as the authoritative `CrossCoreSetFlag` page.)
- https://juejin.cn/post/7684195084155060233 — "CrossCoreSetFlag 实战：昇腾 950 核间同步与硬通道边界". JS-gated; curl returns 2397 bytes and WebFetch returns only "Please wait...". `nothing relevant` as fetched. Search-engine snippets attribute to it: flagId 0-10, same-flagId counter max 15, and a claim that 0-10 is a CANN-API/per-Group allocation convention rather than a hardware limit (STARS2.0 providing 128K single-bit or 4096 32-bit hardware sync flags) — NOT verified against the page body, do not cite.
- https://blog.csdn.net/zjl1991309/article/details/165717296 — HTTP 521 to both curl and WebFetch. `nothing relevant` as fetched.
- https://blog.csdn.net/gitblog_00732/article/details/157265908 ("CANN/asc-devkit核间同步SyncAll函数") — HTTP 521. `nothing relevant` as fetched.
- https://asc.gitcode.com/guide/programming_guide/advanced_programming/hardware_implementation/architecture_spec/npu_arch_3510.html — VitePress prerendered page; usable, but its markdown source is item 6's sibling `npu_arch_3510.md`. The 3510 (A5) page is the 950 variant, not the A3 target; the A3 text is item 6.
- `gh search code 'CrossCoreSetFlag flagId %'` — zero results. No public code does `flagId = stage % N` written that literally; the only modulo rotation found is item 14's `MAKE_ID ((++idCounterNum) % 11)`.
- `gh search code 'CrossCoreFlagWithReverse flagAicFinish'` / `'... flagAivFinishStore'` — zero results for those exact two-term queries (the identifiers exist, see item 13, but the search index did not pair them).
- bbs.huaweicloud.com / www.hiascend.com/forum — no on-topic post surfaced for the Chinese queries 「CrossCoreSetFlag 计数器 15 死锁」「跨核同步 flagId 复用」「CrossCoreWaitFlag 挂死」「AscendC 跨核同步 flagId 范围」「CrossCoreSetFlag 连续两次」「ffts 跨核同步 计数器」「SyncAll 原理 AscendC」. All substantive Chinese-language discussion found lives on gitcode.com issues/MRs (items 11, 19-25) and in repo markdown (items 15, 16). `nothing relevant` for the two forum domains.
- https://gitcode.com/cann/asc-devkit/issues/1773, /1062, /289, /1786, /1613, /1323 — titles indicate doc-wording and sample-request issues around CrossCoreSetFlag/WaitFlag (e.g. "CrossCoreWaitFlag 示例错误", "约束说明中\"情况如不：\"应为\"情况如下：\"", "新增核间同步接口 CrossCoreSetFlag/CrossCoreWaitFlag样例"). Not fetched in full; typo/sample-request class, no new technical content expected.
- https://gitcode.com/Kurtnirvana/cannbot-knowledge/issues/31 and /33 — titles report that mode 2's documented "all AIV must Set before AIC's wait releases" does not match 950PR measurements (single AIV Set releases AIC). 950-specific, not A3; listed for completeness. Titles verbatim: "[Knowledge-Report|知识问题反馈]: CrossCoreSetFlag/WaitFlag 模式2「所有AIV Set 才释放AIC等待」与 950PR 实测不符（单个AIV Set 后即释放），需补充版本例外与 all-AIV 屏障提示" and "[Knowledge-Report|知识问题反馈]: CrossCore mode2 AIC 等待的 AIV 参与范围条件建议补充 950PR 实测行为与显式屏障要求".
- https://gitcode.com/cann/pto-isa/issues/729 — "CPU_SIM 中文文档遗漏 A2/A3 FFTS 跨核同步契约". Not fetched in full; flagged as a lead for A2/A3 FFTS contract wording.

---

## SUMMARY OF THE CONTRACT AS ESTABLISHED BY THE ABOVE (pointers only, no new claims)

- Hardware encoding (A3 / 2201): `GetffstMsg(mode, flagId) = 0x1 + ((mode & 0x3) << 4) + ((flagId & 0xf) << 8)` — item 7. So 4 bits of flagId ⇒ 16 ids per core per mode-family; out-of-range ids are truncated to the low 4 bits (items 3, 21).
- Per-flagId counter depth: 0-15. Exceeding it is documented two different ways: "会异常报错，中断流程" (item 3/4) and empirically "a system freeze" (items 10, 15). Catlass's answer is a forced reverse handshake every 15 Sets (item 10), after the original depth-16 version was found to hang (item 11).
- No reset/clear primitive exists. The only documented way to return a counter to 0 is to execute the matching Waits — stated as the mode-switch precondition "须在模式切换前完成前一个模式的所有同步操作" (item 3) and implemented as `CrossCoreFlagWithReverse` (item 10). The inter-core sync API index (item 28) contains no clear/reset entry.
- Usable budget on A3 for modes 0/1/2: 0-15 minus whatever AscendC reserves — SyncAll `isAIVOnly=false` takes 11/12/13, `isAIVOnly=true` takes 14, SuperKernel task sync takes 11-14, Matmul with N objects takes [0, 2N-1] plus 15 in the 1:2 SuperKernel case (item 5, matching the `SYNC_AIC_FLAG=11 / SYNC_AIV_FLAG=12 / SYNC_AIC_AIV_FLAG=13 / SYNC_AIV_ONLY_ALL=14` constants in item 7). Catlass additionally claims 8/9/10 for its barriers and treats 0-7 as user space (`FFTS_MAX_FLAG = 7`, item 10).
- Mode 4 is a different hardware instruction (`set_intra_block`/`wait_intra_block`, item 9) with an independent flag pool (item 5) and only exists on 950PR/DT — not on A3 (items 1, 3, 5).
- `IBSet`/`IBWait` and soft `SyncAll` are GM polling loops with unbounded software eventIDs; they do not consume the 16-deep hardware counter (items 8, 27).


---

## A8. ★ THE MECHANISM, re-fetched whole and independently verified: CATLASS `cross_core_sync.hpp`

https://raw.gitcode.com/cann/catlass/raw/master/include/catlass/arch/cross_core_sync.hpp

Author: Huawei Technologies Co., Ltd., copyright header 2025. Repo `cann/catlass`, branch
`master`. Re-fetched whole by me on 2026-10-20 (4037 bytes) to confirm the quotes above.

This is the official CANN library's answer to counter saturation across many sequential stages,
and it is the most directly applicable thing in this whole dossier to a 78-layer megakernel. The
comment states the failure mode; `CrossCoreSetFlagWithReverse` states the fix; the cost is
**two** flagIds per producer/consumer edge, independent of how many stages there are. Whole file:

```cpp
/**
 * Copyright (c) 2025 Huawei Technologies Co., Ltd.
 * This program is free software, you can redistribute it and/or modify it under the terms and conditions of
 * CANN Open Software License Agreement Version 2.0 (the "License").
 * Please refer to the License for details. You may not use this file except in compliance with the License.
 * THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
 * INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
 * See LICENSE in the root of the software repository for the full text of the License.
 */

#ifndef CATLASS_ARCH_CROSS_CORE_SYNC_HPP
#define CATLASS_ARCH_CROSS_CORE_SYNC_HPP

#include "catlass/catlass.hpp"

namespace Catlass::Arch {

// A certain cross core flag can be continuously set up to 15 times without waiting. In scenarios where there is only
// one-way synchronization between cores and the synchronization operation is executed multiple times, if the core
// performing the set operation runs faster, it may result in the flag being set more than 15 times consecutively,
// leading to a system freeze. To prevent such a freeze, we need to wait for the waiting cores to perform a reverse
// synchronization operation after executing the set operation MAX_REVERSE_DEPTH times.
constexpr uint32_t MAX_REVERSE_DEPTH = 15;

using FlagID = uint16_t;
constexpr FlagID AIV_INTER_BLOCK_BARRIER = 8;
constexpr FlagID AIC_INTER_BLOCK_BARRIER = 9;
constexpr FlagID AIV_INTER_SUBBLOCK_BARRIER = 10;
constexpr FlagID FFTS_MAX_FLAG = 7;

struct CrossCoreFlag {
    CATLASS_DEVICE
    CrossCoreFlag() : id(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlag(FlagID id) : id(id)
    {}

    FlagID id;
};

template <uint32_t REVERSE_DEPTH_ = MAX_REVERSE_DEPTH>
struct CrossCoreFlagWithReverse {
    CATLASS_DEVICE
    CrossCoreFlagWithReverse() : id(0), reverseId(0)
    {}

    CATLASS_DEVICE
    CrossCoreFlagWithReverse(FlagID id, FlagID reverseId) : id(id), reverseId(reverseId)
    {}

    FlagID id;
    FlagID reverseId;
    uint32_t count{0};
};

template <uint8_t MODE, int32_t CORE_TYPE>
struct BarrierFlag {
    static_assert(MODE != 255 && MODE == 255, "Unsupported cross core barrier flag, can not find the specialization.");
};

template <>
struct BarrierFlag<0x0, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x0, AscendC::AIC> {
    static constexpr FlagID ID = AIC_INTER_BLOCK_BARRIER;
};

template <>
struct BarrierFlag<0x1, AscendC::AIV> {
    static constexpr FlagID ID = AIV_INTER_SUBBLOCK_BARRIER;
};

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreBarrier()
{
    constexpr FlagID flagId = BarrierFlag<MODE, g_coreType>::ID;
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flagId);
    AscendC::CrossCoreWaitFlag(flagId);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreSetFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
}

CATLASS_DEVICE
void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
}

template <uint8_t MODE, pipe_t PIPE>
CATLASS_DEVICE void CrossCoreWaitFlag(CrossCoreFlag& flag)
{
    AscendC::CrossCoreWaitFlag<MODE, PIPE>(flag.id);
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreSetFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreWaitFlag(flag.reverseId);
        flag.count = 0;
    }
}

template <uint8_t MODE, pipe_t PIPE, uint32_t REVERSE_DEPTH>
CATLASS_DEVICE void CrossCoreWaitFlagWithReverse(CrossCoreFlagWithReverse<REVERSE_DEPTH>& flag)
{
    AscendC::CrossCoreWaitFlag(flag.id);
    if (++flag.count >= REVERSE_DEPTH) {
        AscendC::CrossCoreSetFlag<MODE, PIPE>(flag.reverseId);
        flag.count = 0;
    }
}

} // namespace Catlass::Arch

#endif // CATLASS_ARCH_CROSS_CORE_SYNC_HPP
```

## A9. ★ The bugfix that proves the 15 is a real hazard, re-fetched and re-verified

https://gitcode.com/cann/catlass/merge_requests/325

Author: `triwooder` (张云淞). State: merged, `2025-12-18T20:44:03+08:00`. Title:
`fix: 更改默认的MAX_REVERSE_DEPTH`. Re-fetched by me on 2026-10-20 via
`https://gitcode.com/api/v5/repos/cann/catlass/pulls/325`. Body, verbatim:

```
## 描述
更改默认的MAX_REVERSE_DEPTH为15，原设置会导致卡死

## 类型标签
- [x] Bug修复
- [ ] 新特性
- [ ] 性能优化
- [ ] 文档更新
```

i.e. the previous default (16) deadlocked. 15, not 16, is the safe credit depth — one Set must be
left in hand.

## A10. ★ Field report: two consecutive Sets of one flagId in shipped code, re-fetched and re-verified

https://gitcode.com/cann/ops-solver/issues/13

Author: `zhanghua145`. Created `2026-06-29T17:05:12+08:00`. Title:
`[Bug-Report|缺陷反馈]: cgetrf_kernel.cpp 中 CrossCoreSetFlag 重复设置相同标志`.
Re-fetched by me on 2026-10-20 via `https://gitcode.com/api/v5/repos/cann/ops-solver/issues/13`.
Body, verbatim:

```
## 问题描述

src/cgetrf/cgetrf_kernel.cpp:304-305 连续两次调用 `CrossCoreSetFlag<0x0, PIPE_MTE3>(0x6)` 设置完全相同的标志。同样在第439-440行连续两次 `CrossCoreWaitFlag(0x6)` 等待相同标志。这可能是意图设置/等待两个不同标志但代码错误地使用了相同的0x6，导致同步语义错误。

## 环境信息

- 芯片型号：Ascend 910B3
- CANN 版本：8.0.0
- 操作系统：Ubuntu 22.04

## 重现步骤

1. 分析 blockIdx>=8 且 blockM>512 时的核心同步行为

## 预期结果

若需设置两个独立标志，应分别使用不同的 flag 值

## 日志 / 截图

文件：src/cgetrf/cgetrf_kernel.cpp:304

## 备注

严重等级：medium
```


---

## A11. The `dav-2201` build recipe for a hand-written megakernel

Not asked for, but it is the one thing in `megagdn-pto` that a hand-written A3 megakernel project
needs and that is nowhere else in this dossier: the exact `bisheng` invocation, including the
`--npu-arch=dav-2201` mapping and the stack-size / dcci `-mllvm` flags.

https://github.com/huawei-csl/megagdn-pto/blob/main/megagdn_pto/compile.py
(raw: https://raw.githubusercontent.com/huawei-csl/megagdn-pto/main/megagdn_pto/compile.py)

Author: Huawei Technologies Co., Ltd. (repo `huawei-csl/megagdn-pto`, branch `main`),
10606 bytes. Fetched 2026-10-20.

The arch mapping, with the comment that states what `dav-2201` expands to and why mix mode
matters (both `__DAV_*_CUBE__` and `__DAV_*_VEC__` defined — which is what makes the
`#if defined(__DAV_CUBE__)` / `#elif defined(__DAV_VEC__)` structure in A1/A2 compile):

```python
# The memory-base backend targets dav-2201 (A2/A3); every other backend targets
# dav-3510 (A5), matching the SOC_VERSION → arch mapping used by the pto-isa tests.
# These are the driver-level ``--npu-arch`` names; bisheng expands them to the
# AI Core archs pto-isa names directly (dav-c220 / dav-c310), keeping mix mode
# so both __DAV_*_CUBE__ and __DAV_*_VEC__ are defined.
_IS_MEMORY_BASE = MEMORY_MODEL == "MEMORY_BASE"
AICORE_ARCH: str = "dav-2201" if _IS_MEMORY_BASE else "dav-3510"
```

`BLOCK_DIM` is taken from the device's **cube** core count, not the AIV count — which is what
makes the `bd * 2` / `bd * 4` workspace shapes in B2 line up with `get_block_idx()` on the Cube
side:

```python
_npu_dev = os.environ.get("GDN_NPU_DEVICE", "npu:0")
try:
    BLOCK_DIM: int = int(
        getattr(torch.npu.get_device_properties(_npu_dev), "cube_core_num", 20)
    )
except (RuntimeError, AssertionError):
    BLOCK_DIM = 24
```

The flag list. Note `-cce-aicore-record-overflow=true` and
`-cce-aicore-dcci-insert-for-scalar=false` — the latter matters because the GM-counter barriers in
A4/A5.3 rely on *explicit* `dcci`, and letting the compiler insert its own around scalar access
would be both redundant and a performance cost:

```python
def _common_flags(*, hidden_size: int, chunk_size: int) -> list[str]:
    """Return bisheng flags shared by all chunk-GDN kernels."""
    flags = [
        "-fPIC", "-shared", "-xcce", f"-D{MEMORY_MODEL}", "-O2", "-std=gnu++17",
        f"--npu-arch={AICORE_ARCH}",
        "-mllvm", "-cce-aicore-stack-size=0x8000",
        "-mllvm", "-cce-aicore-function-stack-size=0x8000",
        "-mllvm", "-cce-aicore-record-overflow=true",
        "-mllvm", "-cce-aicore-dcci-insert-for-scalar=false",
        "-Wno-macro-redefined", "-Wno-ignored-attributes",
        f"-I{_KERNEL_INCLUDE}",
        f"-I{os.path.join(PTO_LIB_PATH, 'include')}",
        f"-I{ASCEND_TOOLKIT_HOME}/include",
        f"-I{ASCEND_TOOLKIT_HOME}/pkg_inc",
        f"-I{ASCEND_TOOLKIT_HOME}/pkg_inc/runtime",
        f"-I{ASCEND_TOOLKIT_HOME}/pkg_inc/profiling",
        f"-DGDN_D={hidden_size}",
        f"-DGDN_C={chunk_size}",
        f"-DTRI_INV_DOUBLING_BLOCK={TRI_INV_DOUBLING_BLOCK}",
    ]
    if os.path.isdir(_DRIVER_INC):
        flags.append(f"-I{_DRIVER_INC}")
    extra = os.environ.get("PTO_DYNAMIC_EXTRA_FLAGS", "").split()
    flags.extend(extra)
    return flags
```

The invocation itself is a bare `bisheng` call producing a `.so` loaded by `ctypes` — no op
framework, no `.json` registration:

```python
def _run_bisheng(cmd: list[str], timeout: int) -> None:
```

```python
    subprocess.run(cmd, check=True, timeout=timeout)
```

```python
    flags = _common_flags(hidden_size=hidden_size, chunk_size=chunk_size)
    _run_bisheng(["bisheng", *flags, cpp_path, "-o", lib_path], timeout=300)
```

The environment knobs, from the module docstring:

```python
    VERBOSE_COMPILE         Set to ``1`` to print the full bisheng command.
    PTO_DYNAMIC_EXTRA_FLAGS Extra flags appended to every bisheng invocation.
```


---


---

## 41. Growing the brick into a per-layer kernel: the Matmul object's lifetime across stages, `SyncAll<false>` as a mid-kernel phase boundary, and `rope_matrix`'s pairing tiling

### 41.1 Can a second cube stage follow a vector stage? The `REGIST_MATMUL_OBJ` lifecycle

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0628.html
CANN Community Edition 9.0, `REGIST_MATMUL_OBJ`. Retrieved 2026-10-20. Verbatim and complete:

```
REGIST_MATMUL_OBJ
 功能说明
 初始化Matmul对象。
 函数原型
 REGIST_MATMUL_OBJ(tpipe, workspace, ...)
 参数说明
 tpipe  输入  Tpipe对象。
 workspace  输入  系统workspace指针。
 ...  输入  可变参数，传入Matmul对象和与之对应的Tiling结构，要求Tiling结构的数据类型为TCubeTiling结构。
 Tiling参数可以通过Host侧GetTiling接口获取，并传递到kernel侧使用。
 返回值说明
 无
 约束说明
 在分离模式中，本接口必须在InitBuffer接口前调用。
 在程序中，最多支持定义4个Matmul对象。
 当代码中只有一个Matmul对象时，本接口可以不传入tiling参数，通过Init接口单独传入tiling参数。
 当代码中有多个Matmul对象时，必须满足Matmul对象与其tiling参数一一对应，依次传入，具体方式请参考调用示例。
 在分离模式中，调用本接口后，AIC核仅会执行下述AIV核发起的接口，其他接口不会在AIC核执行：
 Matmul Kernel侧接口。
 基础数据搬运和随路转换ND2NZ搬运接口，仅支持数据通路为GM -> A1、B1的数据搬运。
 调用示例
 Tpipe pipe;
// 推荐：初始化单个matmul对象，传入tiling参数
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, &tiling);
// 推荐：初始化多个matmul对象，传入对应的tiling参数
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm1, mm1tiling, mm2, mm2tiling, mm3, mm3tiling, mm4, mm4tiling);
// 初始化单个matmul对象，未传入tiling参数。注意，该场景下需要使用Init接口单独传入tiling参数。这种方式将matmul对象的初始化和tiling的设置分离，比如，Tiling可变的场景，可通过这种方式多次对Tiling进行重新设置
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm);
mm.Init(&tiling);
```

https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0630.html
`Init`. Retrieved 2026-10-20. Verbatim:

```
功能说明
Init主要用于对Matmul对象中的Tiling数据进行初始化，根据Tiling参数进行资源划分，Tiling参数的具体介绍请参考Matmul Tiling侧接口。
开发者可以先通过REGIST_MATMUL_OBJ不传入Tiling参数对单个Matmul对象进行初始化，后续通过Init接口单独传入Tiling参数，对Matmul对象中的Tiling数据进行调整。比如，Tiling参数可变的场景下，可以通过多次调用Init来重新设置Tiling参数。
不需要Tiling变更的场景下，推荐使用REGIST_MATMUL_OBJ传入Tiling参数进行初始化。
函数原型
Tiling参数传入栈地址
__aicore__ inline void Init(const TCubeTiling* __restrict cubeTiling, TPipe* tpipe = nullptr)
Tiling参数传入GM地址
__aicore__ inline void Init(const __gm__ TCubeTiling* gmCubeTiling, TPipe* tpipe = nullptr)
约束说明
Tiling参数传入栈地址的接口：无。
Tiling参数传入GM地址的接口：仅支持Matmul Tiling参数的部分常量化场景。
不支持CPU域调试。
```

and its two call examples, verbatim — note the pure-cube one sets `KERNEL_TYPE_AIC_ONLY`, and the MIX one says
`Init` is not needed at all:

```cpp
#define ASCENDC_CUBE_ONLY
GET_TILING_DATA_PTR_WITH_STRUCT(MatmulCustomTilingData, tilingDataPtr, tiling);
KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIC_ONLY);
// ...
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm);
mm.Init(&(tilingDataPtr->cubeTilingData));
```
```cpp
GET_TILING_DATA_PTR_WITH_STRUCT(MatmulCustomTilingData, tilingDataPtr, tiling);
KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_2);
// ...
// MIX模式下，只调用REGIST_MATMUL_OBJ接口，传入Tiling参数的GM地址，不需调用Init接口
REGIST_MATMUL_OBJ(&pipe, GetSysWorkSpacePtr(), mm, &(tilingDataPtr->cubeTilingData));
```

`End`, repeated from §31.9 because it is the other half of the answer, verbatim:

```
End
功能说明
多个Matmul对象之间切换计算时，必须调用一次End函数，用于释放Matmul计算资源，防止多个Matmul对象的计算资源冲突。
调用示例
mm1.IterateAll(gm_c1);
mm1.End();
mm2.IterateAll(gm_c2);
mm2.End();
```

### 41.2 How a shipped multi-stage fused MIX kernel actually does cube → vector → cube: Catlass tiled Mmad, not the Matmul high-level API

https://raw.githubusercontent.com/flashserve/flash-linear-attention-npu/main/fla/ops/ascendc/kda/chunk_kda_bwd/op_kernel/chunk_kda_bwd_finalize.h
`flashserve/flash-linear-attention-npu`, branch `main`. Retrieved 2026-10-20. The complete top-level body of the
fused MIX kernel, verbatim — this is the exact shape the brick is growing into:

```cpp
template <typename DataT, uint32_t V_DIM, typename BetaT,
          bool SAFE_GATE, bool VARLEN_TND>
__aicore__ inline void RunChunkKdaBwdC(
    GM_ADDR q, GM_ADDR k, GM_ADDR v, GM_ADDR vNew, GM_ADDR gk,
    GM_ADDR beta, GM_ADDR akk, GM_ADDR h, GM_ADDR dh, GM_ADDR dvScan,
    GM_ADDR dqRaw, GM_ADDR dAqk, GM_ADDR cuSeqlens,
    GM_ADDR chunkIndices, GM_ADDR rawG, GM_ADDR aLog, GM_ADDR dtBias,
    GM_ADDR dq, GM_ADDR dk, GM_ADDR dv, GM_ADDR db, GM_ADDR dg,
    GM_ADDR dAkk, GM_ADDR dA, GM_ADDR dBias, GM_ADDR workspace,
    const ChunkKdaBwdCTilingData *tiling, bool active)
{
    if ASCEND_IS_AIC {
        if (active) {
            ChunkKdaBwdCCubeProcess<DataT, V_DIM, SAFE_GATE> process(
                v, vNew, akk, h, dh, dvScan, dq, dk, dg, dAkk,
                cuSeqlens, chunkIndices, workspace);
            process.Init(*tiling);
            process.Process();
        }
    }
    if ASCEND_IS_AIV {
        if (active) {
            AscendC::TPipe pipe;
            ChunkKdaBwdCVectorProcess<DataT, V_DIM, BetaT> process(
                q, k, v, gk, beta, h, dh, dqRaw,
                dq, dk, dv, db, dg, dAkk, cuSeqlens, chunkIndices,
                workspace);
            process.Init(*tiling, &pipe);
            process.Process();
        }
    }

    // WY materializes the base gradients in GM and Intra immediately reads
    // them back for the local correction.  Complete every WY store before
    // remapping the same buffers to the Intra owner.
    AscendC::SyncAll<false>();

    if ASCEND_IS_AIC {
        if (active) {
            ChunkKdaBwdCIntraCubeProcess process(
                cuSeqlens, chunkIndices, workspace);
            process.Init(*tiling);
            process.Process();
        }
    }
    if ASCEND_IS_AIV {
        if (active) {
            AscendC::TPipe pipe;
            ChunkKdaBwdCIntraVectorProcess<
                128, 64, SAFE_GATE, false, VARLEN_TND,
                DataT, BetaT, DTYPE_RAW_G> process(
```

then, verbatim, the second and third barriers:

```cpp
    // Intra writes dg by half rows on both AIV sub-blocks, whereas Gate
    // remaps the work to complete heads and updates dg in place.  Finish the
    // whole Intra phase before any core starts the Gate read/scan/write phase.
    AscendC::SyncAll<false>();

    if ASCEND_IS_AIV {
        if (active) {
            AscendC::TPipe pipe;
            ChunkKdaBwdCGateProcess<SAFE_GATE, DTYPE_RAW_G> process(
                dg, rawG, aLog, dtBias, dA, dBias,
                cuSeqlens, chunkIndices);
            if (tiling->deferGatePost == 0) {
                process.Init(*tiling, &pipe);
                process.Process();
            }
        }
    }

    // Gate is the final phase of the fused MIX kernel.  Do not return while
    // either AIV sub-block still has a queued dg/dA/dbias store: a following
    // invocation can reuse the same output allocation and observe that late
    // write as a stale cross-shape generation.
    bool needsFinalSync =
        tiling->seqlen < static_cast<int32_t>(kA5SharedGateMinSeqlen);
#if defined(__CCE_AICORE__) && __CCE_AICORE__ == 310
    needsFinalSync = needsFinalSync ||
        (tiling->useGateInKernel != 0 &&
         !CanUseA5SharedGateAnchor(*tiling));
#endif
    if (needsFinalSync) {
        AscendC::SyncAll<false>();
    }
```

What the two cube stages use for their matmuls —
`.../chunk_kda_bwd/op_kernel/chunk_kda_bwd_finalize_intra.h` and `..._wy.h`, retrieved 2026-10-20. Neither contains
`REGIST_MATMUL_OBJ` or `matmul::Matmul`; both build Catlass tile objects locally, verbatim fragments:

```cpp
    using ArchTag = Catlass::Arch::Ascend950;
```
```cpp
    using ArchTag = Catlass::Arch::AtlasA2;
```
```cpp
    using RowMajor = Catlass::layout::RowMajor;
    using Copy = Catlass::Gemm::Tile::PackedTileCopyTla<
```
```cpp
    using TileMmad = Catlass::Gemm::Tile::TileMmadTla<
```
```cpp
    __aicore__ inline explicit CIntraSingleTileMmad(
        Catlass::Arch::Resource<ArchTag> &resource)
```
```cpp
    explicit WyTileGemmDirect(Catlass::Arch::Resource<ArchTag> &resource)
```
with `Catlass::Arch::PositionL1{}`, `PositionL0A{}`, `PositionL0B{}`, `PositionL0C{}` as the staging positions.

### 41.3 `rope_matrix`'s tiling — the pairing arithmetic in one line

https://github.com/hicann/ops-transformer/blob/master/experimental/posembedding/rope_matrix/op_host/rope_matrix_tiling.h
and `.../inc/rope_matrix_extern.h`. Copyright 2025 Huawei. Retrieved 2026-10-20.

The shared tiling struct, verbatim and complete:

```cpp
#ifndef ROPE_MATRIX_EXTERN_H
#define ROPE_MATRIX_EXTERN_H

#include <cstdint>

namespace npu_ops_transformer_ext {
namespace RopeMatrix {
// define a struct as TCubeTiling, which can be call by both op_device and op_host
struct RopeMatrixTiling
{
    uint32_t blockDim;
    uint32_t b;
    uint32_t n;
    uint32_t s;
    uint32_t d;
};
} // namespace RopeMatrix
} //namespace npu_ops_transformer_ext

#endif
```

`GenerateTiling`, verbatim and complete — **`aicRatio = 2` and the `calSingleCoreM` line are the whole pairing
constraint**:

```cpp
uint8_t *GenerateTiling(RopeMatrixTiling *ropeTiling, uint32_t* mmTilingData, uint32_t mmSize)
{
    constexpr uint32_t baseSize = 128;
    uint32_t usedCoreNum = ropeTiling->blockDim;
    uint32_t B = ropeTiling->b;
    uint32_t H = ropeTiling->n;
    uint32_t M = ropeTiling->s;
    uint32_t N = ropeTiling->d;
    uint32_t K = ropeTiling->d;

    matmul_tiling::TPosition leftPosition = matmul_tiling::TPosition::GM;
    matmul_tiling::CubeFormat leftFormat = matmul_tiling::CubeFormat::ND;
    matmul_tiling::DataType leftDtype = matmul_tiling::DataType::DT_BFLOAT16;
    bool isTransA = false;

    matmul_tiling::TPosition rightPosition = matmul_tiling::TPosition::GM;
    matmul_tiling::CubeFormat rightFormat = matmul_tiling::CubeFormat::ND;
    matmul_tiling::DataType rightDtype = matmul_tiling::DataType::DT_BFLOAT16;
    bool isTransB = false;

    matmul_tiling::TPosition resultPosition = matmul_tiling::TPosition::GM;
    matmul_tiling::CubeFormat resultFormat = matmul_tiling::CubeFormat::ND;
    matmul_tiling::DataType resultDtype = matmul_tiling::DataType::DT_BFLOAT16;

    bool isBias = false;
    uint32_t aicRatio = 2;

    uint32_t calSingleCoreM = CeilingTiling(M, usedCoreNum * aicRatio) * aicRatio;
    uint32_t baseM = baseSize;
    uint32_t baseN = baseSize;

    optiling::TCubeTiling tilingData;
    const char *socVersion = "Ascend910B3";
    auto ascendcPlatform = platform_ascendc::PlatformAscendCManager::GetInstance(socVersion);
    matmul_tiling::MultiCoreMatmulTiling tilingApi(*ascendcPlatform);

    tilingApi.SetDim(usedCoreNum);
    tilingApi.SetAType(leftPosition, leftFormat, leftDtype, isTransA);
    tilingApi.SetBType(rightPosition, rightFormat, rightDtype, isTransB);
    tilingApi.SetCType(resultPosition, resultFormat, resultDtype);

    tilingApi.SetOrgShape(M, N, K); // 完成的MNK大小，单位为元素个数
    tilingApi.SetShape(M, N, K); // matmul计算形状的MNK，考虑脏数据
    tilingApi.SetSingleShape(calSingleCoreM, baseSize, baseSize);
    tilingApi.SetFixSplit(baseM, baseN, -1);
    tilingApi.SetBias(isBias);
    tilingApi.SetBufferSpace(-1, -1, -1);

    int64_t res = tilingApi.GetTiling(tilingData);
    int64_t checkCode = -1;
    if (res == checkCode) {
        std::cout << "gen tiling failed" << B << H << M << N << K << std::endl;
    }
    return GetTilingBuf(&tilingData, mmTilingData, mmSize);
}
```

and the helper that flattens `TCubeTiling` into the operator's own tiling blob, verbatim — the mechanism by which
one GM tiling buffer carries both the cube tiling and the vector tiling (see §39.1's `CopyTiling`):

```cpp
uint8_t *GetTilingBuf(optiling::TCubeTiling *tilingData, uint32_t* mmTilingData, uint32_t mmSize)
{
    uint8_t *buf = nullptr;
    uint32_t tilingSize = tilingData->GetDataSize();
    if (tilingSize > 0) {
        buf = (uint8_t *)malloc(tilingSize);
        tilingData->SaveToBuffer(buf, tilingSize);

        uint32_t num = tilingSize / sizeof(uint32_t);
        num = (num < mmSize) ? num : mmSize;
        uint32_t *ptr = mmTilingData;
        auto mmtiling32 = reinterpret_cast<uint32_t *>(buf);
        for (uint32_t i = 0; i < num; i++) {
            *(ptr + i) = *(mmtiling32 + i);
        }

        free(buf);
        buf = nullptr;
    }
    return reinterpret_cast<uint8_t *>(mmTilingData);
}
```

with one compilation gotcha from the same file, verbatim:

```cpp
#include <iostream>
// must define this before tiling.h, otherwise will compile error
typedef uint8_t char_t; 
#include "tiling/tiling_api.h"
```

## Relevance
- **Question 1, the cube→vector→cube chain. Do not construct a second `Matmul` object after a vector stage.** The
  high-level API forbids it structurally: 「在分离模式中，本接口必须在InitBuffer接口前调用」 — in separated mode
  `REGIST_MATMUL_OBJ` must be called *before* `InitBuffer`, so every Matmul object has to be registered up front,
  before the vector half's queues exist. Also 「在程序中，最多支持定义4个Matmul对象」. The two supported spellings
  are therefore:
  (a) **register both objects up front, use them in stage order, `End()` between them** — which is exactly the
  documented 「多个Matmul对象之间切换计算时，必须调用一次End函数」 and the
  `mm1.IterateAll(); mm1.End(); mm2.IterateAll(); mm2.End();` example. An intervening vector stage changes nothing
  about that, because the objects were already registered; the registration is not what crosses the stage boundary.
  `REGIST_MATMUL_OBJ(&pipe, ws, mm1, mm1tiling, mm2, mm2tiling)` is the one-call form.
  (b) **one object, re-`Init(&newTiling)`** — 「Tiling参数可变的场景下，可以通过多次调用Init来重新设置Tiling参数」.
  Register without a tiling, then `Init` per stage. Note `Init` is 「不支持CPU域调试」, so this form cannot be
  validated in CPU twin mode.
  For the gate/up (6144→128) then down (128→6144) pair, (a) is the better fit: the two shapes are fixed at
  batch=1, so two objects with two const tilings keeps §12's static-tiling Scalar win on both.
- **But the shipped precedent does something else, and it is worth knowing before committing.** §41.2's
  `chunk_kda_bwd_finalize.h` is a fused MIX kernel with cube → vector → barrier → cube → vector → barrier → vector
  in one function, and neither cube stage uses the Matmul high-level API at all: both build
  `Catlass::Gemm::Tile::TileMmadTla` with a locally constructed `Catlass::Arch::Resource<ArchTag>`
  (`ArchTag = Catlass::Arch::AtlasA2` on our arch). Local construction has no registration constraint, no 4-object
  cap, and no flagId cost — §31.8 shows `catlass` synchronises through `CrossCoreSetFlag` only where the author asks
  it to. So if the layer kernel ends up wanting more than four cube stages, or cube objects whose lifetime must
  straddle a barrier, the basic-API route is the one with a working multi-stage precedent on `arch22`.
- One constraint to check against the brick's AIC half, verbatim and easy to miss:
  「在分离模式中，调用本接口后，AIC核仅会执行下述AIV核发起的接口，其他接口不会在AIC核执行：Matmul Kernel侧接口。
  基础数据搬运和随路转换ND2NZ搬运接口，仅支持数据通路为GM -> A1、B1的数据搬运。」 That is written for the
  message-driven MIX mode, where the AIC runs nothing but AIV-issued Matmul calls and GM→A1/B1 copies. Under
  `ASCENDC_CUBE_ONLY` with `ASCEND_IS_AIC` the AIC runs its own instruction stream, which is why the brick works —
  but it means any attempt to put non-Matmul, non-GM→A1/B1 work on the AIC in a *registered MIX* kernel will
  silently not execute.
- **Question 2, `SyncAll<false>()` as a mid-kernel phase boundary. Confirmed legal between two Matmul stages, and
  confirmed it must be at top level.** §41.2 is a shipped fused MIX kernel with three of them, and every one sits
  outside both `if ASCEND_IS_AIC { }` and `if ASCEND_IS_AIV { }` and outside the `if (active)` guard. The
  coordinator's prediction from §38's arithmetic is correct and this is the existence proof: `SyncAll<false>` is a
  collective over all AIC and all AIV, so every core must arrive, including cores whose stage work is skipped.
  The in-source reasons are quoted verbatim above and generalise directly to our case — the second one
  (「Intra writes dg by half rows on both AIV sub-blocks, whereas Gate remaps the work to complete heads」) is
  precisely our situation: the vector stage owns half-rows per subblock and the next stage re-partitions, so the
  barrier is not optional. The third is a warning we need too: a final barrier before returning, so a queued store
  cannot leak into the next invocation's reuse of the same allocation — at 78 layers in one kernel that becomes a
  barrier before the *layer* boundary, not just the kernel's end.
  The costs, from §35.5 and §40: flagIds 11/12/13 on 2201, `isAIVOnly=false` mandatory (`true` in a MIX kernel
  silently degrades to a Vector-only barrier), `numBlocks` must not exceed the physical core count, `__schedmode__`
  strongly recommended, and `SyncAll` is mutually exclusive with the `aclshmem` barriers (Part 7). One shipped
  kernel quoted in §36 deliberately chose `SyncAll<true>` over `SyncAll<false>` *specifically* to avoid burning
  12/13 where an earlier AIC→AIV handshake had unspent credits on them — worth knowing once the layer kernel has
  both a grid barrier and hand-written flags.
- **Question 4, closed.** §39.1 and §39.2 carry the whole `op_kernel`; §41.3 carries the tiling. The pairing
  constraint from §37 is two lines of shipped host code:
  `uint32_t aicRatio = 2;` and `uint32_t calSingleCoreM = CeilingTiling(M, usedCoreNum * aicRatio) * aicRatio;`,
  then `tilingApi.SetDim(usedCoreNum)` and `tilingApi.SetSingleShape(calSingleCoreM, baseSize, baseSize)`. Read
  with §39.2's vector side (`aivNum = GetBlockNum() * GetSubBlockNum()`, `sSize = CeilDiv(seqLen, aivNum)`,
  `startSize = sSize * aivIdx` with `aivIdx = GetBlockIdx()`): the cube's `singleCoreM` is exactly `2 ×` the
  per-AIV chunk, so AIV `2i` and `2i+1` cover exactly AIC `i`'s output range. That is the general recipe — compute
  the per-AIV chunk as `ceil(axis / (blockDim * 2))`, give the cube `2 ×` that as `singleCoreM`, and round the
  *product* rather than either factor so the tail lands on the last pair. `SetDim` takes the AIC count
  (`ropeTiling->blockDim`), confirming §39.3's AIC-vs-AIV unit distinction from the other direction.
  Incidental but real: `typedef uint8_t char_t;` must precede `#include "tiling/tiling_api.h"` or the host tiling
  does not compile, and `GetTilingBuf` is the idiom for packing `TCubeTiling` and an operator-specific tiling
  struct into one GM blob that both halves decode (§39.1's `CopyTiling` is the device side of it).
- **Question 3 is open and reported as open.** What exists: the canonical CANN per-token row max is
  partials-in-workspace plus `SyncAll()` plus a second pass (§36), and two kernels avoid the reduction entirely by
  **M-split** per-core row ownership. What was not found: any published decode kernel that **N-splits** a gate/up
  GEMM and still does per-token dynamic quant without a grid reduction. The N-split case is structurally harder —
  every block holds a column slice of the same token's row, so the row max is inherently cross-block — and the
  honest reading of §36 is that the published answer for that shape is the two-pass `SyncAll` structure, which
  §41.2 now shows is legal mid-kernel. That makes the cost estimable rather than unknown: one `SyncAll<false>` plus
  one float per block in workspace, between the GEMM and the quantise, at the same place the down projection
  already needs a barrier. Whether it can be folded into *that* barrier instead of adding a second one is the open
  design question, and it is answerable by construction rather than by more searching.


## Gaps

What was looked for and not found, or found only partially.

- **No published per-kernel launch-cost figures on A3.** Nothing in the vendor docs gives a microsecond number for
  "cost of one MIX_AIC launch" versus "one AI_VECTOR_CORE launch". The closest quantitative anchors found were
  (a) the Matmul static-tiling case study (21.88 us -> 17.728 us per call, Scalar time -44.4%, section 12) and
  (b) the `__schedmode__` hang statistic (3/49 vs 0/240, section 25). Our measured 0.70 / 2.30 / 12.04 / 13.58 us
  floors have no published counterpart; the documented *mechanisms* (core-count multiplier, 硬同步, two task-param
  pointers per MIX FFTS+ context, full-pipe cross-core waits on 2201) are consistent with them but are not a
  published decomposition.
- **The `super_kernel/src/jit` and `src/aot` implementation sources in `cann/graph-autofusion` were not read.**
  Only the public header, README and docs were retrieved. The actual fusion/segmentation policy, the ICache-preload
  insertion pass, and the sub-kernel-split code generation live there. GitCode's API rate-limited at 10^5 calls/hour
  partway through, so directory listings under `super_kernel/src`, `super_kernel/kernel` and
  `super_kernel/examples/{jit,aot}/*` are unread. Likewise `super_kernel/docs/zh/super_kernel/super_kernel_migration_design.md`.
- **Partially closed: one measured SuperKernel A/B exists (section 28), but none on a transformer decode round.**
  The vendor's own profiling sample reports 5.61% end-to-end on a 6-segment MoE-shaped graph. Neither the TorchAir docs
  nor the vllm-ascend docs publish a before/after latency for Super Kernel on a full model. The GLM-5.2 A3 config in
  section 7 carries `baseline: 733.1813` for a 128k throughput benchmark but no A/B against `enable_super_kernel: false`.
- **The hiascend `llms-content/*.md` endpoint is WAF-blocked** (returns the HuaweiCloudWAF JS challenge), as is the
  `document/detail/...` SPA viewer. Only `doc_center/source/<lang>/<product>/<vol>/<book>/<id>.html` returns raw HTML,
  and the id space is sparse — several probed ids returned S3 `AccessDenied`. Volumes not reachable this way at the
  paths tried: `devaids/opdev/ascendcbestP` (zh), `opdevg/cceintrinsicguide` (all versions tried), and the zh
  rendering of the Matmul-constant best practice (only the en CANN 8.0 copy was obtainable).
- **`matmul_gelu_high_performance` Scenario 2 and the Matmul basic-API / Gelu tuning samples were only partly read.**
  The `01_matrix_compute/matmul_basic_api_high_performance` and `02_reg_compute/gelu_high_performance` READMEs that
  section 16 cross-references were not fetched; they contain the L1/L0 double-buffer and 512B-alignment case studies
  (Case 1 单核Tiling优化 / Case 2 多核切分 2x12 / Case 3 多核切分 4x6) referenced by title only.
- **No `cann-ops-adv` repository found under that name on GitCode.** The CANN operator tree appears to have been
  split into `cann/ops-nn`, `cann/ops-math`, `cann/ops-blas`, `cann/ops-transformer` (and GitHub mirrors
  `hicann/ops-nn`, `hicann/ops-transformer`, `hicann/ops-blas`). No fusion-specific issue or PR with a quantified
  MIX-overhead discussion was located; searches surfaced only PR numbers (`cann/ops-nn#8743`, `#8172`,
  `cann/ops-math#4354`, `cann/graph-autofusion#1871`, `cann/ge#993`) whose bodies were not retrieved.
- **`__schedmode__` has no API-reference page.** It is referenced by name in the `SyncAll` and `CrossCoreSetFlag`
  constraint sections and documented in prose in a production header comment (section 25), but no page giving its
  syntax, legal `N` values, or placement rules was found. `SetScheduleMode(schedule_mode)` with `0 = 普通模式`,
  `1 = batchmode模式` is the only formally documented form.
- **No published L2 cache size for A3.** Section 8's architecture doc says only 「根据硬件规格不同，Cache Line大小不同
  （128/256/512Byte等）」 and that buffer sizes must be queried via `GetCoreMemSize`. `CoreMemType` has no L2 member in
  the `catlass` usage found. HBM bandwidth figures for A3 were not found in any vendor doc reached.
- **`DEVICE_USE_ONLY` and AICPU-dispatched kernels were not covered.** No doc page was located for `DEVICE_USE_ONLY`.
  AICPU appears only indirectly: as `RT_CTX_TYPE_AICPU` in the FFTS+ taxonomy (section 18), as the Tiling-下沉
  Notify/Wait partner in the SuperKernel README (section 6), and as the default `task_breaker_bypass = 0` fusion
  breaker (section 22).
- **`aclrtLaunchKernel` vs taskless dispatch was not resolved.** `ACLRT_LAUNCH_KERNEL` and `<<<>>>` are documented
  (section 14) and `aclrtLaunchKernelAttr` has a page at
  `https://www.hiascend.com/doc_center/source/en/CANNCommunityEdition/900/API/runtimeapi/aclcppdevg_03_1815.html`,
  but that page's body (2.8 KB) was not extracted, and no doc comparing launch paths' overhead was found.
- **`SetLocalWorkspace` is documented only as an Atlas-inference-AI-Core requirement** (section 11). No page
  describing it as a general megakernel UB-reservation mechanism was found.
- **Closed for `MatmulCallBackFunc` (section 29); `MatmulPolicy` still unread.** `MatmulPolicy` has a page at
  `https://www.hiascend.com/doc_center/source/zh/CANNCommunityEdition/900/API/ascendcopapi/atlasascendc_api_07_0619.html`
  and `MatmulConfig` at `..._0616.html`, `GetNormalConfig` at `..._0621.html`; none of those three bodies were extracted,
  so the full `MatmulConfig` field list (including `enUnitFlag`'s siblings) and the `MatmulPolicy` module-replacement
  mechanism remain unread.
- **Closed: the `BareMix` sample is reproduced in section 30.** Found only in community mirrors of the
  `Ascend/samples` tree (`XJ19023/ascend_samples`, `c303803919-jpg/transmit`) at
  `operator/ascendc/0_introduction/22_baremix_kernellaunch/`. The canonical `Ascend/samples` upstream path was not
  confirmed, and the sample's own `README.md` / `main.cpp` / `baremix_custom_tiling.cpp` were not fetched (so the host
  side's `blockDim`, `__schedmode__` setting and workspace sizing are unverified).
- **`matmul_client.h` was not obtained, so the vendor's own cross-core DCCI could not be quoted first-hand.**
  §31.2's comment cites 「与 CANN matmul_client.h 中"读跨核 GM flag 前先 DCCI"的用法一致」, which would be the
  strongest possible evidence (the Matmul high-level API doing it internally). `cann/asc-devkit` does not appear to
  ship the Matmul high-level implementation headers: `include/lib/matmul_intf.h`,
  `include/high_level_api/lib/matmul_intf.h`, `impl/high_level_api/lib/matmul/matmul_client.h` and
  `impl/high_level_api/matmul/matmul_client.h` all return 404, while `include/basic_api/...` resolves. The file
  presumably lives only in the installed CANN toolkit under `.../tikcpp/tikcfw/lib/matmul/matmul_client.h` — read it
  on the A3 and quote it.
- **`WaitIterateAll` has no reachable API page.** It is listed in the 「Matmul Kernel侧接口」 TOC (§11) but the TOC
  link extraction in §31.9 returned pages for `IterateAll` (0640) and `End` (0645) and no `WaitIterateAll` entry;
  the referenced 「IterateAll异步场景样例」 was likewise not located. So the exact asynchronous contract
  (`sync=false` plus `waitIterateAll=true` plus a `WaitIterateAll()` call) is documented only by the parameter
  descriptions quoted there, not by its own page.
- **The `pipe`-argument conflict on 2201 is unresolved.** §20 quotes the official claim 「在NPU架构版本2201上，
  `CrossCoreWaitFlag`传入的`pipe`参数无效，无论取值为何都默认阻塞全部流水的后续指令，建议省略`pipe`参数并使用默认值」;
  §31.3 quotes a measured counter-claim from a shipping A2 kernel that a `PIPE_S` wait lets the following MTE2 issue
  early and read half-stale C, which is why they pass `PIPE_MTE2` on 2201. No third source was found to adjudicate,
  and no erratum or DTS number was located for either statement.
- **No vendor erratum or DTS number was found for the cross-core GM visibility behaviour itself.** The evidence in
  §31 is three independent third-party kernels plus the API pages' silence. Nothing on `hiascend.com`,
  `bbs.huaweicloud.com` or gitcode states the DAV_2201 publication rule as a documented hardware property, and the
  official `DataCacheCleanAndInvalid` page positively asserts the opposite for DMA
  (「DMA搬运单元读写Global Memory ... 没有Cache一致性问题」).
- **`MemDsbT::SEQ` is 「预留参数，暂未启用」** and `DcciDst::CACHELINE_UB` / `CACHELINE_ATOMIC` are both
  「预留参数，暂未支持」 on the pages quoted in §31.5/§31.6, so the only usable combinations on A3 are
  `CacheLine::{SINGLE_CACHE_LINE, ENTIRE_DATA_CACHE}` × `DcciDst::{CACHELINE_ALL, CACHELINE_OUT}` and
  `MemDsbT::{ALL, DDR, UB}`. No cost figure was found for any of them; PPFM's own accounting is only
  「AIC 每 chunk 10 次整缓存 DCCI + AIV 6 次 + 4 次 DSB」 with no per-instruction time.

### Section 36 (grid-wide reduction) negative findings, reported as found
- https://github.com/hicann/cann-ops-adv — repo does not exist on GitHub (404); so does github.com/Ascend/cann-ops-adv and github.com/hicann/ascendc-api-adv. The adv-API/ops-adv content now lives under hicann/asc-devkit (docs/zh/api/SIMD-API/adv_api/...) and hicann/ops-nn, both of which are quoted above.
- https://github.com/Ascend/samples — `gh search code "SyncAll" --repo Ascend/samples` returns zero hits and the recursive tree has no sync_all/syncall path; the SyncAll sample moved into hicann/asc-devkit/examples (quoted above).
- https://raw.gitcode.com/cann/ops-nn/raw/master/quant/dynamic_quant/op_kernel/dynamic_quant.h — gitcode raw refuses unregistered traffic with `429 ... Limited account:unregisteredUser`; the same files were taken from the hicann/ops-nn GitHub mirror instead.
- https://github.com/hicann/ops-nn — no kernel in the tree builds a per-token quant row max with SetAtomicMax into GM. Every cross-core max in the repo is done as partials-in-workspace + SyncAll + a second reduce pass (ITEM 28, 30, 31). `gh search code "SetAtomicMax" --limit 30` finds the API only in asc-devkit headers/docs and in sgl-kernel-npu / unified-cache-management / AReno wrappers, never as a row-max reduction.
- https://github.com/hicann/catlass — no dcci polling loop; catlass synchronises purely through CrossCoreSetFlag/CrossCoreWaitFlag (ITEM 21). Its tla_dsl subtree lowers flag barriers in MLIR, not in AscendC kernel source.

## 42. ★ Sub-byte (`int4b_t`) tensor addressing on dav-2201, read off the shipped AscendC headers — and the hard negative on `SetGlobalBuffer`'s length argument

Source: the AscendC devkit source tree present on this machine,
`/home/shanshan/repo/cann/asc-devkit/` (the `hicann/asc-devkit` tree — the same one quoted in §35 and §A11).
This is the implementation, not a doc page, so it settles the question rather than describing it.
Read 2026-10-20.

This section exists because of a live defect: a `DataCopy` from `LocalTensor<int4b_t>` (UB) to
`GlobalTensor<int4b_t>` (GM) lands at element offset 0 every time and never at element offset 12288, same
function, same staging buffers, same 2048-element span, same run — while the identical copy at offset 12288
*does* land in an isolated probe whose `GlobalTensor` was declared 14336 elements long instead of 98304. The
question asked was whether the declared length in `SetGlobalBuffer` is the remaining variable. It is not, and
the code below is why.

### 42.1 `int4b_t` is a one-byte C++ struct holding one nibble — `sizeof(int4b_t) == 1`

`impl/utils/common_types.h:41,49-71,102` (identical copy at `impl/basic_api/utils/kernel_utils_constants.h:81,606`):

```cpp
constexpr uint32_t INT4_BIT_NUM = 4;

template <int bit_num, bool sign = true>
struct integer_sub_type {
    static int const k_bits = bit_num;
    static bool const k_signed = sign;

    using T = typename conditional<k_signed, int8_t, uint8_t>::type;
    using Storage = uint8_t;

    static Storage const mask = Storage(((static_cast<uint64_t>(1)) << static_cast<uint32_t>(k_bits)) - 1);
    Storage storage;
    __aicore__ inline integer_sub_type() = default;

    __aicore__ inline integer_sub_type(uint32_t value) : storage(reinterpret_cast<Storage const&>(value) & mask) {}

    __aicore__ inline integer_sub_type(int32_t value) : storage(reinterpret_cast<Storage const&>(value) & mask) {}

    __aicore__ inline operator T() const
    {
        if (k_signed && ((storage & Storage(static_cast<uint64_t>(1) << static_cast<uint32_t>(k_bits - 1))) != 0)) {
            // Sign extend
            return T(storage) | ~T(mask);
        }
        return T(storage);
    }
    ...
};

using int4b_t = integer_sub_type<INT4_BIT_NUM, true>;
```

So the C++ object is **one byte with one `uint8_t storage` member**: `sizeof(int4b_t) == 1`, and
`alignof(int4b_t) == 1`. The *logical* width is carried separately, by an explicit specialization at
`impl/basic_api/utils/kernel_utils_constants.h:663-670`:

```cpp
template <typename T>
struct SizeOfBits {
    static constexpr uint32_t value = sizeof(T) * ONE_BYTE_BIT_SIZE;
};

template <>
struct SizeOfBits<int4b_t> {
    static int const value = INT4_BIT_NUM;
};
```

**This is the whole trap.** `sizeof(int4b_t)` is 1 (one nibble per byte, as a scalar), but `SizeOfBits<int4b_t>`
is 4 (two nibbles per byte, as packed tensor storage). Every tensor-level API uses the second convention and
every raw-pointer expression uses the first. Mixing them gives a factor of two in the address.

### 42.2 `GlobalTensor<int4b_t>::operator[]` counts NIBBLES, and truncates an odd index silently

`impl/basic_api/kernel_tensor_impl.h:1651-1675`, verbatim and complete:

```cpp
template <typename T>
__aicore__ inline GlobalTensor<T> GlobalTensor<T>::operator[](const uint64_t offset) const
{
    GlobalTensor result = *this;
    if constexpr (IsHalfByteDataType<PrimType>()) {
        result.address_ = result.address_ + offset / INT4_TWO;
        result.oriAddress_ = result.oriAddress_ + offset / INT4_TWO;
#if (__NPU_ARCH__ == 5102)
    } else if constexpr (SupportType<PrimType, int2b_t>()) {
        result.address_ = result.address_ + offset / INT2_FOUR;
        result.oriAddress_ = result.oriAddress_ + offset / INT2_FOUR;
    } else if constexpr (SupportType<PrimType, uint1b_t>()) {
        result.address_ = result.address_ + offset / INT1_EIGHT;
        result.oriAddress_ = result.oriAddress_ + offset / INT1_EIGHT;
#endif
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3003) || (__NPU_ARCH__ == 3113))
    } else if constexpr (IsSameType<PrimType, uint2b_t>::value) {
        result.address_ = result.address_ + offset / INT2_FOUR;
        result.oriAddress_ = result.oriAddress_ + offset / INT2_FOUR;
#endif
    } else {
        result.address_ = result.address_ + offset;
        result.oriAddress_ = result.oriAddress_ + offset;
    }
    return result;
}
```

with `constexpr uint32_t INT4_TWO = 2;` at `impl/basic_api/utils/kernel_utils_constants.h:80`.

Three consequences, all exact:

1. **`operator[](offset)` counts elements (nibbles), not bytes.** `address_` has type `__gm__ PrimType*` =
   `__gm__ int4b_t*` with `sizeof == 1`, so `address_ + offset / 2` advances exactly `offset/2` bytes =
   `offset` nibbles. `gm[12288]` is byte 6144. Correct.
2. **An odd index is silently truncated down.** `offset / INT4_TWO` is integer division with no assert on this
   path. `gm[12289]` and `gm[12288]` are the same address. There is no diagnostic even in CPU debug.
3. **`operator[]` does NOT adjust `bufferSize_`.** `GlobalTensor result = *this;` copies it unchanged, so
   after `auto sub = gm[12288]`, `sub.GetSize()` still reports the *original* 98304. Any logic of yours that
   derives a remaining span from `GetSize()` after a subscript is wrong by the offset.

`GetPhyAddr(offset)` applies the same halving but *does* assert evenness —
`impl/basic_api/kernel_tensor_impl.h:1337-1341` (the non-3510 branch, i.e. ours):

```cpp
    if constexpr (IsHalfByteDataType<PrimType>()) {
        ASCENDC_DEBUG_ASSERT(
            (offset % 2 == 0),
            KERNEL_LOG_INTERNAL(KERNEL_ERROR, "The offset for int4b_t GetPhyAddr should be an even num."));
        return this->address_ + offset / INT4_TWO;
```

`ASCENDC_DEBUG_ASSERT` is compiled out on NPU. So the evenness rule is real but unenforced on device.

### 42.3 ★ The hard negative: `SetGlobalBuffer`'s `bufferSize` argument has NO device-side effect whatsoever

Declaration, `include/basic_api/kernel_tensor.h` (class `GlobalTensor`), with the field's own comment at line 291:

```cpp
    __aicore__ inline void SetGlobalBuffer(__gm__ PrimType* buffer, uint64_t bufferSize);
    __aicore__ inline void SetGlobalBuffer(__gm__ PrimType* buffer);
...
public:
    // element number of Tensor
    uint64_t bufferSize_;
```

Definition, `impl/basic_api/kernel_tensor_impl.h:1251-1300`, verbatim (2201 takes the `#else` arm):

```cpp
template <typename T>
__aicore__ inline void GlobalTensor<T>::SetGlobalBuffer(
    __gm__ typename GlobalTensor<T>::PrimType* buffer, uint64_t bufferSize)
{
#if (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102)
    ...
#else
    if (this->cacheMode_ == CacheMode::CACHE_MODE_NORMAL) {
        this->address_ = buffer;
    } else {
        this->address_ = L2CacheAlter<PrimType, CacheRwMode::RW>(buffer, cacheMode_);
    }
    this->oriAddress_ = buffer;
#endif
    bufferSize_ = bufferSize;
}

template <typename T>
__aicore__ inline void GlobalTensor<T>::SetGlobalBuffer(__gm__ typename GlobalTensor<T>::PrimType* buffer)
{
...
#if ASCENDC_CPU_DEBUG
    bufferSize_ = 0;
#endif
}
```

An exhaustive grep for every reference to `bufferSize_` in the whole devkit (`impl/` + `include/`, excluding
the unrelated HCCL `comm_config_pub.h` / `hccl_comm_pub.h` / `aicpu_communicator.h` fields of the same name)
returns exactly four sites:

```
impl/basic_api/kernel_tensor_impl.h:1273:    bufferSize_ = bufferSize;                 // the 2-arg SetGlobalBuffer, above
impl/basic_api/kernel_tensor_impl.h:1298:    bufferSize_ = 0;                          // the 1-arg SetGlobalBuffer, ASCENDC_CPU_DEBUG only
impl/basic_api/kernel_tensor_impl.h:1647:    return bufferSize_;                       // GetSize()
impl/basic_api/kernel_tensor_impl.h:1725:    output.bufferSize_ = this->GetSize() * SizeOfBits<T>::value / SizeOfBits<U>::value;   // ReinterpretCast, 3510/5102 only
include/basic_api/kernel_tensor.h:291:    uint64_t bufferSize_;                     // the declaration
```

It is stored, it is returned by `GetSize()`, and on 3510/5102 it is rescaled by `ReinterpretCast`. **Nothing
on the `DataCopy` path reads it.** The only consumer that could ever have stopped a copy is the overflow
reporter, and that macro is empty off CPU debug — `impl/basic_api/kernel_log.h:76-84` and `:299`:

```cpp
#define ASCENDC_REPORT_OVERFLOW_MEM(cond) \
    do {                                  \
        if (!(cond)) {                    \
            raise(SIGABRT);               \
        }                                 \
    } while (0)
#else
#define ASCENDC_REPORT_OVERFLOW_MEM(cond)
#endif
```

```cpp
#define ASCENDC_REPORT_OVERFLOW_MEM(cond)
```

The Level-2 (count-based) `DataCopy` to GM is the only place it is invoked for this direction —
`impl/basic_api/kernel_operator_data_copy_intf_impl.h:844-851`:

```cpp
template <typename T>
__aicore__ inline __inout_pipe__(MTE3) void DataCopy(
    const GlobalTensor<T>& dst, const LocalTensor<T>& src, const uint32_t count)
{
    ASCENDC_REPORT_OVERFLOW_MEM((CheckDataCopyTensorSizeOverflow(dst, src, count)));
    struct DataCopyParams repeatParams;
    DataCopyCheck<T>(count, repeatParams);
    DataCopy(dst, src, repeatParams);
}
```

**Therefore: for a sub-byte type, the `bufferSize` argument is in ELEMENTS (nibbles) — the field's own comment
says `element number of Tensor`, and `ReinterpretCast`'s rescale by `SizeOfBits` confirms it — but passing a
length larger than the real allocation is inert on NPU. It does not clamp, truncate, reroute or drop a
`DataCopy`. It only disables a CPU-debug `SIGABRT`.** 98304 vs 14336 cannot be the cause of the
offset-12288 failure. That hypothesis is closed.

### 42.4 ★ What CAN silently drop a UB→GM `DataCopy`: the unguarded `else` in the Level-0 overload

`impl/basic_api/kernel_operator_data_copy_intf_impl.h:271-329`, the overload every other form funnels into:

```cpp
template <typename T>
__aicore__ inline __inout_pipe__(MTE3) void DataCopy(
    const GlobalTensor<T>& dst, const LocalTensor<T>& src, const DataCopyParams& repeatParams)
{
    ...
    using PrimType = PrimT<T>;
    const Hardware srcHWPos = GetPhyType((TPosition)src.GetPosition());
#if defined(ASCENDC_DEBUG) || defined(ASCENDC_CPU_DEBUG)
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
    CheckBasicDataCopyTypeSupport<T>("DataCopy from LocalTensor to GlobalTensor with DataCopyParams");
    CheckDataCopyTensor(dst, src, repeatParams, "DataCopy from LocalTensor to GlobalTensor with DataCopyParams");
#endif
#endif
#ifdef ASCENDC_CPU_DEBUG
    if (!CheckFuncDataCopy(dst, src, repeatParams, "DataCopy from LocalTensor to GlobalTensor")) {
        ASCENDC_REPORT_CHECK_ERROR("DataCopy from LocalTensor to GlobalTensor", KernelFuncType::NONE_MODE);
    }
    ASCENDC_REPORT_OVERFLOW_MEM(CheckDataCopyTensorSizeOverflow(dst, src, repeatParams));
    ...
#endif // ASCENDC_CPU_DEBUG
    if (srcHWPos == Hardware::UB) {
        // ub -> gm
        DataCopyUB2GMImpl((__gm__ PrimType*)dst.GetPhyAddr(), (__ubuf__ PrimType*)src.GetPhyAddr(), repeatParams);
    } else if (srcHWPos == Hardware::L1) {
        // l1 -> gm
        DataCopyL12GMImpl((__gm__ PrimType*)dst.GetPhyAddr(), (__cbuf__ PrimType*)src.GetPhyAddr(), repeatParams);
    } else {
        ASCENDC_CHECK_TPOSITION(
            false, "src", "L1 Buffer(A1/B1)/UB(VECOUT)",
            "DataCopy from LocalTensor to GlobalTensor with DataCopyParams",
            GetPositionDisplay(static_cast<TPosition>(src.GetPosition())));
    }
    ...
}
```

Two things to read off this:

- **If `GetPhyType(src.GetPosition())` is neither `UB` nor `L1`, the function emits no move instruction at
  all and returns silently.** The `else` arm is a check macro, and `ASCENDC_CHECK_TPOSITION` is compiled out
  on an NPU build without `ASCENDC_DEBUG`. That is a mechanism whose symptom is exactly «the copy never lands
  anywhere» — no hang, no error, no data. It is driven by the *source* `LocalTensor`'s `TPosition`, not by the
  destination offset, so it fits a per-call-site difference rather than a per-offset one.
- **The destination address is taken with the no-argument `dst.GetPhyAddr()`.** The offset must already be
  baked into `dst` by `operator[]` (as §42.2) or by `SetGlobalBuffer` on an already-advanced pointer. There is
  no offset parameter on this path at all.

And the pointer-advance trap that follows from §42.1: because `SetGlobalBuffer` takes `__gm__ PrimType*` =
`__gm__ int4b_t*` and `sizeof(int4b_t) == 1`, writing

```cpp
gm.SetGlobalBuffer(reinterpret_cast<__gm__ int4b_t*>(base) + 12288, len);   // 12288 BYTES  = element 24576
gm = gm[12288];                                                            // 12288 NIBBLES = byte 6144
```

gives two different addresses a factor of two apart. The official example uses the second form exclusively
(§42.6).

### 42.5 `int4b_t` `DataCopy` granularity: count must be a multiple of 64 elements

`impl/basic_api/kernel_operator_data_copy_intf_impl.h:763-793`:

```cpp
template <typename T>
__aicore__ inline void DataCopyCheck(const uint32_t count, DataCopyParams& repeatParams)
{
    using PrimType = PrimT<T>;
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 5102)
    if constexpr (Std::is_same<PrimType, int2b_t>::value) {
        ...
        repeatParams.blockLen = count / ConstantsInternal::ONE_BLK_B2_NUM;
    } else if constexpr (Std::is_same<PrimType, uint1b_t>::value) {
        ...
        repeatParams.blockLen = count / ConstantsInternal::ONE_BLK_B1_NUM;
    } else if constexpr (
        Std::is_same<PrimType, fp4x2_e2m1_t>::value || Std::is_same<PrimType, fp4x2_e1m2_t>::value ||
        Std::is_same<PrimType, int4b_t>::value) {
        ASCENDC_ASSERT((count % ConstantsInternal::ONE_BLK_FP4_NUM == 0), {
            KERNEL_LOG(
                KERNEL_ERROR, "DataCopy count is %d, which should be 32B align. \
                    In NPU mode, no error is reported. The value is rounded down by 32B.",
                count);
        });
        repeatParams.blockLen = count / ConstantsInternal::ONE_BLK_FP4_NUM;
    } else
    ...
```

with `impl/basic_api/utils/kernel_utils_constants.h:311-313`:

```cpp
const uint32_t ONE_BLK_FP4_NUM = 64;
const uint32_t ONE_BLK_B2_NUM = 128;
const uint32_t ONE_BLK_B1_NUM = 256;
```

So an `int4b_t` `DataCopy` moves whole 32-byte blocks of 64 nibbles, and the quantum is 64 elements.
Note the assert's own wording: **「In NPU mode, no error is reported. The value is rounded down by 32B.」** — a
misaligned count is silently floored on device. 2048 and 12288 are both multiples of 64, so this is not the
present defect, but it is the rule for any future span.

`int4b_t` is a first-class `DataCopy` type on 2201 — `impl/basic_api/kernel_operator_data_copy_check.h:31-51`:

```cpp
template <typename T>
__aicore__ inline constexpr bool IsBasicDataCopySupportedType()
{
    return SupportType<
               PrimT<T>, int4b_t, uint8_t, int16_t, uint16_t, int32_t, uint32_t, int64_t, uint64_t, half, float,
               double>()
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
           || SupportType<PrimT<T>, bfloat16_t>()
#endif
        ;
}

template <typename T>
__aicore__ inline constexpr bool IsNd2NzSupportedType()
{
    return SupportType<PrimT<T>, int4b_t, int8_t, uint8_t, int16_t, uint16_t, int32_t, uint32_t, half, float>()
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
           || SupportType<PrimT<T>, bfloat16_t>()
#endif
        ;
}
```

and `IsDataCopyPadSupportedType<T>()` is defined as `IsBasicDataCopySupportedType<T>()`, so `DataCopyPad`
accepts it too.

### 42.6 The vendor's own int4 idiom: element-counted `SetGlobalBuffer`, then tensor `operator[]`

`examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_int4/matmul_int4.asc`, verbatim — note that this
is a `#define ASCENDC_CUBE_ONLY` kernel, the same mode as ours:

```cpp
#include "kernel_operator.h"
#define ASCENDC_CUBE_ONLY
#include "lib/matmul_intf.h"
...
    aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ AType*>(a), tiling.M * tiling.Ka);
    bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ BType*>(b), tiling.Kb * tiling.N);
    cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ CType*>(c), tiling.M * tiling.N);
    biasGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ BiasType*>(bias), tiling.N);

    int32_t offsetA = 0;
    int32_t offsetB = 0;
    int32_t offsetC = 0;
    int32_t offsetBias = 0;
    CalcOffset(AscendC::GetBlockIdx(), offsetA, offsetB, offsetC, offsetBias);
    aGlobal = aGlobal[offsetA];
    bGlobal = bGlobal[offsetB];
    cGlobal = cGlobal[offsetC];
    biasGlobal = biasGlobal[offsetBias];
```

The length is the element count (`M * Ka`, not `M * Ka / 2`), and the offset is applied with
`tensor = tensor[offset]`, never by advancing the raw pointer. `AType` here is `AscendC::int4b_t`.

### 42.7 The official int4 Matmul constraint list — and a 950 forward-compat warning

`examples/01_simd_cpp_api/04_advanced_api/00_matmul/matmul_int4/README.md`, 「约束条件」 verbatim:

```
- 约束条件
  - 左矩阵A、右矩阵B的数据类型必须同时为int4，对应输出C矩阵的数据类型只支持int32、half。
  - 左矩阵A为int4数据类型时，不支持转置。
  - int4数据类型输入的Matmul对象仅支持Norm、MDL、IBShare模板。
```

and the product table:

```
| 产品 | CANN软件版本 |
|------|-------------|
| Atlas A3 训练系列产品/Atlas A3 推理系列产品 | >= CANN 9.0.0 |
| Atlas A2 训练系列产品/Atlas A2 推理系列产品 | >= CANN 9.0.0 |
```

This is the vendor's own, independent confirmation of our `mad_s4` finding: **both operands must be int4, C is
int32 or half only, an int4 A matrix cannot be transposed, and only the Norm / MDL / IBShare templates
support it.**

`examples/01_simd_cpp_api/06_compatibility_guide/matmul_s4/README.md` adds the forward-compat shape, verbatim:

```
## 概述

本样例演示 int4 矩阵乘计算的端到端实现，通过编译时宏隔离不同硬件实现。
- Atlas A2/A3 训练/推理系列产品支持int4数据类型，可直接进行Matmul计算。
- Ascend 950PR/Ascend 950DT的Cube计算单元不支持int4数据类型，需将int4x2解压为int8后再进行Matmul计算。
```

```
## 样例实现：

  - **Atlas A2/A3 训练/推理系列产品**：Cube计算单元支持int4数据类型，可直接执行Matmul计算。
  - **Ascend 950PR/950DT**：Cube计算单元不支持int4数据类型，需通过mix模式在Vector Core执行Unzip操作，将int4x2解压为int8后再进行Matmul计算。
```

So the A3 int4 Cube path we rely on is removed on 950PR/950DT, where the sanctioned route is a Vector-core
unzip of int4x2 to int8 in mix mode.

### 42.8 ★ There is no unsigned int4 on 2201 — `uint4b_t` exists in the headers but is arch-gated away

`impl/basic_api/utils/kernel_utils_constants.h:606-615`:

```cpp
using int4b_t = integer_sub_type<INT4_BIT_NUM, true>;

#if (__NPU_ARCH__ == 5102)
using int2b_t = IntegerSubType<INT2_BIT_NUM, true>;
using int1b_t = IntegerSubType<INT1_BIT_NUM, true>;
using uint1b_t = IntegerSubType<INT1_BIT_NUM, false>;
#endif

#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3003) || (__NPU_ARCH__ == 3113))
using uint4b_t = IntegerSubType<INT4_BIT_NUM, false>;
```

and its `SizeOfBits` specialization at `:684-688` carries the same gate:

```cpp
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3003) || (__NPU_ARCH__ == 3113))
template <>
struct SizeOfBits<uint4b_t> {
    static int const value = INT4_BIT_NUM;
};
```

`GlobalTensor::GetPhyAddr`'s `uint4b_t` arm (`kernel_tensor_impl.h:1343-1348`) sits inside the same
`3003 || 3113` guard. **On `__NPU_ARCH__ == 2201` the type `AscendC::uint4b_t` does not exist**, so there is
no unsigned-int4 operand to be had on A3 and no `Mmad` flag to ask for one: the signed −8..7 range plus a
per-column `8*sum(w)` correction fold is the only route. The type being present-but-gated also means a
compile error naming `uint4b_t` on 2201 is a *missing arch*, not a missing CANN version.

## Relevance

42.3 is the answer to the live question and it is a negative: the declared length in `SetGlobalBuffer` is in
elements for `int4b_t`, and over-declaring it is inert on NPU — nothing on the `DataCopy` path reads
`bufferSize_`, and the only check that could have fired is a `SIGABRT` macro that expands to nothing off CPU
debug. 98304 versus 14336 is not the variable. 42.4 supplies the one mechanism in this code that produces
exactly «never lands anywhere, no error»: if the source `LocalTensor`'s `TPosition` maps to neither `UB` nor
`L1`, the Level-0 overload emits no instruction and returns, because its `else` arm is a debug-only check.
42.1 and 42.2 give the factor-of-two trap to rule out next — `sizeof(int4b_t) == 1` but
`SizeOfBits<int4b_t> == 4`, so a raw `int4b_t*` advance counts bytes while `tensor[i]` counts nibbles — and
42.6 shows the vendor applying offsets only the second way, inside a `ASCENDC_CUBE_ONLY` kernel like ours.
42.5 fixes the span quantum at 64 elements with silent floor-rounding on device. 42.7 independently confirms
the `mad_s4` both-operands-int4 rule from Huawei's own README, adds two constraints we had not recorded (no
transpose on an int4 A, and only Norm/MDL/IBShare templates), and warns that the whole A3 int4 Cube path
disappears on 950PR/950DT. 42.8 closes the unsigned-int4 question for 2201.

The actionable next probe follows from 42.4, not from the buffer length: build the failing kernel once with
the vendor's own CPU-debug switch, which is the only configuration in which `ASCENDC_CHECK_TPOSITION`,
`CheckFuncDataCopy` and `CheckDataCopyTensorSizeOverflow` are compiled in at all. The flag is in
`examples/01_simd_cpp_api/06_compatibility_guide/matmul_s4/README.md`:

```bash
cmake -DCMAKE_ASC_RUN_MODE=cpu -DCMAKE_ASC_ARCHITECTURES=dav-2201 ..;make -j; # cpu调试模式
```

and `-DCMAKE_ASC_RUN_MODE=sim` for the NPU simulator. A silent drop becomes a named check failure under
either.

## 43. ★ The authoritative `PipeBarrier` vs `SetFlag`/`WaitFlag` rule, the complete `HardEvent` enumeration per core half, and the Set/Wait asymmetry that makes a foreign-core `WaitFlag` a silent no-op on 2201

Sources, all read 2026-10-20:

- 「同步控制简介」, CANN 商用版 8.0.RC2.2 — https://www.hiascend.com/doc_center/source/zh/canncommercial/80RC22/apiref/opdevgapi/atlasascendc_api_07_0262.html
  (the `document/detail/...` twin at `.../canncommercial/80RC22/apiref/opdevgapi/atlasascendc_api_07_0262.html`
  returns an empty body to a fetcher; the `doc_center` form works — see §35.0)
- 「PipeBarrier」, same book — `.../atlasascendc_api_07_0264.html`
- 「SetFlag/WaitFlag」, same book — `.../atlasascendc_api_07_0263.html`; the newer ISASI copy is
  `https://www.hiascend.com/document/detail/zh/CANNCommunityEdition/80RC3alpha003/apiref/opdevgapi/atlasascendc_api_07_0260.html`
- the shipped AscendC implementation on this machine, `/home/shanshan/repo/cann/asc-devkit/` — which settles
  everything the doc pages leave open

### 43.1 The official rule: `PipeBarrier` is SAME-pipe only. It is not a cross-pipe primitive at all.

From 「同步控制简介」, the two categories as published:

> **多流水同步**：通过SetFlag/WaitFlag完成不同流水线之间的同步控制。
> SetFlag：「当前序指令的所有读写操作都完成之后，当前指令开始执行，并将硬件中的对应标志位设置为1。」
> WaitFlag：标志位为0时「该队列的后续指令将一直被阻塞」；为1则清零并继续执行。
>
> **单流水同步**：通过PipeBarrier完成同一流水线内的同步控制，用于在同一流水线内部约束执行顺序，
> 「保证前序指令中所有数据的读写工作全部完成，后序指令才能执行。」

And the hardware pipe table from the same page, verbatim:

```
PIPE_S     — scalar 流水，Tensor GetValue 等
PIPE_V     — vector 计算，以及 L0C→UB 搬运
PIPE_M     — matrix 计算
PIPE_MTE1  — L1→L0A / L1→L0B 搬运
PIPE_MTE2  — GM→L1 / GM→L0A / GM→L0B / GM→UB 搬运
PIPE_MTE3  — UB→GM / UB→L1 搬运
PIPE_FIX   — L0C→GM / L0C→L1 搬运（当前版本暂不支持该流水类型）
```

Manual-versus-automatic insertion, verbatim from the same page — this is the sentence that matters most:

> Vector 单元：单流水同步中「PIPE_V由编译器自动完成同步插入」，PIPE_MTE2/PIPE_MTE3「在搬运地址有重叠的情况下需要开发者插入同步」。
> 多流水同步中 PIPE_V、PIPE_MTE2、PIPE_MTE3、PIPE_S 之间的同步「都是双向的」，图中黄色连线由编译器插入，其余由 Ascend C 框架完成。
>
> Cube 单元：「Cube侧所有流水同步都由Ascend C框架完成，不需要算子开发者插入同步。」

with the caveat the page itself attaches:

> 编译器自动插入强依赖于 LocalTensor 的依赖关系，部分场景仍需手动同步，约束见《毕昇编译器使用指南》。

The `PipeBarrier` page (`..._0264.html`) is shorter and blunter. 功能说明, verbatim:

> 阻塞相同流水，具有数据依赖的相同流水之间需要插此同步。

函数原型:

```cpp
template <pipe_t pipe>
__aicore__ inline void PipeBarrier();
```

参数说明: 「pipe — 模板参数，表示阻塞的流水类别。」 返回值: 无. 支持的型号: 「Atlas 训练系列产品 /
Atlas推理系列产品AI Core / Atlas A2训练系列产品、Atlas 800I A2推理产品」. 约束说明, verbatim, and this is a
trap worth writing on the wall:

> Scalar流水之间的同步由硬件自动保证，调用PipeBarrier<PIPE_S>()会引发硬件错误。

调用示例, verbatim — note that the example's two instructions are both on PIPE_V, i.e. the documented use is
*same pipe*:

> Mul指令的输入dst0Local是Add指令的输出，两个矢量运算指令产生依赖，需要插入PipeBarrier保证两条指令的执行顺序。

```cpp
LocalTensor<half> src0Local;
LocalTensor<half> src1Local;
LocalTensor<half> src2Local;
LocalTensor<half> dst0Local;
LocalTensor<half> dst1Local;

Add(dst0Local, src0Local, src1Local, 512);
PipeBarrier<PIPE_V>();
Mul(dst1Local, dst0Local, src2Local, 512);
```

**So the authoritative rule is a taxonomy, not a strength ordering.** `PipeBarrier` is the 单流水 primitive —
it drains one named pipe. `SetFlag`/`WaitFlag` is the 多流水 primitive — it orders two *different* pipes.
`PipeBarrier` is not a weaker version of `SetFlag`; it is a different instrument, and no amount of it
substitutes for a cross-pipe event. A `Cast` on V followed by a `DataCopy` to GM on MTE3 reusing the same UB
buffer is a V→MTE3 then MTE3→V hazard, which is by construction outside what `PipeBarrier` is defined to do.

### 43.2 `PIPE_ALL`: legal, used by the vendor, and absent from the documented pipe set

`pipe_t` is a Bisheng builtin — it is not declared anywhere in the devkit headers. What the headers do declare
is the *supported* set, `impl/basic_api/kernel_event.h:244-250`:

```cpp
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ != 1001) && (__NPU_ARCH__ != 2002)
constexpr int32_t PIPE_NUM = 7;
constexpr pipe_t SUPPORTED_PIPE[PIPE_NUM] = {PIPE_S, PIPE_V, PIPE_M, PIPE_MTE1, PIPE_MTE2, PIPE_MTE3, PIPE_FIX};
#else
constexpr int32_t PIPE_NUM = 6;
constexpr pipe_t SUPPORTED_PIPE[PIPE_NUM] = {PIPE_S, PIPE_V, PIPE_M, PIPE_MTE1, PIPE_MTE2, PIPE_MTE3};
#endif
```

`PIPE_ALL` is not in `SUPPORTED_PIPE` and is not in the doc page's 流水类型 table. It is nevertheless used by
the vendor's own header-conformance suite, `tests/api/basic_api/ascendc_header_checker/kernel_operator_block_sync_intf.cpp:37,91`:

```cpp
extern "C" __global__ __aicore__ void KernelTestPipeBarrier1() { AscendC::PipeBarrier<PIPE_ALL>(); }
...
    AscendC::CrossCoreSetFlag<0, PIPE_ALL>(flagId);
```

and freely throughout `tests/api/basic_api/ascendc_case_common/` in the C form `pipe_barrier(PIPE_ALL)`. So it
compiles and runs. But it is an undocumented pipe selector, it drains pipes rather than establishing a
cross-pipe dependency, and §43.1's taxonomy says a drain of every pipe is still a set of same-pipe
constraints. There is also a direct third-party judgement on it: the Ascend static-analysis checker emits
**`AKA3001 "PipeBarrier(PIPE_ALL) antipattern"` at Warning level**, and
https://github.com/tile-ai/tilelang-ascend/issues/110 — "In double buffer scenarios, using the automatic
synchronization insertion feature, the generated AscendC code does not meet expectations, using
`AscendC::PipeBarrier<PIPE_ALL>()`" — is a filed bug whose expected behaviour is two `set_flag`/`wait_flag`
pairs on distinct flag ids instead.

Also quoted, from the Huawei Cloud performance guide 「Ascend C算子性能优化实用技巧05——API使用优化」
(https://bbs.huaweicloud.com/blogs/438903): fine-grained event sync is preferred because it blocks only the
dependency chain, whereas each `PipeBarrier` or `WaitFlag` costs a pipeline stall.

### 43.3 ★ The complete `HardEvent` enumeration, and the two reduced per-core-half enumerations

`impl/basic_api/kernel_event.h:38-111`, verbatim and complete — the naming convention is
源流水_目标流水, so `MTE2_V` means PIPE_V waits on PIPE_MTE2:

```cpp
enum class HardEvent : uint8_t {
    // src_dst
    MTE2_MTE1,
    MTE1_MTE2,
    MTE1_M,
    M_MTE1,
    MTE2_V,
    V_MTE2,
    MTE3_V,
    V_MTE3,
    M_V,
    V_M,
    V_V,
    MTE3_MTE1,
    MTE1_MTE3,
    MTE1_V,
    MTE2_M,
    M_MTE2,
    V_MTE1,
    M_FIX,
    FIX_M,
    MTE3_MTE2,
    MTE2_MTE3,
    S_V,
    V_S,
    S_MTE2,
    MTE2_S,
    S_MTE3,
    MTE3_S,
    MTE2_FIX,
    FIX_MTE2,
    FIX_S,
    M_S,
    FIX_MTE3,
    MTE1_FIX,
    FIX_MTE1,
    FIX_FIX,
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 5102) || (__NPU_ARCH__ == 3003))
    FIX_V,
    V_FIX,
#endif
    MAX,
};

enum class HardEventAic : uint8_t {
    // src_dst
    MTE2_MTE1,
    MTE1_MTE2,
    MTE1_M,
    M_MTE1,
    MTE3_MTE1,
    MTE1_MTE3,
    MTE2_M,
    M_MTE2,
    M_FIX,
    FIX_M,
    MTE3_MTE2,
    MTE2_MTE3,
    S_MTE2,
    MTE2_S,
    S_MTE3,
    MTE3_S,
    MTE2_FIX,
    FIX_MTE2,
    FIX_S,
    M_S,
    FIX_MTE3,
    MTE1_FIX,
    FIX_MTE1,
    FIX_FIX,
    MAX,
};

enum class HardEventAiv : uint8_t {
    // src_dst
    MTE2_V,
    V_MTE2,
    MTE3_V,
    V_MTE3,
    V_V,
    MTE3_MTE2,
    MTE2_MTE3,
    S_V,
    V_S,
    S_MTE2,
    MTE2_S,
    S_MTE3,
    MTE3_S,
    MAX,
};
```

So the **legal `HardEvent` set on an A3 AIV is exactly thirteen**: `MTE2_V, V_MTE2, MTE3_V, V_MTE3, V_V,
MTE3_MTE2, MTE2_MTE3, S_V, V_S, S_MTE2, MTE2_S, S_MTE3, MTE3_S`. On an A3 AIC it is exactly twenty-four, the
`HardEventAic` list. The vendor's own comments state the counts and the reason, at `:140` and `:197`:

```cpp
    // in v220 aic, only 21 events is useful, so convert evt to index in event pool
    // in other chip version, all events are valid;
```

```cpp
    // in v220 aiv, only 13 events is useful, so convert evt to index in event pool
    // in other chip version, all events are valid;
```

**`MTE3_V` and `V_MTE3` are both in `HardEventAiv` and in neither `HardEventAic`.** `M_V`, `V_M`, `MTE1_V` and
`V_MTE1` are in NEITHER reduced enum — they cross the AIC/AIV boundary, which on a split core is not a pipe
event at all.

### 43.4 How many event IDs: eight, per `HardEvent` kind, per `TPipe`

`impl/basic_api/kernel_macros.h:98-104`:

```cpp
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 2002) || (__NPU_ARCH__ == 2201) || (__NPU_ARCH__ == 3002) || \
                              (__NPU_ARCH__ == 3102) || (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102) || \
                              (__NPU_ARCH__ == 3003) || (__NPU_ARCH__ == 3113)) // Available for V200 and V210
constexpr int32_t QUE_MAX_EVENT = 8;
#else
constexpr int32_t QUE_MAX_EVENT = 4;
#endif
```

and both `SetFlagImpl` and `WaitFlagImpl` open with the same range check
(`impl/basic_api/kernel_event.h:911-915` and `:1046-1050`):

```cpp
    ASCENDC_ASSERT((eventID >= 0 && eventID < QUE_MAX_EVENT), {
        KERNEL_LOG(KERNEL_ERROR, "eventID %d should be in range [0, %d)", eventID, QUE_MAX_EVENT);
    });
```

So on 2201 the ids are **0-7, eight of them, and the budget is per `HardEvent` kind** — `MTE3_V` id 0 and
`V_MTE3` id 0 are different hardware events, exactly as the 「核内同步」 page says
(「SetFlag<HardEvent::S_MTE3>(1)和SetFlag<HardEvent::MTE3_MTE1>(1)设置的不是同一个EventID，因为其模板参数不同。
只有当模板参数和事件ID完全一致时，才表示同一个EventID。」). The pool is a bitmask per kind,
`impl/basic_api/kernel_tpipe_base.h:103-105` and `:136-137`:

```cpp
struct TEventPool {
    uint64_t eventOccupy;
};
...
struct TPipeImpl {
    struct TEventPool eventPool_[EVENT_NUM];
    struct TPipeBufPool bufPool_[static_cast<uint8_t>(Hardware::MAX)];
```

`impl/basic_api/kernel_tpipe_impl.h:497-540`:

```cpp
template <HardEvent evt>
__aicore__ inline TEventID TPipe::AllocEventID()
{
    ASCENDC_DEBUG_ASSERT(
        (evt < HardEvent::MAX), KERNEL_LOG_INTERNAL(KERNEL_ERROR, "illegal event %d", static_cast<int32_t>(evt)));
    auto ptr = this->g_tpipeImpl.eventPool_ + EventToIndex(evt);
    auto lastId = sff0(ptr->eventOccupy);
    ASCENDC_DEBUG_ASSERT(
        (lastId < QUE_MAX_EVENT && lastId >= 0),
        KERNEL_LOG_INTERNAL(
            KERNEL_ERROR, "current id is %ld, max buffer number in same queue position is %d", lastId, QUE_MAX_EVENT));
    ptr->eventOccupy = sbitset1(ptr->eventOccupy, lastId);
    return lastId;
}
...
__aicore__ inline TEventID TPipe::FetchEventID(HardEvent evt)
{
    auto ptr = this->g_tpipeImpl.eventPool_ + EventToIndex(evt);
    auto lastId = sff0(ptr->eventOccupy);
    ...
    return lastId;
}
```

`AllocEventID` *claims* a bit; `FetchEventID` only *peeks* at the first free bit and does not claim it.
**Reusing one id in a loop is safe iff the Set/Wait pairs on that id are strictly nested or strictly
sequential**, because the hardware event is a single bit per (pipe-pair, id): a second Set before the first
Wait is the documented 「不允许连续设置同一个EventID」 and merges the two dependencies. `FetchEventID` returning
the same id on every iteration — which it will, since it does not claim — is therefore only correct for a
Set…Wait pair that closes inside the iteration. A cross-iteration (double-buffered) protocol needs two ids and
must prime the first `WaitFlag` before the loop.

### 43.5 ★★★ The Set/Wait asymmetry: on 2201 a foreign-core `WaitFlag` is a SILENT no-op while its `SetFlag` really fires

`SPLIT_CORE_CUBE` is the cube half of a split-architecture kernel, `impl/utils/sys_macros.h:55-62`:

```cpp
#if (defined(__DAV_CUBE__) && (__NPU_ARCH__ == 2201 || __NPU_ARCH__ == 3510))
#define SPLIT_CORE_CUBE
#endif

#if (defined(__DAV_VEC__) && (__NPU_ARCH__ == 2201 || __NPU_ARCH__ == 3510))
#define SPLIT_CORE_VEC
#endif
```

— so in a `__mix__(1,2)` kernel the cube-half translation unit has `SPLIT_CORE_CUBE` defined and the vector
half has `SPLIT_CORE_VEC`, independently of `ASCENDC_CUBE_ONLY`.

The public entry points, `include/basic_api/kernel_operator_block_sync_intf.h:42-46`:

```cpp
template <HardEvent event>
__aicore__ inline void SetFlag(int32_t eventID);

template <HardEvent event>
__aicore__ inline void WaitFlag(int32_t eventID);
```

routed in `impl/basic_api/kernel_operator_block_sync_intf_impl.h:84,110` to

```cpp
    SetFlagImpl<event>(eventID);
```
```cpp
    WaitFlagImpl(event, eventID);
```

Both bottom out in a `switch` with a bare `default: break;`. The two switches are **not guarded the same way.**

`WaitFlagImpl` (`impl/basic_api/kernel_event.h:1046-1200`) is per-core-half gated:

```cpp
    switch (event) {
#ifndef SPLIT_CORE_VEC // CUBE core
        case HardEvent::MTE2_MTE1:
            WaitFlagInternal<PIPE_MTE2, PIPE_MTE1>(e);
            break;
        ...
#endif
#ifndef SPLIT_CORE_CUBE // VECTOR core
        case HardEvent::MTE2_V:
            WaitFlagInternal<PIPE_MTE2, PIPE_V>(e);
            break;
        case HardEvent::V_MTE2:
            WaitFlagInternal<PIPE_V, PIPE_MTE2>(e);
            break;
        case HardEvent::MTE3_V:
            WaitFlagInternal<PIPE_MTE3, PIPE_V>(e);
            break;
        case HardEvent::V_MTE3:
            WaitFlagInternal<PIPE_V, PIPE_MTE3>(e);
            break;
#endif
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ != 2201) && (__NPU_ARCH__ != 3510))
        case HardEvent::M_V:
            WaitFlagInternal<PIPE_M, PIPE_V>(e);
            break;
        case HardEvent::V_M:
            WaitFlagInternal<PIPE_V, PIPE_M>(e);
            break;
        case HardEvent::MTE1_V:
            WaitFlagInternal<PIPE_MTE1, PIPE_V>(e);
            break;
        case HardEvent::V_MTE1:
            WaitFlagInternal<PIPE_V, PIPE_MTE1>(e);
            break;
#endif
        ...
        case HardEvent::V_V:
            return;
        case HardEvent::MAX:
            break;
        default:
            break;
    }
```

and under CPU debug it says the same thing as an explicit early return, `:1051-1070` — which is the vendor
documenting the intent in their own code:

```cpp
#ifdef ASCENDC_CPU_DEBUG
    if ASCEND_IS_AIC {
        if (event == HardEvent::MTE2_V || event == HardEvent::V_MTE2 || event == HardEvent::MTE3_V ||
            event == HardEvent::V_MTE3 || event == HardEvent::V_V || event == HardEvent::S_V ||
...
            event == HardEvent::V_S) {
            return;
        }
    }
    if ASCEND_IS_AIV {
        if ((event == HardEvent::MTE2_MTE1) || (event == HardEvent::MTE1_MTE2) || (event == HardEvent::MTE1_M) ||
            (event == HardEvent::M_MTE1) || (event == HardEvent::M_FIX) || (event == HardEvent::FIX_M)) {
            return;
        }
    }
#endif
```

`SetFlagImpl` (`:910-1044`) has **neither** guard. It opens straight with the eventID assert and the switch,
and its `MTE2_V / V_MTE2 / MTE3_V / V_MTE3` cases, and its `M_V / V_M / MTE1_V / V_MTE1` cases, are compiled
unconditionally — the only `#if`s in its switch are around `V_V` (`!= 3002 || == 3003`), the `FIX_*` block
(2201 included), and `FIX_V`/`V_FIX` (5102 only). And the emitter itself is unguarded on 2201,
`impl/basic_api/kernel_event.h:299-316`:

```cpp
template <pipe_t srcPipe, pipe_t dstPipe>
__aicore__ inline void SetFlagInternal(event_t evt)
{
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 3510)
    if constexpr (IsSplitVectorPipe<srcPipe>() && IsSplitVectorPipe<dstPipe>()) {
        if ASCEND_IS_AIV {
            set_flag(srcPipe, dstPipe, evt);
        }
    }
    if constexpr (IsSplitCubePipe<srcPipe>() && IsSplitCubePipe<dstPipe>()) {
        if ASCEND_IS_AIC {
            set_flag(srcPipe, dstPipe, evt);
        }
    }
#else
    set_flag(srcPipe, dstPipe, evt);
#endif
}
```

The per-core `if constexpr` screen exists only for `__NPU_ARCH__ == 3510` (A5/950). **On 2201 the `#else`
fires and `set_flag` is emitted unconditionally.**

Two consequences, both exact and both silent:

1. **On the CUBE half of a 2201 mix kernel, `WaitFlag<HardEvent::MTE3_V>`, `V_MTE3`, `MTE2_V`, `V_MTE2`
   compile to `default: break;` — nothing — while the matching `SetFlag` emits a real
   `set_flag(PIPE_MTE3, PIPE_V, e)`.** The flag is raised and never consumed.
2. **`WaitFlag<HardEvent::M_V>`, `V_M`, `MTE1_V`, `V_MTE1` are compiled out on 2201 on BOTH halves** (the
   `__NPU_ARCH__ != 2201 && != 3510` gate), while their `SetFlag`s still fire. These four are the events that
   cross the AIC/AIV boundary, so they have no meaning on a split core — but the API accepts them and the Set
   half still runs.

There is no `static_assert`, no runtime log and no compile diagnostic for either. The only check is
`ASCENDC_DEBUG_ASSERT((evt < HardEvent::MAX))` in `AllocEventID`, and `MTE3_V < HardEvent::MAX` is true, so it
passes — and it is compiled out on NPU anyway. And the docs say precisely what an unpaired Set costs:

> SetFlag和WaitFlag必须成对使用，且SetFlag和WaitFlag的参数必须完全一致（包括模板参数和事件ID）。
> 如果不匹配，可能导致当前核的计算异常，或影响下一个核的算子执行，引发timeout问题。

### 43.6 ★ The event pool indexes one past its end for any foreign-core `HardEvent`

`EventToIndex` maps a `HardEvent` to a slot in `eventPool_`, `impl/basic_api/kernel_event.h:127-145,236-246`:

```cpp
#if defined(ASCENDC_CPU_DEBUG) || (defined(__NPU_ARCH__) && (__NPU_ARCH__ != 2201) && (__NPU_ARCH__ != 3510))
constexpr uint8_t EVENT_NUM = static_cast<uint8_t>(HardEvent::MAX);
#else
#ifdef SPLIT_CORE_CUBE
constexpr uint8_t EVENT_NUM = static_cast<uint8_t>(HardEventAic::MAX);
#else
constexpr uint8_t EVENT_NUM = static_cast<uint8_t>(HardEventAiv::MAX);
#endif
#endif
```

```cpp
__aicore__ constexpr uint8_t EventToIndex(HardEvent evt)
{
#if defined(ASCENDC_CPU_DEBUG) || \
    defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 5102) || ((__NPU_ARCH__ != 2201) && (__NPU_ARCH__ != 3510)))
    return static_cast<uint8_t>(evt);
#elif defined(SPLIT_CORE_CUBE)
    return EventToIndexAic(evt);
#else
    return EventToIndexAiv(evt);
#endif
}
```

and both mappers end with

```cpp
    } else {
        return static_cast<uint8_t>(HardEventAic::MAX);
    }
```
```cpp
    } else {
        return static_cast<uint8_t>(HardEventAiv::MAX);
    }
```

i.e. **an unmapped event returns exactly `EVENT_NUM`, one past the last valid slot of
`TEventPool eventPool_[EVENT_NUM]`.** The next member is `bufPool_[Hardware::MAX]`, and the two structs are
different sizes — `TEventPool` is one `uint64_t`, `TPipeBufPool` is one `uint32_t`
(`impl/basic_api/kernel_tpipe_base.h:103-109`) — so a `uint64_t` access at `eventPool_[EVENT_NUM]` straddles
`bufPool_[0]` and `bufPool_[1]`, which with

```cpp
enum class Hardware : uint8_t { GM, UB, L1, L0A, L0B, L0C, BIAS, FIXBUF, MAX };
```

(`impl/utils/common_types.h:23`) are **`bufPool_[Hardware::GM].maxAddr` and `bufPool_[Hardware::UB].maxAddr`** —
the UB allocator's high-water mark. `FetchEventID` reads there; `AllocEventID` writes there with `sbitset1`;
`ReleaseEventID` writes there with `sbitset0`. On 2201, `ASCENDC_CPU_DEBUG` builds take the
`EVENT_NUM = HardEvent::MAX` arm and `EventToIndex` becomes the identity, so **the out-of-range aliasing only
exists on the NPU build and cannot be reproduced under CPU debug.**

The out-of-range sets on 2201 are therefore:

- cube half (`SPLIT_CORE_CUBE`, `EVENT_NUM = 24`): `MTE2_V, V_MTE2, MTE3_V, V_MTE3, M_V, V_M, V_V, MTE1_V,
  V_MTE1, S_V, V_S` — eleven events, all aliasing slot 24.
- vector half (`SPLIT_CORE_VEC`, `EVENT_NUM = 13`): `MTE2_MTE1, MTE1_MTE2, MTE1_M, M_MTE1, M_V, V_M,
  MTE3_MTE1, MTE1_MTE3, MTE1_V, MTE2_M, M_MTE2, V_MTE1, M_FIX, FIX_M, MTE2_FIX, FIX_MTE2, FIX_S, M_S,
  FIX_MTE3, MTE1_FIX, FIX_MTE1, FIX_FIX` — twenty-two events, all aliasing slot 13.
- `M_V`, `V_M`, `MTE1_V`, `V_MTE1` alias out of range on **both** halves.

Note also that all aliased events share one slot, so two different out-of-range events hand back the *same*
id from `FetchEventID`.

### 43.7 `V_V` and `FIX_FIX` are not flags

`SetFlagImpl`/`WaitFlagImpl`, `impl/basic_api/kernel_event.h`:

```cpp
        case HardEvent::V_V:
            return;
```

and

```cpp
        case HardEvent::FIX_FIX:
            PipeBarrierInternal<PIPE_FIX>();
            break;
```

`V_V` is a no-op by design on every arch — consistent with 「PIPE_V由编译器自动完成同步插入」 — and `FIX_FIX`
is not a flag at all but a `PipeBarrier<PIPE_FIX>` wearing a `HardEvent`'s clothes.

### 43.8 An independent measurement of exactly this nondeterminism, and the warning it carries

"AccelSync: Verifying Synchronization Coverage in Accelerator Pipeline Programs", https://arxiv.org/html/2605.07881,
read 2026-10-20. It checks cross-unit write-read pairs for a happens-before path. Results, verbatim where
quoted:

> Across 6,292 CANN production kernels, 6,289 came back SAFE and 3 were flagged (0.048%).

| Kernel | Unit Pair | Violations | Missing Coverage |
|---|---|---|---|
| cross_v2 | VPU→scalar | 27 | V-to-S sync |
| quest_block_select_paged | MTE→VPU | 10 | MTE2-to-V sync |
| unique_consecutive_apt | scalar→VPU | 6 | "sync coverage under review" |

Corpus statistics: 5,618 kernels (89.3%) have at least one cross-unit write-read pair; 14,827 pairs checked;
4,291 (68.2%) use explicit pipe-drain APIs. Separately: 23/120 LLM-generated kernels unsafe (19.2%, CI
[13.0%, 27.4%]), dominant mode scalar↔MTE; 688/688 non-equivalent mutants detected; 5/5 microbenchmarks
detected versus msSanitizer's 2/5 at roughly 400× lower cost. Its `HardEvent`-level model is coarse — it
names only `HardEvent::V_S` and `HardEvent::MTE2_V`, never enumerates pairs, and **never mentions `PIPE_ALL`**,
treating "barrier" as "an abstract ordering primitive in the model, covering vendor pipe barriers, hard-event
synchronization, and equivalent frontend-normalized synchronization points… not necessarily the literal
Ascend C PipeBarrier API."

The part that matters to us is the hardware confirmation of the `cross_v2`-shaped hazard on Ascend 910B2 under
CANN 8.0.RC3:

> 30/30 correct with sync, but only 9/29 correct without, outputs ranging 336–1993 (nondeterministic).

and then:

> After a driver upgrade to 25.0.rc1.1, this vanished — the authors label it "observed but unconfirmed,"
> attributing the change to "a toolkit/driver compatibility issue rather than a fix."

## Relevance

43.1 is the authoritative answer and it reframes the question: `PipeBarrier` is the 单流水 primitive, defined
as 「阻塞相同流水」, and `SetFlag`/`WaitFlag` is the 多流水 primitive for 「不同流水线之间」. These are different
instruments, not a strength ordering, so no quantity of `PipeBarrier` — `PIPE_ALL` included — is defined to
cover a V→MTE3 or MTE3→V hazard on a reused UB buffer. 43.2 adds that `PIPE_ALL` is not in the documented
pipe set nor in the headers' `SUPPORTED_PIPE`, is used anyway by the vendor's own conformance tests, and is
flagged as an antipattern (`AKA3001`) by the Ascend checker, with a filed tilelang-ascend bug whose expected
fix is two distinct `set_flag`/`wait_flag` pairs. 43.3 gives the complete enumeration asked for, and the key
structural fact: the legal set is thirteen events on an AIV and twenty-four on an AIC, not the thirty-five in
`HardEvent`. 43.4 fixes the id budget at 0-7 per `HardEvent` kind and says exactly when loop reuse of one id
is safe — only for a Set…Wait pair that closes inside the iteration, because `FetchEventID` peeks without
claiming and will hand back the same id every time.

43.5 and 43.6 are the finding, and they are the reason the `V_MTE3`/`MTE3_V` attempt behaved the way it did.
In a `__mix__(1,2)` kernel the cube-half TU has `SPLIT_CORE_CUBE` defined, and on that half
`WaitFlag<HardEvent::MTE3_V>` compiles to `default: break;` — nothing at all — while `SetFlag<HardEvent::MTE3_V>`
still emits a real `set_flag`, because the per-core `if constexpr` screen in `SetFlagInternal` exists only for
`__NPU_ARCH__ == 3510` and 2201 takes the unguarded `#else`. The result is a raised, never-consumed hardware
flag, which is exactly the 「可能导致当前核的计算异常…引发timeout问题」 the docs warn about. Worse, on the same
half `FetchEventID(HardEvent::MTE3_V)` returns `EVENT_NUM` and indexes one past the end of
`TEventPool eventPool_[EVENT_NUM]`, landing on `bufPool_[Hardware::GM].maxAddr` and
`bufPool_[Hardware::UB].maxAddr` — the UB allocator's high-water mark — which `AllocEventID` then writes with
`sbitset1`. So the operational rule for our megakernel is: **any `SetFlag`/`WaitFlag`/`FetchEventID` naming a
vector event must be inside `if ASCEND_IS_AIV`, and any naming a cube event inside `if ASCEND_IS_AIC`; an
`__aicore__` helper shared by both halves must never name a `HardEvent` unguarded.** `M_V`, `V_M`, `MTE1_V`
and `V_MTE1` must never be named at all on 2201 — their Waits are compiled out on both halves and they alias
out of the pool on both halves.

43.6 also explains why this class of bug survives a CPU-debug run: on 2201, `ASCENDC_CPU_DEBUG` switches
`EVENT_NUM` to `HardEvent::MAX` and `EventToIndex` to the identity, so the out-of-range aliasing exists only
on the NPU build. The CPU-debug path additionally early-returns on foreign-core waits, so it also hides the
missing wait. A kernel that passes CPU debug is not cleared of either defect.

43.8 is the warning to carry: an independent group measured this exact failure shape — 9 of 29 runs correct,
nondeterministic garbage in between — and then watched it disappear on a driver bump without a fix, which
they call 「observed but unconfirmed」. A sync defect on this part can be masked by a toolkit or driver change.
Our 24-consecutive-clean-runs standard for the fused brick is the right bar, and it must be re-run after any
CANN or driver change rather than assumed to carry over.

## 44. ★ The vendor's two shipped `int4b_t` kernels, start to finish — and what they say about aliasing two int4 tensors over one allocation, and about the 950PR unzip tax

Source: `/home/shanshan/repo/cann/asc-devkit/examples/01_simd_cpp_api/06_compatibility_guide/matmul_s4/matmul_s4.asc`
and `.../04_advanced_api/00_matmul/matmul_int4/matmul_int4.asc`, with their READMEs. Read 2026-10-20.
Copyright header: "Copyright (c) 2025 Huawei Technologies Co., Ltd.", CANN Open Software License Agreement
Version 2.0. `matmul_s4` is the arch-compatibility sample and is the more informative of the two: it is a
`__mix__(1, 2)` kernel with `#define ASCENDC_CUBE_ONLY`, i.e. exactly our kernel shape, and it carries both the
A3 int4-native path and the 950PR/950DT unzip path behind `__NPU_ARCH__` guards.

### 44.1 ★ The vendor never holds two int4 tensors over one allocation — the unzip uses two distinct buffers

This is the direct answer to the question asked. `matmul_s4`'s `Init`, verbatim:

```cpp
    __aicore__ inline void Init(
        __gm__ uint8_t* a4GM, __gm__ uint8_t* b4GM, __gm__ uint8_t* aGM, __gm__ uint8_t* bGM, __gm__ uint8_t* cGM,
        __gm__ uint8_t* tilingGM, AscendC::TPipe* pipeIn)
    {
        pipe = pipeIn;
        CopyTiling(&tiling, tilingGM, pipe);
        cGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ typename C_TYPE::T*>(cGM), tiling.M * tiling.N);
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
        aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ typename A_TYPE::T*>(a4GM), tiling.M * tiling.Ka);
        bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ typename B_TYPE::T*>(b4GM), tiling.Kb * tiling.N);
#elif defined(__NPU_ARCH__) && (__NPU_ARCH__ == 3510)
        aGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ typename A_TYPE::T*>(aGM), tiling.M * tiling.Ka);
        a4Global.SetGlobalBuffer(reinterpret_cast<__gm__ int8_t*>(a4GM), tiling.M * tiling.Ka / 2);
        bGlobal.SetGlobalBuffer(reinterpret_cast<__gm__ typename B_TYPE::T*>(bGM), tiling.Kb * tiling.N);
        b4Global.SetGlobalBuffer(reinterpret_cast<__gm__ int8_t*>(b4GM), tiling.Kb * tiling.N / 2);
        pipe->InitBuffer(inQueueSrc, 1, sizeof(int8_t) * M * K);
        pipe->InitBuffer(tmpQueue, 1, sizeof(half) * M * K);
        pipe->InitBuffer(outQueueDst, 1, sizeof(int8_t) * M * K);
#endif
    }
```

`a4GM` and `aGM` are **separate kernel arguments bound to separate device allocations** — `main()` allocates
them independently with `a4InputByteSize = M * K * sizeof(int8_t) / 2` and
`aInputByteSize = M * K * sizeof(int8_t)` into `x4Device` and `xDevice`. The packed int4 and the unpacked int8
never share a block. The same holds in `matmul_int4.asc`: one `GlobalTensor` per kernel pointer, offsets applied
only as `aGlobal = aGlobal[offsetA]`.

So across both shipped int4 samples there is **no instance of two `GlobalTensor`s over one allocation for a
sub-byte type**, and therefore no sanctioned pattern for it and no sample to copy. That is a negative result,
not a prohibition — and §42.3's grep settles what it means: `SetGlobalBuffer` writes only `address_`,
`oriAddress_` and `bufferSize_`, all per-object members of that one `GlobalTensor`, and there is **no
per-allocation registry anywhere in the library**. The only case in which a second tensor can perturb the first
is `cacheMode_ != CACHE_MODE_NORMAL`, i.e. after `SetL2CacheHint`, where `SetGlobalBuffer` rewrites the stored
pointer through `L2CacheAlter<PrimType, CacheRwMode::RW>(buffer, cacheMode_)` instead of storing it as given.
Absent `SetL2CacheHint`, two `GlobalTensor`s over one allocation are completely independent objects as far as
AscendC is concerned, and the library cannot be the cause of one of them failing to land.

### 44.2 The two shipped `int4b_t` arch paths, verbatim

`Process()`, verbatim — note that on 2201 the vector half does nothing at all and there is no cross-core flag,
while on 3510 the vector half does the unzip and hands off with sync mode 4:

```cpp
    __aicore__ inline void Process()
    {
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
        if ASCEND_IS_AIC {
            RunMatmul();
        }
#elif defined(__NPU_ARCH__) && (__NPU_ARCH__ == 3510)
        if ASCEND_IS_AIV {
            Unzip(aGlobal, a4Global, tiling.M * tiling.Ka / 2);
            Unzip(bGlobal, b4Global, tiling.Kb * tiling.N / 2);
            AscendC::CrossCoreSetFlag<4, PIPE_MTE3>(8);
        }
        if ASCEND_IS_AIC {
            AscendC::CrossCoreWaitFlag<4, PIPE_MTE2>(8);
            RunMatmul();
        }
#endif
    }
```

`RunMatmul()`, verbatim — the Matmul object is constructed *inside* the function, per call, and
`SetSubBlockIdx(0)` is explicit:

```cpp
    __aicore__ inline void RunMatmul()
    {
        if (block_idx >= tiling.usedCoreNum) {
            return;
        }

        int offsetA = 0;
        int offsetB = 0;
        int offsetC = 0;
        CalcGMOffset<A_TYPE, B_TYPE, C_TYPE>(block_idx, tiling.usedCoreNum, tiling, offsetA, offsetB, offsetC);

        auto gmA = aGlobal[offsetA];
        auto gmB = bGlobal[offsetB];
        auto gmC = cGlobal[offsetC];

        AscendC::Matmul<A_TYPE, B_TYPE, C_TYPE, BIAS_TYPE, CFG_MDL> mm;
        mm.SetSubBlockIdx(0);
        mm.Init(&tiling, pipe);
        mm.SetTensorA(gmA, false);
        mm.SetTensorB(gmB, false);
        mm.IterateAll(gmC);
    }
```

the type bindings, verbatim — and note `CubeFormat::ND_ALIGN` for the int32 C and bias, not plain `ND`:

```cpp
template <int32_t M, int32_t N, int32_t K>
__global__ __mix__(1, 2) void matmul_s4(
    __gm__ uint8_t* a4GM, __gm__ uint8_t* b4GM, __gm__ uint8_t* aGM, __gm__ uint8_t* bGM, __gm__ uint8_t* cGM,
    __gm__ uint8_t* tilingGM)
{
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, AscendC::int4b_t, false> aType;
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, AscendC::int4b_t, false> bType;
#elif defined(__NPU_ARCH__) && (__NPU_ARCH__ == 3510)
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, int8_t, false> aType;
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND, int8_t, false> bType;
#endif
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 2201) || (__NPU_ARCH__ == 3510))
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND_ALIGN, int32_t> cType;
    typedef AscendC::MatmulType<AscendC::TPosition::GM, CubeFormat::ND_ALIGN, int32_t> biasType;
    AscendC::TPipe pipe;
    MatMulKernel<aType, bType, cType, biasType, M, N, K> op;
    op.Init(a4GM, b4GM, aGM, bGM, cGM, tilingGM, &pipe);
    op.Process();
#endif
}
```

and the build line from the README, verbatim:

```bash
cmake -DCMAKE_ASC_ARCHITECTURES=dav-2201 ..;make -j; # 默认npu模式
```

### 44.3 ★ The 950PR/950DT unzip, in full — and why it costs the whole W4 win

`Unzip`, verbatim and complete, with the vendor's own comment:

```cpp
    // int4 解压为 int8：搬运/计算阶段间用 EnQue/DeQue 衔接，自动完成 MTE2->V、V->MTE3 同步。
    __aicore__ inline void Unzip(
        AscendC::GlobalTensor<int8_t>& dstGlobalTensor, AscendC::GlobalTensor<int8_t>& srcGlobalTensor, uint32_t count)
    {
        AscendC::LocalTensor<int8_t> srcLocalTensor = inQueueSrc.AllocTensor<int8_t>();
        AscendC::DataCopy(srcLocalTensor, srcGlobalTensor, count);
        inQueueSrc.EnQue(srcLocalTensor);

        srcLocalTensor = inQueueSrc.DeQue<int8_t>();
        AscendC::LocalTensor<half> tmpTensor = tmpQueue.AllocTensor<half>();
        AscendC::LocalTensor<int8_t> dstLocalTensor = outQueueDst.AllocTensor<int8_t>();
        AscendC::LocalTensor<AscendC::int4b_t> int4SrcLocalTensor = srcLocalTensor.ReinterpretCast<AscendC::int4b_t>();
        AscendC::Cast<half, AscendC::int4b_t>(tmpTensor, int4SrcLocalTensor, AscendC::RoundMode::CAST_NONE, count * 2);
        AscendC::Cast<int8_t, half>(dstLocalTensor, tmpTensor, AscendC::RoundMode::CAST_CEIL, count * 2);
        outQueueDst.EnQue<int8_t>(dstLocalTensor);
        inQueueSrc.FreeTensor(srcLocalTensor);
        tmpQueue.FreeTensor(tmpTensor);

        dstLocalTensor = outQueueDst.DeQue<int8_t>();
        AscendC::DataCopy(dstGlobalTensor, dstLocalTensor, count * 2);
        outQueueDst.FreeTensor(dstLocalTensor);
    }
```

Read off the cost, with no figure needed because the structure decides it:

- **The unpacked int8 is written back to GM.** `DataCopy(dstGlobalTensor, dstLocalTensor, count * 2)` lands in
  `aGM`/`bGM`, a second allocation of twice the packed size, and the Cube then reads *that*. So on 950PR the
  weight crosses GM twice at **int8** width: the W4 memory footprint advantage at the point of consumption is
  zero. For a bandwidth-bound decode this is the entire win, gone.
- **Two full vector `Cast` passes over every weight element**, int4→half then half→int8, with no fused form —
  `Cast<half, int4b_t>` with `RoundMode::CAST_NONE` and `Cast<int8_t, half>` with `RoundMode::CAST_CEIL`.
- **UB must hold four bytes per element of the tile simultaneously**: `InitBuffer` reserves
  `sizeof(int8_t) * M * K` for the packed source, `sizeof(half) * M * K` for the intermediate, and
  `sizeof(int8_t) * M * K` for the unpacked destination — 1 + 2 + 1 bytes per unpacked element. At the sample's
  own M = K = 256 that is 256 KB of UB for A alone.
- **It runs per kernel invocation**, not once at load time: `Process()` calls `Unzip` on A and on B on every
  call, before `RunMatmul`.
- The handoff is `CrossCoreSetFlag<4, PIPE_MTE3>(8)` / `CrossCoreWaitFlag<4, PIPE_MTE2>(8)` — **sync mode 4,
  flagId 8**, which is the 3510-only mode (§3b). There is no 2201 equivalent in this sample because on 2201 the
  vector half has nothing to do.

Two useful side-facts in the same function. First, the packed int4 is handled by
`srcLocalTensor.ReinterpretCast<AscendC::int4b_t>()` **from a `LocalTensor<int8_t>`** — the canonical way to view
packed nibbles is a reinterpret of an int8 tensor, not a separately typed allocation, and the element count then
doubles (`count * 2`). Second, the vendor's own comment states the sanctioned intra-core sync idiom for exactly
the hazard §43 is about: 「搬运/计算阶段间用 EnQue/DeQue 衔接，**自动完成 MTE2->V、V->MTE3 同步**」 — `EnQue`/`DeQue`
on a `TQue` *is* the `SetFlag`/`WaitFlag` pair, inserted for you, and it is what the vendor writes instead of
naming `HardEvent`s by hand.

## Relevance

44.1 answers the aliasing question as far as the library can answer it, and the answer is that the library has
nothing to do with it: `SetGlobalBuffer` keeps no per-allocation state, so two `GlobalTensor<int4b_t>` over one
block are independent objects and AscendC cannot be making one of them fail. The only exception is
`SetL2CacheHint`, which makes `SetGlobalBuffer` store an *altered* pointer via `L2CacheAlter` rather than the
one passed — worth checking only if that call is present. The vendor's own int4 samples never alias two tensors
over one allocation, so there is no pattern to copy and no evidence either way that it is supported; the unzip
path deliberately uses two separate allocations for the packed and unpacked forms. Since the library is
exonerated, the remaining candidates are all outside it: another writer in the same kernel (a Matmul system
workspace, or an `ND_ALIGN` output footprint wider than the logical shape — the vendor uses `ND_ALIGN` for C,
not plain `ND`), the host-side binding of the two pointers, or the readback. The discriminating experiment is to
distinguish «never issued» from «issued then destroyed», which the present evidence cannot: have the kernel
itself read the 2048 values back from `+12288` at the very end — `DataCacheCleanAndInvalid` first, per §31 — into
a *separate* witness allocation. Right data in the witness and nothing in the allocation means the store landed
and something later overwrote it, and the hunt becomes «who else writes this block»; wrong data in the witness
means the store never happened, and §42.4's silent `else` arm is the place to look.

44.3 is the figure asked for on the 950PR int4 path, and the structure gives the answer without a measurement:
the sanctioned route materialises the unpacked int8 weight back into GM and the Cube reads that, so the W4
bandwidth advantage is zero at the point of consumption, on top of two vector `Cast` passes and 4 bytes of UB
per unpacked element, executed per kernel call. Any layer-fusion design that banks on the A3 int4 Cube path is
A3-only and does not carry to 950PR/950DT without re-deriving the weight path — the 950 answer is not «a bit
slower», it is «W4 stops being a memory optimisation». 44.2 is the shipped template for our own kernel shape:
a `__mix__(1,2)` `ASCENDC_CUBE_ONLY` kernel in which the 2201 path is `if ASCEND_IS_AIC { ... }` with the vector
half idle and no cross-core flag at all, which is both a confirmation of the §43 per-half guarding rule and a
reminder that on A3 a pure-int4 matmul needs no CV handshake whatsoever.

## 45. ★★★ The public `int4b_t` erratum: a found-and-fixed Ascend W4A4 defect whose root cause is `sizeof(int4b_t) == 1`, with the GM nibble-packing contract, the undocumented s4 transposing-load parameters, and three more sub-byte traps

Primary source: **https://github.com/tile-ai/tilelang-ascend/pull/1731** — "[Fix] gemm_v0: fix W4A4 int4xint4
GEMM producing wrong results (#438)" by `2Sheldonlaw`, state OPEN as of 2026-10-20, 630 additions / 23
deletions across 7 files. Fixes **https://github.com/tile-ai/tilelang-ascend/issues/438** — "[Bug] W4A4
int4×int4 GEMM produces incorrect results" by `Mocchibird`, opened 2026-02-05, environment "TileLang version:
ascendc_pto / Ascend CANN version: 8.5.0 / Hardware: Ascend 910B". Validated by the PR on **Ascend910 / CANN
9.0.0**. Read 2026-10-20 via `gh`.

Secondary: https://github.com/tile-ai/tilelang/issues/3391 — "[BUG][Ascend] T.copy from an FP4 view with an
odd source offset floors to the wrong byte"; https://github.com/tile-ai/tilelang/issues/2963 —
"[BUG][Fuzzer][wrong-code] `T.copy` of a packed sub-byte buffer (`int4`/`uint4`/`float4_e2m1fn`) silently drops
~half the elements via a non-atomic cross-thread byte read-modify-write" (CUDA path, included because the
mechanism is the same); https://gitcode.com/cann/pto-isa/issues/115.

This is the closest public analogue to our own int4 defect, it is on the same part, and its root cause is
exactly the hazard §42.1 identified from the headers. The whole root-cause section is reproduced verbatim.

### 45.1 The root cause, verbatim

> ## 根因
>
> W4A4（int4×int4→int32）GEMM 结果错误的根源：整个 C++ 模板栈都用 `sizeof(AscendC::int4b_t) == 1` 推导分形几何，
> 但 `int4b_t` 是**半字节打包类型**（每元素 4 bit，每字节装 2 个元素）。32 字节 C0 块的正确元素数是 **64 而非 32**
> ——于是所有拷贝 stride、repeat 次数、字节计算全部 2× 偏差。三层搬运错误叠加：
>
> 1. **分形几何 2× 偏差**：L1→L0A/L0B 的 LoadData 参数（repeatTimes、srcStride、dstGap）由 sizeof 推导的常数
>    计算——数据在 L0A/L0B 内堆叠到了错误的位置。
>
> 2. **B 的转置加载被静默丢弃**：通用 `LoadData` 路径对 zN→nZ 的 B 操作数加载设置 `ifTranspose=true`，但 s4 专用
>    指令 `load_cbuf_to_cb_s4` **硬编码关闭转置**并静默忽略该标志——B 永远得不到 `mad_s4` 期望的 nZ 布局。正确
>    路径是 `LoadDataWithTranspose` → `load_cbuf_to_cb_transpose_s4`，其参数语义在 CANN 头文件中**没有任何文档**，
>    只能用探针 kernel 在设备上**实测逆向**（一次 repeat 搬运完整 64K×64N 块；正确参数：
>    `repeatTimes=N/64, srcStride=roundUp16(K)/64, dstGap=3`）。⚠️ 通用 `LoadDataWithTranspose` 文档标注
>    stride/repeat 单位为 512B fractal，但 s4 版本实际按 **2048B 块**工作——文档单位不适用于 s4。
>
> 3. **UB↔GM 字节计数 2× 偏差**：`DataCopyExtParams` 的字节长度按每元素 `sizeof(T)=1` 计算而非 0.5 → 每行拷贝
>    长度 2× 过长，混入相邻行数据（量化 kernel 的输出）。内存规划同样按 2× 分配 buffer（浪费但安全）。
>
> 计算指令 `mad_s4` 本身始终正确——它忠实地把摆错的数据相乘，产生量级正常但数值完全错误的结果（issue 症状：
> 99.6% 不匹配，输出 -501/627 而正确值是 641/1785）。
>
> **错误 1 和 3 同源**：`sizeof(int4b_t) == 1` 谎报了每元素 0.5 字节的真实密度——在 Cube 侧毒害分形几何（错误 1），
> 在 Vector 侧毒害字节计数（错误 3）。错误 2 是独立的派发缺陷（s4 wrapper 静默丢弃转置标志）。

### 45.2 ★ The GM int4 packing contract, stated as an interface contract and cross-checked against CANN's own A4W4

Verbatim:

> **GM int4 打包约定**（消费量化 kernel 输出或喂 int4 输入的接口契约）：每字节两个 nibble，**低 nibble = 偶数元素，
> 高 nibble = 奇数元素**；(M, N) tensor 的第 r 行起始于字节 `r * N / 2`。与 CANN 自家的 A4W4 ND 格式
> （`grouped_matmul_swiglu_quant_v2`）一致。

and from the guide the PR adds, verbatim:

> `int4` 为半字节打包类型（两个元素共享一个字节，低 nibble 为偶数元素），GM 上的 int4 …

So: **low nibble = even element index, high nibble = odd element index, and row r of an (M, N) tensor begins at
byte `r * N / 2`.** The PR states this agrees with CANN's own A4W4 ND layout in
`grouped_matmul_swiglu_quant_v2`, which makes it the de facto contract for anything consuming or producing int4
in GM on this part.

### 45.3 ★ An odd contiguous dimension silently truncates — and the validator written to catch it

From the PR's new `ValidateInt4BufferPacking`, verbatim from the diff:

```cpp
// int4 is nibble-packed (two elements per byte, low nibble = even element):
// ... lengths (floor division in EleNumToBytes) silently truncate the last
// ...
static void ValidateInt4BufferPacking(const PrimFunc &f) {
  ...
          << "int4 buffer '" << name << "' has an odd contiguous dimension ("
          ...
          << "): int4 is nibble-packed (two elements per byte), "
```

The shape constraint the PR documents, verbatim:

> 4. **形状约束**：int4 GEMM 要求 K 和 N 为 64 的倍数（一个 s4 C0 块）；example 中有断言。

**K and N must be multiples of 64** — one s4 C0 block, which is the same 64 as `ONE_BLK_FP4_NUM = 64`
(§42.5). And an odd contiguous dimension is floor-divided and silently loses the last element, with no
diagnostic in the library.

### 45.4 The bit-width-aware helpers, as written — the shape of the fix

Verbatim from the diff, `src/tl_templates/ascend/common.h`:

```cpp
// ... width, NOT sizeof(): int4b_t has sizeof == 1 but only occupies 4 bits (two
// ... fractal layouts), so any geometry derived from sizeof() is 2x off for int4.
template <typename T> CATLASS_DEVICE constexpr uint32_t ElementSizeBits() {
  if constexpr (std::is_same_v<T, int4b_t>) {
  ...
}

// Elements of T that fit in one 32-byte C0 block (64 for int4b_t).
template <typename T> CATLASS_DEVICE constexpr uint32_t EleNumPerC0() {
  return BYTE_PER_C0 * 8 / ElementSizeBits<T>();
}

// Elements of T that fit in one 512-byte fractal (1024 for int4b_t).
template <typename T> CATLASS_DEVICE constexpr uint32_t EleNumPerFractal() {
  return BYTE_PER_FRCATLASSAL * 8 / ElementSizeBits<T>();
}

template <typename T>
CATLASS_DEVICE constexpr uint64_t EleNumToBytes(uint64_t n) {
  return n * ElementSizeBits<T>() / 8;
}
```

and the PR's own note on why this is safe to apply everywhere, verbatim:

> ① 位宽感知工具（`ElementSizeBits` / `EleNumPerC0` / `EleNumPerFractal` / `EleNumToBytes`）——**对所有非
> sub-byte dtype 与旧 sizeof 数学数值完全一致**

### 45.5 ★ A unit inconsistency inside one API family: GM→L1 Nd2Nz of int4 takes `dValue`/`srcDValue` in BYTES

Verbatim from the diff comment on the `copy_gm_to_l1` int4 branch:

```cpp
  if constexpr (std::is_same_v<T, int4b_t>) {
    // int4 GM -> L1 (Nd2Nz into the zN fractal layout), calling the AscendC
    // ... from sizeof(T) and has no int4 support. The CCE intrinsic behind this
    // DataCopy reinterprets int4b_t as int8_t (b8 path), so dValue /
    // srcDValue are in BYTES ...
```

So within the same `DataCopy` family, the Level-2 `count` form is in **elements** (§42.5, divided by
`ONE_BLK_FP4_NUM = 64`) while the `Nd2NzParams` form's `dValue`/`srcDValue` are in **bytes**, because the
underlying CCE intrinsic reinterprets `int4b_t` as `int8_t`. There is no diagnostic for mixing them.

### 45.6 ★ The reverse-engineered s4 transposing-load parameters, with the doc-unit warning

Verbatim from the diff — the only public statement of these semantics, obtained by device probing because the
CANN headers document nothing:

```cpp
    // int4 (W4A4) L1(zN) -> L0B(nZ) via the s4 transposing load, calling the
    // AscendC intrinsic directly: the generic LoadData path dispatches to
    // load_cbuf_to_cb_s4 which hardcodes transpose OFF and silently drops the
    // ifTranspose flag, so B never receives the nZ layout mad_s4 expects.
    static_assert(!transpose,
                  "int4 (W4A4) does not support transpose_B: the s4 L1->L0B "
                  "transposing load requires a zN source layout");
    // s4 transposing-load semantics (measured on dav_c220 / Ascend 910B; the
    // generic LoadDataWithTranspose documents 512B-fractal units, but the s4
    // variant does NOT follow them):
    //   - one repeat moves a whole 64K x 64N nibble block (2048B): it reads
    //     the four consecutive 512B zN row-fractals of one K-64 band and
    //     writes 64 complete nZ N-columns (16 fractals) to L0B;
    //   - srcStride steps the source between repeats in 2048B blocks, so one
    //     N-C0 block (64 columns) needs srcStride = roundUp16(K) / 64, where
    //     K is the FULL L1 tile depth (template srcM) because the zN buffer
    //     is allocated for the whole tile;
    //   - dstGap advances the destination by (1 + dstGap) nZ N-fractals (16
    //     columns each), so 64 columns per repeat needs dstGap = 3.
    AscendC::LoadData2dTransposeParams loadDataParams;
    loadDataParams.startIndex = 0;
    loadDataParams.repeatTimes = (dstN + 63) / 64;
    loadDataParams.srcStride = ((srcM + 15) / 16 * 16) / 64;
    loadDataParams.dstGap = 3;
    loadDataParams.dstFracGap = 0;
    loadDataParams.addrMode = 0;
    // One LoadDataWithTranspose per K-C0 block (64 K elements). Block stride:
    // 2048B (4 fractals) in the zN source; roundUp16(N) x 64 elements in the
    // nZ destination (64 K rows spanning the whole N extent).
    const uint32_t kBlocks = (dstM + 63) / 64;
    const uint32_t dstKBlockStride = ((dstN + 15) / 16 * 16) * 64;
    const uint32_t srcKBlockStride = 4 * EleNumPerFractal<T>();
    for (uint32_t b = 0; b < kBlocks; b++) {
      AscendC::LoadDataWithTranspose(dstTensor[b * dstKBlockStride],
                                     srcTensor[b * srcKBlockStride],
                                     loadDataParams);
    }
```

and the matching L0A `static_assert`, verbatim:

```cpp
    static_assert(!transpose,
                  "int4 (W4A4) does not support transpose_A: the s4 L1->L0A "
```

This is the mechanism behind the official README's bare constraint
「左矩阵A为int4数据类型时，不支持转置」 (§42.7): there is no L0A transpose mode in the s4 instruction set at all,
and B's transposing load needs a zN source.

### 45.7 ★ `torch.int4` is UNPACKED — a documented 2× host/device mismatch

Verbatim from the PR's known-limitations list:

> 1. **torch.int4 互操作**：`torch.int4` 是**非打包** dtype（存储中每元素 1 字节），而 tilelang kernel 使用**打包**
>    约定（每字节 2 元素）。纯 tilelang 链路（quant→matmul）可正常工作（buffer 大 2×，仅使用前半部分）。经 torch
>    外部输入的 int4 tensor 需要显式打包——见测试辅助函数。完整的 `adapt_torch2tvm` 打包桥接留作 follow-up。

So a `torch.int4` tensor is one byte per element, while the device contract is two elements per byte. A buffer
sized from the torch view is **2× too large and only its first half is used**. Any host-side readback or golden
that indexes with the torch convention is off by a factor of two in where it looks.

### 45.8 `pto` has no int4 instructions at all

Verbatim:

> **附带 bug（pto target）**：`target="pto"` 以一句裸的 `Unsupported datatype` 失败，原因是 pto-isa 缺少全部 int4
> 指令（`mad_s4`、`vconv_f162s4`、`vconv_s42f16`）——见 [cann/pto-isa#115](https://gitcode.com/cann/pto-isa/issues/115)。
> 这是上游限制

> 3. **pto target**：在 pto-isa 添加 `mad_s4` / `vconv_f162s4` / `vconv_s42f16` 之前无法支持 int4
>    （[cann/pto-isa#115](https://gitcode.com/cann/pto-isa/issues/115)，官方确认"在需求计划中"）。

Note the instruction names: the int4 conversion intrinsics are `vconv_f162s4` and `vconv_s42f16`, i.e. the
`Cast<int4b_t, half>` / `Cast<half, int4b_t>` pair of §44.3, and there is no int4↔float32 or int4↔int8 direct
conversion in the list.

### 45.9 The reported symptom, and the PR's test results

The issue's symptom, verbatim:

> NPU Kernel tensor([
>         [ -501,    26,   627,  1182],
>         [-1382,  1544,  -840,    78],
>         ...
> Reference tensor([
>         [  641,  1785,   665,   871],
>         [ -111,   735, -1332,  -442],
>         ...

and the reproduction's own calibration note, verbatim:

```python
    # Integer-valued fp16 in [-8, 7] (the full int4 range) so that CAST_RINT
    # quantization is lossless and the int4 matmul is exact.
```

The PR's results table, verbatim:

> | 验证项 | 结果 |
> |---|---|
> | Issue 复现（1024³，quant + matmul 端到端） | **通过**（0 mismatch，原为 99.6%） |
> | 新示例 `examples/w4a4_matmul/`（默认 1024³） | 通过 |
> | 新增 10 个 int4 回归测试 | 10/10 |
> | 既有 gemm_v0 套件（fp16 precision/transpose、int8 kL0split、n_tiling、n_actual） | 48/48（含 int4 共 58） |
> | 既有 l1_to_l0 + gm_to_ub + cast_on_copy | 263/263 |
> | 既有 elementwise | 492/492 + 2 xfailed |

### 45.10 Two sibling sub-byte defects, for the pattern

https://github.com/tile-ai/tilelang/issues/3391 — "[BUG][Ascend] `T.copy` from an FP4 view with an **odd source
offset** floors to the wrong byte": on the Ascend GM→L1 MTE path, copying a byte-backed FP4 view from an odd
logical element offset addresses the **preceding** byte and selects the wrong values, because the storage-byte
helper uses floor division on the logical offset and the GM→L1 branch emits the transfer as `int8_t` with a
packed-byte inner extent; odd row strides are likewise rounded **up** to integer byte strides. This is the same
`offset / 2` floor as `GlobalTensor<int4b_t>::operator[]` (§42.2), reported as a defect in a different compiler.

https://github.com/tile-ai/tilelang/issues/2963 — "`T.copy` of a packed sub-byte buffer
(`int4`/`uint4`/`float4_e2m1fn`) **silently drops ~half the elements** via a non-atomic cross-thread byte
read-modify-write": per-logical-element stores with no sub-byte awareness lower to non-atomic byte
read-modify-write packed stores, so concurrent writers to the two nibbles of one byte lose one of them. This is
the CUDA path, but it is the same shape as AscendC's own `GlobalTensor<int4b_t>::SetValue`, which is a
read-modify-write of one byte:

```cpp
    if constexpr (IsHalfByteDataType<PrimType>()) {
        ...
        uint8_t val = (*addr) & mask;
        uint8_t shift = (offset % INT4_TWO == 0) ? 0 : INT4_BIT_NUM;
        *addr = val + (value.storage << shift);
```

(`impl/basic_api/kernel_tensor_impl.h`, the 2201 arm). Two agents writing the two nibbles of one byte through
`SetValue` lose one of them, and the official `SetValue` page's own rule compounds it, verbatim:

> SetValue 首先修改每个 AI Core 内部的 Data Cache，不会立即写出到 Global Memory，后续写出以 CacheLine（64B）
> 为单位进行。… 多核操作 GM 地址时，不同核涉及的地址（由 offset 元素参数决定）之间至少要相隔一个 CacheLine，
> 否则会出现跨核数据随机覆盖，同时需要考虑 64B 地址对齐。

(https://www.hiascend.com/document/detail/zh/CANNCommunityEdition/82RC1alpha001/API/ascendcopapi/atlasascendc_api_07_00028.html,
CANN 社区版 8.2.RC1.alpha001.) The forcing fix is a `DataCacheCleanAndInvalid` after the `SetValue`.

## Relevance

45.1 is the erratum asked for, and it is on our part: a real, reproduced, fixed W4A4 defect on Ascend 910B whose
single root cause is the one §42.1 derived from the headers — `sizeof(int4b_t) == 1` lying about a 0.5-byte
element, poisoning fractal geometry on the Cube side and byte counts on the Vector side with a uniform factor of
two. The authors' own summary of the failure mode is worth memorising: 「`mad_s4` 本身始终正确——它忠实地把摆错的
数据相乘，产生量级正常但数值完全错误的结果」. A plausible-magnitude wrong answer, not a crash, and 99.6%
mismatch.

Four items bear directly on our live defect. 45.2 gives the packing contract we must match and it is
nibble-indexed with **low nibble = even element and row r at byte `r*N/2`**, agreeing with CANN's own A4W4 ND
format — so if our 2048-element span is one row of a wider tensor, its byte start is `r*N/2` and not
`r*stride`. 45.3 says K and N must be multiples of 64 and that an odd contiguous dimension is floor-divided and
silently loses its last element with no diagnostic. 45.5 is the unit inconsistency inside one API family: the
Level-2 `DataCopy(gm, ub, count)` form counts **elements**, while `Nd2NzParams`'s `dValue`/`srcDValue` count
**bytes**, because the CCE intrinsic reinterprets `int4b_t` as `int8_t` — mixing them is a silent 2×. And 45.7
is the one that is not in our elimination list at all: `torch.int4` is **unpacked**, one byte per element, so a
buffer sized or indexed from a torch view is 2× too large and only its first half carries data. Our offset
12288 elements is byte 6144; a host that indexes bytes where elements are meant looks at byte 12288 instead,
which in a 49152-byte allocation is a perfectly valid, zeroed address — and the symptom of that is exactly
«lands at offset 0, never lands at 12288», because at offset 0 the two conventions agree. **The readback is the
one thing the elimination list does not cover, and this is a documented, known, factor-of-two way for it to be
wrong.** Worth one print of the raw bytes at both 6144 and 12288 before anything else.

45.6 matters the moment we transpose: `load_cbuf_to_cb_s4` **hardcodes transpose off and silently drops the
`ifTranspose` flag**, so a transposed int4 B load through the generic `LoadData` path produces no error and the
wrong layout. The sanctioned route is `LoadDataWithTranspose` → `load_cbuf_to_cb_transpose_s4`, whose parameter
semantics are undocumented in the CANN headers and had to be measured on-device, and whose units are 2048-byte
blocks rather than the documented 512-byte fractals. That is the mechanism behind the official README's bare
「左矩阵A为int4数据类型时，不支持转置」 (§42.7), and it means our weight layout must be prepared so that no int4
transpose is ever requested. 45.8 records that `pto` cannot compile int4 at all until `mad_s4`,
`vconv_f162s4` and `vconv_s42f16` are added (cann/pto-isa#115, officially 「在需求计划中」), which closes the
`pto` route for our W4A8 work and names the only two int4 conversion intrinsics that exist — int4↔half, with no
direct int4↔float32 or int4↔int8.

## 46. ★ The mechanical `PipeBarrier<PIPE_ALL>` → `HardEvent` conversion table, as the library itself computes it — `GetQueEvt`

Source: `/home/shanshan/repo/cann/asc-devkit/impl/basic_api/kernel_event.h:540-670`. Read 2026-10-20.

This exists because a `PipeBarrier<PIPE_ALL>` site is only ever standing in for a specific pipe pair, and
AscendC already contains the function that names it. `GetQueEvt` is what `TQue`/`TQueBind` use to decide which
`HardEvent` an `EnQue`/`DeQue` pair compiles into: `TQueConfig` holds
`static constexpr HardEvent freeBufEvt = GetQueEvt(srcHardType, dstHardType, false, 0, 0);`
(`impl/basic_api/kernel_tpipe_base.h:284`) and the enqueue event is the same call with `fwdDirect = true`.
So the table below is not advice; it is the library's own choice, and converting a barrier site means reading
off the row for the movement that site is protecting.

### 46.1 The function, verbatim and complete (the arch-dependent `L0C` tail trimmed to the 2201 arm)

```cpp
__aicore__ constexpr HardEvent GetQueEvt(
    Hardware src, Hardware dst, bool fwdDirect, bool nd2nz = false, bool nz2nd = false)
{
    (void)(nz2nd);
    ASSERT(
        (src == Hardware::GM) || (src == Hardware::UB) || (src == Hardware::L1) || (src == Hardware::L0A) ||
        (src == Hardware::L0B) || (src == Hardware::L0C));
    ASSERT(src != Hardware::MAX);
    ASSERT(dst != Hardware::MAX);
    if (src == Hardware::GM) { // MTE2
        ASSERT(dst != Hardware::GM);
        ASSERT(dst != Hardware::L0C);
        ASSERT(dst != Hardware::BIAS);
        ASSERT(dst != Hardware::FIXBUF);
        if (dst == Hardware::UB) { // MTE3
            return fwdDirect ? HardEvent::MTE2_V : HardEvent::V_MTE2;
        } else if (dst == Hardware::L1) { // MTE1
            ...
            return fwdDirect ? HardEvent::MTE2_MTE1 : HardEvent::MTE1_MTE2;
        } else if (dst == Hardware::L0A) {
            return fwdDirect ? HardEvent::MTE2_M : HardEvent::M_MTE2;
        } else if (dst == Hardware::L0B) {
            return fwdDirect ? HardEvent::MTE2_M : HardEvent::M_MTE2;
        }
    } else if (src == Hardware::UB) { // MTE3
        ASSERT(dst != Hardware::L0A);
        ASSERT(dst != Hardware::L0B);
        ASSERT(dst != Hardware::BIAS);
        ASSERT(dst != Hardware::FIXBUF);
        if (dst == Hardware::GM) {
            return fwdDirect ? HardEvent::V_MTE3 : HardEvent::MTE3_V;
        } else if (dst == Hardware::L1) { // MTE1
            return fwdDirect ? HardEvent::MTE3_MTE1 : HardEvent::MTE1_MTE3;
        } else if (dst == Hardware::L0C) {
            return fwdDirect ? HardEvent::V_V : HardEvent::MAX; // HardEvent::M_V
        } else if (dst == Hardware::UB) {
            return fwdDirect ? HardEvent::MTE2_MTE3 : HardEvent::MTE3_MTE2;
        }
    } else if (src == Hardware::L1) { // MTE1
        ASSERT(dst != Hardware::GM);
        ASSERT(dst != Hardware::L1);
        ASSERT(dst != Hardware::L0C);
        if (dst == Hardware::UB) {
            return fwdDirect ? HardEvent::MTE1_V : HardEvent::V_MTE1;
        } else if (dst == Hardware::L0A) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        } else if (dst == Hardware::L0B) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        } else if (dst == Hardware::FIXBUF) {
            return fwdDirect ? HardEvent::MTE1_FIX : HardEvent::FIX_MTE1;
        } else if (dst == Hardware::BIAS) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        }
    } else if (src == Hardware::L0A) {
        ASSERT(dst == Hardware::L0C);
        return fwdDirect ? HardEvent::M_V : HardEvent::V_M;
    } else if (src == Hardware::L0B) {
        ASSERT(dst == Hardware::L0C);
        return fwdDirect ? HardEvent::M_V : HardEvent::V_M;
#elif defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 2201) || (__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102))
    } else if (src == Hardware::L0C) {
        ASSERT(dst == Hardware::GM);
        return fwdDirect ? HardEvent::M_FIX : HardEvent::FIX_M;
    }
#endif
    return HardEvent::MAX;
}
```

and the `TPosition` overload, which special-cases the Matmul logical positions before delegating:

```cpp
__aicore__ constexpr HardEvent GetQueEvt(TPosition src, TPosition dst, bool fwdDirect)
{
    if (src == TPosition::GM) { // MTE2
        if (dst == TPosition::A1 || dst == TPosition::A2 || dst == TPosition::B2) {
            return fwdDirect ? HardEvent::MTE2_M : HardEvent::M_MTE2;
        } else if (dst == TPosition::B1 || dst == TPosition::C1) {
            return fwdDirect ? HardEvent::MTE2_MTE1 : HardEvent::MTE1_MTE2;
        }
    } else if (src == TPosition::A1) {
        if (dst == TPosition::A2) {
            return fwdDirect ? HardEvent::MTE2_M : HardEvent::M_MTE2;
        }
    } else if (src == TPosition::B1) {
        if (dst == TPosition::B2) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        } else if (dst == TPosition::C2PIPE2GM) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        }
    } else if (src == TPosition::C1) {
        if (dst == TPosition::C2) {
            return fwdDirect ? HardEvent::MTE1_M : HardEvent::M_MTE1;
        }
    }
    return GetQueEvt(GetPhyType(src), GetPhyType(dst), fwdDirect, false, false);
}
```

### 46.2 The table, read off the function

`fwdDirect = true` is the producer→consumer direction (the `EnQue`, "data is ready"); `fwdDirect = false` is the
consumer→producer direction (the `FreeTensor`/`DeQue`, "the buffer may be refilled"). **Both halves of a reused
staging buffer need a row.**

| Movement | ready (fwd) | buffer-free (rev) |
| --- | --- | --- |
| GM → UB (`DataCopy` in) | `MTE2_V` | `V_MTE2` |
| GM → L1 | `MTE2_MTE1` | `MTE1_MTE2` |
| GM → L0A / GM → L0B | `MTE2_M` | `M_MTE2` |
| **UB → GM** (`DataCopy` out) | **`V_MTE3`** | **`MTE3_V`** |
| UB → L1 | `MTE3_MTE1` | `MTE1_MTE3` |
| UB → UB | `MTE2_MTE3` | `MTE3_MTE2` |
| L1 → UB | `MTE1_V` | `V_MTE1` |
| L1 → L0A / L1 → L0B / L1 → BiasTable | `MTE1_M` | `M_MTE1` |
| L1 → FIXBUF | `MTE1_FIX` | `FIX_MTE1` |
| L0A → L0C / L0B → L0C (`Mmad`) | `M_V` | `V_M` |
| **L0C → GM (Fixpipe), on 2201** | **`M_FIX`** | **`FIX_M`** |
| UB → L0C | `V_V` (a no-op) | `HardEvent::MAX` (a no-op) |

### 46.3 ★ Three things the table says that are not obvious

1. **`UB → GM` is `V_MTE3` forward and `MTE3_V` reverse — and the reverse row is the one a reused staging
   buffer needs.** The forward row says "the vector writes are done, the store may start". The reverse row says
   "the store has drained, the buffer may be overwritten". A function that `Cast`s into a staging buffer,
   `DataCopy`s it out, and is then called again through the same buffer needs **`MTE3_V`** on entry (or
   `V_MTE3`/`MTE3_V` as a pair around the reuse), which is precisely the idiom the vllm-ascend attention PR
   uses: `SetFlag<HardEvent::MTE3_V>(event); WaitFlag<HardEvent::MTE3_V>(event);` placed after the
   `DataCopyPad` out and before `outQue_.FreeTensor(out)`
   (https://github.com/vllm-project/vllm-ascend/pull/17617, "[Feat][Kimi-K3] Migrate attention residual
   operators to AscendC on A3").
2. **`L0A/L0B → L0C` resolves to `M_V` / `V_M`, which §43.5 showed are compiled out of `WaitFlagImpl` on
   2201 on *both* halves.** So on this part the library's own answer for the `Mmad`→L0C dependency is an event
   whose Wait does nothing — consistent with the hardware handling it, and with `L0C → GM` being `M_FIX`/`FIX_M`
   instead. Do not hand-write `M_V` expecting it to do something. Likewise `UB → L0C` returns `V_V` forward,
   itself a documented no-op (§43.7), and `HardEvent::MAX` reverse, with the intended `M_V` sitting
   commented out in the source.
3. **The `L0C` arm's own `ASSERT` on 2201 is `dst == Hardware::GM`, and nothing else.** No UB, no L1 — a third
   independent confirmation of §35.4's finding that A3 has no `L0C → UB` and no `L0C → L1` path, this time from
   the library's internal assertion rather than from an API page's 「不支持」.

### 46.4 The checker that flags the pattern, and the filed bug

`PipeBarrier<PIPE_ALL>` is flagged by the Ascend static-analysis checker as rule
**`AKA3001 "PipeBarrier(PIPE_ALL) antipattern"`, severity Warning.** The reasoning given in the Huawei Cloud
performance guide 「Ascend C算子性能优化实用技巧05——API使用优化」
(https://bbs.huaweicloud.com/blogs/438903) is that fine-grained event synchronization blocks only the
dependency chain while a barrier stalls unrelated instructions on the same pipe, and that each `PipeBarrier` or
`WaitFlag` costs a pipeline bubble.

The matching filed bug is https://github.com/tile-ai/tilelang-ascend/issues/110 — "In double buffer scenarios,
using the automatic synchronization insertion feature, the generated AscendC code does not meet expectations,
using `AscendC::PipeBarrier<PIPE_ALL>()`" — whose stated expected behaviour is **two `set_flag`/`wait_flag`
pairs on two distinct flag ids** rather than a full-pipe barrier. That issue also names the classic failure of
the conversion, worth writing down before doing 66 of them: a loop-carried `WaitFlag` that is not primed before
the loop makes iteration 0 wait on a flag only the previous iteration would raise, which is the commonest
deadlock in double buffering; and a `SetFlag` without its `WaitFlag` (or the reverse) leaks the event slot or
blocks permanently, with an unbalanced pair inside a loop body drifting the count once per iteration.

## Relevance

This is the conversion table for the 66 `PipeBarrier<PIPE_ALL>` sites, and it is the library's own, so there is
no judgement in applying it: find the movement each barrier protects, read the row, and write the pair. Three
rules make the conversion safe rather than mechanical-and-wrong. First, a reused staging buffer needs the
**reverse** row, not the forward one — `MTE3_V` for a UB buffer that a store is still draining, which is the
row the vllm-ascend attention PR uses and the row §43 showed is a silent no-op if the code also compiles into
the cube half. Second, three rows are no-ops on 2201 and must not be relied on: `M_V`/`V_M` for `Mmad`→L0C
(compiled out of `WaitFlagImpl` on both halves), `V_V` for UB→L0C, and `HardEvent::MAX` for its reverse. Third,
the `L0C` arm asserts `dst == Hardware::GM` on 2201 and nothing else, so any design that wants a cube result in
UB must route it through GM and the `M_FIX`/`FIX_M` pair.

The cheaper alternative is §44.3's: let a `TQue` do it. `EnQue`/`DeQue` *is* this table applied automatically —
`TQueConfig::freeBufEvt = GetQueEvt(srcHardType, dstHardType, false, 0, 0)` — and the vendor's own int4 sample
says so in a comment: 「搬运/计算阶段间用 EnQue/DeQue 衔接，自动完成 MTE2->V、V->MTE3 同步」. Staging a kernel's
phases through `TQue`s removes the hand-allocation of event ids, removes the per-half guarding question, and
removes the unspecified-behaviour exposure that §43.2 and `AKA3001` identify — at the cost of restructuring the
kernel around queue positions rather than raw `LocalTensor`s.

## 47. ★★★ `Cast` is AIC-guarded and plain `DataCopy` to GM is NOT — a `Cast → Cast → DataCopy(GM)` function compiled into both halves of a MIX kernel has a second, uncoordinated writer

Source: the shipped AscendC implementation, `/home/shanshan/repo/cann/asc-devkit/`. Read 2026-10-20.
This is the same tree as §42-§46 and the finding is a two-line difference between two functions in it.

### 47.1 Every `Cast` on 2201 is wrapped in `if ASCEND_IS_AIV` and does nothing on the cube half

`impl/basic_api/dav_c220/kernel_operator_vec_vconv_impl.h:993-1021`, the Level-2 (count-mode) `Cast`, verbatim
and complete:

```cpp
// Cast::Level 2
template <typename T, typename U>
__aicore__ inline void CastImpl(__ubuf__ T* dst, __ubuf__ U* src, const RoundMode& roundMode, const uint32_t count)
{
    if ASCEND_IS_AIV {
        CheckCastDatatype<T, U>();
        set_mask_count();
        set_vector_mask(0, count);
        if constexpr (sizeof(T) > sizeof(U)) {
            if constexpr (IsSameType<U, int4b_t>::value) {
                CastIntrinsicsImpl(
                    dst, src, roundMode, 1, {1, 1, DEFAULT_REPEAT_STRIDE, ONE_FOURTH_DEFAULT_REPEAT_STRIDE});
            } else {
                CastIntrinsicsImpl(dst, src, roundMode, 1, {1, 1, DEFAULT_REPEAT_STRIDE, DEFAULT_REPEAT_STRIDE / 2});
            }
        } else if constexpr (sizeof(T) < sizeof(U)) {
            if constexpr (IsSameType<T, int4b_t>::value) {
                CastIntrinsicsImpl(
                    dst, src, roundMode, 1, {1, 1, ONE_FOURTH_DEFAULT_REPEAT_STRIDE, DEFAULT_REPEAT_STRIDE});
            } else {
                CastIntrinsicsImpl(dst, src, roundMode, 1, {1, 1, DEFAULT_REPEAT_STRIDE / 2, DEFAULT_REPEAT_STRIDE});
            }
        } else {
            CastIntrinsicsImpl(dst, src, roundMode, 1, {1, 1, DEFAULT_REPEAT_STRIDE, DEFAULT_REPEAT_STRIDE});
        }
        set_mask_norm();
        set_vector_mask(static_cast<uint64_t>(-1), static_cast<uint64_t>(-1));
    }
}
```

Both Level-0 forms (mask-bit and mask-count, `:1025` and `:1044`) open with the same `if ASCEND_IS_AIV {`.
`ASCEND_IS_AIV` on an NPU build expands to `constexpr(g_coreType == AscendC::AIV)` with
`constexpr int32_t g_coreType = AscendC::AIC;` on the cube half (`impl/utils/sys_macros.h:64-76`, §43.5), so on
the cube half the entire body is compiled out. **A `Cast` on the cube half of a MIX kernel is a silent no-op.**
That is correct — the AIC has no vector unit — and it is also undiagnosed.

Note in passing, because it closes a false alarm worth not raising: AscendC's own Level-2 `Cast` **does** handle
operands of different element width. It picks the repeat strides itself from `sizeof(T)` versus `sizeof(U)`,
with a dedicated `int4b_t` arm using `ONE_FOURTH_DEFAULT_REPEAT_STRIDE` against
`DEFAULT_REPEAT_STRIDE` (`= 8`, `impl/basic_api/utils/kernel_utils_constants.h:33`). So the four-argument
`Cast(dst, src, roundMode, count)` is correct for `float → half` and for `half → int4b_t`, and
https://github.com/tile-ai/tilelang-ascend/issues/269 — "cast_tl does not support int4 dtype despite
AscendC::Cast support", closed, which reports `int8 → half` through a four-argument lowering returning
`[16., 0., 0., 0., 0., 0., 0., 0.]` where `[-8., -4., 0., 4., 7., -1., 2., 5.]` was expected — is a defect in
*that compiler's* lowering, not in AscendC's.

### 47.2 ★★★ Plain `DataCopy` to GM has no such guard; `DataCopyPad` does

`DataCopyPad(const GlobalTensor<T>&, const LocalTensor<T>&, const DataCopyParams&)`,
`impl/basic_api/kernel_operator_data_copy_intf_impl.h:1414-1444`, verbatim:

```cpp
template <typename T, PaddingMode mode>
__aicore__ inline __inout_pipe__(MTE3) void DataCopyPad(
    const GlobalTensor<T>& dst, const LocalTensor<T>& src, const DataCopyParams& dataCopyParams)
{
    ...
    using PrimType = PrimT<T>;
#if defined(ASCENDC_DEBUG) || defined(ASCENDC_CPU_DEBUG)
#if defined(__NPU_ARCH__) && (__NPU_ARCH__ == 2201)
    CheckDataCopyPadTypeSupport<T>("DataCopyPad from LocalTensor to GlobalTensor with DataCopyParams");
    CheckDataCopyPadTensor(
        dst, src, dataCopyParams, "DataCopyPad from LocalTensor to GlobalTensor with DataCopyParams");
#endif
#endif
#if (__NPU_ARCH__ != 5102)
    if ASCEND_IS_AIC {
        return;
    }
#endif
    ASCENDC_REPORT_OVERFLOW_MEM((CheckDataCopyPadTensorSizeOverflow(dst, src, dataCopyParams)));
    const Hardware srcHWPos = GetPhyType((TPosition)src.GetPosition());
    const uint8_t cacheMode = ExtractCacheMode(dst);
    if (srcHWPos == Hardware::UB) {
        DataCopyPadUB2GMImpl<T, mode>(
            (__gm__ PrimType*)dst.GetPhyAddr(), (__ubuf__ PrimType*)src.GetPhyAddr(), dataCopyParams, cacheMode);
    } else {
        ASCENDC_CHECK_TPOSITION(
            false, "src", "UB(VECIN/VECOUT)", "DataCopyPad from LocalTensor to GlobalTensor with DataCopyParams",
            GetPositionDisplay(static_cast<TPosition>(src.GetPosition())));
    }
}
```

**`if ASCEND_IS_AIC { return; }` — an explicit, unconditional early return on the cube half.**

The plain `DataCopy(const GlobalTensor<T>&, const LocalTensor<T>&, const DataCopyParams&)` at `:271-336`
(reproduced in full in §42.4) has **no `ASCEND_IS_AIC` guard at all**. It goes from the CPU-debug block
straight to:

```cpp
    if (srcHWPos == Hardware::UB) {
        // ub -> gm
        DataCopyUB2GMImpl((__gm__ PrimType*)dst.GetPhyAddr(), (__ubuf__ PrimType*)src.GetPhyAddr(), repeatParams);
    } else if (srcHWPos == Hardware::L1) {
```

A grep for `ASCEND_IS_AIC` / `ASCEND_IS_AIV` across
`impl/basic_api/kernel_operator_data_copy_intf_impl.h` returns eight hits, **all of them inside the
`DataCopyPad` family** (`:1430, :1466, :1516, :1617, :1672, :1696, :1728, :1807`). None is in the plain
`DataCopy` family. For contrast, the library does guard this case elsewhere when it matters — the
`LocalTensor::SetValue` path at `impl/basic_api/kernel_tensor_impl.h:318-322`:

```cpp
    if ASCEND_IS_AIC {
        if (GetPhyType(AscendC::TPosition(this->GetPosition())) == Hardware::UB) {
            return;
        }
    }
```

so the omission in plain `DataCopy` is an omission, not a convention.

### 47.3 What that means for a `Cast → Cast → DataCopy(GM)` function in a `__mix__(1,2)` kernel

If such a function is compiled into both halves — i.e. it is an `__aicore__` function that the cube half also
reaches, rather than one called only inside `if ASCEND_IS_AIV { ... }` — then on the cube half:

1. both `Cast`es are **skipped silently** (§47.1), so nothing is produced in the staging buffer;
2. the `DataCopy` to GM is **still issued** (§47.2), with a `__ubuf__` pointer, on a core that has no Unified
   Buffer on this architecture (§3b: A3's UB is physically in the AIV);
3. the destination address is the same GM address the AIV half is writing correctly.

So the allocation has **two uncoordinated writers**: one producing the right data and one producing whatever an
AIC's UB-pointer dereference resolves to, racing with no synchronisation between them. Which one lands last is
timing-dependent, and nothing in the toolchain reports any of it — no hang, no error, no check. Swapping the
plain `DataCopy` for `DataCopyPad` removes writer (2) by construction, because `DataCopyPad` returns on the AIC
half; so does wrapping the function body in `if ASCEND_IS_AIV`.

This also explains why an isolated probe can pass where the real kernel fails even when the probe is built
`__mix__` and `ASCENDC_CUBE_ONLY`: a probe written with the vector half gated to one subblock has only one
writer, and the whole effect disappears. The discriminating observation is not the offset and not the
allocation — it is **whether the enclosing function is reachable from the cube half**.

### 47.4 ★★★ REFINEMENT, added after an adversarial check: `REGIST_CUBE_OBJ` *is* the half-partition, and it works by `return`

§47.3's hazard has a precondition that the first draft did not state, and finding it took checking the claim
against the vendor's own `__mix__` examples. Of the three shipped `__mix__` examples that perform a UB→GM
`DataCopy`, two guard with `ASCEND_IS_AIV`/`ASCEND_IS_AIC` (`matmul_s4.asc`, `matmul_fused_manual.asc`) and one
does not — `examples/01_simd_cpp_api/04_advanced_api/00_matmul/batch_matmul_iterate_n_batch/batch_matmul_iterate_n_batch.asc`
has a bare `DataCopy(cGlobal, bufferC, sizeC / sizeof(cType));` at line 179 inside
`__mix__(1, 2)` with zero guards. That looked like a counter-example. It is not; it is the precondition.

`impl/adv_api/detail/kfc/kfc_register_obj.h:274-332`, verbatim — the four arms that matter:

```cpp
#ifdef SPLIT_CORE_CUBE
#ifdef ASCENDC_CUBE_ONLY
#define REGIST_CUBE_OBJ(tpipe, workspace, ...) AscendC::InitCurObj(tpipe, __VA_ARGS__)

#define REGIST_CUBE_OBJ_REMOTE(tpipe, workspace, ...)
#else
...
#define REGIST_CUBE_OBJ(tpipe, workspace, ...)                                                     \
    using ASCubeObjConfig = AscendC::GetCubeObjConfig<decltype(AscendC::GetObjType(__VA_ARGS__))>; \
    static_assert(                                                                                 \
        ASCubeObjConfig::enableABShareValue != AscendC::CUBEOBJ_MIX_MODE,                          \
        "If both aType ibshare and bType ibshare are set to true, the values must "                \
        "be the same for all cube objects.");                                                      \
    constexpr int8_t asEnableMixDualMaster = ASCubeObjConfig::enableMixDualMasterValue;            \
    ...                                                                                            \
    AscendC::KfcServer server;                                                                     \
    server.Init(workspace);                                                                        \
    server.InitObj(tpipe, __VA_ARGS__);                                                            \
    if constexpr (!asEnableMixDualMaster) {                                                        \
        while (server.isRun()) {                                                                   \
            server.Run(__VA_ARGS__);                                                               \
        };                                                                                         \
        server.Quit();                                                                             \
        return;                                                                                    \
    }
#endif
#endif

#elif defined(SPLIT_CORE_VEC)
#ifdef ASCENDC_CUBE_ONLY
#define REGIST_CUBE_OBJ(tpipe, workspace, ...) return
#elif ...
```

So the macro partitions the halves by **returning out of the kernel**, and which half it kills depends on
`ASCENDC_CUBE_ONLY`:

| build | cube half (`SPLIT_CORE_CUBE`) | vector half (`SPLIT_CORE_VEC`) |
| --- | --- | --- |
| MIX (no `ASCENDC_CUBE_ONLY`) | runs the KFC server loop, then **`return`** — never reaches the user body | falls through as a KFC *client*; runs the user body |
| `ASCENDC_CUBE_ONLY` | `InitCurObj`, falls through — **runs the user body** | **`return`** — never reaches the user body |

Two consequences, and the second is the one that matters to us.

**(a) An unguarded UB→GM `DataCopy` after `REGIST_MATMUL_OBJ` in MIX mode is safe**, because the cube half has
already returned out of the kernel inside the macro. That is why `batch_matmul_iterate_n_batch.asc` needs no
guard. §47.3's two-writer hazard therefore applies to a **hand-written** `__mix__` kernel that partitions the
halves itself (or not at all) — not to one whose halves are partitioned by `REGIST_*_OBJ`.

**(b) ★ Under `ASCENDC_CUBE_ONLY`, `REGIST_CUBE_OBJ` expands to a bare `return` on the vector half.** So in a
`#define ASCENDC_CUBE_ONLY` kernel that calls `REGIST_MATMUL_OBJ`/`REGIST_CUBE_OBJ`, **the AIV exits at that
line and every vector stage after it never executes at all** — no `Cast`, no vector `DataCopy`, nothing. The
AIC alone continues through the whole body. That is not a race; it is the vector half being switched off, and
it is silent.

## Relevance

This is the sharpest remaining candidate for the live int4 defect, and it needs no new measurement to check —
only a reading of which half can reach the function. **Read §47.4 first: it states the precondition and adds a
second, simpler failure mode that may fit even better.** Our failing function is exactly
`Cast(half, float)` → `Cast(int4b_t, half)` → `DataCopy(GM, int4b_t)` inside a `__mix__(1,2)`
`ASCENDC_CUBE_ONLY` kernel. On the cube half the two `Cast`es compile to nothing because every `CastImpl` on
dav_c220 opens with `if ASCEND_IS_AIV`, while the plain `DataCopy` to GM has no matching guard and issues its
MTE3 move anyway — the guard exists only in the `DataCopyPad` family, eight occurrences, none in plain
`DataCopy`. Two writers to one address, one of them garbage, unsynchronised and unreported.

Three things follow. First, the cheap fix is `DataCopyPad` instead of `DataCopy` for every UB→GM store in code
that both halves can reach, because `DataCopyPad` is AIC-safe by construction (`if ASCEND_IS_AIC { return; }`),
and it is also the form that handles a non-32B-aligned tail. Second, the correct fix is the §43 rule applied one
level up: a function containing vector work must be reachable only from `if ASCEND_IS_AIV`, and the vendor's own
int4 sample does exactly that — `if ASCEND_IS_AIV { Unzip(...); }` / `if ASCEND_IS_AIC { RunMatmul(); }`
(§44.2). Third, §47.4's refinement is the thing to check before any of that, because it is a yes/no question about one
line: **does this kernel call `REGIST_MATMUL_OBJ` / `REGIST_CUBE_OBJ`, and is `ASCENDC_CUBE_ONLY` defined?** If
both, the vector half executes `return` at that macro and every vector stage after it — both `Cast`es included
— never runs at all, on any core, with the AIC alone continuing through the body. That is a simpler and more
complete failure than the two-writer race, and it predicts garbage rather than a race. If the kernel does *not*
call those macros, the halves are partitioned by hand and §47.3's two-writer hazard is live. Fourth, this is a
general audit item for the megakernel, not a one-off: every stage that writes GM from
UB should be checked for cube-half reachability, because the failure is silent on both sides — the `Cast` that
should have run produces nothing and says nothing, and the `DataCopy` that should not have run executes and says
nothing.

A false alarm closed in passing, so that it is not raised later: AscendC's four-argument
`Cast(dst, src, roundMode, count)` **is** correct across differing element widths, including `half → int4b_t`;
it computes the repeat strides itself with a dedicated `int4b_t` arm. The contrary report at
tilelang-ascend#269 is a defect in that compiler's own lowering, which passed four arguments where seven were
needed, not in AscendC. And for the record from the same file, the legal round modes are asymmetric:
`Cast<int4b_t, half>` accepts `CAST_RINT` (`vconv_f162s4r`), `CAST_FLOOR` (`vconv_f162s4f`) and `CAST_CEIL`,
and rejects `CAST_ODD` with 「CAST_ODD from half to int4b_t is not supported on current device」, while
`Cast<half, int4b_t>` accepts **only** `CAST_NONE` (`vconv_s42f16`) and rejects everything else with
「only support CAST_NONE from int4b_t to half on current device」.

## 48. ★ The official constraint list for hand-written ISASI kernels, and the exact API allowlist that applies once you allocate event ids yourself

Source: `/home/shanshan/repo/cann/asc-devkit/docs/zh/guide/programming_guide/programming_model/ai_core_simd_programming/cpp_tensor_programming/cpp_tensor_programming_overview.md`,
§「编程约束和限制」 (lines 388-395), §「支持的API范围」 (表1-表4) and §「使用预留UB空间的API范围」 (表5-表6).
Read 2026-10-20. This is the chapter that governs exactly our regime: a hand-written kernel that calls
`SetFlag`/`WaitFlag(ISASI)` and `PipeBarrier(ISASI)` directly instead of letting `TQue` do it.

### 48.1 ★ The five constraints, verbatim and complete

```
## 编程约束和限制

- 同步事件由开发者使用`SetFlag/WaitFlag(ISASI)`和`PipeBarrier(ISASI)`手动插入，事件的类型和事件ID由开发者自行管理，但需要注意事件ID不能使用6和7（可能与内部使用的事件ID出现冲突，进而出现未定义行为）。
- 核函数（Kernel）入口处需要开发者手动调用InitSocState接口用来初始化全局状态寄存器。因为全局状态寄存器处于不确定状态，如果不调用该接口，可能导致算子执行过程中出现未定义行为。在TPipe框架编程中，初始化过程由TPipe完成，无需开发者关注。
- 核函数（Kernel）结束前需要开发者手动调用PipeBarrier<PIPE_ALL>()。
- 部分API内部通过软仿真实现，需占用Ascend C预留的UB空间，开发者使用时需关注目标API是否依赖该预留空间（针对NPU架构版本2201，Select等API内部使用了8KB的预留UB空间，用于存储中间数据；针对NPU架构版本3510，Exp等API内部使用了2KB的预留UB空间，用于指令兼容或存储中间数据）。若开启--cce-disable-asc-reserved-ubuf编译选项，在对应产品版本下调用相关API会触发编译期报错。具体API范围见使用预留UB空间的API列表。
- 同时另外一些软仿实现接口内部会占用系统分配的事件ID，如果开发者手动调用`SetFlag/WaitFlag(ISASI)`插入自定义事件ID时会跟接口内部的事件ID产生冲突，所以用户自定义事件ID时，只能支持部分API。具体支持的API列表见支持的API范围。
```

Four of these are hard rules, and two of them cut against the reflex that a `PipeBarrier<PIPE_ALL>` is always
an antipattern:

- **Event ids 6 and 7 must not be used manually.** `QUE_MAX_EVENT` is 8 on 2201 (§43.4), so ids 0-7 exist, but
  6 and 7 are reserved and using them is 「未定义行为」. The hand-allocatable range is **0-5**. This is the same
  rule as the 核内同步 page's 「不能手动插入6和7的TEventID」 (§8).
- **`InitSocState()` is mandatory at kernel entry — unless a `TPipe` is constructed.** 「因为全局状态寄存器处于
  不确定状态，如果不调用该接口，可能导致算子执行过程中出现未定义行为。在TPipe框架编程中，初始化过程由TPipe完成」.
  So a hand-written kernel that does *not* declare a `TPipe` and does *not* call `InitSocState` runs with the
  global status registers in an indeterminate state, which is a run-to-run nondeterminism source by
  construction.
- **`PipeBarrier<PIPE_ALL>()` is mandatory before the kernel returns.** 「核函数（Kernel）结束前需要开发者手动
  调用PipeBarrier<PIPE_ALL>()」. The `AKA3001` antipattern warning (§43.2/§46.4) is about barriers standing in
  for a cross-pipe dependency *inside* the kernel; the one at the exit is required and must not be removed.
- **Hand-allocating event ids restricts which APIs you may call at all.** 「另外一些软仿实现接口内部会占用系统
  分配的事件ID … 所以用户自定义事件ID时，只能支持部分API」. The allowlist is per-product; §48.2 is the A3 one.

### 48.2 ★ 表3 — the complete A3 allowlist, for kernels that allocate their own event ids

Verbatim (HTML stripped), 「**表3** 针对Atlas A3 训练系列产品/Atlas A3 推理系列产品，支持的API范围」:

| 接口分类 | 接口名称 | 备注 |
| --- | --- | --- |
| 基础API > 标量计算 | `GetBitCount`、`CountLeadingZero`、`CountBitsCntSameAsSignBit`、`GetSFFValue`、`Cast`（float转half、int32_t）、`Cast`（float转bfloat16_t）、`Cast`（多类型转float） | - |
| 基础API > 矢量计算 > 基础算术 | `Exp`、`Ln`、`Abs`、`Reciprocal`、`Sqrt`、`Rsqrt`、`Relu`、`Add`、`Sub`、`Mul`、`Div`、`Max`、`Min`、`BilinearInterpolation`、`Adds`、`Muls`、`Maxs`、`Mins`、`LeakyRelu` | - |
| 基础API > 矢量计算 > 逻辑计算 | `Not`、`And`、`Or`、`ShiftLeft`、`ShiftRight` | - |
| 基础API > 矢量计算 > 复合计算 | `Axpy`、`CastDequant`、`AddRelu`、`AddReluCast`、`SubRelu`、`SubReluCast`、`MulAddDst`、`MulCast`、`FusedMulAdd`、`FusedMulAddRelu` | - |
| 基础API > 矢量计算 > 比较与选择 | `Compare`、`Compare`（结果存入寄存器）、`Compares`、`GetCmpMask`、`SetCmpMask`、`GatherMask` | - |
| 基础API > 矢量计算 > 类型转换 | `Cast` | - |
| 基础API > 矢量计算 > 归约计算 | `WholeReduceMax`、`WholeReduceMin`、`WholeReduceSum`、`BlockReduceMax`、`BlockReduceMin`、`BlockReduceSum`、`PairReduceSum`、`RepeatReduceSum`、`GetReduceRepeatSumSpr`、`GetReduceRepeatMaxMinSpr` | - |
| 基础API > 矢量计算 > 数据转换 | `Transpose`、`TransDataTo5HD` | `TransDataTo5HD`（不支持dst与src类型为uint64_t的LocalTensor的场景） |
| 基础API > 矢量计算 > 数据填充 | `Duplicate`、`Brcb` | - |
| 基础API > 矢量计算 > 排序组合 | `Sort32`、`MrgSort`、`GetMrgSortResult` | - |
| 基础API > 矢量计算 > 离散与聚合 | `Gather`、`Gatherb` | - |
| 基础API > 矢量计算 > 掩码操作 | `SetMaskCount`、`SetMaskNorm`、`SetVectorMask`、`ResetMask` | - |
| 基础API > 矢量计算 > 量化设置 | `SetDeqScale` | - |
| 基础API > 数据搬运 > DataCopy | 基础数据搬运 | 不支持UB（VECIN/VECCALC/VECOUT）->L1 Buffer（TSCM）通路的数据搬运。 |
| 基础API > 数据搬运 | 增强数据搬运 / 切片数据搬运 / 随路转换ND2NZ搬运 / 随路转换NZ2ND搬运 / 随路量化激活搬运 | 增强数据搬运、随路转换ND2NZ搬运 不支持UB（VECIN/VECCALC/VECOUT）->L1 Buffer（TSCM）通路的数据搬运。 |
| 基础API > 数据搬运 | `Copy`、`DataCopyPad`、`SetPadValue` | `DataCopyPad`不支持UB（VECIN/VECCALC/VECOUT）->L1 Buffer（TSCM）通路的数据搬运。 |
| 基础API > 同步控制 > 核内同步 | `SetFlag/WaitFlag`、`PipeBarrier`、`DataSyncBarrier` | - |

Two things to read off it. **`Cast`, `DataCopy`, `DataCopyPad`, `SetFlag`/`WaitFlag`, `PipeBarrier` and
`DataSyncBarrier` are all on the list** — so the `Cast → Cast → DataCopy` chain of §47 is permitted alongside
hand-allocated event ids. And **`Select` is absent from the A3 比较与选择 row**, where the 310P table (表1) has
「`Select`、`GatherMask`」 and A3 has only 「`GatherMask`」. `AddDeqRelu` is likewise absent from A3's 复合计算
row where the 310P table has it. Both omissions are explained by §48.3: those two are precisely the APIs that
consume the reserved UB space on 2201.

### 48.3 表5 — the APIs that consume the 8 KB reserved UB on 2201

Verbatim:

```
## 使用预留UB空间的API范围

以下API内部会使用Ascend C预留的UB空间。当开启--cce-disable-asc-reserved-ubuf编译选项后，在对应产品版本下调用相关API会触发编译期报错。由于同一API使用预留UB空间的情况在不同NPU架构下有差异，开启该编译选项后，需要手动调整API调用方式或替换为不依赖预留UB空间的实现，才能完成兼容性迁移。

[!CAUTION]注意
 同一接口若提供多个重载原型，可能只有部分原型会使用UB预留空间。
```

| API类别 | API名 |
| --- | --- |
| 基础API | `AddDeqRelu`、`Select` |
| 高阶API | `Digamma`、`Lgamma`、`Power`、`Sign`、`LayerNorm`、`DropOut`、`SelectWithBytesMask` |

(表6 is the 3510 list, where the reserve is 2 KB and `Exp` is among the users.)

### 48.4 The sanctioned `__mix__` shape, from the same chapter

Verbatim, with its own comment:

```cpp
// Define CV fusion operator, marked with __mix__ to execute on Device, suitable for operators combining Cube and Vector computation
__global__ __mix__ void mix_kernel(__gm__ float* x, __gm__ float* y, __gm__ float* z)
{
    if ASCEND_IS_AIV {
        // ...
        AscendC::Add(zLocal, xLocal, yLocal, 4096);
        // ...
    }

    if ASCEND_IS_AIC {
        // ...
        AscendC::Mmad(l0c_buf, l0a_buf, l0b_buf, {BLOCK_M, BLOCK_K, BLOCK_N, 0, false, false});
        // ...
    }
}
```

The whole body of a `__mix__` kernel is one source compiled for both halves, and `ASCEND_IS_AIV` /
`ASCEND_IS_AIC` are the *only* partition — they are `constexpr(g_coreType == AscendC::AIV)` with `g_coreType` a
per-translation-unit `constexpr` (§43.5), so anything not inside one of those two `if`s is compiled into, and
executed by, both halves.

## Relevance

This is the governing constraint list for the regime we are actually in, and it qualifies two things said
earlier in this file. **Not every `PipeBarrier<PIPE_ALL>` is an antipattern: the one before the kernel returns
is mandatory** — 「核函数（Kernel）结束前需要开发者手动调用PipeBarrier<PIPE_ALL>()」 — so a sweep that converts
all of them to named pairs must keep the exit barrier. And **the hand-allocatable event-id range is 0-5, not
0-7**: 6 and 7 are reserved and using them is explicitly 「未定义行为」, which matters as soon as a
double-buffered protocol needs more than one id per `HardEvent` (§43.4).

Two items are audit work that can be done by grep, with no hardware. First, 表3 is an allowlist, not advice:
once a kernel allocates its own event ids, calling an API outside that list conflicts with the system event ids
those APIs consume internally. The good news is that `Cast`, `DataCopy`, `DataCopyPad`, `SetFlag`/`WaitFlag`,
`PipeBarrier` and `DataSyncBarrier` are all on it, so §47's chain is permitted; the item to grep for is
**`Select`**, which is on the 310P allowlist and *not* on A3's, and `AddDeqRelu` likewise — both because they
are the two basic APIs that use the 8 KB reserved UB on 2201 (表5). Any kernel of ours that mixes `Select` with
hand-written `SetFlag`/`WaitFlag` is outside the documented contract. Second, if any kernel of ours does not
declare a `TPipe`, it must call `InitSocState()` at entry, because the global status registers are otherwise
「处于不确定状态」 and the result is 「未定义行为」 — a textbook run-to-run nondeterminism source, and one that a
`TPipe`-based kernel is immune to for free.

Finally, 48.4 is the official confirmation of §47's premise: a `__mix__` kernel is one source compiled for both
halves, and `ASCEND_IS_AIV` / `ASCEND_IS_AIC` are the only partition. Anything not inside one of those two
guards executes on both cores — which is precisely why an ungated `DataCopy` to GM in a `Cast`-bearing function
gives the allocation a second, uncoordinated writer.

## 49. ★ The Fixpipe dtype matrix on A3 — int32→int8 requant is free on the cube's drain, int4 is NOT, and the architecture doc contradicts the API doc on that

Source: `/home/shanshan/repo/cann/asc-devkit/docs/zh/api/SIMD-API/basic_api/cube_compute_ISASI/cube_compute_store/Fixpipe_L0CToGM.md`
and `Fixpipe_L0CToUB.md`, plus
`docs/zh/api/SIMD-API/basic_api/cube_compute_TensorAPI/cube_store_key_features/quant_pre.md` for the newer
Tensor-API form. Read 2026-10-20. This matters because our `Cast` family costs 2.300 ms a round against
0.076 ms of bytes it must move — 30x off roofline, the worst ratio in the profile — and the question is how much
of it the cube can absorb on the way out of L0C instead.

### 49.1 ★ The supported source/destination dtype combinations, per product, verbatim

```
## 数据类型

**源矩阵与目的矩阵支持的数据类型组合**

针对Ascend 950PR/Ascend 950DT，Fixpipe接口支持的数据类型组合如下：
| 源矩阵（L0C Buffer） | 目的矩阵（GM） |
| float   | int8_t、uint8_t、hifloat8_t、fp8_e4m3fn_t、half、bfloat16_t、float。 |
| int32_t | int8_t、uint8_t、half、bfloat16_t、int32_t。 |

针对Atlas A3 训练系列产品/Atlas A3 推理系列产品，Fixpipe接口支持的数据类型组合如下：
| 源矩阵（L0C Buffer） | 目的矩阵（GM） |
| float   | int8_t、uint8_t、half、bfloat16_t、float。 |
| int32_t | int8_t、uint8_t、half、int32_t。 |

针对Atlas A2 训练系列产品/Atlas A2 推理系列产品，Fixpipe接口支持的数据类型组合如下：
| 源矩阵（L0C Buffer） | 目的矩阵（GM） |
| float   | int8_t、uint8_t、half、bfloat16_t、float。 |
| int32_t | int8_t、uint8_t、half、int32_t。 |

针对Kirin X90，Fixpipe接口支持的数据类型组合如下：
| float   | int8_t、half。 |
| int32_t | int8_t、half、int32_t。 |

针对Kirin 9030，Fixpipe接口支持的数据类型组合如下：
| float   | half |
| int32_t | half |
```

**No `int4b_t` appears in any row, for any product.** Not A3, not A2, not even 950PR/950DT.

### 49.2 ★★ The contradiction: the architecture doc says the hardware can do S322S4, the API doc does not expose it

§8 of this file quotes the A3 architecture chapter's own Fixpipe capability list, verbatim:

> 量化反量化：包括S322FP16、S322S32、S322S4、S322S8、S322S16、FP322FP16、FP322BF16、FP322S8、FP322S4、FP322FP32。

— i.e. the hardware Fixpipe is documented to do **S322S4** (int32→int4) and **FP322S4** (float→int4), and the
same chapter describes the int4 channel-merge that goes with it:

> Channel merge（S4和U4数据类型）
> 对于转换为S4或U4的目标数据类型，分形矩阵通过硬件从16x16转换为16x64，如果输出通道数N是64的倍数，则N方向上每4个相邻的16x16分形矩阵将合并为1个16x64分形矩阵。
> 在这种情况下，N的配置必须是64的倍数。

But §49.1's API table has no int4 destination on any part, and the `QuantMode_t` enum exposed on A3 (§49.3) has
no S4 mode. **So the capability exists in the architecture description and is not reachable through the
`Fixpipe` API.** Either an undocumented path exists, or the architecture list describes a superset of what CANN
binds. Treat int4-out-of-Fixpipe as unavailable until someone produces a working call.

### 49.3 The exact `QuantMode_t` enum available on A3, verbatim

From the A3 arm of the `quantPre` parameter description:

```cpp
enum QuantMode_t{
    NoQuant,      // 不开启量化功能
    F322F16,      // Float32_2_Float16：float cast成half，cast mode为CAST_RINT模式
    F322BF16,     // Float32_2_BFloat16：float cast成bfloat16_t，cast mode为CAST_RINT模式
    DEQF16,       // DeQuant_Float16：int32_t量化成half，scalar量化
    VDEQF16,      // Vector_DeQuant_Float16：int32_t量化成half，tensor量化
    QF322B8_PRE,  // Quant_Float32_2_B8：float量化成int8_t/uint8_t，scalar量化
    VQF322B8_PRE, // Vector_Quant_Float32_2_B8：float量化成int8_t/uint8_t，tensor量化
    REQ8,         // ReQuant_int8：int32_t量化成uint8_t/int8_t，scalar量化
    VREQ8,        // Vector_ReQuant_int8：int32_t量化成uint8_t/int8_t，tensor量化
};
```

Nine modes. **`REQ8` / `VREQ8` are the int32→int8 requantization, scalar and per-channel-tensor respectively**,
and `DEQF16` / `VDEQF16` are int32→half. The 950PR list adds the FP8 and HiFloat8 modes
(`QF322FP8_PRE`, `VQF322FP8_PRE`, `QF322HIF8_PRE`, `VQF322HIF8_PRE`, `QF322HIF8_PRE_HYBRID`,
`VQF322HIF8_PRE_HYBRID`, `QS322BF16_PRE`, `VQS322BF16_PRE`, `QF322F16_PRE`, `VQF322F16_PRE`, `QF322BF16_PRE`,
`VQF322BF16_PRE`, `QF322F32_PRE`, `VQF322F32_PRE`) — still no S4. Also recorded from the 950 list, because it
is a precision note that applies to any `float→float` drain:

> QF322F32_PRE, // Quant_Float32_2_Float32: float量化成float，scalar量化，精度可以达到双千分之一，无法达到双万分之一。如果有双万分之一的精度要求，建议使用AscendDeQuant高阶API。

The tensor-quantization parameter constraints, verbatim from `quant_pre.md`:

> - tensor量化参数张量应位于L1 Buffer，元素类型为`uint64_t`，地址要求32字节对齐。
> - 量化参数不能为`inf`、`nan`或非规格化数。该约束属于硬件约束，接口不单独检查参数值。
> - 不传入`quant`时，仅支持不量化输出或`float`到`half`/`bfloat16_t`的直接cast输出。

So a per-channel requant scale lives in **L1**, is `uint64_t` per channel, 32-byte aligned, and an `inf`/`nan`/
denormal in it is a hardware constraint the API does **not** check.

### 49.4 `Fixpipe(L0C→UB)` is 不支持 on A3 — a fourth independent confirmation

`Fixpipe_L0CToUB.md`, 产品支持情况, verbatim:

```
- Ascend 950PR/Ascend 950DT：支持包含FixpipeParamsArch3510参数的接口。
- Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
- Atlas A2 训练系列产品/Atlas A2 推理系列产品：不支持
- Atlas 200I/500 A2 推理产品：支持包含FixpipeParamsM300参数的接口。
- Atlas 推理系列产品AI Core：不支持
...
```

and `Fixpipe_L0CToGM.md`'s own 产品支持情况 names the A3 restriction on the interface shape:

```
- Atlas A3 训练系列产品/Atlas A3 推理系列产品：仅支持包含FixpipeParamsV220参数的接口。
```

So on A3 the cube's only drain destination is GM, through the `FixpipeParamsV220` form — consistent with §35.4,
§46.3 and the `GetQueEvt` assert, now from the API page too.

### 49.5 ★ `ndNum = 0` turns a Fixpipe into a silent NOP

From the `params` description, verbatim:

> ndNum：源NZ矩阵的数目，也就是传输ND矩阵的数目，取值范围为ndNum∈[0, 65535]。**注：ndNum=0表示不执行搬运，该接口将被视为NOP（空操作）。**

and for the 950 NZ2DN form:

> dnNum：传输DN矩阵的数目，取值范围为dnNum∈[0, 65535]。**注：dnNum=0表示不执行搬运，该接口将被视为NOP（空操作）。**

A zero count is not an error and not a one-element move; it is a documented no-op. Add it to the §42.4 /
§43.5 list of silent-drop mechanisms.

### 49.6 Two more drain knobs worth having

Verbatim from the same parameter table:

> unitFlag | unitFlag是一种Mmad指令和Fixpipe指令细粒度的并行，开启该功能后，硬件每计算完一个分形，计算结果就会被搬出，该功能不适用于在L0C Buffer累加的场景。取值说明如下：0（2'b00）：不开启unitFlag；2（2'b10）：开启unitFlag，硬件执行完指令之后，不会设置寄存器；3（2'b11）：开启unitFlag，硬件执行完指令之后，会将unitFlag关闭。

> isChannelSplit | 是否开启通道拆分的功能。默认为false，不开启该功能。仅在src和dst都为float时才能开启通道拆分，且不能同时开启ChannelSplit和NZ2ND功能。

> reluEn | 是否开启ReLU的开关

`unitFlag` is Mmad/Fixpipe fine-grained overlap — the result of each fractal drains as soon as it is computed —
and it is **incompatible with accumulating in L0C**, which rules it out for any split-K or multi-pass
accumulation. `isChannelSplit` requires both src and dst `float` and cannot be combined with NZ2ND.

## Relevance

The headline is a split verdict on the `Cast` family's 2.300 ms. **The int32→int8 half of it is absorbable into
the cube's drain at zero vector cost**: `REQ8` is a scalar requant and `VREQ8` a per-output-channel tensor
requant, both int32→int8, both applied by Fixpipe on the way out of L0C with no Vector involvement, with the
per-channel scale sitting in L1 as `uint64_t` 32-byte-aligned. Every place we currently matmul to int32 and then
`Cast` down to the int8 activation of the next stage is a candidate. **The int4 direction is not available**:
no product's Fixpipe table has an int4 destination and the A3 `QuantMode_t` has no S4 mode, so the W4 output
quantization has to stay a Vector `Cast` — which also means §47's `Cast → Cast → DataCopy` shape is not
avoidable by pushing the quantization into the cube, and the fix there really is the half-guarding one.

49.2 is the contradiction to carry: the A3 *architecture* chapter lists `S322S4` and `FP322S4` among Fixpipe's
hardware quantization conversions, and documents the matching S4 channel-merge (16x16 fractals merged four-wide
into 16x64, with N required to be a multiple of 64 — the same 64 as §45.3's shape constraint), while the Fixpipe
*API* exposes no int4 destination on any part. Hardware capability and API surface disagree. If an undocumented
S4 drain exists it is worth a probe, because it would remove the last Vector pass from a W4A8 expert chain
entirely; until then, plan for the Vector `Cast`.

Two traps for the silent-failure list that §42.4 and §43.5 started: `ndNum = 0` makes a Fixpipe a documented
NOP rather than an error, and a tensor quant scale containing `inf`/`nan`/a denormal is a hardware constraint
the API explicitly does not check — 「该约束属于硬件约束，接口不单独检查参数值」. And one scheduling knob with a
hard precondition: `unitFlag` overlaps Mmad with Fixpipe at fractal granularity but is 「不适用于在L0C Buffer
累加的场景」, so it cannot be combined with L0C accumulation across K-passes.

## 50. ★★★ `KERNEL_TYPE_AIC_ONLY` IS supported on A3 — the type we need is `KERNEL_TYPE_MIX_AIC_1_0`; plus the head-overhead itemization, the 512-byte same-address serialization rule, and the transfer-size and L2 rules

Sources, all in the shipped devkit on this machine, read 2026-10-20:

- `docs/zh/api/SIMD-API/basic_api/Kernel-Tiling/set_Kernel_type.md`
- `docs/zh/guide/operator_practice/simd_operator_optimization/overhead_optimization/core_count_kernel_type.md`
- `.../simd_operator_optimization/memory_access/avoid_same_address_access.md`
- `.../simd_operator_optimization/memory_access/gm_address_512b_alignment.md`
- `.../simd_operator_optimization/memory_access/transfer_larger_data_blocks.md`
- `.../simd_operator_optimization/memory_access/l2_cache_mode_config.md`

### 50.1 ★★★ The contradiction: the official page lists `KERNEL_TYPE_AIC_ONLY` as supported on A3

We measured `KERNEL_TYPE_AIC_ONLY` being **rejected at kernel submission with `sqe_type=3, errType=0x20`**.
The official 「设置核函数（Kernel）类型」 page says it is supported. 产品支持情况, verbatim:

```
- Ascend 950PR/Ascend 950DT：支持
- Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
- Atlas A2 训练系列产品/Atlas A2 推理系列产品：支持
- Atlas 200I/500 A2 推理产品：不支持
- Atlas 推理系列产品AI Core：支持
- Atlas 推理系列产品Vector Core：不支持
- Atlas 训练系列产品：不支持
```

and 约束说明 → kernel type 取值约束, verbatim:

```
-   Ascend 950PR/Ascend 950DT，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
-   Atlas A3 训练系列产品/Atlas A3 推理系列产品，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
-   Atlas A2 训练系列产品/Atlas A2 推理系列产品，支持KERNEL_TYPE_AIV_ONLY、 KERNEL_TYPE_AIC_ONLY、KERNEL_TYPE_MIX_AIV_1_0、KERNEL_TYPE_MIX_AIC_1_0、KERNEL_TYPE_MIX_AIC_1_1、KERNEL_TYPE_MIX_AIC_1_2。
-   Atlas 推理系列产品，支持KERNEL_TYPE_AICORE、KERNEL_TYPE_MIX_VECTOR_CORE。
```

### 50.2 ★★★ The resolution, from the same page: `AIC_ONLY` has no hard sync; `MIX_AIC_1_0` does

The full enum and the 表2 descriptions, verbatim:

```cpp
enum KernelMetaType {
    KERNEL_TYPE_AIV_ONLY,
    KERNEL_TYPE_AIC_ONLY,
    KERNEL_TYPE_MIX_AIV_1_0,
    KERNEL_TYPE_MIX_AIC_1_0,
    KERNEL_TYPE_MIX_AIC_1_1,
    KERNEL_TYPE_MIX_AIC_1_2,
    KERNEL_TYPE_AICORE,
    KERNEL_TYPE_VECTORCORE,
    KERNEL_TYPE_MIX_AICORE,
    KERNEL_TYPE_MIX_VECTOR_CORE,
    KERNEL_TYPE_MAX
};
```

> **KERNEL_TYPE_AIV_ONLY** — 算子执行时仅启动AI Core上的Vector核：比如用户在host侧设置numBlocks为10，则会启动10个Vector核。
>
> **KERNEL_TYPE_AIC_ONLY** — 算子执行时仅启动AI Core上的Cube核：比如用户在host侧设置numBlocks为10，则会启动10个Cube核。
>
> **KERNEL_TYPE_MIX_AIV_1_0** — AIC、AIV混合场景下，**使用了多核控制相关指令时**，设置核函数（Kernel）的类型为MIX AIV:AIC 1:0（**带有硬同步**），算子执行时仅会启动AI Core上的Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Vector核。
> 硬同步的概念解释如下：当不同核之间操作同一块全局内存且可能存在读后写、写后读以及写后写等数据依赖问题时，通过调用SyncAll()函数来插入同步语句来避免上述数据依赖时可能出现的数据读写错误问题。目前多核同步分为硬同步和软同步，硬同步是利用硬件自带的全核同步指令由硬件保证多核同步。
>
> **KERNEL_TYPE_MIX_AIC_1_0** — AIC、AIV混合场景下，**使用了多核控制相关指令时**，设置核函数（Kernel）的类型为MIX AIC:AIV 1:0（**带有硬同步**），算子执行时仅会启动AI Core上的Cube核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核。
>
> **KERNEL_TYPE_MIX_AIC_1_1** — AIC、AIV混合场景下，设置核函数（Kernel）的类型为MIX AIC:AIV 1:1，算子执行时会同时启动AI Core上的Cube核和Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核和10个Vector核。
>
> **KERNEL_TYPE_MIX_AIC_1_2** — AIC、AIV混合场景下，设置核函数（Kernel）的类型为MIX AIC:AIV 1:2，算子执行时会同时启动AI Core上的Cube核和Vector核，比如用户在host侧设置numBlocks为10，则会启动10个Cube核和20个Vector核。
>
> **KERNEL_TYPE_AICORE** — 算子执行时仅会启动AI Core，比如用户在host侧设置numBlocks为5，则会启动5个AI Core。
>
> **KERNEL_TYPE_VECTORCORE** — 该参数为预留参数，当前版本暂不支持。
>
> **KERNEL_TYPE_MIX_AICORE** — 该参数为预留参数，当前版本暂不支持。
>
> **KERNEL_TYPE_MIX_VECTOR_CORE** — 基于Ascend C开发的矢量计算相关的算子可以运行在Vector Core上，调用本接口传入该参数用于启用Vector Core。启用Vector Core后，算子执行时会同时启动AI Core和Vector Core，用于并行计算。… 需要注意的是，通过SetSimdNumBlocks设置核数时，需要大于AI Core的核数，否则不会启动VectorCore。

**`KERNEL_TYPE_MIX_AIC_1_0` launches only the Cube cores *and carries the hard sync*, and the page says in so
many words that it is the type to use 「使用了多核控制相关指令时」.** `KERNEL_TYPE_AIC_ONLY` is the plain
cube-only launch with no hard sync. So a cube-only kernel that calls `SyncAll()` or any cross-core control
instruction is a *content/type mismatch* when declared `AIC_ONLY`, and the page states the matching rule
explicitly, verbatim:

> -   当设置具体的kernel task type时，用户的算子实现需要与kernel type相匹配。比如用户设置kernel type为KERNEL_TYPE_MIX_AIC_1_2，则算子内部实现应与核配比AIC:AIV为1:2相对应；若用户设置kernel type为KERNEL_TYPE_AIC_ONLY，则算子内部实现应该为纯cube逻辑，不应该存在vector部分的逻辑。其他的kernel type类似。

and a second constraint that is a plausible independent cause of a submission-time rejection, verbatim:

> -   当纯cube或者纯vec算子强制设定kernel type为MIX类型时，workspace的大小不能设置为0，需要设置一个大于0的值（比如16、32等）。

The remaining constraints, verbatim:

> -   **KERNEL_TASK_TYPE**优先级高于**KERNEL_TASK_TYPE_DEFAULT**，同时设置了全局kernel type和某一个tiling key的kernel type，该tiling key的kernel type以**KERNEL_TASK_TYPE**设置的为准。
> -   没有设置全局默认kernel type的情况下，如果开发者只为其中的某几个tiling key设置kernel type，即部分tiling key没有设置kernel type，会导致算子kernel编译报错。
> -   使用Tiling模板编程时，需要通过ASCENDC_TPL_KERNEL_TYPE_SEL设置核函数（Kernel）类型即可，无需再通过该接口进行设置，本接口不生效。

and the two setters, with their project-type restriction, verbatim:

> -   设置全局默认的kernel type，对所有的tiling key生效。当前支持在自定义算子工程和核函数（Kernel）直调工程中使用。
>     `KERNEL_TASK_TYPE_DEFAULT(value)`
> -   设置某一个具体的tiling key对应的kernel type。当前仅支持在自定义算子工程中使用。
>     `KERNEL_TASK_TYPE(key, value)`

so a `<<<>>>` direct-launch project (ours) can only use `KERNEL_TASK_TYPE_DEFAULT`.

### 50.3 ★ Head overhead, itemized — and the official advice to use FEWER cores at microsecond scale

`core_count_kernel_type.md`, verbatim and nearly complete:

> 在算子执行过程中，可能会因为以下几个原因产生额外的启动开销或者头开销：
>
> 1. **核启动**：每个核在启动时需要进行初始化操作，加载必要的配置和资源。
> 2. **核取址TLB MISS**：当核在访问内存时，如果Translation Lookaside Buffer（TLB）中没有对应的页表项，就需要从内存中加载页表项，这会导致额外的延迟。
> 3. **同地址访问冲突**：由于硬件限制，多个核同时访问相同的内存地址时可能会发生冲突，导致额外的时延。
> 4. **变量资源初始化**：在算子执行前，需要初始化一些变量和资源，这也可能带来额外的性能开销。
>
> 头开销会随着使用的核数增加而增加。
>
> **对于整体耗时在微秒级别且单核计算量耗时较少的算子，可以通过减少启动核数并增加单核计算量的方式来获得性能提升。** 这种优化方式的本质是在头开销耗时和单核计算量耗时之间进行权衡。为了达到最佳性能，开发者需要通过实践尝试，找到最合适的核数设置。
>
> - 对于自定义算子工程，可以在TilingFunc中通过SetSimdNumBlocks接口来设置算子使用的核数…；对于核函数（Kernel）直调工程，可以在>>>调用时指定算子使用的核数。
> - 此外，算子的核函数（Kernel）类型也会影响算子启动的核数。**以纯Vector算子为例，如果以混合启动的方式执行该算子，调度器会同时启动Vector核和Cube核。然而，此时Cube核并没有实际的计算指令，但仍会产生核启动和核初始化的头开销。** 因此，建议设置合适的核函数（Kernel）类型以最小化头开销。
>
>   通常，算子工程会通过算子使用的指令自动识别算子类型，但该功能**无法区分AIC和AIV的配比，默认按照AIV:AIC为1:2的配比下发任务**。此外，**自动识别功能可能失效，因为其依赖于编译优化的结果**。所以推荐用户手动设置算子的核函数（Kernel）类型。

### 50.4 ★★ 「避免同地址访问」 — GM requests are coalesced at 512-byte granularity and SERIALIZED, and this applies to A3

Verbatim, 【优先级】高, with the product list naming A3 explicitly:

> 该性能优化指导适用于如下产品型号：Ascend 950PR/Ascend 950DT；Atlas A3 训练系列产品/Atlas A3 推理系列产品；Atlas A2 训练系列产品/Atlas A2 推理系列产品
>
> 【描述】**MTE2、MTE3、Scalar等单元访问Global Memory数据时，其地址请求会按照512字节粒度对齐后进行处理。当同时访问Global Memory的数据，且地址处于连续的512字节范围内时，由于数据一致性的原因，多个请求会被串行处理，进而影响数据搬运效率。**
>
> 当前算子执行机制保证用户核函数（Kernel）入参（包括Workspace/Tiling）的地址512字节对齐，因此开发者只需要根据地址的偏移量即可判断两个地址是否会落入连续的512字节范围内。
>
> …尽管addr0~addr5是多个不同的地址，但因为落在连续的512字节范围内，被视为同一个地址请求，此时这几个数据请求会被串行处理，数据访问效率会降低。**同地址访问的影响受同时访问的核数影响，同地址访问的核数越多时，串行导致的性能劣化越严重。**

The fix is a rotation of the access order, and the guide ships both arms verbatim. Scenario: a `[6144, 512]`
half input, GM→UB, 48 cores, tile `[128, 64]`, `DataCopyPad`, L2 cache hint off, **每个核都会完整载入一遍输入
矩阵** — every core loads the whole input matrix, which is exactly the decode-time weight-broadcast pattern.

反例 (原始实现), verbatim:

```cpp
uint32_t blockIdx = AscendC::GetBlockIdx();
for (uint32_t mBlockIdx = 0; mBlockIdx < fullMBlockCount; mBlockIdx++) {
    // 原始实现：所有核使用相同的mBlockIdx。
    uint32_t curMBlockIdx = mBlockIdx;
    uint32_t mStart = curMBlockIdx * singleCoreM;
    DataCopyPad(...) // 搬运逻辑相同
}
```

正例 (优化实现), verbatim:

```cpp
uint32_t blockIdx = AscendC::GetBlockIdx();
for (uint32_t mBlockIdx = 0; mBlockIdx < fullMBlockCount; mBlockIdx++) {
    // 优化实现：在每组numBlocks 个M块内，
    // 按当前核的blockIdx轮转访问顺序。
    uint32_t blockGroupStart = (mBlockIdx / numBlocks) * numBlocks;
    uint32_t curMBlockIdx = blockGroupStart + (mBlockIdx + blockIdx) % numBlocks;
    uint32_t mStart = curMBlockIdx * singleCoreM;
    DataCopyPad(...) // 搬运逻辑相同
}
```

> 原始实现下，48个核在同一时刻访问相同的curMBlockIdx：T0时刻均访问M0，T1时刻均访问M1，T2时刻均访问M2，依次类推。
> 优化实现下，不同核在同一时刻访问不同的curMBlockIdx：T0时刻block0访问M0、block1访问M1、block46访问M46、block47访问M47；T1时刻分别访问M1、M2、M47、M0。

and the measurement recipe, verbatim: 「你可以通过执行如下命令行，通过msOpProf工具获取上述示例的性能数据并进行
对比。`msopprof ./demo`。重点关注op_summary_*.csv中的MTE2搬运相关指标。」 The worked sample is at
`examples/01_simd_cpp_api/05_best_practices/04_memory_access/data_copy`, 优化点4.

### 50.5 The two bandwidth rules: ≥16 KB per transfer, and 512-byte GM alignment (A2 only)

`transfer_larger_data_blocks.md`, 【优先级】高, verbatim:

> 【描述】搬运不同大小的数据块时，对带宽的利用率（有效带宽/理论带宽）不一样。**根据实测经验，单次搬运数据长度16KB以上时，通常能较好地发挥出带宽的最佳性能。** 因此对于单次搬运，应考虑尽可能的搬运较大的数据块。

★ **CORRECTION, from a controlled A/B that post-dates this subsection** — see `mla-decode-fusion.md` §8-§21,
sourced from the devkit's own A3-labelled
`examples/01_simd_cpp_api/05_best_practices/04_memory_access/data_copy/README.md`. That README separates burst
length from instruction count, which the guidance above conflates. Holding `blockLen = 128B` and the total byte
count **identical** and changing only `blockCount` from 1 to 64, `aiv_mte2_time` falls **548.161 → 220.772 us,
2.48x**. Then raising `blockLen` from 128B to 2048B buys only **220.772 → 202.657 us, 1.09x**. So on A3 the
penalty for many small moves is overwhelmingly **per-`DataCopy`-instruction issue overhead, not burst length**,
and the 16 KB figure is worth about 9% once the descriptors are already batched into one instruction. Cite the
instruction count, not the burst length, when explaining a scattered gather that is off its byte roofline. The
same README gives A3 **L2 = 192 MB** and the hit-rate formula
`(r0_hit + r1_hit) / (r0_hit + r1_hit + r0_miss_allocate + r1_miss_allocate)`.

`gm_address_512b_alignment.md`, 【优先级】高, verbatim — note the product restriction, which is **A2 only**:

> 【描述】由于AI处理器内部设计约束，从GM向Local Memory搬运数据时，保证GM地址512B对齐可以最有效的发挥出带宽的效率。如下图示例，展示了在512B对齐以及32B对齐情况下单核的带宽效率：**搬运同等数据量，带宽差距最大的情况，32B对齐场景只能达到512B对齐场景的70%。**
>
> - 本性能优化手段仅针对Atlas A2 训练系列产品/Atlas A2 推理系列产品生效。

`reduce_non_contiguous_transfer.md`, 【优先级】中, is **950-only** (「该性能优化建议适用于如下产品型号：
Ascend 950PR/Ascend 950DT」) and describes `DataCopyPad`'s Loop mode and `DataCopy`'s multi-dimensional
(NDDMA) form as the way to collapse many small non-contiguous moves into one. Neither is offered for A3.

### 50.6 L2 CacheMode, and why a streaming read evicts the data you wanted cached

`l2_cache_mode_config.md`, 【优先级】高, product list includes A3, verbatim:

> L2 Cache的带宽相比GM的带宽有数倍的提升，因此当数据命中L2 Cache时，数据的搬运耗时会优化数倍。…
>
> 从上面的流程可以看出，**当数据访问总量超出L2 Cache容量时，AI Core会对L2 Cache进行数据替换。由于Cache一致性的要求，替换过程中旧数据需要先写回GM（此过程中会占用GM带宽），旧数据写回后，新的数据才能进入L2 Cache。**
>
> 开发者可以针对访问的数据设置其CacheMode，**对于只访问一次的Global Memory数据设置其访问状态为不进入L2 Cache**，这样可以更加高效的利用L2 Cache缓存需要重复读取的数据，避免一次性访问的数据替换有效数据。
>
> Ascend C基于GlobalTensor提供了SetL2CacheHint接口，用户可以根据需要指定CacheMode。

The worked sample is `examples/01_simd_cpp_api/05_best_practices/00_vector_compute/add_high_performance`
(two-tensor add, `(8192, 8192)` each, 384 MB total, 48 cores, 6-way row × 8-way column split).

## Relevance

50.1 and 50.2 are the most consequential pair in this file, because they contradict a measurement of ours and
then supply the fix. We measured `KERNEL_TYPE_AIC_ONLY` rejected at submission with
`sqe_type=3, errType=0x20`; the official page lists it as supported on A3. The reconciliation is in the type
descriptions: **`KERNEL_TYPE_AIC_ONLY` is a plain cube-only launch with no hard sync, while
`KERNEL_TYPE_MIX_AIC_1_0` is a cube-only launch 「带有硬同步」 and is documented as the type to use
「使用了多核控制相关指令时」** — i.e. when the kernel calls `SyncAll()` or any cross-core control instruction.
A kernel that uses those and declares `AIC_ONLY` violates the page's own matching rule
(「若用户设置kernel type为KERNEL_TYPE_AIC_ONLY，则算子内部实现应该为纯cube逻辑，不应该存在vector部分的逻辑」),
which is exactly the shape of a submission-time rejection. **So for a cube-only megakernel that needs a grid
barrier, the type is `MIX_AIC_1_0`, not `AIC_ONLY` — that is the one-line unblock for the in-kernel-collective
work.** A second candidate from the same constraint list is worth checking in the same breath: 「当纯cube或者
纯vec算子强制设定kernel type为MIX类型时，workspace的大小不能设置为0，需要设置一个大于0的值（比如16、32等）」.
And since we launch with `<<<>>>`, only `KERNEL_TASK_TYPE_DEFAULT(value)` is available — `KERNEL_TASK_TYPE(key,
value)` is 「仅支持在自定义算子工程中使用」.

50.3 explains the measured MIX floor and points the opposite way from intuition. The vendor itemizes head
overhead as 核启动 + 核取址TLB MISS + **同地址访问冲突** + 变量资源初始化, says 「头开销会随着使用的核数增加而
增加」, and then advises in bold that **for microsecond-scale operators with little per-core work the way up is
to launch FEWER cores and give each more work** — which is precisely our batch=1 regime, and precisely the
opposite of filling all 20/24. It also names the mechanism behind our 0.70 us AI_VECTOR_CORE versus 12.04 us
MIX_AIV gap: a pure-vector operator launched as MIX still pays the Cube cores' launch and init overhead for
cores that have no instructions. And it warns that automatic kernel-type detection **cannot distinguish the
AIC:AIV ratio and defaults to 1:2**, and 「可能失效，因为其依赖于编译优化的结果」 — so our 505 MIX_AIC calls a
round may be partly a misclassification we can set away by hand.

50.4 is a mechanism for the roofline gaps that is not launch overhead and not bandwidth. **GM address requests
from MTE2/MTE3/Scalar are coalesced at 512-byte granularity, and simultaneous requests landing in one
contiguous 512-byte window are serialized for coherence, worse the more cores participate** — and it is listed
as applying to A3 at 【优先级】高. The guide's own scenario is 「每个核都会完整载入一遍输入矩阵」, which is the
decode-time weight broadcast: every core reading the same weight tile at the same time is the worst case for
this rule, and it would show up exactly as we see it — time far above the bytes moved, with no single operator
to blame. The fix is free and is given as code: rotate each core's access order by
`blockGroupStart + (mBlockIdx + blockIdx) % numBlocks`. This belongs on the list of things to try before any
redesign, and `msopprof ./demo` with 「op_summary_*.csv中的MTE2搬运相关指标」 is the vendor's own way to see it.

50.5 and 50.6 are the two remaining cheap rules, and 50.5 needs its own correction read first: on A3 the
**instruction count**, not the burst length, is what costs. The controlled A/B in 50.5's correction gives
**2.48x for batching descriptors into one `DataCopy` against only 1.09x for lengthening the burst**, at
identical total bytes. The 16 KB figure is real but second-order; the first-order rule for any sparse-attention
gather reading many small KV blocks is to **minimise the number of `DataCopy` instructions** — and
`mla-decode-fusion.md` records that A3 has no gather DMA at all (`Gather` / `asc_gather_datablock` take
`__ubuf__` sources and run on `PIPE_V`, not MTE2; the multi-dimensional `NdDmaParams` `DataCopy` is
`Atlas A3系列产品：不支持`; and the 950 generation added a SIMT unit whose listed use cases are scatter/gather),
so a scattered GM gather on 2201 necessarily becomes N descriptors and the only lever is N. The 512-byte GM alignment rule with its 70% penalty is
**A2 only** and does not apply to us, which is worth knowing because it is easy to assume otherwise; the
same-address rule in 50.4 is the one that does. And `SetL2CacheHint` matters more than it looks: when the
working set exceeds L2, eviction must write the old line back to GM *before* the new line can enter, so a
streaming read with no hint actively burns GM bandwidth evicting the weights we wanted resident — the fix is to
mark read-once data as not entering L2.

## 51. ★★ Three measured vendor cases that all blame GM same-address conflict for an MTE2-bound matmul — and the skinny-M parallelism answer, split-K

Sources, all in the shipped devkit, read 2026-10-20:
`docs/zh/guide/operator_practice/best_practices/matmul_tuning_cases/matmul_multi_core_split_k.md`,
`matmul_multi_core_k_stagger.md`, `matmul_l2_cache_split.md`. Read these together with §50.4, which states the
512-byte serialization rule; these three are its measured consequences on real matmuls.

### 51.1 ★ Split-K: the only parallelism available when M and N are small, with its three hard constraints

案例介绍, verbatim:

> 为了实现算子在多核上并行执行，提升计算效率，需要将矩阵数据进行切分，切分后的数据块被分配到不同的核上处理。**通常情况下，切分矩阵数据时仅切分M、N轴，不切分K轴。若M和N较小，切分M和N轴较困难，此时需要考虑K轴切分**；开启多核切K功能后，该场景下可以对矩阵的K轴进行切分，从而使算子在多核上并行执行。由于K轴较大，在该场景下不切分K轴通常会导致单核的输入数据量过大，开启K轴切分后，切分策略能够更有效地平衡输出带宽和输入带宽。
>
> - 开启多核切K的适用场景
>     - 矩阵的K轴较大，M轴和N轴相比K轴较小，可以在K轴进行切分，使算子并行执行的核数更多。
>     - 矩阵的M轴、N轴和K轴均较大时，可以在K轴进行切分，使切分策略更好地平衡输入和输出带宽。
> - 开启多核切K的约束条件
>     - 开启多核切K的场景，**获取C矩阵结果时仅支持输出到Global Memory**。
>     - 开启多核切K的场景，**需在核函数（Kernel）侧代码中首次将C矩阵分片的结果写入Global Memory之前，先对Global Memory进行清零，在获取C矩阵分片的结果时，开启AtomicAdd累加**。如果不预先清零Global Memory，可能会因为累加Global Memory中的原始无效数据而产生精度问题。
>     - 开启多核切K的场景，**不支持Bias参与矩阵乘计算**。

The case spec, verbatim — note how skinny it is:

> | 输入 | Shape | Data type | Format |
> | a | 16, 1024 | float16 | ND |
> | b | 1024, 16 | float16 | ND |
>
> 当前案例使用的AI处理器共24个核，算子中开启高阶API Matmul的纯Cube模式。Tiling参数如下：
> - 原始shape：M=16, N= 16, K=1024。
> - 单核shape：未开启多核切K时，singleCoreM=16，singleCoreN=16，singleCoreK=1024；开启多核切K后，singleCoreM=16，singleCoreN=16，singleCoreK=512。

and the measurement, verbatim:

> - 优化前的流水图如下，由于未开启多核切K，且M和N非常小，原始矩阵数据未进行切分，**所有数据在单核上进行计算**。
> - 优化前的Profiling数据如下，可以看到算子只在单核上执行，**aic_time耗时约19.60us**，其中**aic_mte2_time的平均耗时约为13.72us**，aic_mte2_ratio占比较高。
> - 优化后的流水图如下，开启多核切K后，切分原始矩阵的K方向，单核处理K方向的数据量由原来的1024变为512，单核处理的数据量减半，MTE2流水变短。
> - 优化后的Profiling数据如下，可以看到算子在两个核上执行，**aic_time平均耗时约为13.70us**，较优化前的19.60us有较大提升。

**19.60 → 13.70 us, −30.1%, with `aic_mte2_time` 13.72 us of the original 19.60 dominating.** Only two cores,
because K/512 = 2.

### 51.2 ★★ K-axis staggering: the same-address conflict, measured, −13.2% end to end

案例介绍, verbatim — this is §50.4's rule stated as a matmul problem:

> 在多核并行执行Matmul计算时，**如果输入矩阵A或B的内存位置位于GM，并且参与多核计算的矩阵相同，那么将出现多核同时访问相同GM地址的情况，导致地址访问冲突，从而影响算子性能。** 若开启多核K轴错峰访问Device内存，切分的矩阵K轴方向对应的不同核将尽量从不同的GM起始地址开始访问和搬运数据，缓解地址访问冲突，提升算子性能。
>
> - 开启多核K轴错峰访问内存的适用场景：多核执行Matmul，且输入矩阵的K轴较大。
> - 开启多核K轴错峰访问内存的约束条件：
>     - **输入矩阵的K轴非全载**，K轴非全载即矩阵的K方向数据不能同时搬入及保持在L1 Buffer中。
>     - **仅支持MDL模板。**
>     - 在多核上执行Matmul计算。
>     - **A矩阵或B矩阵的内存位置位于GM。**

Spec: `a` (768, 6144) float16 ND, `b` (6144, 2048) float16 ND. The diagnosis and result, verbatim:

> 优化前的Profiling数据（PipeUtilization.csv）如下所示，**aic_mte2_ratio平均达到0.93**，MTE2在算子整体执行时长中占比较高，算子当前为MTE2 Bound。本案例中，矩阵按M和N方向切分，单核shape[singleCoreM，singleCoreN，singleCoreK]为[128, 512, 6144]，基本块shape[baseM，baseN，baseK]为[128, 256, 64]，**每次加载A矩阵的数据时，多核有概率同时访问同一GM地址，引发地址冲突，导致MTE2搬运效率降低，MTE2执行耗时增加。**
>
> 查看OpBasicInfo.csv文件，优化前算子整体耗时为**98.72us**。
>
> 算子Tiling参数不变，优化后的Profiling数据（PipeUtilization.csv）如下所示。可以看到，**MTE2耗时显著降低，MTE2的平均耗时从90us降低到69.87us，最大耗时从91.94us降低到75.82us。**
>
> 查看OpBasicInfo.csv文件，优化后算子整体耗时为**85.68us**，耗时从98.72us降低到85.68us，**性能提升13.2%**。

> 总结：在多核执行Matmul的场景，当输入矩阵K轴较大（**一般大于4096**）时，可以尝试使用MDL模板并开启K轴错峰访问内存的功能，缓解地址访问冲突，提升MTE2搬运效率，进而优化算子性能。

**98.72 → 85.68 us, −13.2%, with the tiling unchanged.** MTE2 mean 90 → 69.87 us, max 91.94 → 75.82 us. The
only change is which GM address each core starts from.

### 51.3 L2 Cache splitting — and a third appearance of the same-address fix

案例介绍 and the diagnosis, verbatim:

> 当前案例基于Tiling全量常量化进一步优化… 优化前的Profiling数据如下，C列的**aic_time是867us**，K列的**aic_mte2_time是861.9us，MTE2占比为99%**，MTE2数据搬运是当前算子性能的瓶颈。

The three optimization points, verbatim:

> - 优化点一：调整切块大小和计算次数
>     - 优化前，输入数据不进行切分，所有核一次计算全部数据。…24个核一次计算A和B矩阵的所有数据。
>     - 优化后，输入数据被切分多次，所有核分多次计算，每个核单次计算只依赖切分后的数据量。**L2 Cache切分方案确保单次计算的数据都在L2 Cache缓存中**，搬运输入数据的效率更高。
> - 优化点二：**选择拖尾较小的L2 Cache切分方案**
> - 优化点三：**错位分核，减少左右矩阵同地址冲突问题**

and the result, verbatim:

> 优化后的Profiling数据如下，C列的**aic_time为805.6us**，相比于优化前，**总执行时间降低了约7.1%，MTE2搬运时间降低了约10.7%**。

**867 → 805.6 us, −7.1%, MTE2 −10.7%** — and note that optimization point three is 「错位分核」, staggered core
assignment to reduce left/right-matrix same-address conflict, i.e. the same fix again.

## Relevance

Three independent vendor tuning cases, on three different shapes, all diagnose an MTE2-bound matmul and all
reach for staggering as part of the fix: §50.4's `(mBlockIdx + blockIdx) % numBlocks` rotation for a plain
`DataCopy`, §51.2's K-axis staggering worth **−13.2% end to end with the tiling unchanged**, and §51.3's
「错位分核」 as one of three points worth **−7.1%**. Together with §50.4's statement of the mechanism — GM
requests coalesced at 512 bytes and serialized when several cores land in one window, worse the more cores
participate, at 【优先级】高 on A3 — that is a convergent, measured explanation for time far above bytes moved
with no single operator to blame. Our above-roofline families all share the shape the cases describe: 「参与多核
计算的矩阵相同」, every core reading the same weight. It costs index arithmetic to test.

§51.1 is the structural answer for our regime rather than a tuning knob. At batch=1 M is 1 (or 8 rows under the
MSD stack) and N per expert is modest, so **M and N cannot supply 20-24 cores of parallelism and K is the only
axis left** — which is exactly the case the document is written for, and it measures 19.60 → 13.70 us, −30.1%,
on M=N=16, K=1024, the skinniest shape in the whole guide. Its three constraints are the price and all three
bite us: C must go to **Global Memory** (no L0C-resident accumulation across the split), the output buffer must
be **zeroed before the first write and accumulated with AtomicAdd** (「如果不预先清零Global Memory，可能会因为
累加Global Memory中的原始无效数据而产生精度问题」), and **Bias is not supported** in a split-K matmul — which
collides directly with folding our `8*sum(w)` correction in as a bias, and pushes it back to a post-GEMM
row-scale (`fused-moe-expert.md` §B7.2, equation 6) or to the extra `-8` matmul row of PR #17201.

§51.2's constraints are cheaper and worth checking against our tiling now: it needs the **MDL template**, K
**not** fully resident in L1 (`singleK > baseK * stepK`), multi-core execution, and A or B in GM — and the
summary puts the useful threshold at K **> 4096**. GLM-5.2's per-expert K is in that range, so the gate is the
MDL template and L1 residency rather than the shape.

## 52. ★ IBShare — sharing one L1-resident B across the AIVs that use the same weight, and the only int4-compatible template that does it

Sources: `docs/zh/guide/operator_practice/best_practices/matmul_tuning_cases/matmul_ibshare_b.md` and
`matmul_ibshare_ab.md` in the shipped devkit. Read 2026-10-20. This matters because at decode every core uses
the *same* weight, which is IBShare's precondition verbatim, and because `IBShare` is one of only three
Matmul templates that accept `int4b_t` at all (§42.7: 「int4数据类型输入的Matmul对象仅支持Norm、MDL、IBShare模板」).

### 52.1 B-only IBShare: MTE2 −15.46%, and the exact residency condition

案例介绍, verbatim:

> - 开启IBShare的适用场景
>   **MIX场景（包含矩阵计算和矢量计算）下，多个AIV的A矩阵或B矩阵GM地址相同，且多个AIV复用的A矩阵或B矩阵在L1 Buffer上全载。**
> - 开启IBShare的约束条件
>   - A矩阵和B矩阵同时开启IBShare的场景，**同一算子中其它Matmul对象的A矩阵和B矩阵也必须同时开启IBShare**。
>   - A矩阵和B矩阵同时开启IBShare的场景，获取矩阵计算结果时，**只支持调用IterateAll接口，且只支持输出到Global Memory**。

Spec and tiling, verbatim:

> - 原始shape：M=64, N= 256, K=384。
> - 单核shape：singleCoreM=32，singleCoreN=256，singleCoreK=384。**A矩阵拆成两半，一半在AIV0上处理，一半在AIV1上处理；AIV0和AIV1使用的B矩阵数据相同。**
> - 基本块shape：baseM=32，baseN=256，baseK=64。
> - L1缓存相关Tiling参数：stepM=1，stepN=1，stepKa=6，stepKb=6。

The diagnosis, verbatim — and it contains the residency test:

> 优化前的流水图如下，不开启IBShare模板，默认使用的Norm模板。黑框标识AIV0发起的MTE2搬运流水：**MTE2总共搬运了12次，其中A矩阵搬运了6次（stepM*stepKa=6），B矩阵搬运了6次（stepN*stepKb=6）**。红框标识的AIV1发起的MTE2搬运流水，跟AIV0基本一致。在该案例中，因为AIV1使用的B矩阵跟AIV0使用的B矩阵数据相同，且 **singleCoreN=baseN*stepN，singleCoreK=baseK*stepKb，即B矩阵可以在L1全载**。考虑在AIV0搬入B矩阵到L1 Buffer后，将B矩阵数据缓存在L1 Buffer上等待AIV1进行复用，进而节省B矩阵的MTE2重复搬运开销。
>
> 优化前的Profiling数据如下，C列的aic_time是 **10.29us**，K列的aic_mte2_time是 **5.56us**。

The mechanism stated twice, verbatim:

> 下图是不开启IBShare模板（默认使用Norm模板）的Matmul计算流水示意图。MTE2分多次从Global Memory搬运基本块到L1 Buffer（A1或B1），**即使前后两次搬运的B矩阵基本块数据是相同的数据，也会重复搬运**。
>
> 下图是开启IBShare模板的Matmul计算流水示意图。MTE2分多次从Global Memory搬运基本块到L1 Buffer（A1或B1），**若前后两次搬运的B矩阵基本块数据相同，不会重复搬运，第一次搬运到B1内的数据会被复用**。

The enabling code, verbatim (template arguments elided by the HTML strip, but the comments survive):

```cpp
#define ASCENDC_CUBE_ONLY
#include "lib/matmul_intf.h"
using A_TYPE = AscendC::MatmulType< ... >;
using B_TYPE = AscendC::MatmulType< ... >; // 设置B矩阵的IBSHARE参数为true
using C_TYPE = AscendC::MatmulType< ... >;
using BIAS_TYPE =  AscendC::MatmulType< ... >;
AscendC::Matmul< ... > matmulObj; // 使用默认的IBShare模板参数CFG_IBSHARE_NORM定义Matmul对象
```

The result, verbatim:

> - 优化后的流水图如下，黑框标识的AIV0发起的MTE2搬运流水，与优化前一致。红框标识的AIV1发起的MTE2搬运流水，**相较于优化前的A矩阵和B矩阵一共12次MTE2数据搬运，减少到了仅6次A矩阵的MTE2数据搬运，省去了B矩阵的6次MTE2数据搬运开销**。
> - 优化后的Profiling数据如下，C列的aic_time是 **9.93us**，较优化前的10.29us提升了 **3.55%**。K列的aic_mte2_time是 **4.71us**，较优化前的5.56us提升了 **15.46%**。

> 总结：MIX场景（包含矩阵计算和矢量计算）下，若多个AIV的A矩阵或B矩阵GM地址相同，且多个AIV复用的A矩阵/B矩阵在L1 Buffer上全载。可以考虑开启IBShare模板，通过共享L1 Buffer上相同的A矩阵或B矩阵数据，减少重复的MTE2数据搬运开销，提升算子性能。

**`aic_time` 10.29 → 9.93 us (−3.55%), `aic_mte2_time` 5.56 → 4.71 us (−15.46%)**, by halving the MTE2 moves
from 12 to 6 on the second AIV.

### 52.2 A-and-B IBShare with a cube-view core split: 27.11 → 22.44 us, and it attacks Scalar not MTE2

`matmul_ibshare_ab.md`, verbatim:

> 本案例呈现了在**融合算子场景**中，使用Matmul高阶API进行矩阵乘法计算时，A矩阵和B矩阵同时启用IBShare对性能的提升效果。该案例的关键优化措施包括：
> - 分核逻辑：**以Cube核视角分核**，Matmul计算结果输出到GM，提供给Vector核进行后续计算。
> - 开启IBShare：A矩阵和B矩阵同时开启IBShare。

> 通过分析以上Profiling数据可以看出，算子执行多次的平均耗时为 **27.11us**，**aic_scalar_time的平均耗时为26.27us，当前性能瓶颈点为Cube的Scalar流水**。

> 优化后执行多次的平均耗时：**22.44us**，较优化前有较大提升。

> 总结：融合算子场景下，Matmul A矩阵和B矩阵同时开启IBShare，**以Cube核视角分核，可以有效减少Cube侧的Scalar开销**，提升性能。

**27.11 → 22.44 us, −17.2%**, with `aic_scalar_time` 26.27 of 27.11 us beforehand — i.e. 97% Scalar-bound
before, and the fix is the combination of a cube-view core split and AB IBShare. The `Init` it ships is the
ordinary one, with the element-counted `SetGlobalBuffer` and the tensor-subscript offsets of §42.6:

```cpp
    aGlobal.SetGlobalBuffer(reinterpret_cast< ... >(a), tiling.M * tiling.Ka);
    bGlobal.SetGlobalBuffer(reinterpret_cast< ... >(b), tiling.Kb * tiling.N);
    cGlobal.SetGlobalBuffer(reinterpret_cast< ... >(c), tiling.M * tiling.N);
    int32_t offsetA, offsetB, offsetC;
    CalcOffset(AscendC::GetBlockIdx(), tiling, offsetA, offsetB, offsetC); // calculate offset
    aGlobal = aGlobal[offsetA];
    bGlobal = bGlobal[offsetB];
    cGlobal = cGlobal[offsetC];
```

## Relevance

IBShare's stated precondition is our decode situation written out: 「多个AIV的A矩阵或B矩阵GM地址相同」 — several
AIVs reading the same weight from the same GM address. And it is one of only three templates that accept
`int4b_t` at all (§42.7), so unlike most of the Matmul tuning surface it is not closed to us by the W4 weight
type. What it buys is the removal of *duplicate* MTE2 traffic for the shared operand: 12 moves become 6 in the
B-only case, `aic_mte2_time` −15.46%. Against families spending two to five times their byte-movement time,
removing the duplicate fetch of a weight that every core wants is the right shape of fix, and it composes with
§51.2's staggering (which reorders the fetches that remain) rather than competing with it.

The gate is residency, and it is arithmetic we can check without a run: the shared operand must be **fully
loaded in L1**, tested as `singleCoreN = baseN * stepN` and `singleCoreK = baseK * stepKb`. A whole GLM-5.2
expert weight will not fit L1, so this constrains `singleCoreN` and `singleCoreK` to a slice that does — which
is a tiling choice, not an impossibility. Two constraints to price in if we enable it on both operands: every
other `Matmul` object in the same operator must then also have both on
(「同一算子中其它Matmul对象的A矩阵和B矩阵也必须同时开启IBShare」), and the result can only be taken with
`IterateAll` to Global Memory — which closes `Iterate()`-level CV handoff (§B8.4's per-`Iterate` flag) and
L0C-resident accumulation for that object. So B-only IBShare is the composable choice and AB IBShare is the
all-or-nothing one.

52.2 is also the third measurement in this file pointing at Scalar rather than compute or movement as the real
cost at small shapes: 26.27 us of 27.11 us was `aic_scalar_time` there, 15.02 of 17.85 was Scalar in the
pure-Cube case (§B8.6 in `fused-moe-expert.md`), and the measured 13.58 us MIX_AIC launch floor is itself a
Scalar-side cost. Three independent cases say that at our shapes the Cube's Scalar pipeline, not its Cube
pipeline, is what to profile first — `aic_scalar_time` against `aic_time` in column G against column C of the
msOpProf output is the one ratio to look at.

## 53. ★ Three more measured Matmul cases: constant tiling (−25.9%, Scalar −46.5%), the 256-byte inner-axis rule behind an AIV ND2NZ (−39.0%), and NBuffer33

Sources, in the shipped devkit, read 2026-10-20:
`docs/zh/guide/operator_practice/best_practices/matmul_tuning_cases/matmul_tiling_constant.md`,
`aiv_nd2nz_conversion.md`, `matmul_nbuffer33.md`.

### 53.1 ★★ Tiling constantization — the fourth Scalar-bound case in this file, and the largest

案例介绍, verbatim:

> 本案例呈现了在使用Matmul高阶API进行矩阵乘法计算时，开启Matmul Tiling全量常量化对算子性能的提升效果。**Matmul API在初始化和迭代过程中有大量Scalar计算，Matmul初始化时的Scalar计算影响指令头开销，Matmul迭代间的Scalar计算可能阻塞MTE2流水。** 在调用Matmul API实现矩阵乘法时，使用 **MatmulApiStaticTiling** 参数替代TCubeTiling变量参数，**将Scalar计算提前到编译期进行**，以减少运行时的Scalar计算开销，实现算子性能的提升。
>
> - Matmul Tiling常量化的适用场景：
>     - Matmul初始化时的Scalar计算较多，影响指令头开销。
>     - Matmul迭代之间的Scalar计算较多，阻塞MTE2流水。
> - Matmul Tiling常量化需要在编译期确定部分Tiling参数，根据确定参数的不同，分为全量常量化和部分常量化两种场景，使用Matmul Tiling常量化需要满足两种场景中任一场景的条件：
>     - **全量常量化：能够确定常量singleCore Shape（singleCoreM/singleCoreN/singleCoreK）和常量base Shape（basicM/basicN/basicK，也称baseM/baseN/baseK）。**
>     - **部分常量化：能够确定常量base Shape（basicM/basicN/basicK，也称baseM/baseN/baseK）。**
>
>     其中，**全量常量化场景比部分常量化场景可以减少更多的Scalar计算开销。**

Spec: `a` (128, 64) float16 ND, `b` (64, 30720) float16 ND, M=128 N=30720 K=64, 24 AIC cores, pure-Cube mode,
singleCoreM=128 singleCoreN=1280 singleCoreK=64, baseM=128 baseN=256 baseK=64, stepM=1 stepN=1 stepKa=4
stepKb=4 depthA1=8 depthB1=8 — i.e. the same case as §B8.6's pure-Cube one, tuned further.

The measurement, verbatim:

> - 优化前的流水图如下，默认不开启Tiling常量化，**Tiling参数需要从Host侧拷贝到核函数（Kernel）侧，导致Matmul初始化时的Scalar计算较多，第一个MTE2指令开始于3.536us左右**，MTE2前的指令头开销在算子整个流水中占比较大，因此需要优化Scalar计算。
> - 优化前的Profiling数据如下，从C列的aic_time数据来看，多个核中最大算子执行耗时为 **10.62us**，从G列的aic_scalar_time数据来看，Scalar平均耗时 **6.32us**。
> - 优化后的流水图如下，通过开启Tiling全量常量化，无需将Tiling参数从Host侧拷贝到核函数（Kernel）侧，在编译期完成Tiling常量化，减少了Matmul初始化时的Scalar计算。**从0us起到第一个MTE2指令发起，这之间的时间为Matmul初始化时间，Matmul初始化时间从优化前的3.536us减少到2.185us**，性能有所提升。
> - 优化后的Profiling数据如下，从C列的aic_time数据来看，多个核中最大算子执行耗时为 **7.87us**，相较于优化前的10.62us提升了 **25.9%**。从G列的aic_scalar_time数据来看，Scalar平均耗时 **3.38us**，相较于优化前的6.32us提升了 **46.5%**。

**`aic_time` 10.62 → 7.87 us (−25.9%), `aic_scalar_time` 6.32 → 3.38 us (−46.5%), Matmul init 3.536 → 2.185 us.**

### 53.2 ★★ The 256-byte inner-axis rule — and doing ND2NZ on the AIV instead, −39.0%

案例介绍, verbatim. This is a *data-layout* rule we did not have:

> 本案例展示了在矩阵乘算子场景中，使用Matmul高阶API进行计算，**对内轴（内轴即矩阵的行方向）非256字节对齐的输入矩阵**，在AIV核上进行ND2NZ格式转换对算子性能提升的效果。为提升Cube单元的计算效率，ND格式的输入矩阵在执行Cube计算前会先转换为NZ格式… Matmul API内部使用随路ND2NZ指令同时进行格式转换以及数据搬运。**但在数据非256字节对齐时，随路ND2NZ指令存在带宽利用率低的问题。** 因此输入矩阵的内轴非256字节对齐时，在进行Matmul计算前，利用AIV核上Vector计算单元完成ND格式到NZ格式的转换，可以避免随路非对齐数据搬运存在的效率低的问题，从而提升算子性能。
>
> - AIV核上的ND2NZ格式转换的适用场景
>   **输入矩阵内轴非256字节对齐，且数据量较大影响随路格式转换的效率。**

Spec: `a` (1024, 1024) float16, M=1024, **N=4095**, K=1024 — N deliberately one short of alignment.
singleCoreM=128 singleCoreN=1408 singleCoreK=1024, baseM=128 baseN=256 baseK=64, stepM=1 stepN=1 stepKa=4
stepKb=4.

The measurement, verbatim:

> - 优化前的Cube流水图如下，由于使用了随路ND2NZ指令，在MTE2数据搬运过程中进行数据格式的转换，导致MTE2整体占比较高。
> - 优化前的Profiling数据如下，可以看到只使用Cube单元执行计算，**aic_time最大耗时149.04us**，其中aic_mte2_ratio占比很高。
> - 优化后的Vector流水图如下所示，利用Vector计算单元的能力，完成B矩阵的数据格式转换。
> - 优化后的Cube流水图如下所示，不使用随路ND2NZ指令对B矩阵进行格式转换后，MTE2的占比明显下降。
> - 优化后的Profiling数据如下，可以看到同时使用Cube单元和Vector单元，**aic_time最大耗时90.95us**，其中aic_mte2_ratio占比明显降低。

and the summary, with its warning, verbatim:

> 对于矩阵乘计算中矩阵内轴非256字节对齐的场景，随路ND2NZ指令的带宽利用率低，影响算子性能，通过在AIV核上进行ND2NZ的数据重排，提升算子整体性能。**值得注意的是，带宽利用率与数据量有关，如果矩阵数据总量太小，即使是在AIV核上进行的ND2NZ转换也无法明显提升有效带宽，反而会因为引入了多核同步，导致算子端到端的性能劣化。**

**`aic_time` max 149.04 → 90.95 us, −39.0%** — the largest single-knob delta in the whole guide.

### 53.3 NBuffer33 — balancing MTE2 against FixPipe, with six constraints

案例介绍, verbatim:

> NBuffer33模板的实现为**单核计算的A矩阵切分为3x3个基本块，该3x3个A矩阵的基本块全载和保持在L1 Buffer中，每次与3x1个B矩阵的基本块计算矩阵乘，同时DoubleBuffer并行搬入下次计算所需的3x1个B矩阵基本块**，直到singleCoreN方向的矩阵乘计算完成。针对MTE2 Bound场景，通过NBuffer33算法的切分数据方式，**错开搬运流水，减少单次搬运的数据量，平衡MTE2和FixPipe的数据流量，让两者带宽均匀分布**。
>
> - 开启NBuffer33模板的适用场景：MTE2 Bound的场景，Tiling参数满足约束条件时，可以开启NBuffer33模板。
> - 开启NBuffer33模板的约束条件
>     - **仅支持MatmulConfig为MDL模板。**
>     - **A矩阵、B矩阵的内存逻辑位置只支持TPosition::GM。**
>     - **仅支持纯Cube模式（只有矩阵计算），暂不支持MIX模式（包含矩阵计算和矢量计算）。**
>     - **仅支持通过IterateAll接口获取Matmul的计算结果C矩阵。**
>     - **stepM、stepKa、stepKb小于等于3，且满足：stepKa=stepKb=Ceil(singleCoreK/baseK)。**
>     - **A矩阵全载的基本块大小与B矩阵载入的基本块大小之和不超过L1 Buffer的大小。**

Spec: M=256 N=512 K=192, singleCoreM=256 singleCoreN=256 singleCoreK=192, baseM=128 baseN=256 baseK=64,
stepM=2 stepN=1 stepKa=3 stepKb=3. Result, verbatim:

> - 优化前的流水图如下，MatmulPolicy的默认模板下A、B矩阵全载，A、B矩阵都只搬运一次。此时MTE2执行时间较长，且流水整体呈串行。
> - 优化前的Profiling数据如下，**aic_time平均耗时34.01us**。
> - 优化后的流水图如下，Tiling参数不变，但由于stepM为2，NBuffer33模式会将左矩阵数据的搬运拆分为两次。可以看到，**第一次MTE2结束后的计算过程（包括MTE1、MMAD和FIXPIPE）可以和第二次MTE2并行**。分块搬运数据可以减少一次搬运数据导致的部分头开销，优化加载数据的性能。
> - 优化后的Profiling数据如下，**aic_time平均耗时32.66us**，较优化前的34.01us有所提升。

**34.01 → 32.66 us, −4.0%.**

## Relevance

53.2 is the finding to check first because it is a property of our *weight shapes*, not of our code. The
on-the-fly ND2NZ instruction that `Matmul` uses by default has poor bandwidth utilization whenever the input's
**inner (row-direction) axis is not 256-byte aligned**, and the vendor's fix — doing the ND→NZ rearrangement on
the AIV instead — is worth **−39.0%** on their case, the largest single-knob delta in the guide. For
`int4b_t`, 256 bytes is **512 elements**. GLM-5.2's `hidden = 5120` is 2560 bytes, a clean 10 × 256; but
`moe_intermediate = 1792` is **896 bytes = 3.5 × 256, which is not aligned**. So any matmul whose inner axis
is the 1792 one — the down-projection's K — sits in exactly the bad regime this case describes, and would
present as a high `aic_mte2_ratio` with no obvious cause. Two caveats before acting: the weights in the
GroupedMatmul tuning case (§B8.1 表1) are already **NZ** on disk, which sidesteps the conversion entirely and
is the cheaper answer if we control the offline layout; and the document's own warning is that below some data
volume the AIV route loses — 「如果矩阵数据总量太小…反而会因为引入了多核同步，导致算子端到端的性能劣化」.

53.1 is the fourth Scalar-bound case in this file and the largest, and it is the operator-level number behind
the 2.845 → 0.038 us TilingData figure we already had: **`aic_time` −25.9%, `aic_scalar_time` −46.5%, Matmul
init 3.536 → 2.185 us**, purely from passing `MatmulApiStaticTiling` instead of a runtime `TCubeTiling`. Two
gates, and batch=1 specialization satisfies the stronger one: 全量常量化 needs constant `singleCoreM/N/K` **and**
constant `baseM/N/K`; 部分常量化 needs only constant `base*`. The sentence to note is that the Scalar cost
appears in two places, not one — 「Matmul初始化时的Scalar计算影响指令头开销，Matmul迭代间的Scalar计算可能阻塞
MTE2流水」 — so constantization is both a head-overhead fix and an MTE2-stall fix.

53.3 is the smallest of the three (−4.0%) and the most constrained, but its mechanism is the one worth
remembering: NBuffer33 exists to **balance MTE2 against FixPipe bandwidth** by splitting one large A load into
staggered pieces so that MTE1/MMAD/FIXPIPE on piece one overlaps MTE2 on piece two. Its six constraints are
restrictive and two of them conflict with other levers we want: **pure-Cube only, no MIX** (so it cannot
coexist with an in-kernel vector stage), and **`IterateAll` only** (so no per-`Iterate` CV handoff, the same
exclusion IBShare-AB carries in §52.1). Its tiling gate is exact and checkable:
`stepM, stepKa, stepKb <= 3` with `stepKa = stepKb = Ceil(singleCoreK / baseK)`, and A's fully-loaded blocks
plus B's loaded blocks must fit L1.

## 54. ★★★ The Matmul GM-traffic formula, the base-block selection criteria, large-packet transfer — and what they prove about a batch=1 roofline gap

Source: `docs/zh/guide/operator_practice/best_practices/matmul_tuning_cases/matmul_tiling_strategy.md`,
「Matmul算子优化Tiling策略」, in the shipped devkit. Read 2026-10-20. Case: M=4096, N=5120, K=4096, half in,
float out, ND output, on A2, 20 cores each with 1 Cube and 2 Vector.

### 54.1 ★★★ The traffic formula

分析主要瓶颈点, verbatim — this is the analytical core and it is worth reading twice:

> - Profiling数据的Block Dim可见分核未分满，考虑分核逻辑的优化。设CurrentCore是未优化前分核的Cube核数，MaxCore为最大Cube核数，当开启全部核并行做当前shape数据量的计算时，**预估性能收益为MaxCore / CurrentCore的倍数**。
> - 优化基本块切分，将影响搬运数据的效率，算子搬运的总数据量为搬运的左矩阵和右矩阵数据量之和。**在Matmul计算K方向不能全载的场景下，根据矩阵乘法的算法，搬运左矩阵的次数为 N / baseN，搬运右矩阵的次数为 M / baseM，即搬运总数据量 totalCnt = (N / baseN) * M * K + (M / baseM) * K * N。** 预估性能收益为搬运数据量的比值，优化前搬运数据量totalCnt0/优化后搬运数据量totalCnt1，**化简后结果为 (1 / baseM0 + 1 / baseN0) / (1 / baseM1 + 1 / baseN1)**，其中，baseM0, baseN0为优化前基本块参数，baseM1, baseN1为优化后基本块参数。
> - 开启大包搬运后，指令条数变化、地址对齐等因素会影响性能，按照经验预估，**对于MTE2为性能瓶颈的场景，会有20%以上的MTE2性能收益**。

So, with K not fully resident:

```
totalCnt = (N / baseN) * M * K  +  (M / baseM) * K * N
         = M * N * K * (1/baseN + 1/baseM)
```

**Matmul GM traffic is proportional to `(1/baseM + 1/baseN)`** — the harmonic sum of the two output-tile
dimensions, and nothing else. `baseK` does not appear.

### 54.2 ★ Base-block selection: maximize compute-per-byte, subject to a 512-byte output-offset constraint

优化点二, verbatim and complete — note that the *rejected* block was rejected partly on an alignment ground:

> 当前Tiling中设置的base块为 [baseM, baseN, baseK] = [64, 64, 256]，这种基本块Cube计算cycle少，计算访存比（即计算量与需要数据量的比值）低；**搬出一次Matmul结果到GM的base块是64 * 64，由于输出格式是ND，数据类型是float，搬出下一次Matmul结果的起始地址需要偏移一个baseN的大小，即 64 * 4 = 256字节，导致fixpipe搬出时GM地址非512byte对齐**，那么需要设置更优的基本块。
>
> 针对当前shape较大的场景，**基本块的选择原则为计算访存比最大，即在Cube计算量最大的情况下，访存的数据量最小。在输入为fp16类型的情况下，Cube执行单元1 cycle能算 16 * 16 * 16 个数。** 根据经验，[baseM, baseN, baseK] = [128, 256, 64] 和 [128, 128, 128] 两种切分方案均满足搬出时GM地址512Byte对齐（每搬出一次Matmul结果时，地址分别偏移 256 * 4byte 和 128 * 4byte），Cube计算cycle数一致，为 (128 * 64 * 256) / (16 * 16 * 16) = (128 * 128 * 128) / (16 * 16 * 16) = 512cycle。针对 [128, 256, 64]，计算访存比为 512cycle / (128 * 64 * 2 + 256 * 64 * 2) = 512cycle / 48KB；针对 [128, 128, 128]，计算访存比为 512cycle / (128 * 128 * 2 + 128 * 128 * 2) = 512cycle / 64KB；**可见 [128, 256, 64] 基本块方案的计算访存比更高，计算密度更大**，同样的计算量，需要的数据量最小，最大限度提高Cube单元的计算量。
>
> 修改Tiling代码，通过 **SetFixSplit()** 接口设置baseM和baseN，tiling函数会自动计算出最优baseK，这里得到64。

```cpp
    tilingApi.SetShape(M, N, K);
    tilingApi.SetFixSplit(baseM, baseN, -1);
```

Two criteria, then:

1. **Compute-to-memory ratio.** Cube does `16*16*16` elements per cycle for fp16, so a block costs
   `baseM*baseN*baseK / 4096` cycles and loads `(baseM*baseK + baseN*baseK) * sizeof(dtype)` bytes. Maximize
   the ratio. `[128,256,64]` wins over `[128,128,128]` at equal cycles: 48 KB against 64 KB.
2. **The Fixpipe output offset must be 512-byte aligned.** The next result tile starts one `baseN` later, so
   the constraint is on `baseN * sizeof(outputDtype)`: `64*4 = 256` bytes fails, `256*4 = 1024` and
   `128*4 = 512` pass. **For an int32 output that means `baseN` must be a multiple of 128; for a half output,
   a multiple of 256.**

### 54.3 Large-packet transfer: `depthA1` / `depthB1`, and a measured bandwidth number

案例介绍 and 优化点三, verbatim:

> - 开启大包搬运：从GM搬运数据到L1时，**对于A矩阵，一次搬入depthA1个基本块，基本块大小为baseM * baseK，对于B矩阵，一次搬入depthB1个基本块，基本块大小为baseN * baseK。开启大包搬运后，一次搬入的数据量变大，从而提升MTE2搬运效率。**
>
> - 当前带宽利用率为：totalSize / mte2Time = totalCnt * dtype / mte2Time，代入数据计算为 **2491GB/s**。未开启大包搬运的情况下，矩阵从GM搬运到L1一次只搬运1个基本块。通过模板参数开启大包搬运，一次搬运多个基本块，提高MTE2带宽利用率。
> - 从下图可以看到，开启大包搬运后，**MTE2耗时从808us下降到591us，带宽利用率代入数据计算为3406GB/s，利用率提升36%+，Cube利用率达到80%+**。

### 54.4 The measured ladder, each step against its prediction

验证优化方案性能收益, verbatim:

> - 优化分核逻辑，**实际收益4.75倍**，约等于 (20核 / 4核) = 5倍收益，并且考虑到核的启动开销，可以认为收益一致。
> - 优化基本块，**实际收益约3倍**，理论评估代入上述分析公式，收益为 (1/64 + 1/64) / (1/128 + 1/256)，**约等于2.7倍**，考虑到cache缓存的影响，认为收益一致。
> - 大包搬运，**实际收益25%+**，与经验值一致。

with the absolute numbers from 优化点一 and 优化点二: 「修改代码后，算子执行时间从 **12045us** 下降到 **2532us**」
and 「使用这组基本块后，MTE2耗时（对应aic_mte2_time）从 **2452us** 降低到 **808us**，MTE2性能提升3倍」.

And the scope caveat, 总结, verbatim:

> **优化点一和优化点二的适用场景，需要shape足够大，数据量足够多，才能分满核和开启最优的基本块。** 大shape场景下，MTE2 Bound算子可参考此案例的优化手段。

## Relevance

54.1's formula settles what a batch=1 roofline gap can and cannot be, by arithmetic rather than by profiling.
With `totalCnt = M*N*K*(1/baseM + 1/baseN)` and **M = 1** (or 8 under the MSD stack), `M / baseM` is 1 — you
cannot tile below one row — so the right-matrix term collapses to `1 * K * N`: **the weight is loaded exactly
once, which is the theoretical floor.** The left-matrix term `(N/baseN) * M * K` is negligible at M=1. So at
decode our matmuls are *already* at minimum GM traffic volume, and no base-block choice can reduce it, because
the only lever the formula offers is `1/baseM`, which is pinned.

**Therefore the measured gap between time spent and bytes moved cannot be traffic volume. It must be traffic
efficiency, or Scalar.** Everything else in §49-§53 then reads as a list of the available mechanisms, each with
a vendor measurement behind it:

- *efficiency of the same bytes* — the 512-byte same-address serialization when every core reads one weight
  (§50.4, fixed by rotation; measured −13.2% as K-staggering in §51.2 and −7.1% as 错位分核 in §51.3);
  transfers below 16 KB not saturating bandwidth (§50.5); a 256-byte-misaligned inner axis crippling the
  on-the-fly ND2NZ (§53.2, −39.0%); duplicate fetches of a shared operand (§52, MTE2 −15.46%); a
  non-512-byte-aligned Fixpipe output offset (§54.2); one base block per MTE2 instead of `depthA1`/`depthB1`
  of them (§54.3, 2491 → 3406 GB/s, +36%); and L2 thrash from an unhinted read-once weight (§50.6, §B8.4).
- *Scalar* — the KFC message framework in MIX-mode `Matmul` (§B8.6, `aic_scalar_time` 15.02 → 5.17 us);
  runtime rather than compile-time tiling (§53.1, −46.5%); and a cube-view core split with IBShare (§52.2,
  26.27 of 27.11 us was Scalar).

54.4's honesty about its own scope is the caution to keep: 「需要shape足够大，数据量足够多，才能分满核和开启最优
的基本块」. Optimization points one and two of *this* case are for large shapes and do not transfer to us —
indeed 54.1's core-count lever points the opposite way from §50.3's advice to launch *fewer* cores at
microsecond scale, and the reconciliation is simply which regime you are in: under-split a millisecond operator
and you lose a factor of `MaxCore/CurrentCore`; over-split a microsecond one and you pay head overhead that
grows with core count. At 12.389 ms across two GroupedMatmul families and ~6.5 MIX_AIC calls per layer, we are
plausibly in *both* regimes at different points in the round, which is an argument for measuring per-call
rather than per-family.

54.2's two criteria are directly usable despite the scope caveat, because they are constraints rather than
sizing advice: maximize `baseM*baseN*baseK / ((baseM+baseN)*baseK*sizeof(dtype))`, and keep
`baseN * sizeof(outputDtype)` a multiple of 512 so the Fixpipe drain address stays aligned — a multiple of 128
for `baseN` with an int32 output, 256 with a half output. `tilingApi.SetFixSplit(baseM, baseN, -1)` lets the
tiling function derive the best `baseK` from a chosen `baseM`/`baseN`.

## 55. ★★★ Working public code for both kernel types — the `MIX_AIC_1_0` cube-only idiom, and the vendor's own FFN kernel using `AIC_ONLY` as its default with per-tiling-key overrides

Sources, read 2026-10-20 via `gh`:

- https://github.com/XPU-Forces/mojo_opset — `native/src/npu_a2/group_gemm_fwd/kernel.cpp` and
  `native/src/npu_a2/group_gemm_bwd/kernel.cpp`
- https://github.com/hicann/ops-transformer — `experimental/ffn/swiglu_gated_mlp/op_kernel/swiglu_gated_mlp.cpp`

§50.1 established from the official page that `KERNEL_TYPE_AIC_ONLY` is listed as supported on A3, contradicting
our measured submission failure, and §50.2 identified `KERNEL_TYPE_MIX_AIC_1_0` as the cube-only type that
carries the hard sync. This section is the working code for both, which settles the question by existence rather
than by documentation.

### 55.1 ★ The `MIX_AIC_1_0` idiom, complete, from a grouped-GEMM kernel

`XPU-Forces/mojo_opset`, `native/src/npu_a2/group_gemm_fwd/kernel.cpp`, verbatim and complete — the `bwd`
sibling is byte-identical in its first thirteen lines:

```cpp
#include "../common/group_tiling.h"
#include "../common/group_gemm_training.h"
#include "../common/group_gemm_training_epilogue.h"
#include "../common/group_gemm_training_main_loop.h"
extern "C" __global__ __aicore__ void MOJO_GROUP_KERNEL(GM_ADDR input, GM_ADDR weight, GM_ADDR counts,
                                                        GM_ADDR output, GroupTiling tiling) {
  KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_0);
  if ASCEND_IS_AIV {
    return;
  }
  static_assert(sizeof(TCubeTiling) <= sizeof(tiling.matmul), "increase native TCubeTiling payload");
  TCubeTiling matrix = *reinterpret_cast<TCubeTiling *>(tiling.matmul);
  AscendC::TPipe pipe;
  using Config = mojo::native::a2::kernels::GroupGemmKernelConfig<false, MOJO_GROUP_TRANS_A,
                                                                  MOJO_GROUP_TRANS_B, false, false>;
  using Gemm = mojo::native::a2::kernels::GroupGemm<DTYPE_INPUT, DTYPE_INPUT, Config>;
  using Epi = mojo::native::a2::kernels::GroupGemmEpilogueNone;
  mojo::native::a2::kernels::GroupGemmMainLoop<Gemm, Config, Epi> op;
  op.init(input, weight, nullptr, counts, output, nullptr, &tiling.base, matrix, nullptr, pipe);
  op.process();
}
```

Four things to read off it:

1. **`__global__ __aicore__`, not `__mix__`.** The cube-only-with-hard-sync shape does not use the `__mix__`
   attribute at all; the kernel type is declared with `KERNEL_TASK_TYPE_DEFAULT`.
2. **`KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_0);` is the first statement in the kernel body**, before
   anything else.
3. **It is immediately followed by `if ASCEND_IS_AIV { return; }`** — an explicit, hand-written vector-half
   exit, exactly the shape `REGIST_CUBE_OBJ` generates for us under `ASCENDC_CUBE_ONLY` (§47.4). So even with
   `MIX_AIC_1_0` the author still writes the guard rather than relying on the type alone.
4. `AscendC::TPipe pipe;` is declared after the guard, so only the cube half constructs it — which also
   satisfies §48.1's `InitSocState` requirement on the half that runs (「在TPipe框架编程中，初始化过程由TPipe
   完成」) and leaves the vector half having returned before any state is touched.

### 55.2 ★★ `AIC_ONLY` in the vendor's own SwiGLU gated MLP, as the default, with per-tiling-key overrides

`hicann/ops-transformer`, `experimental/ffn/swiglu_gated_mlp/op_kernel/swiglu_gated_mlp.cpp`, verbatim — note
the parameter list, which is our expert chain: `x`, `gate_up_weight`, `down_weight`, `y`:

```cpp
    GM_ADDR x_gm,
    GM_ADDR gate_up_weight_gm,
    GM_ADDR down_weight_gm,
    GM_ADDR y_gm,
    GM_ADDR workspace,
    GM_ADDR tiling)
{
    REGISTER_TILING_DEFAULT(SwigluGatedMlpTilingData);
    KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(100, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(1101, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(1102, KERNEL_TYPE_AIV_ONLY);
    KERNEL_TASK_TYPE(1103, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(2101, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(2102, KERNEL_TYPE_AIV_ONLY);
    KERNEL_TASK_TYPE(2103, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(2104, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(3101, KERNEL_TYPE_AIC_ONLY);
    KERNEL_TASK_TYPE(3102, KERNEL_TYPE_AIV_ONLY);
    KERNEL_TASK_TYPE(3103, KERNEL_TYPE_AIC_ONLY);

    if (TILING_KEY_IS(WG_MLP_EMPTY_TILING_KEY)) {
        return;
    }

    GET_TILING_DATA(tilingData, tiling);
```

**`KERNEL_TYPE_AIC_ONLY` is the global default here, in a shipped vendor FFN kernel**, and the per-tiling-key
overrides switch three branches (`1102`, `2102`, `3102`) to `KERNEL_TYPE_AIV_ONLY` while nine stay `AIC_ONLY`.
Note the numbering: the `x101`/`x103`/`x104` branches are cube work and the `x102` branches are vector work, so
the operator is **decomposed into pure-AIC and pure-AIV stages selected by tiling key, with no MIX branch at
all.**

### 55.3 Who else ships `AIC_ONLY`

`gh search code "KERNEL_TYPE_AIC_ONLY"`, 2026-10-20, first page:

```
inclusionAI/AReno              areno/accel/csrc/npu/fused_experts_matmul_kernel.cpp
huawei-csl/pto-kernels         csrc/kernel/kernel_simple_matmul.cpp
huawei-csl/pto-kernels         csrc/kernel/kernel_batch_matrix_square.cpp
huawei-csl/pto-kernels         csrc/kernel/kernel_scan_ul1.cpp
huawei-csl/pto-kernels         csrc/kernel/kernel_tri_inv_trick.cpp
huawei-csl/pto-kernels         csrc/kernel/kernel_tri_inv_ns.cpp
huawei-csl/pytorch-tcuscan     src/row_scan.cpp
huawei-csl/pytorch-tcuscan     src/block_scan.cpp
hw-native-sys/pto-isa          docs/isa/tile/ops/sync-and-config/syncall.md
sgl-project/sgl-kernel-npu     csrc/batch_matmul_transpose/op_kernel/batch_matmul_transpose_kernel.cpp
xLLM-AI/xllm-ops               xllm_ops/index_group_matmul/op_kernel/index_group_matmul.cpp
hicann/ops-transformer         experimental/ffn/swiglu_gated_mlp/op_kernel/swiglu_gated_mlp.cpp
tilesim/vTriton                perfbound/calibration/microbench/mte_gm_to_l1.cce
tilesim/vTriton                perfbound/calibration/microbench/mte_l0c_to_gm.cce
UsernameFull/kda-ascendc       aclab/k2_min.cpp
```

Of particular note: `inclusionAI/AReno`'s `fused_experts_matmul_kernel.cpp` and `xLLM-AI/xllm-ops`'s
`index_group_matmul.cpp` are both fused MoE expert matmuls — our operator — declared `AIC_ONLY`.

## Relevance

This closes §50.1's contradiction by existence. `KERNEL_TYPE_AIC_ONLY` is not merely listed as supported on A3;
it is the **global default in Huawei's own SwiGLU gated MLP kernel** and appears in at least four other
production repos including two fused MoE expert matmuls. Our `sqe_type=3, errType=0x20` is therefore not the
scheduler refusing the type — consistent with the independent decode of that error from the open-source runtime
as a `RT_DAVID_SQE_TYPE_PLACE_HOLDER` SQE carrying `RT_STARS_CQE_ERR_TYPE_SW_STATUS`, rendered 「sq sw status
error」 (README corrections).

§55.1 is a copyable template for the cube-only megakernel, and it is four lines:
`__global__ __aicore__` (not `__mix__`), then `KERNEL_TASK_TYPE_DEFAULT(KERNEL_TYPE_MIX_AIC_1_0);` as the first
statement, then `if ASCEND_IS_AIV { return; }`, then the `TPipe`. The author writes the vector-half exit by hand
even though the type already says AIC:AIV 1:0 — which is the right instinct given §47.4, and which means the
guard and the type are complementary rather than redundant. That this appears in a *grouped GEMM* makes it the
closest public precedent to what we want.

§55.2 is a different architecture from the one we have been assuming, and it is worth considering on its merits.
Instead of one MIX kernel, the vendor decomposes the FFN into pure-AIC and pure-AIV stages selected by tiling
key — twelve `KERNEL_TASK_TYPE` lines, nine `AIC_ONLY` and three `AIV_ONLY`, no MIX branch anywhere. The payoff
is that no branch pays for cores it does not use, which is §50.3's point
(「Cube核并没有实际的计算指令，但仍会产生核启动和核初始化的头开销」) applied structurally: an AIV-only launch costs
0.70 us against MIX_AIV's 12.04, and an AIC-only launch 2.30 us against MIX_AIC's 13.58. Against an 11.5 ms
launch floor with 82% on MIX, that is the largest lever on the floor itself.

The catch for us is the project type. `KERNEL_TASK_TYPE(key, value)` is 「仅支持在自定义算子工程中使用」 (§50.2),
so a `<<<>>>` direct-launch project gets only `KERNEL_TASK_TYPE_DEFAULT` — one type per kernel binary. The
same decomposition is still available, but as **separate kernels** rather than tiling-key branches of one, which
trades the MIX overhead for additional launches and loses the single-launch property a megakernel wants. That
trade is worth computing: at our measured floors, replacing one MIX_AIC call (13.58 us) with one AIC_ONLY
(2.30 us) plus one AIV_ONLY (0.70 us) is 3.00 us against 13.58 — a 4.5x reduction in launch cost for the pair,
before counting whatever the handoff through GM costs.

## 56. ★★ `Mutex` / `Lock` / `Unlock` — the sanctioned alternative to `SetFlag`/`WaitFlag`, which compiles to NOTHING on 2201, and the production kernel that has a dead arm because of it

Sources, read 2026-10-20:
`/home/shanshan/repo/cann/asc-devkit/docs/zh/api/SIMD-API/basic_api/sync_control/intra_core_sync/Mutex_ISASI.md`
and its siblings `Lock.md`, `Unlock.md`, `AllocMutexID_ISASI.md`, `ReleaseMutexID_ISASI.md`;
`include/basic_api/kernel_common.h:136-180`; and
https://github.com/vllm-project/vllm-ascend — `csrc/attention/common/op_kernel/init_output.h`.

This surfaced from an adversarial check on §43.5: searching public code for `WaitFlag<HardEvent::MTE3_V>` to see
whether anyone uses it on a cube half. Nobody does — every hit in `vllm-project/vllm-ascend` is in a
vector-side file (`sparse_flash_mla_csa_block_vector.h`, `sparse_flash_attention_service_vector_mla.h`,
`sparse_flash_mla_swa_block_vector.h`, `msa_index_score_epilogue.h`, `msa_seg_row_max_epilogue.h`,
`msa_cast_int8_to_fp16.hpp`), which corroborates §43.5's rule by convention. But one of those files turned out
to carry a second synchronization mechanism we had no record of.

### 56.1 What it is, and the vendor's own case for preferring it

`Mutex_ISASI.md`, verbatim:

> Mutex用于核内异步流水指令之间的同步控制，其功能类似于传统CPU中的锁机制。通过先锁定再释放指定流水来完成流水间的同步依赖，锁定/解锁指定流水对应Lock/Unlock接口。
>
> - **Lock**：根据MutexID获取Mutex，若Mutex已被锁定，将阻塞后续指定流水指令队列，直到当前流水的前序指令中对应MutexID的Mutex被Unlock。
> - **Unlock**：直到当前流水的前序指令执行完成后，根据MutexID释放对应Mutex。
>
> 每个锁有固定的一个MutexID，在不同编程范式中，该ID的获取以及释放方式不同：
> - 采用TPipe-TQue框架编程范式时，MutexID需要通过AllocMutexID/ReleaseMutexID进行申请释放。
> - 采用静态Tensor编程范式时，MutexID由开发者自行管理，**建议使用0-27，28-31为系统内部规划预留，不建议使用**。
>
> 相对于SetFlag/WaitFlag同步机制，使用Lock/Unlock接口有以下优势：
> - **内聚性更强，使用时与其它流水线解耦，可以简化反向同步**，如图2所示，以PIPE_MTE2与PIPE_V之间同步为例。
> - **可以使用更多的同步信号量。**

```cpp
class Mutex {
template <pipe_t pipe>
static __aicore__ inline void Lock(MutexID id);
template <pipe_t pipe>
static __aicore__ inline void Unlock(MutexID id);
};
```

So it is a per-pipe lock with **28 usable ids (0-27)** against `SetFlag`/`WaitFlag`'s 6 hand-allocatable event
ids per `HardEvent` (§48.1: 0-5, since 6 and 7 are reserved), and its stated advantage is exactly the pain
point §43 documents — 「简化反向同步」, simplifying the reverse direction, which is the half of a reused-buffer
protocol that §46.3 says is easy to get wrong.

### 56.2 ★★ It does not exist on 2201 — `不支持`, and the bodies compile to nothing

产品支持情况, verbatim and identical on `Lock.md`, `Unlock.md`, `AllocMutexID_ISASI.md` and
`ReleaseMutexID_ISASI.md`:

```
- Ascend 950PR/Ascend 950DT：支持
- Atlas A3 训练系列产品/Atlas A3 推理系列产品：不支持
- Atlas A2 训练系列产品/Atlas A2 推理系列产品：不支持
- Atlas 200I/500 A2 推理产品：不支持
```

And the headers do not merely omit it — they define it as an empty function.
`include/basic_api/kernel_common.h:136-178`, verbatim:

```cpp
using MutexID = uint8_t;

class Mutex {
public:
    template <pipe_t pipe>
    static __aicore__ inline void Lock(MutexID id)
    {
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102))
        ASCENDC_ASSERT((id <= MAX_MUTEXID), {
            KERNEL_LOG(KERNEL_ERROR, "For Mutex::Lock current id is %u, max MutexID is %u", id, MAX_MUTEXID);
        });
        GetBufInternal<pipe, 0>(id);
#endif
    }

    template <pipe_t pipe>
    static __aicore__ inline void Unlock(MutexID id)
    {
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102))
        ASCENDC_ASSERT((id <= MAX_MUTEXID), {
            KERNEL_LOG(KERNEL_ERROR, "For Mutex::Unlock current id is %u, max MutexID is %u", id, MAX_MUTEXID);
        });
        RlsBufInternal<pipe, 0>(id);
#endif
    }
};

__aicore__ inline MutexID AllocMutexID()
{
#if defined(__NPU_ARCH__) && ((__NPU_ARCH__ == 3510) || (__NPU_ARCH__ == 5102))
    MutexID id = static_cast<uint8_t>(sff0(Internal::g_bufId));
    Internal::g_bufId = sbitset1(Internal::g_bufId, id);
    ASCENDC_ASSERT((id <= MAX_MUTEXID), { ... });
    return id;
#else
    return 0;
#endif
}
```

**On 2201 both `Lock` and `Unlock` have empty bodies and `AllocMutexID()` returns 0.** No `static_assert`, no
`#error`, no runtime log — the calls compile and do nothing.

### 56.3 ★ A production kernel with a dead arm

`vllm-project/vllm-ascend`, `csrc/attention/common/op_kernel/init_output.h`, verbatim:

```cpp
            LocalTensor<T> popBuffer =
                AscendC::LocalTensor<uint8_t>(TPosition::VECIN, POP_BUF_START_ADDR, POP_BUF_ELE_SIZE * sizeof(T))
                    .template ReinterpretCast<T>();

            if constexpr (ENABLE_LOCK) {
                Mutex::Lock<PIPE_V>(SYNC_ID);
            } else {
                AscendC::SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_ID);

                AscendC::WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_ID);
            }
            ...
                dataCopyParams.blockLen = tailSize * sizeof(T);
                dataCopyParams.srcStride = 0;
                dataCopyParams.dstStride = 0;
                AscendC::DataCopyPad(outGm[gmOffset], popBuffer, dataCopyParams);
            }
            if constexpr (ENABLE_LOCK) {
                Mutex::Unlock<PIPE_MTE3>(SYNC_ID);
            } else {
                AscendC::SetFlag<AscendC::HardEvent::MTE3_V>(SYNC_ID);

                AscendC::WaitFlag<AscendC::HardEvent::MTE3_V>(SYNC_ID);
            }
```

Two things worth lifting even apart from the trap. The `else` arm is the canonical drain idiom with **nothing
between the Set and the Wait** — `SetFlag<MTE3_V>(id); WaitFlag<MTE3_V>(id);` back to back, which is simply
"stall the vector until MTE3 has drained", and it is used in *both* positions: before the vector touches the
buffer and again after the store. And the store itself is **`DataCopyPad`, not `DataCopy`** — the AIC-safe form
of §47.2.

The trap: on A3, `ENABLE_LOCK = true` selects an arm in which **both** synchronization points vanish, because
`Mutex::Lock` and `Mutex::Unlock` have empty bodies on 2201 (§56.2). The `else` arm is correct; the `if` arm is
unsynchronized.

## Relevance

Two results. First, a negative one that saves time: `Mutex`/`Lock`/`Unlock` would be the better tool for our
reused-staging-buffer problem — 28 ids against 6, and the vendor's own stated advantage is
「简化反向同步」, which is precisely the reverse-direction row of §46.2 that a reused UB buffer needs — but it is
`不支持` on A3 on all five of its API pages, its bodies are `#if`-gated to 3510/5102 and empty on 2201, and
`AllocMutexID()` returns 0. **On this part `SetFlag`/`WaitFlag` is the only intra-core mechanism, and that is
settled rather than a preference.** Worth knowing before anyone proposes it, and worth knowing for forward
planning: on 950PR the lock route exists and is the vendor's recommended one.

Second, a tenth entry for the silent-failure list, and one that is live in code we may well be reading or
borrowing from: a `Mutex::Lock`/`Unlock` call on 2201 compiles to nothing with no diagnostic, so any kernel with
an `ENABLE_LOCK`-style switch has an arm that is **completely unsynchronized on A3 while looking synchronized in
the source.** `vllm-project/vllm-ascend`'s `csrc/attention/common/op_kernel/init_output.h` is exactly that
shape. If we lift code from the attention kernels — and §56's search shows the `MTE3_V` idiom we want lives in
precisely those files — check which arm the template flag selects before trusting it.

The corroboration that started this is worth recording too: every public use of `WaitFlag<HardEvent::MTE3_V>`
found by `gh search code` is in a vector-side file, by naming convention (`*_vector*.h`, `*_epilogue.h`,
`msa_cast_*.hpp`). Nobody puts an `MTE3_V` wait on a cube half, which is what §43.5 predicts must be true for
the code to work.

## 57. ★ `GetTaskRatio()`'s return table — a third independent statement of which halves each kernel type launches, and the licence to alternate AIVs over any loop

Source: `/home/shanshan/repo/cann/asc-devkit/docs/zh/api/SIMD-API/basic_api/tool_interface/system_resources_and_variables/GetTaskRatio.md`.
Read 2026-10-20.

产品支持情况, verbatim — note A3:

```
- Ascend 950PR/Ascend 950DT：支持
- Atlas A3 训练系列产品/Atlas A3 推理系列产品：支持
- Atlas A2 训练系列产品/Atlas A2 推理系列产品：支持
- Atlas 200I/500 A2 推理产品：不支持
- Atlas 推理系列产品AI Core：支持
- Atlas 推理系列产品Vector Core：不支持
- Atlas 训练系列产品：不支持
- Kirin X90：支持
- Kirin 9030：支持
```

功能说明 and 函数原型, verbatim:

> 头文件路径为：`"basic_api/kernel_operator_sys_var_intf.h"`。
>
> **分离模式**下，获取任务启动的Cube Core（AIC）或者Vector Core（AIV）的数量与逻辑AI Core数量的比例。
> - 在AIC上调用时返回AIC数量与逻辑AI Core数量的比例。
> - 在AIV上调用时返回AIV数量与逻辑AI Core数量的比例。
>
> **耦合模式**下，固定返回1。

```cpp
__aicore__ inline int64_t GetTaskRatio()
```

返回值说明, 表1, verbatim and complete:

> 针对分离模式，不同核函数（Kernel）类型下（通过设置核函数（Kernel）类型接口设置），在AIC和AIV上调用该接口的返回值如下：
>
> | 核函数（Kernel）类型 | KERNEL_TYPE_AIV_ONLY | KERNEL_TYPE_AIC_ONLY | KERNEL_TYPE_MIX_AIC_1_2 | KERNEL_TYPE_MIX_AIC_1_1 | KERNEL_TYPE_MIX_AIC_1_0 | KERNEL_TYPE_MIX_AIV_1_0 |
> | --- | --- | --- | --- | --- | --- | --- |
> | AIV | 1 | - | 2 | 1 | - | 1 |
> | AIC | - | 1 | 1 | 1 | 1 | - |

## Relevance

The `-` entries are the halves that do not run, so this table is an *official, independent* statement of each
kernel type's launch set, from a page that has nothing to do with §50.2's: **`AIC_ONLY` and `MIX_AIC_1_0` both
launch the AIC alone** (AIV row `-`), **`AIV_ONLY` and `MIX_AIV_1_0` both launch the AIV alone** (AIC row `-`),
and only `MIX_AIC_1_1` and `MIX_AIC_1_2` launch both, at ratios 1 and 2. That is now a **third** confirmation
that `KERNEL_TYPE_AIC_ONLY` is live on A3 — the type page (§50.1), working code in six repos (§55.3), and this
page's own 产品支持情况 listing A3 as 支持 — against our single measured `sqe_type=3, errType=0x20`, which the
runtime source decodes as a PLACE_HOLDER SQE with a software-status error rather than a type rejection.

It also licenses the fix for §B8.3's batch=1 problem. The vendor's two-AIV alternation is
`if (vecCount % taskRation != subBlockIdx) continue;` with `taskRation = GetTaskRatio()`, and this page says
`GetTaskRatio()` on an AIV under `MIX_AIC_1_2` returns **2** — i.e. it is the AIV-per-AIC count and nothing
more. The alternation is therefore over *whatever loop the author increments `vecCount` in*, not over M
specifically. So the §B8.3 precondition 「前提条件，循环次数不为1」 is a property of the chosen loop, not of the
mechanism: at batch=1, where the M loop may have a single iteration, moving `vecCount++` to the N loop
(`for (offsetN = 0; offsetN < curCubeSingleN; offsetN += baseN)`, which the same shipped code already has) keeps
both AIVs busy. That turns the −29.3% step from inapplicable into applicable.

One more thing worth noting from the 功能说明: 「耦合模式下，固定返回1」. On a coupled-architecture part
`GetTaskRatio()` is a constant 1, so any alternation written on it silently degenerates to "AIV 0 does
everything" there — a portability trap for code written against a separated part like ours.

## 58. ★★★ The complete AIV intra-core sync matrix on 2201, the four edges a hand-written kernel must name itself, and the one that is neither nameable with `PipeBarrier` nor inserted for you: Scalar

This section **supersedes part of §43** and **retires the premise of one commit in this repository**. §43 concluded
that `PipeBarrier`, `PIPE_ALL` included, is 「阻塞相同流水」 and therefore cannot cover a cross-pipe hazard. That
quotation is from the CANN 8.0.RC2.2 page. The CANN 9.2.0 page says the opposite in its 参数说明 and 约束说明, and
the correct objection to `PipeBarrier<PIPE_ALL>()` is cost, not coverage. What *is* true, and is what §43 was
reaching for, is narrower and sharper: **`PipeBarrier` cannot name `PIPE_S` at all**, so the Scalar edge is the one
edge no quantity of `PipeBarrier` reaches.

Source: the local devkit clone `/home/shanshan/repo/cann/asc-devkit/`, HEAD `6a51d0b167dd8f5555456a0ebb783ef0427e366e`,
whose version is CANN 9.2.0 (`version.cmake:11`). All paths below are relative to it.

### 58.1 An AIV has exactly four pipes, and the doc names `GetValue` as one of them

`docs/zh/api/SIMD-API/basic_api/sync_control/intra_core_sync/intra_core_sync_overview.md:33`:

> 四个执行单元Scalar、Vector、DMA（MTE2）、DMA(MTE3)并行执行，若访问同一片Local Memory，需要同步机制来控制它们的访问时序：保证先搬入Local Memory后再计算，计算完成后再搬出。

表1, 指令流水类型和相关说明, the first and the two DMA rows verbatim (`:47-53`):

> | 流水类型 | 含义 |
> | --- | --- |
> | PIPE_S | 标量流水线，使用GlobalTensor/LocalTensor的GetValue函数时为此流水 |
> | PIPE_V | 矢量计算流水及部分硬件架构下的L0C Buffer->UB数据搬运流水 |
> | PIPE_MTE2 | GM->L1 Buffer、GM->UB等数据搬运流水 |
> | PIPE_MTE3 | UB->GM、L1 Buffer->GM等数据搬运流水 |

`GetValue` is named in the PIPE_S row of the official pipe table. It is not a vector access that happens to be
scalar-ish; it is the canonical PIPE_S access. The declarations carry the compiler's marker for it —
`include/basic_api/kernel_tensor.h:176` and `:181`:

```cpp
    __aicore__ inline __inout_pipe__(S) PrimType GetValue(const uint32_t index) const;
    __aicore__ inline __inout_pipe__(S) void SetValue(const uint32_t index, const S value) const;
```

and the body is a bare dereference with no implicit wait, `impl/basic_api/kernel_tensor_impl.h:806-808`:

```cpp
    } else {
        return *(reinterpret_cast<__ubuf__ PrimType*>(GetPhyAddr(index)));
    }
```

### 58.2 表3 — every legal AIV sync combination, verbatim. `PipeBarrier` is only on the diagonal

Same file, 表3 「AIV中所有合法的核内同步组合」, `:91-96`, complete and unaltered:

> | 源流水 | PIPE_S | PIPE_V | PIPE_MTE2 | PIPE_MTE3 |
> | --- | --- | --- | --- | --- |
> | PIPE_S | 不涉及 | SetFlag\<S_V\>(0)<br>WaitFlag\<S_V\>(0) | SetFlag\<S_MTE2\>(0)<br>WaitFlag\<S_MTE2\>(0) | SetFlag\<S_MTE3\>(0)<br>WaitFlag\<S_MTE3\>(0) |
> | PIPE_V | SetFlag\<V_S\>(0)<br>WaitFlag\<V_S\>(0) | PipeBarrier\<PIPE_V\>() | SetFlag\<V_MTE2\>(0)<br>WaitFlag\<V_MTE2\>(0) | SetFlag\<V_MTE3\>(0)<br>WaitFlag\<V_MTE3\>(0) |
> | PIPE_MTE2 | SetFlag\<MTE2_S\>(0)<br>WaitFlag\<MTE2_S\>(0) | SetFlag\<MTE2_V\>(0)<br>WaitFlag\<MTE2_V\>(0) | PipeBarrier\<PIPE_MTE2\>() | SetFlag\<MTE2_MTE3\>(0)<br>WaitFlag\<MTE2_MTE3\>(0) |
> | PIPE_MTE3 | SetFlag\<MTE3_S\>(0)<br>WaitFlag\<MTE3_S\>(0) | SetFlag\<MTE3_V\>(0)<br>WaitFlag\<MTE3_V\>(0) | SetFlag\<MTE3_MTE2\>(0)<br>WaitFlag\<MTE3_MTE2\>(0) | PipeBarrier\<PIPE_MTE3\>() |

and its preamble, `:76`, which is what makes this table a *closed* list rather than a set of examples:

> 以NPU架构2201为例，该硬件架构下所有合法的核内同步组合如表2和表3所示。其中，"不涉及"表示硬件层面不存在此种同步组合，"暂无应用场景"表示存在此种同步组合，但在实际开发场景中暂不需要使用。

Sixteen cells. Four are `PipeBarrier` and they are the diagonal. One is 不涉及 (S→S). The other eleven are
`SetFlag`/`WaitFlag` and nothing else is offered. The practical reading: **on an AIV, `PipeBarrier` is for a
same-pipe dependency and a named event pair is for every other dependency.**

### 58.3 Correction to §43: `PipeBarrier<PIPE_ALL>()` *is* an all-pipe wait on 9.2.0 — but it cannot name `PIPE_S`

`docs/zh/api/SIMD-API/basic_api/sync_control/intra_core_sync/PipeBarrier_ISASI.md`, 参数说明 (`:55`):

> | pipe | 模板参数，表示阻塞的流水类别。<br>支持的流水参考硬件流水类型，其中**不支持PIPE_S**。<br>如果不关注流水类别，希望阻塞所有流水，可以传入PIPE_ALL。 |

约束说明, same file, the first three bullets verbatim:

> - Scalar流水之间的同步由硬件自动保证，PipeBarrier接口不支持PIPE_S单流水的同步。
> - `PipeBarrier<PIPE_ALL>()`会等待所有流水线中所有先前提交的接口完成，这会对性能产生影响。若仅阻塞单条流水线即可解决问题，应避免随意调用`PipeBarrier<PIPE_ALL>()`。
> - PIPE_MTE2/PIPE_MTE3在搬运地址有重叠的情况下需要开发者插入同步。例如，当需要执行多个DataCopy指令，且DataCopy的目的地址存在重叠时，需要调用PipeBarrier接口插入单流水同步指令，保证多个DataCopy指令的串行化，防止出现异常数据。

Three things follow, and the middle one overturns a claim this project acted on.

1. `PIPE_ALL` is a legitimate all-pipe drain — 「会等待所有流水线中所有先前提交的接口完成」. §43's "PIPE_ALL is not
   defined to cover a cross-pipe hazard" is **superseded**: it rested on the 8.0.RC2.2 wording 「阻塞相同流水」, which
   9.2.0 replaced. The reason to convert a `PipeBarrier<PIPE_ALL>` site to a named pair is that it drains everything
   (「这会对性能产生影响」), not that it fails to order anything.
2. `PIPE_S` is not a value `PipeBarrier` accepts — 「其中不支持PIPE_S」. So **a Scalar edge is the one edge that no
   `PipeBarrier`, `PIPE_ALL` included, can be written for.** 「Scalar流水之间的同步由硬件自动保证」 covers S→S only.
   An `MTE2`-written UB word read by `GetValue`, or a `SetValue`-written UB word read by `MTE3`, needs `MTE2_S`
   or `S_MTE3` from 表3 and has no barrier equivalent.
3. Two `DataCopy`s whose **destination** UB addresses overlap need a developer-inserted `PipeBarrier<PIPE_MTE2>()`
   between them. The vendor ships a figure for exactly this
   (`figures/datacopy_address_overlap_pipebarrier.png`). A function that loads one staging buffer twice is this
   case, not merely a WAR case.

### 58.4 `DataSyncBarrier<MemDsbT::UB>()` is not an instrument for any of this

`impl/basic_api/kernel_event.h:821-832`, the 2201 arm complete:

```cpp
template <MemDsbT arg>
__aicore__ inline void DataSyncBarrierImpl()
{
    if constexpr (arg == MemDsbT::UB) {
        if ASCEND_IS_AIC {
            return;
        }
    }
    dsb((mem_dsb_t)arg);
}
```

It is a scalar-side `dsb`, a no-op on the cube half for the `UB` selector, and its documented job is 「用于解决
Scalar的内存依赖」 — the scalar unit waiting on *its own* prior accesses. The `UB` selector has **zero** uses in the
whole shipped tree. It belongs next to a `DataCacheCleanAndInvalid` as the thing that waits for a cache-maintenance
op (§58.7), never in place of a 表3 event pair. A `DataSyncBarrier<MemDsbT::UB>()` placed before a `GetValue` of an
`MTE2`-written address orders nothing.

### 58.5 ★ The vendor's own proof that a `PIPE_ALL` bracket does not cover the Scalar edge

`impl/basic_api/dav_c220/kernel_operator_sync_impl.h:63-110`, `SoftSyncAllImpl` — the A3 soft `SyncAll`. It opens
with `PipeBarrier<PIPE_ALL>()` at `:70` and *still* writes the `MTE2_S` pair by hand before dereferencing the UB
word the copy just filled:

```cpp
    copy_gm_to_ubuf(static_cast<__ubuf__ void*>(localUbAddr), static_cast<__gm__ void*>(localSyncGM), 0, 1, 1, 0, 0);
    event_t eventIdMte2ToS = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::MTE2_S));
    SetFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    WaitFlag<HardEvent::MTE2_S>(eventIdMte2ToS);
    int32_t curValue = *(reinterpret_cast<__ubuf__ int32_t*>(localUbAddr)) + 1;
```

Three more shipped sites give the same idiom. `examples/01_simd_cpp_api/.../compare/compare.asc:61-64` and
`.../select/select.asc:63-66` use `MTE2_S`; `impl/basic_api/kernel_operator_block_sync_intf_impl.h:157-172` uses
`MTE2_S`; and `examples/05_simd_simt_hybrid/02_best_practices/simd_simt_adaptive_max_pool3d_grad/adaptive_max_pool3d_grad_common.h:53-57`
names it:

```cpp
__aicore__ inline void wait_mte2_to_scalar()
{
    asc_sync_notify(PIPE_MTE2, PIPE_S, EVENT_ID0);
    asc_sync_wait(PIPE_MTE2, PIPE_S, EVENT_ID0);
}
```

with `wait_v_to_scalar` and `wait_mte3_to_scalar` beside it. The rule is also stated in prose, in the memory-model
chapter, `docs/zh/guide/programming_guide/advanced_programming/memory_model/cache_coherence.md:590`:

> 其中，`sync V->S`用于保证同一AI Core内Scalar读取发生在Vector写UB之后；`Scalar.DCCI`用于处理DCache与UB的一致性，使Scalar后续读取不再使用旧DCache副本；`Scalar.DSB`用于等待DCCI相关操作完成。若生产者是MTE2把GM数据搬入UB，也需要先建立`MTE2 -> S`的流水顺序，再处理Scalar DCache中的旧UB副本。

### 58.6 ★★★ `--cce-auto-sync` would insert the Scalar edges for you — and a bare `bisheng` command line does not have it

This is the trap, because the documentation's phrasing invites the opposite conclusion.
`docs/zh/api/SIMD-API/basic_api/sync_control/intra_core_sync/key_features.md:135`:

> - 异构编译直调（<<<>>>调用）、核函数（Kernel）直调算子工程以及自定义算子开发工程已默认设置`--cce-auto-sync=on`，如果开发者手动设置`--cce-auto-sync=off`，毕昇编译器无法自动插入同步。

Read as "a `<<<>>>` kernel has auto-sync", that sentence is wrong. 「已默认设置」 is a statement about the *project
templates*, not about the compiler. The option is listed as optional and opt-in in the compile-option table,
`docs/zh/guide/programming_guide/compilation_and_execution/operator_compilation/ai_core_operator_compilation.md:119`:

> | --cce-auto-sync | 否 | 开启毕昇编译器自动同步。AI Core内部的执行单元是异步并行的，Tensor的读写可能存在数据依赖，开启后可由毕昇编译器自动插入部分同步。 |

and the build system is what appends it — `tools/build/asc_op_compile_base/asc_op_compiler/compile_op.py:1100-1108`:

```python
    if (
        "--cce-auto-sync=off" not in compile_option_tuple.compile_options
        and js.get("auto_sync") is not False
    ):
        compile_option_tuple.compile_options.append("--cce-auto-sync")
        compile_option_tuple.compile_options.append("-mllvm")
        compile_option_tuple.compile_options.append("-api-deps-filter")
```

while the TBE path turns it **off** for A3 — `tools/build/asc_op_compile_base/common/ccec.py:329-337`:

```python
    if (
        get_soc_spec("SHORT_SOC_VERSION") != ASCEND_610LITE
        and get_soc_spec("SHORT_SOC_VERSION") != BS9SX2A
    ):
        if (
            get_soc_spec("SHORT_SOC_VERSION") != MC61AM21A
            and get_soc_spec("SHORT_SOC_VERSION") != ASCEND_950
        ):
            cmd += ["--cce-auto-sync=off"]
```

**Operational rule: if you invoke `bisheng -xcce` yourself, you have no auto-sync unless you typed
`--cce-auto-sync`.** Every kernel in `tests/glm52/` is built that way (`build.sh`:
`bisheng -xcce "$arch" -std=c++17 -O2 … -c …`), so every one of them is hand-synchronised in full, including the
PIPE_V↔PIPE_V edges.

What the option would have covered, had it been on — 表3 of the same file, `:171-176`:

> | 源流水\目的流水 | PIPE_S | PIPE_V | PIPE_MTE2 | PIPE_MTE3 |
> | --- | --- | --- | --- | --- |
> | PIPE_S | - | 支持 | 支持 | 支持 |
> | PIPE_V | 支持 | 支持 | - | - |
> | PIPE_MTE2 | 支持 | - | - | - |
> | PIPE_MTE3 | 支持 | - | - | - |

i.e. every edge touching PIPE_S, in both directions, plus V→V — and **none** of V↔MTE2, V↔MTE3. Note the shape of
that coverage: the compiler takes exactly the edges a `PipeBarrier` cannot express, and leaves the ones it can. The
`PIPE_S` side must additionally be an allowlisted API, and `GetValue`/`SetValue` are on the list (`:138-140`):

> - 属于PIPE\_S的接口必须在以下接口集合内：
>     - Tensor标量读写：LocalTensor::GetValue、LocalTensor::SetValue、LocalTensor::operator()、GlobalTensor::GetValue、GlobalTensor::operator()。
>     - Vector归约辅助：GetReduceRepeatMaxMinSpr、GetReduceRepeatSumSpr。
>     - 排序组合：GetMrgSortResult。

and raw `__ubuf__` pointer arithmetic defeats it (`:182`): 「操作x_local的第0个元素时直接通过指针访问。此时，毕昇编译器
无法在PIPE_MTE2（asc_copy_gm2ub）与PIPE_S之间自动插入同步」.

### 58.7 The `CTRL[49]` second hazard on the same read

`docs/zh/guide/programming_guide/advanced_programming/memory_model/cache_coherence.md:531`:

> Scalar访问UB路径时可以`CTRL[49]`控制Scalar读取UB时是否通过DCache读取；`CTRL[49] = 1'b0`时，Scalar直接从UB读取；`CTRL[49] = 1'b1`时，Scalar读取UB数据会经过DCache。

`:535` gives the default as `1'b0`, and `:598-599` the consequence:

> - 如果后续消费者以Scalar DCache模式直接读取UB，关注的是DCache与UB的一致性，应使用DCCI处理旧副本，并在读取前建立生产流水到Scalar流水的同步。
> - 如果Scalar读取UB时没有开启DCache模式，即`CTRL[49] = 1'b0`，Scalar直接从UB读取，此时通常只需要处理Scalar流水与Vector/MTE流水之间的执行顺序，不需要通过DCCI处理旧DCache副本。

So on a stock kernel the 表3 event pair is the whole answer. If anything sets `CTRL[49] = 1'b1`, add a UB
`DataCacheCleanAndInvalid` plus a `DataSyncBarrier` to wait on it (`:594`) — that, and only that, is where
`DataSyncBarrier` belongs near a scalar read of UB.

### 58.8 Event ids: 0-5, and why `FetchEventID` is not a claim

`docs/zh/api/SIMD-API/basic_api/sync_control/intra_core_sync/SetFlag_WaitFlag_ISASI.md`, 约束说明, verbatim:

> - SetFlag只是设置硬件标志位，不会阻塞源流水中的下一个指令。
> - SetFlag和WaitFlag必须成对使用，且SetFlag和WaitFlag的参数必须完全一致（包括模板参数event和输入参数eventID）。如果不匹配，会引发timeout问题。例如，`SetFlag<HardEvent::S_MTE3>(1)`和`WaitFlag<HardEvent::MTE3_MTE1>(1)`并不匹配，因为其模板参数event不同。
> - 在采用TPipe-TQue框架编程范式时，eventID需要通过AllocEventID或者FetchEventID来获取。
> - 在采用静态Tensor编程范式时，事件的类型和事件ID由开发者自行管理，建议使用事件ID0-5，事件ID6用于系统内部规划（当前未使用），事件ID7用于TPipe编程中的自动同步功能，目前暂不建议直接使用事件ID6-7。

Range on A3 is 0-7; usable by hand is 0-5. This confirms the correction already carried in `README.md` ("the
hand-allocatable event-id range is 0-5, not 0-7").

`TPipe::FetchEventID` **peeks without claiming** — `impl/basic_api/kernel_tpipe_impl.h:526-535`:

```cpp
__aicore__ inline TEventID TPipe::FetchEventID(HardEvent evt)
{
    auto ptr = this->g_tpipeImpl.eventPool_ + EventToIndex(evt);
    auto lastId = sff0(ptr->eventOccupy);
    ...
    return lastId;
}
```

`sff0` is first-zero-bit and, unlike `AllocEventID` (`:497-509`), there is no `sbitset1`. So a library API that
fetches an id for a `HardEvent` the caller has been using by hand, without ever `AllocEventID`-ing it, gets the
same id. Both must be the same `HardEvent` for this to bite: `eventPool_` is indexed by `EventToIndex(evt)`, so
`MTE2_V` id 0 and `V_S` id 0 are different hardware flags.

### 58.9 ★ `ReduceMax`'s `sharedTmpBuffer` MAY alias its source on A3 — the licence, verbatim

The parameter is `sharedTmpBuffer`, not `workLocal`, in the shipped basic API —
`include/basic_api/kernel_operator_vec_reduce_intf.h:169-172`:

```cpp
template <typename T>
__aicore__ inline void ReduceMax(
    const LocalTensor<T>& dst, const LocalTensor<T>& src, const LocalTensor<T>& sharedTmpBuffer, const int32_t count,
    bool calIndex = 0);
```

`docs/zh/api/SIMD-API/basic_api/memory_vector_compute/reduction_compute/ReduceMax.md:222-223`, the NOTE closing
关键特性说明:

> [!NOTE]说明
> 开发者为了节省地址空间，可以选择`sharedTmpBuffer`空间复用源操作数的空间。此时因为`sharedTmpBuffer`需要的最小空间一定小于源操作数的空间，所以无需关注和计算最小空间。

and 约束说明, `:126-128`:

> - 源操作数及`sharedTmpBuffer`的地址对齐约束请参考通用地址对齐约束，起始地址需要32字节对齐；目的操作数的起始地址对齐约束请参考ReduceRepeat-表3。
> - 操作数地址重叠约束请参考通用地址重叠约束。
> - 需要使用`sharedTmpBuffer`的情况下，支持`dst`与`sharedTmpBuffer`地址重叠（通常情况下`dst`比`sharedTmpBuffer`所需的空间要小），此时`sharedTmpBuffer`必须满足所需空间要求。

So `sharedTmpBuffer` over `src` is explicitly sanctioned, and `dst` over `sharedTmpBuffer` as well. Two warnings
not to transfer:

- The 「可以直接传入`src`或者任意大小的`sharedTmpBuffer`」 sentence on the same page is gated `npu="950"` and does
  **not** apply to A3 (`:165-167`).
- The **adv_api** `ReduceMax` is a different API and forbids exactly this —
  `docs/zh/api/SIMD-API/adv_api/reduction_operations/ReduceMax_interface/ReduceMax.md:90-91`: 「**不支持源操作数与目的
  操作数地址重叠。** 不支持sharedTmpBuffer与源操作数和目的操作数地址重叠。」 Do not read that constraint onto the
  basic-API form.

There is no NPU-side check either way: the only guard is `#if ASCENDC_CPU_DEBUG`
(`impl/basic_api/kernel_operator_vec_reduce_intf_impl.h:1379-1383`), and `ASCENDC_ASSERT` /
`ASCENDC_CHECK_VALUE_RANGE` both expand to nothing on NPU (`impl/basic_api/kernel_log.h:277`, `:294`).

### 58.10 ★ What the 2201 `ReduceMax` actually does to `dst` — a 4-byte scalar store, already fenced

2201 is **not** the `ReduceMaxImpl` path; `impl/basic_api/kernel_operator_vec_reduce_intf_impl.h:1350-1351` gates
that to 3510/5102/3003/3113, and 2201 falls to `ReduceImpl` + a conditional `ReduceTailCompute` (`:1388-1396`). For
`count == 128`, `T == float`, `calIndex == false`: `elementNumPerRep = 256/4 = 64`, `repeatTime = 2`,
`tailCount = 0`, so `ReduceTailCompute` never runs. `ReduceImplFirstStep`
(`impl/basic_api/dav_c220/kernel_operator_vec_reduce_impl.h:426-450`) is one `vcmax` with repeat 2 writing
`work[0..3]` ({value,index} pairs, `VREDUCE_PER_REP_OUTPUT = 2`); `ReduceImplSecondStepNoIndex` (`:748-770`) then
reduces `work → work` in place; and `ReduceImplThirdStepNoIndex` (`:773-792`) ends with:

```cpp
    event_t eventIdVToS = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::V_S));
    SetFlag<HardEvent::V_S>(eventIdVToS);
    WaitFlag<HardEvent::V_S>(eventIdVToS);

    *dstLocal = *sharedTmpBuffer;
    event_t eventIdSToV = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_V));
    event_t eventIdSToMTE3 = static_cast<event_t>(GetTPipePtr()->FetchEventID(HardEvent::S_MTE3));
    SetFlag<HardEvent::S_V>(eventIdSToV);
    WaitFlag<HardEvent::S_V>(eventIdSToV);
    SetFlag<HardEvent::S_MTE3>(eventIdSToMTE3);
    WaitFlag<HardEvent::S_MTE3>(eventIdSToMTE3);
```

Two consequences, both load-bearing for a hand-written requantisation epilogue.

1. **`dst` is written by a 4-byte scalar store, not by a 32-byte-granular vector write.** A belief that "a
   reduction's destination is written a whole 32-byte block at a time, so each row's maximum needs its own block"
   is false on this path, and a `TBuf` split made on that premise buys nothing. (It is true of
   `ReduceImplFirstStep`'s writes into `sharedTmpBuffer`, which is a different buffer.)
2. **A `GetValue` of that `dst` immediately afterwards needs no event** — it is S→S, 「Scalar流水之间的同步由硬件
   自动保证」. The V→S edge is already closed inside the API. The general 表3 answer for "a vector write then a
   scalar read" is still `V_S`; it just does not apply to *this* API's destination on *this* path. It does apply on
   the `calIndex == true` path and to `ReduceTailCompute`, whose trailing `V_S` is inside `if (calIndex)`
   (`:911-940`).

### 58.11 ★ `ReduceMax` is not on §48's allowlist, and it is a 软仿 API that takes system event ids

§48.1's governing sentence, re-quoted here because this is its first concrete instance:

> 同时另外一些软仿实现接口内部会占用系统分配的事件ID，如果开发者手动调用`SetFlag/WaitFlag(ISASI)`插入自定义事件ID时会跟接口内部的事件ID产生冲突，所以用户自定义事件ID时，只能支持部分API。具体支持的API列表见支持的API范围。

表3 of `cpp_tensor_programming_overview.md` (§48.2) lists, under 归约计算, exactly:
「`WholeReduceMax`、`WholeReduceMin`、`WholeReduceSum`、`BlockReduceMax`、`BlockReduceMin`、`BlockReduceSum`、
`PairReduceSum`、`RepeatReduceSum`、`GetReduceRepeatSumSpr`、`GetReduceRepeatMaxMinSpr`」. The single-`vcmax`
primitives are allowed; the multi-pass `sharedTmpBuffer` wrapper `ReduceMax` is **not**, and §58.10 shows why — it
is one of the 「软仿实现接口」 that takes three event ids from the live `TPipe`. `Matmul` is not on the list either
(矩阵计算 is raw `Mmad`/`LoadData`). `Cast`, `DataCopy`, `DataCopyPad`, `SetFlag`/`WaitFlag`, `PipeBarrier` and
`DataSyncBarrier` are all on it.

A row maximum inside a hand-synchronised kernel is therefore better written as `WholeReduceMax` (one `vcmax`, no
`sharedTmpBuffer`, no event ids, on the allowlist) than as `ReduceMax`.

### 58.12 A UB→UB `DataCopy` is PIPE_V, not an MTE pipe

`docs/zh/api/SIMD-API/c_api/vector_data_move/asc_copy_ub2ub.md:68-70`:

> ## 流水类型
>
> PIPE_V

and the Level-2 `DataCopy(LocalTensor, LocalTensor, …)` reaches it: `impl/basic_api/kernel_operator_data_copy_intf_impl.h:366-375`
dispatches `srcHWPos == Hardware::UB && dstHWPos == Hardware::UB` to `DataCopyUB2UBIntf`, which on 2201 is
`impl/basic_api/dav_c220/kernel_operator_data_copy_impl.h:1188-1191` → `DataCopyUB2UBImpl` at `:119-132` →
`copy_ubuf_to_ubuf`. So a UB→UB stage copy is ordered against surrounding vector work by `PipeBarrier<PIPE_V>()`
and needs **no** `MTE2_V`/`V_MTE3` pair. It is easy to misclassify this as a DMA and over-synchronise it — or, worse,
to classify it as a DMA and then wonder why the barrier you wrote for it is on the wrong pipe.

### 58.13 `ASCENDC_CUBE_ONLY` does not trigger §43.5's silent-no-op trap

§43.5 established that `WaitFlagImpl`'s vector-event arms sit behind `#ifndef SPLIT_CORE_CUBE`. `SPLIT_CORE_CUBE`
is set by the compiler's per-half pass, not by the user macro — `impl/utils/sys_macros.h:56-61`:

```cpp
#if (defined(__DAV_CUBE__) && (__NPU_ARCH__ == 2201 || __NPU_ARCH__ == 3510))
#define SPLIT_CORE_CUBE
#endif

#if (defined(__DAV_VEC__) && (__NPU_ARCH__ == 2201 || __NPU_ARCH__ == 3510))
#define SPLIT_CORE_VEC
#endif
```

`ASCENDC_CUBE_ONLY` appears in only two places in the whole tree — `include/adv_api/matmul/matmul_intf.h:45,59,74,88,97`
and `impl/adv_api/detail/kfc/kfc_register_obj.h:152,277,331` — i.e. it selects `MatmulImpl` directly instead of the
KFC client, and touches nothing in the event machinery. So `#define ASCENDC_CUBE_ONLY` at the top of a `__mix__`
kernel does **not** make the vector half's `WaitFlag`s compile away. Its real consequence is §47.4's: a
`REGIST_CUBE_OBJ` under it expands to a bare `return` on the vector half.

### 58.14 `GlobalTensor<int4b_t>::operator[]` already counts nibbles — a hand-rolled byte-pointer helper is redundant

This refines §42 rather than contradicting it, and it retires a rationale that a kernel in this repository acted on
in seven places. `impl/basic_api/kernel_tensor_impl.h:1650-1675`:

```cpp
template <typename T>
__aicore__ inline GlobalTensor<T> GlobalTensor<T>::operator[](const uint64_t offset) const
{
    GlobalTensor result = *this;
    if constexpr (IsHalfByteDataType<PrimType>()) {
        result.address_ = result.address_ + offset / INT4_TWO;
        result.oriAddress_ = result.oriAddress_ + offset / INT4_TWO;
    ...
```

`address_` is a `__gm__ PrimType*` and `sizeof(int4b_t) == 1`, so `address_ + offset / INT4_TWO` advances exactly
`offset / 2` **bytes** — which is bit-for-bit what a hand-written `(__gm__ int8_t*)base + elements / 2` produces,
with the same silent flooring of an odd index. The two are the same expression. §42's warning stands in full on
everything else — `sizeof` against `SizeOfBits`, `bufferSize_` not being adjusted, `DataCopy(count)` counting
elements while `Nd2NzParams` counts bytes, `torch.int4` being unpacked — but the subscript's *unit* is not among
the traps: it counts nibbles, correctly.

The practical consequence: if an int4 store appears to land nowhere when its destination offset is non-zero and
to land every time at offset zero, the subscript is not the variable. Look at the transfer's **length** instead.
The one found-and-fixed instance here was a `DataCopy` given an element count where the API wanted bytes, which
over-wrote each tile's successor and spilled exactly one tile past the region — the symptom being identical bytes
at two offsets one span apart, which reads as "the write went somewhere else" and is in fact "the write went
twice as far".

## Relevance

This section exists because a hand-written MIX kernel in this repository
(`tests/glm52/routed_int4/routed_int4_kernel.cpp`) was 99.9% wrong in its output while its first matmul was
bit-exact, and the whole of the disagreement is in the four stages that run on the vector half. The table in §58.2
turns "which barrier do I need" into an enumeration, and §58.6 says who is responsible for inserting it.

Three concrete lessons for every kernel in `tests/glm52/`, all of which are built by a bare `bisheng` command line:

1. **There is no auto-sync.** Every edge in 表3, including `PipeBarrier<PIPE_V>` between two dependent vector
   instructions, is the author's to write. The `PipeBarrier<PIPE_V>()` calls that look redundant in these kernels
   are not redundant.
2. ★ **A `SetFlag` between two `DataCopy`s does not serialise them, and the API page says so in as many words.**
   `SetFlag_WaitFlag_ISASI.md:42`:

   > SetFlag：当源流水的前序指令的所有读写操作都完成之后，当前指令开始执行，并将硬件中的对应标志位设置为1。SetFlag只是设置硬件中的对应标志位，**并不会阻塞源流水中的下一个指令**。

   and again at `:72`: 「SetFlag只是设置硬件标志位，不会阻塞源流水中的下一个指令。」 (`asc_sync_notify.md:31` repeats
   it for the C API.) The flag's *set* is deferred until the prior MTE2 work retires; the MTE2 **pipe** is not
   stalled. So the idiom

   ```cpp
   DataCopy(staging, product[high], span);
   SetFlag<HardEvent::MTE2_V>(EVENT_ID0); WaitFlag<HardEvent::MTE2_V>(EVENT_ID0);
   Cast(into, staging, RoundMode::CAST_NONE, span);   // V reads staging
   ...
   DataCopy(staging, product[low], span);             // MTE2 writes staging again
   ```

   leaves **two** hazards open on `staging`, and the second load is the site of both:
   `PIPE_MTE2`→`PIPE_MTE2` with a **100% overlapping destination**, which 58.3's third bullet says requires a
   developer-inserted `PipeBarrier<PIPE_MTE2>()` 「保证多个DataCopy指令的串行化，防止出现异常数据」; and
   `PIPE_V`→`PIPE_MTE2` write-after-read against the `Cast`, which 表3 answers with `V_MTE2`. The visible
   consequence of the first is that after the *first* flag fires, `staging` can already hold 32-byte blocks of the
   *second* transfer — a per-block mixture of two GM regions, which reads downstream as a per-column perturbation
   of varying sign and magnitude rather than as any clean formula error.

   Note the asymmetry with the style this replaced. `PipeBarrier<PIPE_ALL>()` placed *after* each load does cover
   the MTE2/MTE2 overlap, because the barrier completes the first transfer before the second is issued; it does
   **not** cover the V→MTE2 write-after-read, because nothing sits before the second load. Converting such a site
   to `MTE2_V` pairs therefore closes nothing and opens the overlap. **A barrier-to-event conversion is only
   faithful if a pair is added before every re-load, not just after every load** — and if the defect metric was
   already saturated (ours was: 99.904% → 99.890% of values wrong), the conversion's cost will not show in it.

2b. ★★★ **Why that is structural rather than a race: the flag is one bit and a lock, and nothing throttles MTE2.**
   `intra_core_sync_overview.md:61-65` gives the mechanism, and calls it a lock in so many words
   (「表示两个指令流水之间完成一组"锁"机制」):

   > - SetFlag：当源流水的前序指令的所有读写操作都完成之后，当前指令开始执行，并将硬件中的对应标志位设置为1。
   > - WaitFlag：当目的流水执行到该指令时，如果发现硬件中对应标志位为0，目的流水的后续指令将一直被阻塞；如果发现硬件中对应标志位为1，则将硬件中对应标志位设置为0，同时目的流水的后续指令开始执行。

   A 标志位 set to 1 and cleared to 0 — one bit per (`HardEvent`, `eventID`), not a counter. Combine that with
   「SetFlag…并不会阻塞源流水中的下一个指令」 and the consequence for a producer pipe is exact: **`WaitFlag`
   blocks the consumer pipe and nothing in the pair ever blocks the producer pipe.** A kernel that writes only
   `MTE2_V`, `V_MTE3` and `MTE3_V` has therefore placed stalls on `PIPE_V` and on `PIPE_MTE3` and *none* on
   `PIPE_MTE2` — and on 2201 `CrossCoreWaitFlag`'s `pipe` template argument is discarded
   (`dav_c220/kernel_operator_sync_impl.h:501-505`), so a cross-core wait does not stall it either. `PIPE_MTE2`
   then runs ahead of the vector pipe, and the only thing bounding the run-ahead is the one bit: a second
   `SetFlag` on an id still holding 1 has nowhere to put its value, so the producer advances by about one transfer
   per event id — **and that one transfer is the one whose destination is the buffer the consumer has not read
   yet.** The corruption is not a coin flip that sometimes lands wrong; it is the steady state. What varies run to
   run is only how much of the buffer the overtaking transfer has replaced when the consumer finally reads it,
   which presents as a per-32-byte-block mixture of two GM regions.

   Corollary, and the cheapest audit in this whole section: **count the Set/Wait pairs that share one event id
   inside one straight-line region.** One is safe. Three on `EVENT_ID0`, as in a three-term recombination that
   loads one staging buffer three times, is not — the sets collapse onto one bit and the pairs are not
   structurally guaranteed to alternate. Distinct ids per load, or distinct destinations per load, fix it; so does
   a `PipeBarrier<PIPE_ALL>()` before each re-load, at its documented cost. And the stage in such a kernel that
   still *works* is usually the one that happens to have an all-pipe drain at its loop boundary, which drains MTE2
   and so deletes the run-ahead — not the one that is better synchronised.
3. **A `GetValue` of an `MTE2`-loaded word, and a `DataCopyPad` of a `SetValue`-written word, need `MTE2_S` and
   `S_MTE3`.** Neither has a `PipeBarrier` form. `DataSyncBarrier<MemDsbT::UB>()` is not a substitute and never was.

One negative result worth banking, because it is what sent the search back to synchronisation. For that kernel's
measured device state — intermediate codes `-9 -9 -5 -13 -2 5 -7 -9` and row quanta `0.00165845`, `0.0013341`
against reference quanta `0.00145008`, `0.000781054` — a host-side replica of the harness's own reference
(exact: it reproduces the printed products `8883 562 -5267` / `-16078 -16791 -3580` and both reference quanta to
all printed digits) was used to search **7776 structured arithmetic variants**: every drop and duplication of the
three recombination terms `16*high`, `low` and `8*sum(w)` on the gate and the up half independently, every
gate/up per-channel scale swap, the per-token scale from every expert and applied to either or both halves, and
the bias taken from the wrong expert. **Zero matched both row maxima to 1e-4.** The closest was −2.265%/+0.168%.
Separately, no single quantum reproduces the device's eight codes from the reference activation — the feasible
interval is empty — so the activation itself differs, per column, by −6% to +29% in the first eight columns while
the row maximum moves by +14.4% and +70.8%. A per-column perturbation of varying sign and relative size that no
deterministic formula error produces is stale or partially-arrived data, which is the signature this section is
about.
