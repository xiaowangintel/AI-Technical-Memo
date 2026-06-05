# ampere_fp64_tensorop_affine2_gemm.cu — Code Analysis / 代码分析

**Source / 源文件**: `examples/18_ampere_fp64_tensorop_affine2_gemm/ampere_fp64_tensorop_affine2_gemm.cu`  
**Purpose / 用途**: Demonstrates Ampere FP64 Tensor Core GEMM using the affine rank-2 tile iterator path. / 演示使用 affine rank-2 tile iterator 路径的 Ampere FP64 Tensor Core GEMM。

---

## Line-by-Line Analysis / 逐行分析

### Lines 1-30 / 第1-30行

```cpp
/***************************************************************************************************
 * Copyright (c) 2017 - 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
 * SPDX-License-Identifier: BSD-3-Clause
 *
 * Redistribution and use in source and binary forms, with or without
 * modification, are permitted provided that the following conditions are met:
 *
 * 1. Redistributions of source code must retain the above copyright notice, this
 * list of conditions and the following disclaimer.
 *
 * 2. Redistributions in binary form must reproduce the above copyright notice,
 * this list of conditions and the following disclaimer in the documentation
 * and/or other materials provided with the distribution.
 *
 * 3. Neither the name of the copyright holder nor the names of its
 * contributors may be used to endorse or promote products derived from
 * this software without specific prior written permission.
 *
 * THIS SOFTWARE IS PROVIDED BY THE COPYRIGHT HOLDERS AND CONTRIBUTORS "AS IS"
 * AND ANY EXPRESS OR IMPLIED WARRANTIES, INCLUDING, BUT NOT LIMITED TO, THE
 * IMPLIED WARRANTIES OF MERCHANTABILITY AND FITNESS FOR A PARTICULAR PURPOSE ARE
 * DISCLAIMED. IN NO EVENT SHALL THE COPYRIGHT HOLDER OR CONTRIBUTORS BE LIABLE
 * FOR ANY DIRECT, INDIRECT, INCIDENTAL, SPECIAL, EXEMPLARY, OR CONSEQUENTIAL
 * DAMAGES (INCLUDING, BUT NOT LIMITED TO, PROCUREMENT OF SUBSTITUTE GOODS OR
 * SERVICES; LOSS OF USE, DATA, OR PROFITS; OR BUSINESS INTERRUPTION) HOWEVER
 * CAUSED AND ON ANY THEORY OF LIABILITY, WHETHER IN CONTRACT, STRICT LIABILITY,
 * OR TORT (INCLUDING NEGLIGENCE OR OTHERWISE) ARISING IN ANY WAY OUT OF THE USE
 * OF THIS SOFTWARE, EVEN IF ADVISED OF THE POSSIBILITY OF SUCH DAMAGE.
 *
 **************************************************************************************************/
```

**EN**: This is the standard BSD-3-Clause license header. It documents redistribution terms before any executable code appears.  
**CN**: 这里是标准的 BSD-3-Clause 许可证头，在任何可执行代码之前先说明再分发条款。

### Lines 32-32 / 第32-32行

```cpp
/**
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 33-36 / 第33-36行

```cpp
In the normal GEMM, the fast changing dimension of a matrix always has stride 
equals to 1, e.g. ColumnMajor and RowMajor matrix.  Affine2 matrix can have 
larger than 1 stride in both dimensions.  To support such layout, we need to 
change to method to visit the global memory:
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 38-42 / 第38-42行

```cpp
  1. We can only visit 1 element a time because elements are not stored
     consecutively anymore.  Vectorized load/store is not possible.
  2. One extra multiplication is needed in calculating the global memory
     address
     addr = base_pointer + coord1 * stride1 + coord2 * stride2
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 44-45 / 第44-45行

```cpp
The rest part of GEMM which includes shared memory load/store, mma comutation
is the same.
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow. Shared-memory accumulator residency trades more on-chip storage for the ability to decouple the two fused stages.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。 共享内存累加器驻留通过使用更多片上存储，换取两个融合阶段之间更强的解耦能力。

### Lines 47-49 / 第47-49行

```cpp
This example uses Ampere fp64 tensore core Affine2 GEMM as an example.  SIMT 
(e.g. sgemm, dgemm) has support Affine2 layout.
*/
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 51-52 / 第51-52行

```cpp
#include <iostream>
#include <sstream>
```

**EN**: These headers pull in the building blocks required by this file. Console stream utilities for logging progress and results. String-stream helpers for assembling formatted text.  
**CN**: 这些头文件引入了当前文件所需的构建模块。用于记录进度和结果的控制台流工具。用于拼接格式化文本的字符串流工具。

### Lines 54-59 / 第54-59行

```cpp
#include "cutlass/cutlass.h"
#include "cutlass/gemm/device/gemm_universal.h"
#include "cutlass/reduction/device/reduce_split_k.h"
#include "cutlass/reduction/kernel/reduce_split_k.h"
#include "cutlass/reduction/thread/reduction_operators.h"
#include "cutlass/matrix_coord.h"
```

**EN**: These headers pull in the building blocks required by this file. Core CUTLASS definitions, architecture tags, and status types. Device-level GEMM wrapper that hides kernel selection and launch details. Provides `cutlass/reduction/device/reduce_split_k.h` so this file can use the related API or helper utilities. Provides `cutlass/reduction/kernel/reduce_split_k.h` so this file can use the related API or helper utilities.  
**CN**: 这些头文件引入了当前文件所需的构建模块。CUTLASS 的核心定义、架构标签与状态类型。设备级 GEMM 封装，隐藏内核选择与启动细节。提供 `cutlass/reduction/device/reduce_split_k.h`，使本文件能够使用相关 API 或辅助工具。提供 `cutlass/reduction/kernel/reduce_split_k.h`，使本文件能够使用相关 API 或辅助工具。

### Lines 61-67 / 第61-67行

```cpp
#include "cutlass/util/command_line.h"
#include "cutlass/util/host_tensor.h"
#include "cutlass/util/tensor_view_io.h"
#include "cutlass/util/reference/device/gemm.h"
#include "cutlass/util/reference/host/tensor_compare.h"
#include "cutlass/util/reference/host/tensor_copy.h"
#include "cutlass/util/reference/host/tensor_fill.h"
```

**EN**: These headers pull in the building blocks required by this file. Convenience parser for command-line flags used by examples. Host/device tensor wrapper used to allocate storage and transfer data. Tensor printing helpers for debugging layouts and values. Device-side reference helper used in validation flows.  
**CN**: 这些头文件引入了当前文件所需的构建模块。用于示例命令行参数的便捷解析器。主机/设备张量封装，用于分配存储并传输数据。用于调试布局和值的张量打印辅助工具。验证流程中使用的设备端参考辅助工具。

### Lines 69-69 / 第69-69行

```cpp
#include "helper.h"
```

**EN**: These headers pull in the building blocks required by this file. Provides `helper.h` so this file can use the related API or helper utilities.  
**CN**: 这些头文件引入了当前文件所需的构建模块。提供 `helper.h`，使本文件能够使用相关 API 或辅助工具。

### Lines 71-72 / 第71-72行

```cpp
// The code section below describes datatype for input, output tensors and computation between
// elements 
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 73-77 / 第73-77行

```cpp
using ElementAccumulator = double;                 // Data type of accumulator
using ElementComputeEpilogue = ElementAccumulator; // Data type of epilogue computation
using ElementInputA = double;                      // Data type of elements in input tensor
using ElementInputB = double;                      // Data type of elements in input tensor
using ElementOutput = double;                      // Data type of elements in output tensor
```

**EN**: These aliases pin down the scalar types used for inputs, accumulators, and outputs. Choosing them explicitly matters because CUTLASS can compute in a different precision from storage.  
**CN**: 这些别名固定了输入、累加器和输出使用的标量类型。显式指定它们很重要，因为 CUTLASS 可以让计算精度与存储精度不同。

### Lines 79-87 / 第79-87行

```cpp
// Since Affine2 explicitly lists the strides of both dimensions, it does not really matter if 
// it is columnmajor and rowmajor.  However, it helps CUTLASS to improve the load locality if 
// CUTLASS can know which dimension of A/B operand has smaller stride or more dense.
//
// Affine2 ColumnMajor means the row stride is smaller and Affine2 RowMajor means the column 
// stride is smaller.
//
// The Affine2 epilogue reuses AffineN epilogue so it does not need to specify column majore
// or row major.
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 88-90 / 第88-90行

```cpp
using LayoutInputA = cutlass::layout::AffineRank2ColumnMajor;
using LayoutInputB = cutlass::layout::AffineRank2RowMajor;
using LayoutOutput = cutlass::layout::AffineRankN<2>;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 92-92 / 第92-92行

```cpp
// This code section describes whether you want to use tensor cores or regular SIMT cores on GPU SM
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 93-93 / 第93-93行

```cpp
using MMAOp = cutlass::arch::OpClassTensorOp;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow. `OpClassTensorOp` selects Tensor Core math instead of plain SIMT arithmetic.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。 `OpClassTensorOp` 选择 Tensor Core 计算，而不是普通的 SIMT 算术。

### Lines 95-95 / 第95-95行

```cpp
// This code section describes CUDA SM architecture number
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 96-96 / 第96-96行

```cpp
using SmArch = cutlass::arch::Sm80;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow. `arch::Sm80` targets Ampere-generation GPUs.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。 `arch::Sm80` 表示面向 Ampere 架构 GPU。

### Lines 98-98 / 第98-98行

```cpp
// This code section describes the tile size a thread block will compute
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 99-99 / 第99-99行

```cpp
using ThreadblockShape = cutlass::gemm::GemmShape<128, 128, 16>;  // Threadblock tile shape
```

**EN**: These aliases describe CUTLASS's tiling hierarchy. The code separately chooses CTA, warp, and instruction shapes so the kernel matches the hardware execution pattern it targets. `GemmShape<M, N, K>` encodes tile extents along the GEMM M/N/K axes. `ThreadblockShape` selects the CTA-sized tile computed by one thread block.  
**CN**: 这些别名描述了 CUTLASS 的分块层次。代码分别选择 CTA、warp 与指令级分块，以匹配目标硬件的执行模式。 `GemmShape<M, N, K>` 用于描述 GEMM 在 M/N/K 三个维度上的分块大小。 `ThreadblockShape` 选择单个线程块负责计算的 CTA 级分块。

### Lines 101-101 / 第101-101行

```cpp
// This code section describes tile size a warp will compute
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 102-102 / 第102-102行

```cpp
using WarpShape = cutlass::gemm::GemmShape<32, 64, 16>;         // Warp tile shape
```

**EN**: These aliases describe CUTLASS's tiling hierarchy. The code separately chooses CTA, warp, and instruction shapes so the kernel matches the hardware execution pattern it targets. `GemmShape<M, N, K>` encodes tile extents along the GEMM M/N/K axes. `WarpShape` controls how the CTA tile is partitioned across warps.  
**CN**: 这些别名描述了 CUTLASS 的分块层次。代码分别选择 CTA、warp 与指令级分块，以匹配目标硬件的执行模式。 `GemmShape<M, N, K>` 用于描述 GEMM 在 M/N/K 三个维度上的分块大小。 `WarpShape` 控制 CTA 分块如何在多个 warp 之间划分。

### Lines 104-104 / 第104-104行

```cpp
// This code section describes the size of MMA op
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 105-105 / 第105-105行

```cpp
using InstructionShape = cutlass::gemm::GemmShape<8, 8, 4>;    // TensorCore instruction shape
```

**EN**: These aliases describe CUTLASS's tiling hierarchy. The code separately chooses CTA, warp, and instruction shapes so the kernel matches the hardware execution pattern it targets. `GemmShape<M, N, K>` encodes tile extents along the GEMM M/N/K axes. `InstructionShape` mirrors the hardware MMA instruction tile used by Tensor Cores.  
**CN**: 这些别名描述了 CUTLASS 的分块层次。代码分别选择 CTA、warp 与指令级分块，以匹配目标硬件的执行模式。 `GemmShape<M, N, K>` 用于描述 GEMM 在 M/N/K 三个维度上的分块大小。 `InstructionShape` 对应 Tensor Core 使用的硬件 MMA 指令级分块。

### Lines 107-107 / 第107-107行

```cpp
// This code section describes how threadblocks are scheduled on GPU
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 108-108 / 第108-108行

```cpp
using SwizzleThreadBlock = cutlass::gemm::threadblock::GemmIdentityThreadblockSwizzle<8>;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 110-110 / 第110-110行

```cpp
// Number of pipelines you want to use
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 111-111 / 第111-111行

```cpp
constexpr int NumStages = 3;
```

**EN**: This block defines compile-time constants or static values that parameterize the kernel or the benchmark.  
**CN**: 这段代码定义编译期常量或静态值，用于参数化内核或基准测试。

### Lines 113-113 / 第113-113行

```cpp
// This code section describes the epilogue part of the kernel, we use default value
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 114-120 / 第114-120行

```cpp
using EpilogueOp = cutlass::epilogue::thread::LinearCombination<
    ElementOutput,                                        // Data type of output matrix.
    1,                                                    // The number of elements per memory
                                                          // access has.  It has to be 1 for
                                                          // affine2. 
    ElementAccumulator,
    ElementComputeEpilogue>;
```

**EN**: This block defines epilogue functors. In CUTLASS, the epilogue converts accumulators into the output type and can fuse extra work such as scaling, bias handling, clamping, or activation. `LinearCombination` is CUTLASS's standard epilogue functor for scaling accumulators and combining them with existing outputs.  
**CN**: 这段代码定义了 epilogue functor。在 CUTLASS 中，epilogue 负责把累加器转换为输出类型，并可融合缩放、偏置处理、截断或激活等附加工作。 `LinearCombination` 是 CUTLASS 标准 epilogue functor，用于缩放累加器并与已有输出组合。

### Lines 122-138 / 第122-138行

```cpp
using Gemm = typename cutlass::gemm::device::GemmUniversal<
  ElementInputA, LayoutInputA,
  ElementInputB, LayoutInputB,
  ElementOutput, LayoutOutput,
  ElementAccumulator,
  MMAOp,
  SmArch,
  ThreadblockShape,
  WarpShape,
  InstructionShape,
  EpilogueOp,
  SwizzleThreadBlock,
  NumStages,
  1,
  1,
  cutlass::arch::OpMultiplyAdd
>;
```

**EN**: This type alias assembles a specialized CUTLASS kernel configuration. The template arguments choose layouts, scalar types, architecture tags, tile shapes, iterator policies, epilogues, swizzles, and staging depth. `ThreadblockShape` selects the CTA-sized tile computed by one thread block. `WarpShape` controls how the CTA tile is partitioned across warps. `InstructionShape` mirrors the hardware MMA instruction tile used by Tensor Cores.  
**CN**: 这个类型别名组装出了一个专门化的 CUTLASS 内核配置。模板参数会选择布局、标量类型、架构标签、分块形状、迭代器策略、epilogue、swizzle 以及流水深度。 `ThreadblockShape` 选择单个线程块负责计算的 CTA 级分块。 `WarpShape` 控制 CTA 分块如何在多个 warp 之间划分。 `InstructionShape` 对应 Tensor Core 使用的硬件 MMA 指令级分块。

### Lines 140-140 / 第140-140行

```cpp
/////////////////////////////////////////////////////////////////////////////////////////////////
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 142-142 / 第142-142行

```cpp
int run() {
```

**EN**: This line starts a function or callable scope. The body that follows typically configures a kernel, launches it, or checks its result.  
**CN**: 这一行开始定义一个函数或可调用作用域。随后的函数体通常会配置内核、启动执行或检查结果。

### Lines 144-144 / 第144-144行

```cpp
  // Construct Gemm ProblemSize with user defined output size
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 145-145 / 第145-145行

```cpp
  cutlass::gemm::GemmCoord problem_size = {1024, 512, 1024};
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 147-153 / 第147-153行

```cpp
  // Stride factor shows the distance between two elements in the different dimensions.  The
  // first data is the logical distance between two rows, the second is between two columns.
  // CUTLASS has a utility tool cutlass::layout::Affine2Layout_Factory<Layout>::layout_factory
  // to help to convert stride_factor to the two strides.
  //
  // It is also totally fine to compute the strides directly without using the utility to 
  // construct the affine2 layout.
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 154-156 / 第154-156行

```cpp
  typename LayoutInputA::Stride::Index stride_factor_A[] = {3, 4}; 
  typename LayoutInputB::Stride::Index stride_factor_B[] = {5, 6};
  typename LayoutOutput::Stride::Index stride_factor_C[] = {7, 8};
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 158-158 / 第158-158行

```cpp
  // Initialize tensors using CUTLASS helper functions
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 159-164 / 第159-164行

```cpp
  cutlass::HostTensor<ElementInputA, LayoutInputA> tensor_a(problem_size.mk(),
         cutlass::layout::Affine2Layout_Factory<LayoutInputA>::layout_factory(problem_size.mk(),
                                                                              stride_factor_A));
  cutlass::HostTensor<ElementInputB, LayoutInputB> tensor_b(problem_size.kn(),
         cutlass::layout::Affine2Layout_Factory<LayoutInputB>::layout_factory(problem_size.kn(),
                                                                              stride_factor_B));
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 166-166 / 第166-166行

```cpp
  // Create matrix C used to load for bias addition.
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 167-169 / 第167-169行

```cpp
  cutlass::HostTensor<ElementOutput, LayoutOutput> tensor_c(problem_size.mn(),
         cutlass::layout::Affine2Layout_Factory<LayoutOutput>::layout_factory(problem_size.mn(),
                                                                              stride_factor_C));
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 171-171 / 第171-171行

```cpp
  // Create matrix D used to store output from CUTLASS kernel
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 172-174 / 第172-174行

```cpp
  cutlass::HostTensor<ElementOutput, LayoutOutput> tensor_d(problem_size.mn(),
         cutlass::layout::Affine2Layout_Factory<LayoutOutput>::layout_factory(problem_size.mn(),
                                                                              stride_factor_C));
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 176-177 / 第176-177行

```cpp
  // Create matrix D with dimensions M x N used to store output from reference
  // kernel
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 178-180 / 第178-180行

```cpp
  cutlass::HostTensor<ElementOutput, LayoutOutput> tensor_ref_d(problem_size.mn(),
         cutlass::layout::Affine2Layout_Factory<LayoutOutput>::layout_factory(problem_size.mn(),
                                                                              stride_factor_C));
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 182-182 / 第182-182行

```cpp
  // Fill input and output matrices on host using CUTLASS helper functions
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 183-188 / 第183-188行

```cpp
  cutlass::reference::host::TensorFillRandomUniform(
      tensor_a.host_view(),
      1,
      ElementInputA(4),
      ElementInputA(-4),
      0);  // <- Fill matrix A on host with uniform-distribution random data
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 190-195 / 第190-195行

```cpp
  cutlass::reference::host::TensorFillRandomUniform(
      tensor_b.host_view(),
      1,
      ElementInputB(4),
      ElementInputB(-4),
      0);  // <- Fill matrix B on host with uniform-distribution random data
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 197-202 / 第197-202行

```cpp
  cutlass::reference::host::TensorFillRandomUniform(
      tensor_c.host_view(),
      1,
      ElementOutput(4),
      ElementOutput(-4),
      0);  // <- Fill matrix C on host with uniform-distribution random data
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 204-207 / 第204-207行

```cpp
  cutlass::reference::host::TensorFill(
      tensor_d.host_view());  // <- fill matrix D on host with zeros
  cutlass::reference::host::TensorFill(
      tensor_ref_d.host_view());  // <- fill matrix D for reference on host with zeros
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 209-209 / 第209-209行

```cpp
  // Copy data from host to GPU
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 210-210 / 第210-210行

```cpp
  tensor_a.sync_device();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 211-211 / 第211-211行

```cpp
  tensor_b.sync_device();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 212-212 / 第212-212行

```cpp
  tensor_c.sync_device();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 213-213 / 第213-213行

```cpp
  tensor_d.sync_device();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 214-214 / 第214-214行

```cpp
  tensor_ref_d.sync_device();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 216-216 / 第216-216行

```cpp
  // Initialize alpha for dot product computation
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 217-218 / 第217-218行

```cpp
  ElementComputeEpilogue alpha = ElementComputeEpilogue(1);
  ElementComputeEpilogue beta = ElementComputeEpilogue(1);
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 220-220 / 第220-220行

```cpp
  cutlass::gemm::GemmUniversalMode mode = cutlass::gemm::GemmUniversalMode::kGemm;
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 222-222 / 第222-222行

```cpp
  int batch_count = 1;
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 224-225 / 第224-225行

```cpp
  // Create a tuple of gemm kernel arguments. This is later passed as arguments to launch
  // instantiated CUTLASS kernel
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 226-243 / 第226-243行

```cpp
  typename Gemm::Arguments arguments{
    mode,
    problem_size,
    batch_count,
    {alpha, beta},
    tensor_a.device_ref().data(),              // <- reference to matrix A on device
    tensor_b.device_ref().data(),              // <- reference to matrix B on device
    tensor_c.device_ref().data(),              // <- reference to matrix C on device
    tensor_d.device_ref().data(),              // <- reference to matrix D on device
    tensor_a.layout().capacity(problem_size.mk()),
    tensor_b.layout().capacity(problem_size.kn()),
    tensor_c.layout().capacity(problem_size.mn()),
    tensor_d.layout().capacity(problem_size.mn()),
    tensor_a.layout().stride(),
    tensor_b.layout().stride(),
    tensor_c.layout().stride(),
    tensor_d.layout().stride()
  };                    
```

**EN**: This line starts a function or callable scope. The body that follows typically configures a kernel, launches it, or checks its result.  
**CN**: 这一行开始定义一个函数或可调用作用域。随后的函数体通常会配置内核、启动执行或检查结果。

### Lines 245-245 / 第245-245行

```cpp
  // Instantiate CUTLASS kernel depending on templates
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 246-246 / 第246-246行

```cpp
  Gemm gemm_op;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 248-248 / 第248-248行

```cpp
  // Using the arguments, query for extra workspace required for matrix multiplication computation
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 249-249 / 第249-249行

```cpp
  size_t workspace_size = Gemm::get_workspace_size(arguments);
```

**EN**: This block exercises the configured CUTLASS object at runtime. Typical calls include initialization, capability checks, workspace queries, kernel launches, or reference validation.  
**CN**: 这段代码在运行时驱动已配置好的 CUTLASS 对象。常见调用包括初始化、能力检查、工作区查询、内核启动以及参考结果验证。

### Lines 251-251 / 第251-251行

```cpp
  // Allocate workspace memory
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 252-252 / 第252-252行

```cpp
  cutlass::device_memory::allocation<uint8_t> workspace(workspace_size);
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 254-254 / 第254-254行

```cpp
  // Check the problem size is supported or not
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 255-255 / 第255-255行

```cpp
  cutlass::Status status = gemm_op.can_implement(arguments);
```

**EN**: This block exercises the configured CUTLASS object at runtime. Typical calls include initialization, capability checks, workspace queries, kernel launches, or reference validation.  
**CN**: 这段代码在运行时驱动已配置好的 CUTLASS 对象。常见调用包括初始化、能力检查、工作区查询、内核启动以及参考结果验证。

### Lines 256-256 / 第256-256行

```cpp
  CUTLASS_CHECK(status);
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 258-258 / 第258-258行

```cpp
  // Initialize CUTLASS kernel with arguments and workspace pointer
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 259-259 / 第259-259行

```cpp
  status = gemm_op.initialize(arguments, workspace.get());
```

**EN**: This block exercises the configured CUTLASS object at runtime. Typical calls include initialization, capability checks, workspace queries, kernel launches, or reference validation.  
**CN**: 这段代码在运行时驱动已配置好的 CUTLASS 对象。常见调用包括初始化、能力检查、工作区查询、内核启动以及参考结果验证。

### Lines 260-260 / 第260-260行

```cpp
  CUTLASS_CHECK(status);
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 262-262 / 第262-262行

```cpp
  // Launch initialized CUTLASS kernel
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 263-263 / 第263-263行

```cpp
  status = gemm_op();
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 265-265 / 第265-265行

```cpp
  CUTLASS_CHECK(status);
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 267-269 / 第267-269行

```cpp
  //
  // Create instantiation for device reference gemm kernel
  //
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 271-271 / 第271-271行

```cpp
  // Launch device reference to compute strictly the product A * B
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 272-280 / 第272-280行

```cpp
  cutlass::reference::device::Gemm<
      ElementInputA, 
      LayoutInputA, 
      ElementInputB, 
      LayoutInputB, 
      ElementOutput,
      LayoutOutput, 
      ElementComputeEpilogue, 
      ElementAccumulator> gemm_device;
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms. `cutlass::gemm::device::Gemm` packages layouts, types, tile sizes, epilogue policy, swizzle, and stage count into a callable kernel object.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。 `cutlass::gemm::device::Gemm` 会把布局、类型、分块大小、epilogue 策略、swizzle 与流水级数打包成可调用的内核对象。

### Lines 282-291 / 第282-291行

```cpp
  gemm_device
    (
      problem_size,
      alpha, 
      tensor_a.device_ref(),
      tensor_b.device_ref(),
      beta, 
      tensor_c.device_ref(), 
      tensor_ref_d.device_ref()
    );
```

**EN**: This block initializes runtime scalars such as `alpha` and `beta`. They control how the epilogue scales accumulated results and mixes in source or bias terms.  
**CN**: 这段代码初始化 `alpha`、`beta` 等运行时标量。它们控制 epilogue 如何缩放累加结果，并混入源项或偏置项。

### Lines 293-293 / 第293-293行

```cpp
  // Wait for kernels to finish
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 294-294 / 第294-294行

```cpp
  cudaDeviceSynchronize();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 296-296 / 第296-296行

```cpp
  // Copy output data from CUTLASS and reference kernel to host for comparison
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 297-297 / 第297-297行

```cpp
  tensor_d.sync_host();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 298-298 / 第298-298行

```cpp
  tensor_ref_d.sync_host();
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 300-301 / 第300-301行

```cpp
  bool pass = cutlass::reference::host::TensorEquals(tensor_d.host_view(),
                                                     tensor_ref_d.host_view());
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 303-303 / 第303-303行

```cpp
  // Check if output from CUTLASS kernel and reference kernel are equal or not
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 304-307 / 第304-307行

```cpp
  std::cout << (pass
                    ? "Passed"
                    : "Failed")
            << std::endl;
```

**EN**: This block prints human-readable status so it is clear which configuration is running and whether validation passed.  
**CN**: 这段代码打印可读的状态信息，让用户清楚当前运行的是哪种配置，以及验证是否通过。

### Lines 309-309 / 第309-309行

```cpp
  CUTLASS_CHECK(status);
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 311-311 / 第311-311行

```cpp
  return (pass ? 0 : -1);
```

**EN**: This return statement propagates the current result back to the caller so the surrounding harness can continue its control flow.  
**CN**: 这个返回语句会把当前结果传回调用者，使外围测试框架能够继续执行后续控制流程。

### Lines 312-312 / 第312-312行

```cpp
}
```

**EN**: This closes the current scope or namespace and keeps the surrounding structure balanced.  
**CN**: 这里关闭当前作用域或命名空间，以保持外围结构的配对完整。

### Lines 314-314 / 第314-314行

```cpp
int main(int argc, char const **args) {
```

**EN**: This line starts a function or callable scope. The body that follows typically configures a kernel, launches it, or checks its result.  
**CN**: 这一行开始定义一个函数或可调用作用域。随后的函数体通常会配置内核、启动执行或检查结果。

### Lines 316-316 / 第316-316行

```cpp
  bool notSupported = false;
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 318-320 / 第318-320行

```cpp
  // Ampere Tensor Core operations exposed with mma.sync are first available in CUDA 11.0.
  //
  // CUTLASS must be compiled with CUDA 11 Toolkit to run Conv2dFprop examples.
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

### Lines 321-322 / 第321-322行

```cpp
  if (!(__CUDACC_VER_MAJOR__ > 11 || (__CUDACC_VER_MAJOR__ == 11 && __CUDACC_VER_MINOR__ >= 0))) {
    std::cerr << "Ampere Tensor Core operations must be compiled with CUDA 11.0 Toolkit or later." << std::endl;
```

**EN**: This control-flow block selects a path based on runtime state, such as argument validation, loop traversal, or pass/fail reporting.  
**CN**: 这个控制流代码块会根据运行时状态选择执行路径，例如参数校验、循环遍历或通过/失败报告。

### Lines 323-323 / 第323-323行

```cpp
    notSupported = true;
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 324-324 / 第324-324行

```cpp
  }
```

**EN**: This closes the current scope or namespace and keeps the surrounding structure balanced.  
**CN**: 这里关闭当前作用域或命名空间，以保持外围结构的配对完整。

### Lines 326-326 / 第326-326行

```cpp
  cudaDeviceProp props;
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 327-327 / 第327-327行

```cpp
  CUDA_CHECK(cudaGetDeviceProperties(&props, 0));
```

**EN**: This block contributes one logical step of the file, such as wiring together types, state, helper objects, or execution flow.  
**CN**: 这段代码构成了文件中的一个逻辑步骤，例如连接类型、状态、辅助对象或执行流程。

### Lines 329-331 / 第329-331行

```cpp
  if (!(props.major >= 8)) {
    std::cerr << "Ampere Tensor Ops must be run on a machine with compute capability at least 80."
              << std::endl;
```

**EN**: This control-flow block selects a path based on runtime state, such as argument validation, loop traversal, or pass/fail reporting.  
**CN**: 这个控制流代码块会根据运行时状态选择执行路径，例如参数校验、循环遍历或通过/失败报告。

### Lines 332-332 / 第332-332行

```cpp
    notSupported = true;
```

**EN**: This block fills in runtime state, object fields, or helper variables needed by later setup and execution steps.  
**CN**: 这段代码填充运行时状态、对象字段或辅助变量，为后续的配置与执行步骤做准备。

### Lines 333-333 / 第333-333行

```cpp
  }
```

**EN**: This closes the current scope or namespace and keeps the surrounding structure balanced.  
**CN**: 这里关闭当前作用域或命名空间，以保持外围结构的配对完整。

### Lines 335-336 / 第335-336行

```cpp
  if (notSupported) {
    return 0;
```

**EN**: This control-flow block selects a path based on runtime state, such as argument validation, loop traversal, or pass/fail reporting.  
**CN**: 这个控制流代码块会根据运行时状态选择执行路径，例如参数校验、循环遍历或通过/失败报告。

### Lines 337-337 / 第337-337行

```cpp
  }
```

**EN**: This closes the current scope or namespace and keeps the surrounding structure balanced.  
**CN**: 这里关闭当前作用域或命名空间，以保持外围结构的配对完整。

### Lines 339-339 / 第339-339行

```cpp
  return run();
```

**EN**: This return statement propagates the current result back to the caller so the surrounding harness can continue its control flow.  
**CN**: 这个返回语句会把当前结果传回调用者，使外围测试框架能够继续执行后续控制流程。

### Lines 340-340 / 第340-340行

```cpp
}
```

**EN**: This closes the current scope or namespace and keeps the surrounding structure balanced.  
**CN**: 这里关闭当前作用域或命名空间，以保持外围结构的配对完整。

### Lines 342-342 / 第342-342行

```cpp
/////////////////////////////////////////////////////////////////////////////////////////////////
```

**EN**: This comment separates sections and documents the purpose of the code that follows.  
**CN**: 这段注释用于分隔不同章节，并说明后续代码的用途。

---

## Key Concepts / 关键概念

- Implicit-GEMM convolution mapping / 隐式 GEMM 卷积映射
- Hierarchical tiling: threadblock / warp / instruction / 分层分块：threadblock / warp / instruction
- Epilogue fusion and output operators / Epilogue 融合与输出算子
- Tensor Core execution / Tensor Core 执行

## Dependencies / 依赖项

- `<iostream>` — Console stream utilities for logging progress and results. / 用于记录进度和结果的控制台流工具。
- `<sstream>` — String-stream helpers for assembling formatted text. / 用于拼接格式化文本的字符串流工具。
- `"cutlass/cutlass.h"` — Core CUTLASS definitions, architecture tags, and status types. / CUTLASS 的核心定义、架构标签与状态类型。
- `"cutlass/gemm/device/gemm_universal.h"` — Device-level GEMM wrapper that hides kernel selection and launch details. / 设备级 GEMM 封装，隐藏内核选择与启动细节。
- `"cutlass/reduction/device/reduce_split_k.h"` — Provides `cutlass/reduction/device/reduce_split_k.h` so this file can use the related API or helper utilities. / 提供 `cutlass/reduction/device/reduce_split_k.h`，使本文件能够使用相关 API 或辅助工具。
- `"cutlass/reduction/kernel/reduce_split_k.h"` — Provides `cutlass/reduction/kernel/reduce_split_k.h` so this file can use the related API or helper utilities. / 提供 `cutlass/reduction/kernel/reduce_split_k.h`，使本文件能够使用相关 API 或辅助工具。
- `"cutlass/reduction/thread/reduction_operators.h"` — Provides `cutlass/reduction/thread/reduction_operators.h` so this file can use the related API or helper utilities. / 提供 `cutlass/reduction/thread/reduction_operators.h`，使本文件能够使用相关 API 或辅助工具。
- `"cutlass/matrix_coord.h"` — Provides `cutlass/matrix_coord.h` so this file can use the related API or helper utilities. / 提供 `cutlass/matrix_coord.h`，使本文件能够使用相关 API 或辅助工具。
- `"cutlass/util/command_line.h"` — Convenience parser for command-line flags used by examples. / 用于示例命令行参数的便捷解析器。
- `"cutlass/util/host_tensor.h"` — Host/device tensor wrapper used to allocate storage and transfer data. / 主机/设备张量封装，用于分配存储并传输数据。
- `"cutlass/util/tensor_view_io.h"` — Tensor printing helpers for debugging layouts and values. / 用于调试布局和值的张量打印辅助工具。
- `"cutlass/util/reference/device/gemm.h"` — Device-side reference helper used in validation flows. / 验证流程中使用的设备端参考辅助工具。
- `"cutlass/util/reference/host/tensor_compare.h"` — Host-side reference implementation used for correctness checking. / 用于正确性检查的主机端参考实现。
- `"cutlass/util/reference/host/tensor_copy.h"` — Host-side reference implementation used for correctness checking. / 用于正确性检查的主机端参考实现。
- `"cutlass/util/reference/host/tensor_fill.h"` — Host-side reference implementation used for correctness checking. / 用于正确性检查的主机端参考实现。
- `"helper.h"` — Provides `helper.h` so this file can use the related API or helper utilities. / 提供 `helper.h`，使本文件能够使用相关 API 或辅助工具。
