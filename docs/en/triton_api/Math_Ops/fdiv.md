# triton.language.fdiv

## 1. Function Overview

Description: Computes the element-wise fast division of x and y.

```python
triton.language.fdiv(x, y, ieee_rounding=False, _semantic=None)
```

## 2. Specification

### 2.1 Parameter Description

| Parameter      | Type              | Description                                                        |
| -------------- | ----------------- | ------------------------------------------------------------------ |
| `x`            | `tensor`          | Tensor data                                                        |
| `y`            | `tensor`          | Tensor data                                                        |
| `ieee_rounding`| `bool`            | Controls whether the floating-point division follows IEEE 754 rounding behavior |
| `_semantic`    | -                 | Reserved parameter, external calls not supported                   |

Return value:
`x`: Output tensor with the same shape as the input tensor `x`

### 2.2 OP Specification

#### 2.2.1 DataType Support

|               | int8 | int16 | int32 | uint8 | uint16 | uint32 | uint64 | int64 | fp16 | fp32 | fp64 | bf16 | bool |
| ------------- | ---- | ----- | ----- | ----- | ------ | ------ | ------ | ----- | ---- | ---- | ---- | ---- | ---- |
| GPU           | ×    | ×     | ×     | ×     | ×      | ×      | ×      | ×     | ×    | √    | √    | ×    | ×    |
| Ascend A2/A3  | ×    | ×     | ×     | ×     | ×      | ×      | ×      | ×     | √    | √    | ×    | √    | ×    |

Conclusion: Compared to GPU, Ascend lacks fp64 support but additionally supports fp16 and bf16.
Torch supports uint8.

#### 2.2.2 Shape Support

|               | Supported Dimension Range |
| ------------- | ------------------------- |
| GPU           | Only supports 1~5D tensors |
| Ascend A2/A3  | Only supports 1~5D tensors |

Conclusion: In terms of shape, there is no difference between GPU and Ascend platforms; both support 1 to 5-dimensional tensors.

### 2.3 Special Limitations

> Missing capabilities compared to the community and cannot be implemented

fp64 is under development.

### 2.4 Usage

The following example demonstrates element-wise fast division of input tensors `x` and `y`:

```python
@triton.jit
def fn_npu_(output_ptr, x_ptr, y_ptr,
            XB: tl.constexpr, YB: tl.constexpr, ZB: tl.constexpr,
            XNUMEL: tl.constexpr, YNUMEL: tl.constexpr, ZNUMEL: tl.constexpr):
    xoffs = tl.program_id(0) * XB
    yoffs = tl.program_id(1) * YB
    zoffs = tl.program_id(2) * ZB

    xidx = tl.arange(0, XB) + xoffs
    yidx = tl.arange(0, YB) + yoffs
    zidx = tl.arange(0, ZB) + zoffs

    idx = xidx[:, None, None] * YNUMEL * ZNUMEL + yidx[None, :, None] * ZNUMEL + zidx[None, None, :]

    X = tl.load(x_ptr + idx)
    Y = tl.load(y_ptr + idx)

    ret = tl.fdiv(X, Y)

    tl.store(output_ptr + idx, ret)

```