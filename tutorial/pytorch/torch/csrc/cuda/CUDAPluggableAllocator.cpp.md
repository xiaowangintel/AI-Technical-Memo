# CUDAPluggableAllocator.cpp — Code Analysis / 代码分析

## Source / 来源

- **File**: `torch/csrc/cuda/CUDAPluggableAllocator.cpp`
- **Repository**: `pytorch/pytorch`
- **Purpose**: This file implements logic for `CUDAPluggableAllocator.cpp` inside the CUDA backend bindings, memory helpers, streams, events, and communication utilities, with emphasis on allocator integration, cuda backend integration. / 该文件在CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具中针对 `CUDAPluggableAllocator.cpp` 实现逻辑，重点涉及分配器集成、CUDA 后端集成。

## Line-by-Line Analysis / 逐行分析

### Lines 1-5: Header dependencies / 头文件依赖
```cpp
#include <c10/cuda/CUDACachingAllocator.h>
#include <c10/cuda/CUDAGuard.h>
#include <mutex>
#include <utility>

```
- **EN**: Pulls in the headers required by this translation unit, including interfaces from the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 引入该翻译单元所需的头文件，包括来自CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的接口。

### Lines 6-7: Header dependencies / 头文件依赖
```cpp
#include <torch/csrc/cuda/CUDAPluggableAllocator.h>

```
- **EN**: Pulls in the headers required by this translation unit, including interfaces from the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 引入该翻译单元所需的头文件，包括来自CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的接口。

### Lines 8-9: Namespace scope / 命名空间作用域
```cpp
namespace torch::cuda::CUDAPluggableAllocator {

```
- **EN**: Opens or organizes namespace scopes so related symbols live under the expected PyTorch component hierarchy.
- **CN**: 打开或组织命名空间作用域，使相关符号位于预期的 PyTorch 组件层级中。

### Lines 10-11: Supporting statements / 辅助语句
```cpp
int device_count = 0;

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 12-13: Supporting statements / 辅助语句
```cpp
void custom_raw_deleter(void* ptr);

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 14-15: Function `_AllocationMetadata` / 函数 `_AllocationMetadata`
```cpp
_AllocationMetadata::_AllocationMetadata() : size(0), device_idx(-1) {}

```
- **EN**: Implements `_AllocationMetadata`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `_AllocationMetadata`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 16-21: Supporting statements / 辅助语句
```cpp
_AllocationMetadata::_AllocationMetadata(
    size_t size,
    c10::DeviceIndex device_idx,
    cudaStream_t stream)
    : size(size), device_idx(device_idx), stream(stream) {}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 22-30: Supporting statements / 辅助语句
```cpp
// This is a fast API to just register allocators
// based on function pointers (ie. external .so libraries)
// This avoids having to link against libtorch for C++ based custom allocators
// And also use this from python
CUDAPluggableAllocator::CUDAPluggableAllocator(
    std::function<void*(size_t, int, cudaStream_t)> alloc_fn,
    std::function<void(void*, size_t, int, cudaStream_t)> free_fn)
    : alloc_fn_(std::move(alloc_fn)), free_fn_(std::move(free_fn)) {}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 31-42: Function `CUDAPluggableAllocator` / 函数 `CUDAPluggableAllocator`
```cpp
CUDAPluggableAllocator::CUDAPluggableAllocator(CUDAPluggableAllocator& other)
    : alloc_fn_(other.alloc_fn_),
      free_fn_(other.free_fn_),
      init_fn_(other.init_fn_),
      reset_fn_(other.reset_fn_),
      memory_fraction_fn_(other.memory_fraction_fn_),
      base_alloc_fn_(other.base_alloc_fn_),
      record_stream_fn_(other.record_stream_fn_),
      begin_allocate_to_pool_fn_(other.begin_allocate_to_pool_fn_),
      end_allocate_to_pool_fn_(other.end_allocate_to_pool_fn_),
      relase_pool_fn_(other.relase_pool_fn_) {}

```
- **EN**: Implements `CUDAPluggableAllocator`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `CUDAPluggableAllocator`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 43-46: Function `set_init_fn` / 函数 `set_init_fn`
```cpp
void CUDAPluggableAllocator::set_init_fn(std::function<void(int)> init_fn) {
  init_fn_ = std::move(init_fn);
}

```
- **EN**: Implements `set_init_fn`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `set_init_fn`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 47-50: Function `set_reset_fn` / 函数 `set_reset_fn`
```cpp
void CUDAPluggableAllocator::set_reset_fn(std::function<void()> reset_fn) {
  reset_fn_ = std::move(reset_fn);
}

```
- **EN**: Implements `set_reset_fn`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `set_reset_fn`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 51-55: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_memory_fraction_fn(
    std::function<void(double, int)> memory_fraction_fn) {
  memory_fraction_fn_ = std::move(memory_fraction_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 56-60: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_base_alloc_fn(
    std::function<void*(void*, size_t*)> base_alloc_fn) {
  base_alloc_fn_ = std::move(base_alloc_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 61-65: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_record_stream_fn(
    std::function<void(void* ptr, cudaStream_t stream)> record_stream_fn) {
  record_stream_fn_ = std::move(record_stream_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 66-72: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_begin_allocate_to_pool(
    std::function<
        void(int, c10::cuda::MempoolId_t, std::function<bool(cudaStream_t)>)>
        capture_begin_fn) {
  begin_allocate_to_pool_fn_ = std::move(capture_begin_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 73-77: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_end_allocate_to_pool_fn(
    std::function<void(int, c10::cuda::MempoolId_t)> capture_about_to_end_fn) {
  end_allocate_to_pool_fn_ = std::move(capture_about_to_end_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 78-82: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::set_release_pool(
    std::function<void(int, c10::cuda::MempoolId_t)> capture_destroy_fn) {
  relase_pool_fn_ = std::move(capture_destroy_fn);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 83-94: Supporting statements / 辅助语句
```cpp
void* CUDAPluggableAllocator::malloc(
    size_t size,
    c10::DeviceIndex device,
    cudaStream_t stream) {
  void* r = alloc_fn_(size, device, stream);
  {
    const std::lock_guard<std::mutex> lock(allocator_mutex_);
    allocation_metadata_.emplace(r, _AllocationMetadata(size, device, stream));
  }
  return r;
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 95-104: Function `allocate` / 函数 `allocate`
```cpp
c10::DataPtr CUDAPluggableAllocator::allocate(size_t size) {
  c10::DeviceIndex device = -1;
  C10_CUDA_CHECK(c10::cuda::GetDevice(&device));
  cudaStream_t stream = c10::cuda::getCurrentCUDAStream(device);
  void* r = this->malloc(size, device, stream);
  c10::DataPtr data_ptr = {
      r, r, raw_deleter(), c10::Device(c10::DeviceType::CUDA, device)};
  return data_ptr;
}

```
- **EN**: Implements `allocate`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `allocate`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 105-108: Function `raw_deleter` / 函数 `raw_deleter`
```cpp
c10::DeleterFnPtr CUDAPluggableAllocator::raw_deleter() const {
  return &custom_raw_deleter;
}

```
- **EN**: Implements `raw_deleter`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `raw_deleter`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 109-115: Function `raw_alloc` / 函数 `raw_alloc`
```cpp
void* CUDAPluggableAllocator::raw_alloc(size_t nbytes) {
  c10::DeviceIndex device = -1;
  C10_CUDA_CHECK(c10::cuda::GetDevice(&device));
  cudaStream_t stream = c10::cuda::getCurrentCUDAStream(device);
  return malloc(nbytes, device, stream);
}

```
- **EN**: Implements `raw_alloc`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `raw_alloc`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 116-123: Supporting statements / 辅助语句
```cpp
void* CUDAPluggableAllocator::raw_alloc_with_stream(
    size_t nbytes,
    cudaStream_t stream) {
  c10::DeviceIndex device = -1;
  C10_CUDA_CHECK(c10::cuda::GetDevice(&device));
  return malloc(nbytes, device, stream);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 124-141: Function `raw_delete` / 函数 `raw_delete`
```cpp
void CUDAPluggableAllocator::raw_delete(void* ptr) {
  cudaStream_t stream{};
  c10::DeviceIndex device_idx = -1;
  size_t size = 0;
  {
    const std::lock_guard<std::mutex> lock(allocator_mutex_);
    TORCH_CHECK(
        allocation_metadata_.count(ptr),
        "Trying to free a pointer not allocated here");
    _AllocationMetadata& metadata = allocation_metadata_[ptr];
    size = metadata.size;
    device_idx = metadata.device_idx;
    stream = metadata.stream;
    allocation_metadata_.erase(ptr);
  }
  free_fn_(ptr, size, device_idx, stream);
}

```
- **EN**: Implements `raw_delete`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `raw_delete`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 142-148: Function `init` / 函数 `init`
```cpp
void CUDAPluggableAllocator::init(int device_count) {
  if (init_fn_) {
    init_fn_(device_count);
  }
  initialized_ = true;
}

```
- **EN**: Implements `init`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `init`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 149-152: Function `initialized` / 函数 `initialized`
```cpp
bool CUDAPluggableAllocator::initialized() {
  return initialized_;
}

```
- **EN**: Implements `initialized`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `initialized`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 153-159: Function `getMemoryFraction` / 函数 `getMemoryFraction`
```cpp
double CUDAPluggableAllocator::getMemoryFraction(c10::DeviceIndex device) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support getMemoryFraction. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Implements `getMemoryFraction`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `getMemoryFraction`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 160-167: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::setMemoryFraction(
    double fraction,
    c10::DeviceIndex device) {
  if (memory_fraction_fn_) {
    memory_fraction_fn_(fraction, device);
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 168-174: Supporting statements / 辅助语句
```cpp
std::vector<c10::cuda::CUDACachingAllocator::StreamSegmentSize>
CUDAPluggableAllocator::getExpandableSegmentSizes(c10::DeviceIndex device) {
  TORCH_CHECK(
      false,
      "CUDAMallocAsyncAllocator does not yet support getExpandableSegmentSizes.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 175-181: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::emptyCache(
    /*unused*/ c10::cuda::MempoolId_t mempool_id) {
  if (reset_fn_) {
    return reset_fn_();
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 182-190: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::cacheInfo(
    c10::DeviceIndex device,
    size_t* largestBlock) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support cacheInfo. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 191-198: Function `getBaseAllocation` / 函数 `getBaseAllocation`
```cpp
void* CUDAPluggableAllocator::getBaseAllocation(void* ptr, size_t* size) {
  if (base_alloc_fn_) {
    return base_alloc_fn_(ptr, size);
  } else {
    return ptr;
  }
}

```
- **EN**: Implements `getBaseAllocation`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `getBaseAllocation`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 199-206: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::recordStream(
    const c10::DataPtr& ptr,
    c10::cuda::CUDAStream stream) {
  if (record_stream_fn_) {
    record_stream_fn_(ptr.get(), stream);
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 207-214: Supporting statements / 辅助语句
```cpp
c10::CachingDeviceAllocator::DeviceStats CUDAPluggableAllocator::getDeviceStats(
    c10::DeviceIndex device) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support getDeviceStats. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 215-221: Function `resetAccumulatedStats` / 函数 `resetAccumulatedStats`
```cpp
void CUDAPluggableAllocator::resetAccumulatedStats(c10::DeviceIndex device) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support resetAccumulatedStats. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Implements `resetAccumulatedStats`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `resetAccumulatedStats`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 222-228: Function `resetPeakStats` / 函数 `resetPeakStats`
```cpp
void CUDAPluggableAllocator::resetPeakStats(c10::DeviceIndex device) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support resetPeakStats. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Implements `resetPeakStats`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `resetPeakStats`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 229-237: Supporting statements / 辅助语句
```cpp
c10::cuda::CUDACachingAllocator::SnapshotInfo CUDAPluggableAllocator::snapshot(
    c10::cuda::MempoolId_t mempool_id,
    bool include_traces) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support snapshot. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 238-245: Supporting statements / 辅助语句
```cpp
c10::cuda::CUDACachingAllocator::ShareableHandle CUDAPluggableAllocator::
    shareIpcHandle(void* ptr) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support shareIPcHandle. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 246-252: Function `getIpcDevPtr` / 函数 `getIpcDevPtr`
```cpp
std::shared_ptr<void> CUDAPluggableAllocator::getIpcDevPtr(std::string handle) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support getIpcDevPtr. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Implements `getIpcDevPtr`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `getIpcDevPtr`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 253-262: Supporting statements / 辅助语句
```cpp
// CUDAGraph interactions
void CUDAPluggableAllocator::beginAllocateToPool(
    c10::DeviceIndex device,
    c10::cuda::MempoolId_t mempool_id,
    std::function<bool(cudaStream_t)> filter) {
  if (begin_allocate_to_pool_fn_) {
    begin_allocate_to_pool_fn_(device, mempool_id, std::move(filter));
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 263-270: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::endAllocateToPool(
    c10::DeviceIndex device,
    c10::cuda::MempoolId_t mempool_id) {
  if (end_allocate_to_pool_fn_) {
    end_allocate_to_pool_fn_(device, mempool_id);
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 271-278: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::releasePool(
    c10::DeviceIndex device,
    c10::cuda::MempoolId_t mempool_id) {
  if (relase_pool_fn_) {
    relase_pool_fn_(device, mempool_id);
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 279-291: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::recordHistory(
    bool enabled,
    c10::cuda::CUDACachingAllocator::CreateContextFn context_recorder,
    size_t alloc_trace_max_entries,
    c10::cuda::CUDACachingAllocator::RecordContext when,
    bool clearHistory,
    const std::vector<std::string>& skip_actions) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support recordHistory. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 292-299: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::attachOutOfMemoryObserver(
    c10::cuda::CUDACachingAllocator::OutOfMemoryObserver observer) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support attachOutOfMemoryObserver. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 300-307: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::attachOomRejectionObserver(
    c10::cuda::CUDACachingAllocator::OomRejectionObserver observer) {
  TORCH_CHECK_NOT_IMPLEMENTED(
      false,
      "CUDAPluggableAllocator does not yet support attachOomRejectionObserver. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 308-315: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::attachAllocatorTraceTracker(
    c10::cuda::CUDACachingAllocator::AllocatorTraceTracker tracker) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not support attachAllocatorTraceTracker. "
      "attachAllocatorTraceTracker is only used inside Pytorch.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 316-325: Supporting statements / 辅助语句
```cpp
std::shared_ptr<c10::cuda::CUDACachingAllocator::AllocatorState>
CUDAPluggableAllocator::getCheckpointState(
    c10::DeviceIndex device,
    at::cuda::MempoolId_t id) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support getCheckpointState. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 326-335: Supporting statements / 辅助语句
```cpp
c10::cuda::CUDACachingAllocator::CheckpointDelta CUDAPluggableAllocator::
    setCheckpointPoolState(
        c10::DeviceIndex device,
        std::shared_ptr<c10::cuda::CUDACachingAllocator::AllocatorState> pps) {
  TORCH_CHECK(
      false,
      "CUDAPluggableAllocator does not yet support setCheckpointPoolState. "
      "If you need it, please file an issue describing your use case.");
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 336-348: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::enablePeerAccess(
    c10::DeviceIndex dev,
    c10::DeviceIndex dev_to_access) {
  c10::cuda::CUDAGuard device_guard(dev);
  cudaError_t err = cudaDeviceEnablePeerAccess(dev_to_access, 0);
  if (err == cudaErrorPeerAccessAlreadyEnabled) {
    // ignore and clear the error if access was already enabled
    (void)cudaGetLastError();
  } else {
    C10_CUDA_CHECK(err);
  }
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 349-359: Supporting statements / 辅助语句
```cpp
cudaError_t CUDAPluggableAllocator::memcpyAsync(
    void* dst,
    int dstDevice,
    const void* src,
    int srcDevice,
    size_t count,
    cudaStream_t stream,
    bool p2p_enabled) {
  return cudaMemcpyAsync(dst, src, count, cudaMemcpyDeviceToDevice, stream);
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 360-363: Function `name` / 函数 `name`
```cpp
std::string CUDAPluggableAllocator::name() {
  return "pluggable";
}

```
- **EN**: Implements `name`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `name`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 364-371: Supporting statements / 辅助语句
```cpp
void CUDAPluggableAllocator::copy_data(
    void* dest,
    const void* src,
    std::size_t count) const {
  C10_CUDA_CHECK(
      cudaMemcpy(dest, src, count, cudaMemcpyKind::cudaMemcpyDeviceToDevice));
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 372-374: Supporting statements / 辅助语句
```cpp
std::shared_ptr<c10::cuda::CUDACachingAllocator::CUDAAllocator>
    current_custom_allocator;

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 375-379: Supporting statements / 辅助语句
```cpp
std::shared_ptr<c10::cuda::CUDACachingAllocator::CUDAAllocator>
getCurrentAllocator() {
  return current_custom_allocator;
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 380-390: Supporting statements / 辅助语句
```cpp
// TODO: add more functions in the argument
std::shared_ptr<c10::cuda::CUDACachingAllocator::CUDAAllocator>
createCustomAllocator(
    std::function<void*(size_t, int, cudaStream_t)> alloc_fn,
    std::function<void(void*, size_t, int, cudaStream_t)> free_fn) {
  std::shared_ptr<CUDAPluggableAllocator> allocator(
      new CUDAPluggableAllocator(std::move(alloc_fn), std::move(free_fn)));
  allocator->init(device_count);
  return allocator;
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 391-400: Supporting statements / 辅助语句
```cpp
void changeCurrentAllocator(
    const std::shared_ptr<c10::cuda::CUDACachingAllocator::CUDAAllocator>&
        allocator) {
  TORCH_CHECK(
      !c10::cuda::CUDACachingAllocator::allocator.load()->initialized(),
      "Can't swap an already initialized allocator");
  c10::cuda::CUDACachingAllocator::allocator.store(allocator.get());
  current_custom_allocator = allocator;
}

```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

### Lines 401-404: Function `custom_raw_deleter` / 函数 `custom_raw_deleter`
```cpp
void custom_raw_deleter(void* ptr) {
  current_custom_allocator->raw_delete(ptr);
}

```
- **EN**: Implements `custom_raw_deleter`, one of the operational units in this file for the CUDA backend bindings, memory helpers, streams, events, and communication utilities.
- **CN**: 实现 `custom_raw_deleter`，它是该文件中服务于CUDA 后端绑定、内存辅助逻辑、流、事件与通信工具的一个运行单元。

### Lines 405-405: Supporting statements / 辅助语句
```cpp
} // namespace torch::cuda::CUDAPluggableAllocator
```
- **EN**: Contains local statements, constants, or helper glue that support the surrounding control flow and data movement.
- **CN**: 包含局部语句、常量或辅助胶水代码，用于支撑周围的控制流与数据传递。

## Key Concepts / 关键概念
- CUDA backend integration / CUDA 后端集成
- Allocator integration / 分配器集成

## Dependencies / 依赖关系
### Internal / 内部
- `c10/cuda/CUDACachingAllocator.h`
- `c10/cuda/CUDAGuard.h`
- `torch/csrc/cuda/CUDAPluggableAllocator.h`
### External / 外部
- `mutex`
- `utility`
