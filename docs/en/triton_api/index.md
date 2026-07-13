# triton.language

## Ascend Extension API List

|api|Description|
|--|--|
|[extract_slice](./Extension_Ops/extract_slice.md)|  Extracts a tensor from an input tensor according to the offset, size, and stride parameters specified by the operation. |
|[insert_slice](./Extension_Ops/insert_slice.md)| Inserts a tensor (sub-tensor) into another tensor at a specified position, according to the offset, size, and stride parameters specified by the operation. |
|[sync_block](./Extension_Ops/sync_block.md) | An explicit inter-core synchronization instruction used to coordinate execution order and data consistency between different cores in the Cube-Vector architecture. |
|[compile_hint](./Extension_Ops/compile_hint.md) | A compiler hint mechanism that allows users to attach metadata information to tensors, which is passed to the compiler backend to guide optimization and code generation.|
|[multibuffer](./Extension_Ops/multibuffer.md) | Sets multi-buffering for a tensor, allowing the compiler to create multiple copies of the same tensor. |
|[parallel](./Extension_Ops/parallel.md) | `parallel` is an iterator specifically designed for multi-core parallel execution, providing explicit multi-core parallel semantics. |
|[get_element](./Extension_Ops/get_element.md)| Reads a single element from an input tensor based on a given index. |
|[index_select High-Performance Interface](./Extension_Ops/index_select_simd.md) | Gathers multiple indices in parallel along non-trailing axes and copies data zero-copy from global memory (GM) directly to the correct position in the unified buffer (UB) in units of tiles. This operation is equivalent to a high-performance implementation of `torch.index_select`, suitable for scenarios like embedding layer lookups and sparse index access. |

```{toctree}
:maxdepth: 3
:hidden:

Extension_Ops/extract_slice.md
Extension_Ops/insert_slice.md
Extension_Ops/sync_block.md
Extension_Ops/compile_hint.md
Extension_Ops/multibuffer.md
Extension_Ops/parallel.md
Extension_Ops/get_element.md
Extension_Ops/index_select_simd.md
```

## Atomic Operations

|api|Description|
|--|--|
|[atomic_add](./Atomic_Ops/atomic_add.md)  |Performs an atomic addition at the memory location specified by pointer |
|[atomic_and](./Atomic_Ops/atomic_and.md)  |Performs an atomic logical AND operation at the memory location specified by pointer |
|[atomic_cas](./Atomic_Ops/atomic_cas.md)  |Performs an atomic compare-and-swap operation at the memory location specified by pointer |
|[atomic_max](./Atomic_Ops/atomic_max.md)  |Performs an atomic maximum operation at the memory location specified by pointer |
|[atomic_min](./Atomic_Ops/atomic_min.md)  |Performs an atomic minimum operation at the memory location specified by pointer |
|[atomic_or](./Atomic_Ops/atomic_or.md)  |Performs an atomic logical OR operation at the memory location specified by pointer |
|[atomic_xchg](./Atomic_Ops/atomic_xchg.md)  |Performs an atomic exchange operation at the memory location specified by pointer |
|[atomic_xor](./Atomic_Ops/atomic_xor.md)  |Performs an atomic logical XOR operation at the memory location specified by pointer |

```{toctree}
:maxdepth: 3
:hidden:

Atomic_Ops/atomic_add.md
Atomic_Ops/atomic_and.md
Atomic_Ops/atomic_cas.md
Atomic_Ops/atomic_max.md
Atomic_Ops/atomic_min.md
Atomic_Ops/atomic_or.md
Atomic_Ops/atomic_xchg.md
Atomic_Ops/atomic_xor.md
```

## Comparing Operations

|api|Description|
|--|--|
| [eq](./Comparing_Ops/eq.md) | Compares elements of two tensors, equivalent to `==` |
| [le](./Comparing_Ops/le.md) | Compares elements of two tensors, equivalent to `<=`. |
| [ge](./Comparing_Ops/ge.md) | Compares elements of two tensors, equivalent to `>=`. |
| [lt](./Comparing_Ops/lt.md) | Compares elements of two tensors, equivalent to `<`. |
| [gt](./Comparing_Ops/gt.md) | Compares elements of two tensors, equivalent to `>`. |
| [ne](./Comparing_Ops/ne.md) | Compares elements of two tensors, equivalent to `!=`. |

```{toctree}
:maxdepth: 3
:hidden:

Comparing_Ops/eq.md
Comparing_Ops/le.md
Comparing_Ops/ge.md
Comparing_Ops/lt.md
Comparing_Ops/gt.md
Comparing_Ops/ne.md
```

## Compiler Hint Operations

|api|Description|
|--|--|
|[debug_barrier](./Compiler_Hint_Ops/debug_barrier.md) |Inserts a barrier to synchronize all threads in a block |
|[max_constancy](./Compiler_Hint_Ops/max_constancy.md) |Informs the compiler that the first value in input is constant |
|[max_contiguous](./Compiler_Hint_Ops/max_contiguous.md) |Informs the compiler that the first value in input is contiguous |
|[multiple_of](./Compiler_Hint_Ops/multiple_of.md) |Informs the compiler that all values in input are multiples of value |
|[assume](./Compiler_Hint_Ops/assume.md)         | Provides conditional assumption information to the compiler, allowing optimization based on known-true conditions. |
|[compile_hint](./Extension_Ops/compile_hint.md) | A compiler hint mechanism that allows users to attach metadata information to tensors, which is passed to the compiler backend to guide optimization and code generation.|
|[multibuffer](./Extension_Ops/multibuffer.md) | Sets multi-buffering for a tensor, allowing the compiler to create multiple copies of the same tensor. |
|[parallel](./Extension_Ops/parallel.md) | `parallel` is an iterator specifically designed for multi-core parallel execution, providing explicit multi-core parallel semantics. |
|[sync_block instruction](./Extension_Ops/sync_block.md) | An explicit inter-core synchronization instruction used to coordinate execution order and data consistency between different cores in the Cube-Vector architecture. |

```{toctree}
:maxdepth: 3
:hidden:

Compiler_Hint_Ops/debug_barrier.md
Compiler_Hint_Ops/max_constancy.md
Compiler_Hint_Ops/max_contiguous.md
Compiler_Hint_Ops/multiple_of.md
Compiler_Hint_Ops/assume.md
Extension_Ops/compile_hint.md
Extension_Ops/multibuffer.md
Extension_Ops/parallel.md
Extension_Ops/sync_block.md
```

## Creation Operations

|api|Description|
|--|--|
|[arange](./Creation_Ops/arange.md) | Returns consecutive values in the half-open interval [start, end) |
|[cat](./Creation_Ops/cat.md) | Concatenates the given blocks |
|[full](./Creation_Ops/full.md) | Returns a tensor filled with a scalar value of the specified shape and dtype|
|[zeros](./Creation_Ops/zeros.md)| Returns a tensor filled with the scalar value 0 of the specified shape and dtype |
|[zeros_like](./Creation_Ops/zeros_like.md)| Returns an all-zeros tensor with the same shape and dtype as the given tensor |
|[cast](./Creation_Ops/cast.md)| Casts a tensor to the specified dtype|

```{toctree}
:maxdepth: 3
:hidden:

Creation_Ops/arange.md
Creation_Ops/cat.md
Creation_Ops/full.md
Creation_Ops/zeros.md
Creation_Ops/zeros_like.md
Creation_Ops/cast.md
```

## Debug Operations

|api|Description|
|--|--|
|[static_print](./Debug_Ops/static_print.md) |Prints values at compile time |
|[static_assert](./Debug_Ops/static_assert.md) |Asserts a condition at compile time |
|[device_print](./Debug_Ops/device_print.md) |Prints values from the device at runtime |
|[device_assert](./Debug_Ops/device_assert.md) |Asserts a condition on the device at runtime |

```{toctree}
:maxdepth: 3
:hidden:

Debug_Ops/static_print.md
Debug_Ops/static_assert.md
Debug_Ops/device_print.md
Debug_Ops/device_assert.md

```

## Indexing and Element Operations

|api|Description|
|--|--|
|[flip](./Indexing_Ops/flip.md) |Flips tensor x along dimension dim |
|[where](./Indexing_Ops/where.md) |Returns a tensor of elements from x or y based on condition |
|[swizzle2d](./Indexing_Ops/swizzle2d.md) |Converts indices of a row-major matrix of size_i * size_j to indices of a column-major matrix with groups of size_g rows |
|[get_element](./Extension_Ops/get_element.md)| Reads a single element from an input tensor based on a given index. |
|[index_select High-Performance Interface](./Extension_Ops/index_select_simd.md) | Gathers multiple indices in parallel along non-trailing axes and copies data zero-copy from global memory (GM) directly to the correct position in the unified buffer (UB) in units of tiles. This operation is equivalent to a high-performance implementation of `torch.index_select`, suitable for scenarios like embedding layer lookups and sparse index access. |
|[gather](./Indexing_Ops/gather.md) | Performs a gather operation on the `src` tensor along the `axis` dimension according to `index` |

```{toctree}
:maxdepth: 3
:hidden:

Indexing_Ops/flip.md
Indexing_Ops/where.md
Indexing_Ops/swizzle2d.md
Extension_Ops/get_element.md
Extension_Ops/index_select_simd.md
Indexing_Ops/gather.md
```

## Inline Assembly

|api|Description|
|--|--|
|[inline_asm_elementwise](./Inline_Assembly/inline_asm_elementwise.md) |Executes inline assembly on tensors |

```{toctree}
:maxdepth: 3
:hidden:

Inline_Assembly/inline_asm_elementwise.md
```

## Iterators

|api|Description|
|--|--|
|[range](./Iterators/range.md)  |An iterator that counts upwards indefinitely |
|[static_range](./Iterators/static_range.md) | An iterator that counts upwards indefinitely |

```{toctree}
:maxdepth: 3
:hidden:

Iterators/range.md
Iterators/static_range.md
```

## Linear Algebra Operations

|api|Description|
|--|--|
|[dot](./Linear_Algebra_Ops/dot.md)| Returns the matrix product of two blocks|
|[dot_scaled](./Linear_Algebra_Ops/dot_scaled.md) | Computes the matrix product of two matrix blocks represented in a scaled format |

```{toctree}
:maxdepth: 3
:hidden:

Linear_Algebra_Ops/dot.md
Linear_Algebra_Ops/dot_scaled.md
```

## Logical Operations

|api|Description|
|--|--|
|[and](./Logical_Ops/and.md) | Logical AND operation |
|[or](./Logical_Ops/or.md) | Logical OR operation |
|[not](./Logical_Ops/not.md) | Logical NOT operation |
|[logical_and](./Logical_Ops/logical_and.md)| Performs element-wise logical AND on two tensors |
|[logical_or](./Logical_Ops/logical_or.md)| Performs element-wise logical OR on two tensors |
|[not](./Logical_Ops/not.md) | Bitwise NOT of tensor values. |
|[invert](./Logical_Ops/invert.md) | Bitwise inversion of each value in the tensor. |
|[lshift](./Logical_Ops/lshift.md) | Left-shifts the tensor by a given number of positions. |
|[rshift](./Logical_Ops/rshift.md) | Right-shifts the tensor by a given number of positions. |
|[xor](./Logical_Ops/xor.md) | Computes the XOR of two elements. |

```{toctree}
:maxdepth: 3
:hidden:

Logical_Ops/and.md
Logical_Ops/or.md
Logical_Ops/not.md
Logical_Ops/logical_and.md
Logical_Ops/logical_or.md
Logical_Ops/not.md
Logical_Ops/invert.md
Logical_Ops/lshift.md
Logical_Ops/rshift.md
Logical_Ops/xor.md
```

## Math Operations

|api|Description|
|--|--|
|[add](./Math_Ops/add.md) | Arithmetic addition ‘+’ |
|[sub](./Math_Ops/sub.md) | Arithmetic subtraction ‘-’ |
|[mul](./Math_Ops/mul.md) | Arithmetic multiplication ‘*’ |
|[div](./Math_Ops/div.md) | Arithmetic division ‘/’ |
|[floordiv](./Math_Ops/floordiv.md) | Floor division, arithmetic ‘//’ |
|[abs](./Math_Ops/abs.md) |Computes the element-wise absolute value of x |
|[neg](./Math_Ops/neg.md) | Negates the values of the tensor |
|[cdiv](./Math_Ops/cdiv.md) |Computes the ceiling division of x by div |
|[ceil](./Math_Ops/ceil.md) |Computes the element-wise ceiling of x |
|[clamp](./Math_Ops/clamp.md) |Clamps the values of the input tensor x to the range [min, max] |
|[cos](./Math_Ops/cos.md) |Computes the element-wise cosine of x |
|[div_rn](./Math_Ops/div_rn.md) |Computes the element-wise exact division of x and y (rounded to nearest according to IEEE standard) |
|[erf](./Math_Ops/erf.md) |Computes the element-wise error function of x |
|[exp](./Math_Ops/exp.md) |Computes the element-wise exponential of x |
|[exp2](./Math_Ops/exp2.md) |Computes the element-wise exponential of x (base 2)|
|[fdiv](./Math_Ops/fdiv.md) |Computes the element-wise fast division of x and y |
|[floor](./Math_Ops/floor.md) |Computes the element-wise floor of x |
|[fma](./Math_Ops/fma.md) |Computes the element-wise fused multiply-add of x, y, and z |
|[log](./Math_Ops/log.md) |Computes the element-wise natural logarithm of x |
|[log2](./Math_Ops/log2.md) |Computes the element-wise logarithm of x (base 2)|
|[mod](./Math_Ops/mod.md) | Modulo operation |
|[maximum](./Math_Ops/maximum.md) |Computes the element-wise maximum of x and y |
|[minimum](./Math_Ops/minimum.md) |Computes the element-wise minimum of x and y |
|[rsqrt](./Math_Ops/rsqrt.md) |Computes the element-wise reciprocal square root of x |
|[sigmoid](./Math_Ops/sigmoid.md) |Computes the element-wise sigmoid function of x |
|[sin](./Math_Ops/sin.md) |Computes the element-wise sine of x. |
|[softmax](./Math_Ops/softmax.md) |Computes the element-wise softmax of x |
|[sqrt](./Math_Ops/sqrt.md) |Computes the element-wise fast square root of x |
|[sqrt_rn](./Math_Ops/sqrt_rn.md) |Computes the element-wise exact square root of x (rounded to nearest according to IEEE standard) |
|[umulhi](./Math_Ops/umulhi.md)  |Computes the element-wise most significant N bits of the 2N-bit product of x and y |

```{toctree}
:maxdepth: 3
:hidden:

Math_Ops/add.md
Math_Ops/sub.md
Math_Ops/mul.md
Math_Ops/div.md
Math_Ops/floordiv.md
Math_Ops/abs.md
Math_Ops/neg.md
Math_Ops/cdiv.md
Math_Ops/ceil.md
Math_Ops/clamp.md
Math_Ops/cos.md
Math_Ops/div_rn.md
Math_Ops/erf.md
Math_Ops/exp.md
Math_Ops/exp2.md
Math_Ops/fdiv.md
Math_Ops/floor.md
Math_Ops/fma.md
Math_Ops/log.md
Math_Ops/log2.md
Math_Ops/mod.md
Math_Ops/maximum.md
Math_Ops/minimum.md
Math_Ops/rsqrt.md
Math_Ops/sigmoid.md
Math_Ops/sin.md
Math_Ops/softmax.md
Math_Ops/sqrt.md
Math_Ops/sqrt_rn.md
Math_Ops/umulhi.md
```

## Memory/Pointer Operations

|api|Description|
|--|--|
|[load](./Memory_Pointer_Ops/tl.load.md) |Returns a tensor whose values are loaded from memory locations defined by pointers|
|[store](./Memory_Pointer_Ops/tl.store.md) |Stores a data tensor to memory locations defined by pointers|
|[make_block_ptr](./Memory_Pointer_Ops/tl.make_block_ptr.md) |Returns a pointer to a block within a parent tensor|
|[advance](./Memory_Pointer_Ops/tl.advance.md) |Advances a block pointer|
|[load_tensor_descriptor](./Memory_Pointer_Ops/load_tensor_descriptor.md) | Loads a data block from a tensor descriptor |
|[make_tensor_descriptor](./Memory_Pointer_Ops/make_tensor_descriptor.md) | Creates a tensor descriptor object |
|[store_tensor_descriptor](./Memory_Pointer_Ops/store_tensor_descriptor.md) | Stores a data block to the memory location specified by a tensor descriptor |

```{toctree}
:maxdepth: 3
:hidden:

Memory_Pointer_Ops/tl.load.md
Memory_Pointer_Ops/tl.store.md
Memory_Pointer_Ops/tl.make_block_ptr.md
Memory_Pointer_Ops/tl.advance.md
Memory_Pointer_Ops/load_tensor_descriptor.md
Memory_Pointer_Ops/make_tensor_descriptor.md
Memory_Pointer_Ops/store_t