---
title: TQ x Mooncake RDMA 内存注册优化总结
date: "2026-04-29 00:00:00"
updated: "2026-04-29 00:00:00"
layout: post
permalink: /collections/0.raw/zhihu/AI-infra/TQ-x-Mooncake-RDMA-内存注册优化总结/
disableNunjucks: true
wiki: false
nav_hidden: true
categories:
  - 文档
tags:
  - 知乎
source_url: https://zhuanlan.zhihu.com/p/2032862444796785454
---


序言
最近 MooncakeStore 更新了一系列针对 RL 场景的关键特性，通过 Hard Pin 机制将数据的生命周期管理交还给用户，并引入 Upsert 接口以实现数据覆写，使 Mooncake 生态在 RL 场景中更具实用性。

[[RFC]: Hard Pin and Upsert for Mooncake Store · Issue #1645 · kvcache-ai/Mooncake](https://link.zhihu.com/?target=https%3A//github.com/kvcache-ai/Mooncake/issues/1645)同时，在TransferQueue项目中，MooncakeStore的接入相对来说还不那么完善，API层面没有利用好zero-copy的能力，同时一些由于上游功能缺失导致的patch也比较多，在3.10.post2 release之后，是时候把MooncakeStore的接入好好优化一下了。

[[perf] Refactor MooncakeStore backend with zero-copy upsert API by 0oshowero0 · Pull Request #77 · Ascend/TransferQueue](https://link.zhihu.com/?target=https%3A//github.com/Ascend/TransferQueue/pull/77)

问题背景
众所周知，RDMA传输之前需要先调ibv_reg_mr注册内存，将对应物理内存 pin 住，防止在传输过程中发生交换，以确保数据的完整性。

但在之前测试NIXL的过程中，我们（主要是 [@提米的大爆炸](https://www.zhihu.com/people/d18e6e8cc2d45129019ccef083eb6536) ）发现，nixl_agent的register_memory对内存缺页的处理不甚完善，对torch.empty的注册耗时会异常地高，导致其注册耗时比 torch.zeros 创建的内存慢 20 倍：

[用empty和zeros创建的tensor注册给RDMA的耗时为什么会差20倍？两种linux缺页的区别处理分析](https://zhuanlan.zhihu.com/p/1981681372750956296)那么在TransferQueue x MooncakeStore里会不会有类似的问题呢？我们如何在考虑全数据流的场景下尽可能提高传输性能，充分发挥RDMA的传输能力，便成为一个值得深入研究的问题。

Mooncake中的register_buffer实现
在 MooncakeStore 的最上层 Python 接口（`store_py.cpp`）中，通过调用RealClient::register_buffer来进行内存注册

```cpp
int RealClient::register_buffer(void *buffer, size_t size) {
    return to_py_ret(register_buffer_internal(buffer, size));
}
```


tl::expected<void, ErrorCode> RealClient::register_buffer_internal(

```cpp
    void *buffer, size_t size) {
    if (!client_) {
        LOG(ERROR) << "Client is not initialized";
        return tl::unexpected(ErrorCode::INVALID_PARAMS);
    }
    auto result = client_->RegisterLocalMemory(buffer, size, kWildcardLocation,
                                               false, true);
    if (!result) {
        return result;
    }
    {
        std::unique_lock<std::shared_mutex> lock(registered_buffer_mutex_);
        registered_buffer_sizes_[buffer] = size;
    }
    return result;
}
```


以RDMA Transport为例，在rdma_transport.cpp中，提供了registerLocalMemory的统一接口，与上层对接。

```cpp
int RdmaTransport::registerLocalMemory(void *addr, size_t length,
                                       const std::string &name,
                                       bool remote_accessible,
                                       bool update_metadata) {
    return registerLocalMemoryInternal(addr, length, name, remote_accessible,
                                       update_metadata, false);
}
```


[https://github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp#L174](https://link.zhihu.com/?target=https%3A//github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp%23L174)

进一步，在registerLocalMemoryInternal里，我们可以明确看到有一段关键的内存pre_touch逻辑：

```cpp
int RdmaTransport::registerLocalMemoryInternal(void *addr, size_t length,
                                               const std::string &name,
                                               bool remote_accessible,
                                               bool update_metadata,
                                               bool force_sequential) {
    (void)remote_accessible;
    BufferDesc buffer_desc;
    const int kBaseAccessRights = IBV_ACCESS_LOCAL_WRITE |
                                  IBV_ACCESS_REMOTE_WRITE |
                                  IBV_ACCESS_REMOTE_READ;

    static int access_rights = kBaseAccessRights;
    if (MCIbRelaxedOrderingEnabled) {
        access_rights |= IBV_ACCESS_RELAXED_ORDERING;
    }
    bool do_pre_touch = context_list_.size() > 0 &&
                        std::thread::hardware_concurrency() >= 4 &&
                        length >= (size_t)4 * 1024 * 1024 * 1024;
    if (do_pre_touch) {
        // Parallel Pre-touch the memory to speedup the registration process.
        int ret = preTouchMemory(addr, length);
        if (ret != 0) {
            return ret;
        }
    }

    /* Parallel register when:
    1. parallel_reg_mr is enabled via MC_ENABLE_PARALLEL_REG_MR;
    2. parallel_reg_mr not set and multiple contexts exist and memory has been
    pre-touched
    Note: If memory hasn't been touched, parallel register can be
    slower. Details in: https://github.com/kvcache-ai/Mooncake/issues/848
    Note: force_sequential is used by batch operations to avoid nested
    parallelism.
    */
    int use_parallel_reg = 0;
    if (!force_sequential) {
        use_parallel_reg = globalConfig().parallel_reg_mr;
        if (use_parallel_reg == -1) {
            use_parallel_reg = context_list_.size() > 1 && do_pre_touch;
        }
    }

    auto reg_start = std::chrono::steady_clock::now();

    if (use_parallel_reg) {
        std::vector<std::thread> reg_threads;
        reg_threads.reserve(context_list_.size());
        std::vector<int> ret_codes(context_list_.size(), 0);
        const int ar = access_rights;  // Local copy for lambda capture

        for (size_t i = 0; i < context_list_.size(); ++i) {
            reg_threads.emplace_back([this, &ret_codes, i, addr, length, ar]() {
                ret_codes[i] =
                    context_list_[i]->registerMemoryRegion(addr, length, ar);
            });
        }

        for (auto &thread : reg_threads) {
            thread.join();
        }

        for (size_t i = 0; i < ret_codes.size(); ++i) {
            if (ret_codes[i] != 0) {
                LOG(ERROR) << "Failed to register memory region with context "
                           << i;
                return ret_codes[i];
            }
        }
    } else {
        for (size_t i = 0; i < context_list_.size(); ++i) {
            int ret = context_list_[i]->registerMemoryRegion(addr, length,
                                                             access_rights);
            if (ret) {
                LOG(ERROR) << "Failed to register memory region with context "
                           << i;
                return ret;
            }
        }
    }

    auto reg_end = std::chrono::steady_clock::now();
    auto reg_duration_ms =
        std::chrono::duration_cast<std::chrono::milliseconds>(reg_end -
                                                              reg_start)
            .count();

    if (globalConfig().trace) {
        LOG(INFO) << "registerMemoryRegion: addr=" << addr
                  << ", length=" << length
                  << ", contexts=" << context_list_.size()
                  << ", parallel=" << (use_parallel_reg ? "true" : "false")
                  << ", duration=" << reg_duration_ms << "ms";
    }

    // Collect keys from all contexts
    for (auto &context : context_list_) {
        buffer_desc.lkey.push_back(context->lkey(addr));
        buffer_desc.rkey.push_back(context->rkey(addr));
    }

    // Get the memory location automatically after registered MR(pinned),
    // when the name is kWildcardLocation("*").
    if (name == kWildcardLocation) {
        bool only_first_page = true;
        const std::vector<MemoryLocationEntry> entries =
            getMemoryLocation(addr, length, only_first_page);
        if (entries.empty()) return -1;
        buffer_desc.name = entries[0].location;
    } else {
        buffer_desc.name = name;
    }

    buffer_desc.addr = (uint64_t)addr;
    buffer_desc.length = length;
#ifdef ENABLE_MULTI_PROTOCOL
    buffer_desc.protocol = "rdma";
#endif
    int rc = metadata_->addLocalMemoryBuffer(buffer_desc, update_metadata);
    if (rc) return rc;
    return 0;
}
```


[https://github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp#L182](https://link.zhihu.com/?target=https%3A//github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp%23L182)

Pre-touch的判断条件是

- context_list_.size() > 0：存在 RDMA 设备上下文。
- hardware_concurrency() >= 4：机器至少有 4 个逻辑 CPU 核心（太弱的机器搞多线程反而增加开销）。
- length >= 4GB：对于小内存，预热的线程创建和销毁开销划不来。

在preTouchMemory的逻辑内部，启动了多个thread去并发touch内存（上限16个thread）。注意，这里只让一个RDMA网卡去进行preTouch，不同线程分别去touch不同的内存段落，从而避免多张网卡的多个线程同时触发缺页中断，竞争mmap_lock。

```cpp
int RdmaTransport::preTouchMemory(void *addr, size_t length) {
    // ... 前置检查 ...

    // 1. 动态决定使用多少个线程
    auto hwc = std::thread::hardware_concurrency();
    // 启发式算法：如果 CPU 核心 > 64，最多只用 16 个线程；否则用核心数和 8 中的较小值。
    // 为什么不拉满核心？因为受限于内存总线带宽，太多线程争抢缺页中断反而会因为锁冲突降低效率。
    auto num_threads = hwc > 64 ? 16 : std::min(hwc, 8u);

    // 限制最大预热长度为网卡允许的单块最大大小
    if (length > (size_t)globalConfig().max_mr_size) {
        length = (size_t)globalConfig().max_mr_size;
    }

    // 2. 将大内存均匀切块给各个线程
    size_t block_size = length / num_threads;
    if (block_size == 0) return 0;

    std::vector<std::thread> threads;
    std::vector<int> thread_results(num_threads, 0);

    // 3. 启动多线程进行分段预热
    for (size_t thread_i = 0; thread_i < num_threads; ++thread_i) {
        // 计算当前线程负责的内存块起始地址
        void *block_addr = static_cast<char *>(addr) + thread_i * block_size;

        threads.emplace_back([this, thread_i, block_addr, block_size, &thread_results]() {
            // 核心预热动作：调用底层真正的预热逻辑
            int ret = context_list_[0]->preTouchMemory(block_addr, block_size);
            thread_results[thread_i] = ret;
        });
    }

    // 4. 等待所有线程完成
    for (auto &thread : threads) thread.join();

    // ... 错误检查 ...
    return 0;
}
```


[https://github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp#L132](https://link.zhihu.com/?target=https%3A//github.com/kvcache-ai/Mooncake/blob/510cd4ee24674ddf6dc070235c7db5e5aa3fc224/mooncake-transfer-engine/src/transport/rdma_transport/rdma_transport.cpp%23L132)

而在preTouchMemory的底层实现里，调用了真正的内存注册逻辑registerMemoryRegionInternal，之后再调用ibv_dereg_mr取消RDMA网卡的registration：

```cpp
int RdmaContext::preTouchMemory(void *addr, size_t length) {
    MemoryRegionMeta mrMeta;
    int ret = registerMemoryRegionInternal(addr, length, IBV_ACCESS_LOCAL_WRITE,
                                           mrMeta);
    if (ret != 0) {
        return ret;
    }
    return ibv_dereg_mr(mrMeta.mr);
}
```


这段逻辑复用主业务逻辑完成了内存pretouch，同时规避了在内核态的锁争抢，从而避免了正式注册内存时缺页中断导致的开销。由于我并不太懂RDMA以及操作系统内核，进一步的分析还有望大佬指点~

相关实测性能对比如下，其中no-fault与fault选项的主要区别是<strong>调用register_buffer前，（通过各种方式，不记入总时间）保证内存已处于 resident 状态；</strong>而lazy与touch的区别则主要是有没有通过朴素的单线程memset去进行pre-touch。（AI写的逻辑，这两个开关没有正交，有点绕。。）

简而言之：

- <strong>no-fault+lazy</strong>：衡量理想情况下（不存在缺页中断）Mooncake进行register_buffer的时间。
- <strong>fault+lazy</strong>：衡量最坏情况下（存在大量缺页中断），Mooncake进行register_buffer的时间。本次测试用例未包含 4GB 以上数据，因此未触发 pre-touch 逻辑（后续可补充对比）。
- <strong>fault+touch</strong>：衡量最坏情况下（存在大量缺页中断）,手动通过单线程memset进行pre-touch后的注册时间。# 通过memset进行touch
LIBC.memset(ctypes.c_void_p(self.ptr), ctypes.c_int(0), ctypes.c_size_t(size))

![](https://pic2.zhimg.com/v2-fa14ad9007e084f8d4dcc5bd3dd6dce7_r.jpg)从实验结果可以看出，缺页中断对 registration 性能的影响显著。此外，简单的单线程 pre-touch 效果有限；即便排除 pre-touch 自身开销，仅在 registration 阶段，pre-touch 也需在 4MB 以上数据量时方可体现收益。

如何在TransferQueue中高效注册内存
Mooncake 作为业界广泛使用的高性能通信库，其内存注册机制已较为完善。那么如何在 TransferQueue 中结合业务特性进一步优化性能？

首先，TransferQueue作为上层RL框架与底层存储传输引擎之间的中间件，肩负着一个“翻译器”的作用：TQ 需将训练数据按行（样本）与列（字段）组织为最小单元，并转换为底层 KV 存储所需的 key-value 形式，这样<strong>上层RL框架就可以实现数据的“零存整取”或“整存零取”，摆脱batch的束缚，实现流式的数据中转</strong>。关于TQ的详细特性介绍可以参考[TransferQueue/tutorial/basic.ipynb at main · Ascend/TransferQueue](https://link.zhihu.com/?target=https%3A//github.com/Ascend/TransferQueue/blob/main/tutorial/basic.ipynb)

![](https://pic4.zhimg.com/v2-fba6fefe2a835132828c3e6657b935df_1440w.jpg)这样把数据粒度拆细会给底层传输传带来不小的挑战，RDMA 倾向于预先注册较大的内存 buffer，让用户直接与 buffer 交互读写，在避免用户态拷贝的同时，一次性发送整块数据以充分利用链路带宽，降低 `register_buffer` 等操作的频率。但在 TQ 的设计中，KV后端看到的是一系列细粒度的 key 和 value，如果真按照这么细的粒度去传输（每个小tensor大约几KB~几百KB），性能肯定是惨不忍睹的。 

为了解决这个问题，朴素思路是在TQ的MooncakeStoreClient内部维护一个buffer，将用户以及TQ上层封装传递下来的values copy一份，再进行RDMA传输。相比于内存registration的开销，内存拷贝则要低至少一个数量级，而且size越小收益越高。

![](https://pica.zhimg.com/v2-f55ac97b1be8d73c1c5ef78ffb50fd2a_r.jpg)memcpy/torch copy性能测试，M2 Mac-mini
![](https://pic3.zhimg.com/v2-80214a660b12f97d4d714575cf96c902_r.jpg)memcpy/torch copy性能测试，ubuntu docker镜像，双通道DDR5 XXXX ；因为在docker容器里，mlock有size限制，因此最后几组实验仅供参考 

但这对TQ来说真的是最优解吗？首先，单台机器可能运行多个 TQ client，每个 client 均维护独立 memory buffer，整体内存占用不容忽视。在 RL 场景中，host memory 还需承载模型 offload，资源并不充裕。其次，memory copy 毕竟引入额外开销，对于大量对象，在 Python 侧循环进行 memory copy 亦非高性能方案。

进一步思考，由于TQ在用户侧约定的数据格式是TensorDict，在打包tensor成TensorDict的时候其实已经做了一次批量的torch.stack/torch.nested.as_nested_tensor，<strong>底层数据已经是内存连续的了</strong>，那么我们其实可以利用这一特点，在MooncakeStoreClient里把上层拆分下来的逐tensor指针+size合成大西瓜，<strong>把物理连续的内存重新合并，这样只需要进行一次（或少量几次，由于不同dtype或多个TensorDict keys）register_memory就可以了</strong>，实现了既要（原地注册省内存）又要（降低register开销）。

![](https://pica.zhimg.com/v2-5fc5a6e9b446612e674d89d15f04922e_1440w.jpg)在PR[[perf] Refactor MooncakeStore backend with zero-copy upsert API by 0oshowero0 · Pull Request #77 · Ascend/TransferQueue](https://link.zhihu.com/?target=https%3A//github.com/Ascend/TransferQueue/pull/77)里，我依照上述思路做了实现，在 put 阶段，找到内存连续的 tensor 进行合并，一次性完成 register_memory：

```python
def merge_contiguous_memory(ptrs: list[int], sizes: list[int]) -> tuple[list[int], list[int]]:
    """Merge contiguous memory regions to reduce register_buffer overhead
```


    Args:

```text
        ptrs: List of memory pointers (starting addresses).
        sizes: List of memory region sizes corresponding to each pointer.
```


    Returns:

```text
        A tuple of (merged_ptrs, merged_sizes) where contiguous regions
        have been merged into single regions.
```


    Example:

```text
        >>> merge_contiguous_memory([0, 10, 30], [10, 20, 10])
        ([0, 30], [30, 10])

        >>> merge_contiguous_memory([0, 5, 20], [5, 5, 10])
        ([0, 20], [10, 10])
    """
    if len(ptrs) != len(sizes):
        raise ValueError("ptrs and sizes must have the same length")
```


    if not ptrs:

```sql
        return [], []

    # Create list of (ptr, size) pairs and sort by pointer address
    regions = sorted(zip(ptrs, sizes, strict=False), key=lambda x: x[0])

    merged_ptrs = []
    merged_sizes = []
```


    # Initialize with the first region
    current_ptr, current_size = regions[0]

    for ptr, size in regions[1:]:
        # Check if current region is contiguous with the next one

```text
        # A region is contiguous if: ptr == current_ptr + current_size
        if ptr == current_ptr + current_size:
            # Merge: extend the current region
            current_size += size
        else:
            # Not contiguous: save the current region and start a new one
            merged_ptrs.append(current_ptr)
            merged_sizes.append(current_size)
            current_ptr, current_size = ptr, size
```


    # Add the last region

```text
    merged_ptrs.append(current_ptr)
    merged_sizes.append(current_size)

    return merged_ptrs, merged_sizes
```

在 get 阶段，先根据 TQ 上层传递的 `BatchMeta` 一次性初始化一个大的 empty tensor，再根据每个 tensor 的 size 切分出对应指针：

BTW，这也是TQ的核心易用性设计之一，把RDMA所需的元数据信息通过BatchMeta进行传递，除了dtype和shape之外，还允许后端传递自定义的字段，并可通过全局的TQ controller进行获取，从而简化了像nixl这种比较裸的通信库需要用户手动交换meta的步骤def allocate_empty_tensors(
    dtypes: list[torch.dtype], shapes: list[tuple]
) -> tuple[list[Tensor], list[int], list[int], list[int]]:
    """Allocate empty tensors, grouping same dtypes into shared memory blocks.

    Instead of allocating each tensor separately, this function groups tensors
    by their dtype and allocates one large contiguous memory block per dtype.
    Each tensor is then created as a view into this shared memory.

    Args:
        dtypes: List of torch dtypes for each tensor.
        shapes: List of shapes (tuples) for each tensor.

    Returns:
        A tuple containing:
            - List of tensors sharing memory within their dtype groups.

```text
            - List of memory pointers (data_ptr) for each tensor.
            - List of base pointers for each allocated memory region (one per dtype).
            - List of total bytes for each allocated memory region (one per dtype).
```


    Example:

```text
        >>> dtypes = [torch.float32, torch.float32, torch.int32, torch.float32]
        >>> shapes = [(10,), (20,), (5,), (15,)]
        >>> tensors, ptrs, region_ptrs, region_sizes = allocate_empty_tensors(dtypes, shapes)
        >>> # tensors[0], [1], [3] share the same dtype and memory block
    """
    assert len(dtypes) == len(shapes), "dtypes and shapes must have the same length"

    if len(dtypes) == 0:
        return [], [], [], []
```


    # Group indices by dtype

```text
    dtype_groups: dict[torch.dtype, list[int]] = {}
    for i, dtype in enumerate(dtypes):
        if dtype not in dtype_groups:
            dtype_groups[dtype] = []
        dtype_groups[dtype].append(i)

    tensor_list = [torch.empty(()) for _ in range(len(dtypes))]
    ptr_list = [0] * len(dtypes)
    region_ptrs: list[int] = []
    region_sizes: list[int] = []
```


    # For each dtype group, allocate one big tensor and create views

```text
    for dtype, indices in dtype_groups.items():
        # Calculate total number of elements needed for this dtype
        total_elements = 0
        shape_info = []  # Store (index, shape, num_elements, offset)
```


        for idx in indices:

```text
            shape = tuple(shapes[idx])
            num_elements = reduce(operator.mul, shape, 1)
            shape_info.append((idx, shape, num_elements, total_elements))
            total_elements += num_elements
```


        # Allocate one big contiguous memory block for this dtype

```text
        big_tensor = torch.empty(total_elements, dtype=dtype)
        region_ptrs.append(big_tensor.data_ptr())
        region_sizes.append(big_tensor.nbytes)
```


        # Create views into the big tensor for each small tensor
        for idx, shape, num_elements, offset in shape_info:
            # Use as_strided to create a view with the correct shape

```text
            small_tensor = big_tensor.as_strided(size=shape, stride=compute_stride(shape), storage_offset=offset)
            tensor_list[idx] = small_tensor
            ptr_list[idx] = small_tensor.data_ptr()

    return tensor_list, ptr_list, region_ptrs, region_sizes
```


在verl上的实测可以发现，这两个函数有效实现了设计目标，将底层client从频繁的内存注册里解放出来（图后续再补😭），真正发挥RDMA的高性能传输（但愿吧，等待一个慷慨的老哥/老姐愿意提供机器帮忙跑个benchmark😭）

One More Thing：How about device memory？
上述讨论均基于 Host Memory，但 Mooncake 还支持 GDR（GPU Direct RDMA）能力，这在目前TQ的接入中还没有完全适配（主要是目前对接的上层 RL 框架通常先将样本数据 to CPU），但随着多模态数据、router replay、OPD forward KL的top K乃至全词表logits需要传输，d2d直传会越来越重要（MooncakeStore还是d2h的，TQ后面也在考虑直接用MooncakeTE去实现d2d传输）。

根据[[feat] Add GPU Direct RDMA (GDR) support for MooncakeStore backend. by xupinjie · Pull Request #79 · Ascend/TransferQueue](https://link.zhihu.com/?target=https%3A//github.com/Ascend/TransferQueue/pull/79) 里的讨论，GPU这边由于nvidia_peermem拦截ibv_reg_mr把GPU mem做了映射，再加上整个内存管理与CPU大不相同，注册开销会显著高于CPU host memory。

![](https://pic2.zhimg.com/v2-4f4c13c26db555c67154e208f6022117_r.jpg)
![](https://pica.zhimg.com/v2-98f525bf1e2a8db59642f6c0c560305e_r.jpg)由于我确实没有什么N卡全家桶可以做测试，前述方案对device memory是否生效还需要进一步探索。

最后，TransferQueue 的设计与实现或许仍有诸多可改进之处。如果你在源码阅读或生产落地中发现了问题，欢迎提交 Issue/PR~ 你的每一次参与，都在帮助这个项目变得更好 ❤️