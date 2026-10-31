# asc_loadunalign_pre

<!-- md-trans-meta sourceCommit=c891f0c5d5b2ac25c5683ff40810fa381d654ece translatedAt=2026-10-23T03:54:33.812557+00:00 pushedAt=2026-10-27T02:26:32.091Z nl=2 -->

## Applicable Products

<!-- npu="950" id1 -->
- Ascend 950PR&950DT products: Supported
<!-- end id1 -->
<!-- npu="A3" id2 -->
- Atlas A3 products: Not supported
<!-- end id2 -->
<!-- npu="910b" id3 -->
- Atlas A2 products: Not supported
<!-- end id3 -->
<!-- npu="310b" id4 -->
- Atlas 200I/500 A2 inference products: Not supported
<!-- end id4 -->
<!-- npu="310p" id5 -->
- Atlas inference products AI Core: Not supported
<!-- end id5 -->
<!-- npu="310p" id6 -->
- Atlas inference products Vector Core: Not supported
<!-- end id6 -->
<!-- npu="910" id7 -->
- Atlas training products: Not supported
<!-- end id7 -->

## Description

The header file path is `"c_api/reg_compute/load/loadunalign.h"`.

This API initializes the [unaligned registers](../../defs/type/data_type_definition.md#unaligned-registers) based on the dtype-aligned start address in the Unified Buffer (UB) to buffer the preceding data needed for subsequent unaligned loads. This stage only completes the initialization of the unaligned register and does not load data into the vector data register.

Assume the effective starting byte address for this initialization is `src_start_addr`. Align `src_start_addr` downward to a 32-byte boundary to obtain `aligned_src_start_addr`. This API loads the 32-byte data in the UB byte address range `[aligned_src_start_addr, aligned_src_start_addr + 32)` into the unaligned register.

The unaligned register output by this API serves as the input unaligned register for [asc_loadunalign](asc_loadunalign.md) or [asc_loadunalign_postupdate](asc_loadunalign_postupdate.md).

This API provides two functional modes:

- **Source address preprocessing mode**: Uses the UB source address as the start address to buffer the preceding data for the contiguous unaligned load mode of [asc_loadunalign](asc_loadunalign.md) or [asc_loadunalign_postupdate](asc_loadunalign_postupdate.md).
- **Address register offset preprocessing mode**: Determines the start address using the UB source address and the element offset recorded in the address register, and buffers the preceding data for the address register offset load mode of `asc_loadunalign_postupdate`. Must be used together with [asc_update_addr_reg](../reg_addr_reg/asc_update_addr_reg.md).

This API is a Reg vector data movement API and takes effect only on AIV.

## Prototype

### Source Address Preprocessing Mode

```c
__simd_callee__ inline void asc_loadunalign_pre(vector_load_unalign& dst,
                                                __ubuf__ <dtype>* src)
```

#### Data Types Supported by dtype

The dtype supports the following data types: `int4b_t`, `int8_t`, `uint8_t`, `fp4x2_e2m1_t`, `fp4x2_e1m2_t`, `hifloat8_t`, `fp8_e8m0_t`, `fp8_e5m2_t`, `fp8_e4m3fn_t`, `int16_t`, `uint16_t`, `half`, `bfloat16_t`, `int32_t`, `uint32_t`, `float`, and `int64_t`.

#### Typical Prototype Example

```c
// Example: float type.
__simd_callee__ inline void asc_loadunalign_pre(vector_load_unalign& dst,
                                                __ubuf__ float* src)
```

### Address Register Offset Preprocessing Mode

```c
__simd_callee__ inline void asc_loadunalign_pre(vector_load_unalign& dst,
                                                __ubuf__ <dtype>* src,
                                                addr_reg offset)
```

#### Data Types Supported by dtype

The dtype supports the following data types: `int4b_t`, `int8_t`, `uint8_t`, `fp4x2_e2m1_t`, `fp4x2_e1m2_t`, `hifloat8_t`, `fp8_e8m0_t`, `fp8_e5m2_t`, `fp8_e4m3fn_t`, `int16_t`, `uint16_t`, `half`, `bfloat16_t`, `int32_t`, `uint32_t`, `float`, and `int64_t`.

#### Typical Prototype Example

```c
// Example: float type.
__simd_callee__ inline void asc_loadunalign_pre(vector_load_unalign& dst,
                                                __ubuf__ float* src,
                                                addr_reg offset)
```

## Parameters

### Source Address Preprocessing Mode

**Table 1** Parameters

| Parameter | Input/Output | Description |
|---|---|---|
| dst | Output | Destination unaligned register. Serves as a buffer for preceding data needed for subsequent unaligned loads. |
| src | Input | Source UB address, which must be aligned to dtype. |

### Address Register Offset Preprocessing Mode

**Table 2** Parameters

| Parameter | Input/Output | Description |
|---|---|---|
| dst | Output | Destination unaligned register. Serves as a buffer for preceding data needed for subsequent unaligned loads. |
| src | Input | Source UB address. The actual access address determined by `src` and `offset` must be aligned to dtype. |
| offset | Input | Address register of type `addr_reg`. This register records the offset relative to the start address of `src`, in elements. The `b8`, `b16`, and `b32` modes indicate that each element occupies 1 byte, 2 bytes, and 4 bytes, respectively. |

## Return Value

None

## Constraints

### General Constraints

- For the general constraints on Reg vector computation C APIs, see [General Constraints](../overview.md#general-constraints).
- The actual access address is aligned downward to a 32-byte boundary inside the API before data is read. The passed `src` or the address determined by `src` and `offset` must be aligned to dtype, and the aligned 32-byte read range must be within the UB address space; otherwise, an error is reported.
- The UB capacity is capped at 256 KB. The capacity available to users varies with compilation options and programming scenarios (by default, 6 KB of SIMD VF stack and 2 KB of Ascend C reserved space are set aside, leaving 248 KB available; in SIMD+SIMT mixed programming, an additional 32 KB to 128 KB is partitioned as Data Cache, further reducing the available capacity). The UB address after applying the offset must not exceed the actual available capacity; otherwise, an error is reported.
- If the UB address ranges accessed by this instruction overlap with those accessed by other instructions, you must insert the synchronization instruction [asc_mem_bar](../reg_sync/asc_mem_bar.md) to ensure that the instructions execute serially and prevent abnormal data from occurring.

### Source Address Preprocessing Mode

- This API and the immediately following load must use the same `src` address.
- When used with [asc_loadunalign](asc_loadunalign.md), this API must be called again to reinitialize before each load.
- When used with the contiguous unaligned load mode of [asc_loadunalign_postupdate](asc_loadunalign_postupdate.md), it can be reused only when continuing to use the automatically updated `src` from the previous call. If `src` is modified separately, reinitialization is required.

### Address Register Offset Preprocessing Mode

- In each loop iteration, `asc_update_addr_reg` must be called first to generate the starting offset for that iteration, and then this API must be called to initialize the unaligned register.
- This API and the immediately following first load must use the same `src` and `offset`.
- Within the same loop iteration, when subsequent loads continue to use the `offset` updated by `inc` through [asc_loadunalign_postupdate](asc_loadunalign_postupdate.md), the updated `src0` can be reused. If `src` or `offset` is modified separately, `src0` must be reinitialized according to the modified actual read address.
- When dtype is `int64_t`, because the address register update API does not support b64 mode, [asc_update_addr_reg_b32](../reg_addr_reg/asc_update_addr_reg.md) must be used to generate the address register. One b64 element occupies two b32 addressing units, so the per-dimension offsets passed to `asc_update_addr_reg_b32` must be set to 2 times the desired b64 element offset.
    ```c
    vector_int64_t src_reg;
    vector_bool mask_b32 = asc_create_mask_b32(PAT_ALL);
    vector_bool mask_b64;
    asc_unpack_lower(mask_b64, mask_b32);
    addr_reg load_offset;
    addr_reg store_offset;
    for (uint16_t i = 0; i < repeatTimes; ++i) {
        load_offset = asc_update_addr_reg_b32(elements_vl * 2);
        // After the data is stored to UB, the data type is B32, so the offset does not need to be multiplied by 2.
        store_offset = asc_update_addr_reg_b32(elements_vl);
        asc_loadalign(src_reg, input, load_offset);
        asc_storealign_pack(output, src_reg, store_offset, mask_b64);
    }
    ```

## Examples

Save the code as `example.asc` and compile and run it with the `bisheng` command, where the `--npu-arch` parameter must specify the corresponding NPU architecture based on the actual product model. For the mapping between specific products and NPU architectures, see [\_\_NPU\_ARCH\_\_](../../../../../guide/programming_guide/language_extension/simd_builtin_keywords.md#npu-arch).

<!-- npu="950" id8 -->
Taking the Ascend 950PR&950DT products (corresponding to the NPU architecture `dav-3510`) as an example, the compilation and execution command is as follows:

```bash
bisheng example.asc -o main --npu-arch=dav-3510 && ./main
```
<!-- end id8 -->

```cpp
#include <cstdint>
#include <iostream>
#include <vector>
#include "c_api/asc_simd.h"
#include "acl/acl.h"

namespace {
__aicore__ constexpr uint32_t ceil_division(uint32_t numerator, uint32_t denominator)
{
    return (numerator + denominator - 1) / denominator;
}

constexpr uint32_t DATA_ELEMENTS = 512;
constexpr uint32_t BUFFER_ELEMENTS = DATA_ELEMENTS + 32;
constexpr uint32_t BUFFER_BYTES = BUFFER_ELEMENTS * sizeof(uint8_t);

__simd_vf__ inline void asc_loadunalign_pre_vf(__ubuf__ uint8_t* dst,
                                               __ubuf__ uint8_t* src,
                                               uint16_t one_repeat_size, uint16_t repeat_time)
{
    vector_load_unalign load_unalign_reg;
    vector_store_unalign store_unalign_reg;
    vector_uint8_t dst_reg;
    asc_loadunalign_pre(load_unalign_reg, src);
    for (uint16_t i = 0; i < repeat_time; ++i) {
        asc_loadunalign_postupdate(dst_reg, load_unalign_reg, src, one_repeat_size);
        asc_storeunalign_postupdate(dst, store_unalign_reg, dst_reg, one_repeat_size);
    }
    asc_storeunalign_post_postupdate(dst, store_unalign_reg, 0);
}

__global__ __vector__ void asc_loadunalign_pre_kernel(__gm__ uint8_t* output, __gm__ uint8_t* input)
{
    asc_init();
    __ubuf__ uint8_t input_local[BUFFER_ELEMENTS];
    __ubuf__ uint8_t output_local[BUFFER_ELEMENTS];
    asc_copy_gm2ub_align(input_local, input, BUFFER_BYTES);
    asc_sync_notify(PIPE_MTE2, PIPE_V, EVENT_ID0);
    asc_sync_wait(PIPE_MTE2, PIPE_V, EVENT_ID0);
    uint16_t one_repeat_size = asc_get_vf_len() / sizeof(uint8_t);
    uint16_t repeat_time = ceil_division(DATA_ELEMENTS, one_repeat_size);
    asc_vf_call<asc_loadunalign_pre_vf>(output_local + 1, input_local + 1, one_repeat_size, repeat_time);
    asc_sync_notify(PIPE_V, PIPE_MTE3, EVENT_ID0);
    asc_sync_wait(PIPE_V, PIPE_MTE3, EVENT_ID0);
    asc_copy_ub2gm_align(output, output_local, BUFFER_BYTES);
    asc_sync();
}
} // namespace

int main()
{
    std::vector<uint8_t> input(BUFFER_ELEMENTS);
    std::vector<uint8_t> output(BUFFER_ELEMENTS, 0xff);
    for (uint16_t i = 0; i < BUFFER_ELEMENTS; ++i) input[i] = static_cast<uint8_t>(i % 251 + 1);

    aclInit(nullptr);
    aclrtSetDevice(0);
    uint8_t* input_device = nullptr;
    uint8_t* output_device = nullptr;
    aclrtMalloc(reinterpret_cast<void**>(&input_device), BUFFER_BYTES, ACL_MEM_MALLOC_HUGE_FIRST);
    aclrtMalloc(reinterpret_cast<void**>(&output_device), BUFFER_BYTES, ACL_MEM_MALLOC_HUGE_FIRST);
    aclrtMemcpy(input_device, BUFFER_BYTES, input.data(), BUFFER_BYTES, ACL_MEMCPY_HOST_TO_DEVICE);
    asc_loadunalign_pre_kernel<<<1, 0>>>(output_device, input_device);
    aclrtSynchronizeDevice();
    aclrtMemcpy(output.data(), BUFFER_BYTES, output_device, BUFFER_BYTES, ACL_MEMCPY_DEVICE_TO_HOST);

    bool passed = true;
    for (uint16_t i = 0; i < DATA_ELEMENTS; ++i) passed = passed && output[i + 1] == input[i + 1];
    std::cout << (passed ? "[Success]" : "[Failed]") << " asc_loadunalign_pre example." << std::endl;
    aclrtFree(input_device);
    aclrtFree(output_device);
    aclrtResetDevice(0);
    aclFinalize();
    return passed ? 0 : 1;
}
```
