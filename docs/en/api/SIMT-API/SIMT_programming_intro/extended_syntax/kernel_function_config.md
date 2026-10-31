# Kernel Function Configuration

<!-- md-trans-meta sourceCommit=57ffc0e98dc1ae7768d3eaadf217e1d94fdb6424 translatedAt=2026-10-22T08:29:42.644Z pushedAt=2026-10-22T08:39:23.588Z nl=2 -->

## Kernel Function Definition

A kernel function is the Device-side entry function of SIMT programming, responsible for coordinating the execution flow of the entire operator. The function definition syntax is as follows:

```cpp
__global__ void kernel_name(uint32_t* param1, float* param2, ...);
```

The key modifiers are described as follows:

-   `__global__`: A required modifier that identifies the kernel function, indicating that it can be invoked from the Host side through <<<...\>\>\>.

The kernel function definition has the following constraints:

-   The return value type must be void.
-   Input parameters support basic data types and pointer types to basic data types, such as int32\_t, **float**, int32\_t\*, float\*, and so on.
-   Pointer parameters must point to memory addresses in Global Memory.

## \_\_launch\_bounds\_\_\(N\)

When multiple threads execute concurrently, each thread using fewer registers allows more threads to be launched within a single thread block, thereby improving performance. Therefore, the compiler uses a heuristic algorithm to keep register spilling and the instruction count at a minimum while reducing register usage as much as possible. The application can restrict the launch bounds by using the `__launch_bounds__()` qualifier in the `__global__` function definition, providing additional information to help the compiler optimize this process. This is an optional configuration.

`__launch_bounds__()`: A function marker macro, optionally configured on the kernel function (Kernel), used to specify the maximum number of threads launched by the kernel function (Kernel) at compile time. If `__launch_bounds__` is not configured, the maximum number of threads defaults to 1024. The parameter N must satisfy the following conditions:

-   N \>= blockDim.x \* blockDim.y \*blockDim.z
-   The value range of N is from 1 to 2048.

    The maximum number of threads determines the number of registers that can be allocated to each thread. For the specific correspondence, see the following table. Registers are used to store local variables in a thread. If the number of local variables exceeds the number of registers, issues such as register spilling are likely to occur. It is recommended that the maximum number of threads be consistent with the number of threads configured when the kernel function (Kernel) is launched.

    **Table 1**  Relationship between __launch_bounds__(N) and the number of registers available per thread

    | N | Number of registers available to each thread |
    | --- | --- |
    | 1025~2048 | 16 |
    | 513~1024 | 32 |
    | 257~512 | 64 |
    | 1~256 | 127 |

## <<<\>\>\> Call

In SIMT programming, when using <<<\>\>\> to call a function decorated with the `__global__` qualifier, the execution configuration must be specified, in the following form:

```cpp
<<<blocks_per_grid, threads_per_block, dyn_ubuf_size, stream>>>
```

The execution configuration is determined by four parameters. For detailed usage, see [Kernel Function Configuration](../../../../guide/programming_guide/language_extension/simt_builtin_keywords.md#kernel-function-configuration):

-   blocks\_per\_grid: [dim3](./builtin_data_types.md#dim3) type, used to specify the dimensions and scale of the grid. blocks\_per\_grid.x \* blocks\_per\_grid.y \* blocks\_per\_grid.z equals the total number of thread blocks launched, and must not exceed 65535.
-   threads\_per\_block: [dim3](./builtin_data_types.md#dim3) type, used to specify the dimensions and scale of each thread block. threads\_per\_block.x \* threads\_per\_block.y \* threads\_per\_block.z equals the number of threads contained in each thread block, and must be less than or equal to the \_\_launch\_bounds\_\_ configuration.
-   dyn\_ubuf\_size: size\_t type, used to specify the size of shared memory dynamically allocated per thread block, in bytes. This memory is used for arrays. For details, see the "dynamic allocation" method in [Shared Memory](../../../../guide/programming_guide/programming_model/ai_core_simt_programming/memory_hierarchy.md#shared-memory).
-   stream: aclrtStream type pointer, specifying the associated stream, used to maintain the execution order of asynchronous operations.

The following example shows how to declare and call a Kernel.

```cpp
// Declare.
__global__ void add_custom(float* x, float* y, float* z, uint64_t total_length);
// Call.
add_custom<<<blocks_per_grid, threads_per_block, dyn_ubuf_size, stream>>>(x, y, z, 1024);
```
