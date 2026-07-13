# floordiv

## 1. OP Overview

Description: Floor division, returns the division result rounded towards zero, arithmetic operator '//', no `tl.floordiv` method.

## 2. OP Specification

### 2.1 Parameter Description

| Parameter    | Type                | Description                                                    |
| ------------ | ------------------- | -------------------------------------------------------------- |
| `self`       | `tensor or Number`  | First input, dividend                                          |
| `other`      | `tensor or Number`  | Second input, divisor                                          |

### 2.2 Supported Specifications

#### 2.2.1 DataType Support

|| uint8 | int8 | uint16 | int16 | uint32 | int32 | uint64 | int64 | fp16 | fp32 | bf16 | bool/int1 |
|---| ------- | ------ | -------- | ------- | -------- | ------- | -------- | ------- | ------ | ------ | ------ | ----------- |
|GPU| √ | √ | √ | √ | √ | √ | √| √    | ×    | ×    | ×    | √    |
|Ascend A2/A3| × | √ | × | √ | × | √ | × | √  | ×    | ×    | ×    | √    |

#### 2.2.2 Shape Support

|        | Supported Dimension Range |
| ------ | ------------------------- |
| GPU    | No restriction            |
| Ascend A2/A3 | No restriction       |

Conclusion: In terms of Shape, there is no difference between GPU and Ascend platforms.

### 2.3 Usage Example

The following example demonstrates performing floor division on input tensors `in_ptr0` and `in_ptr1`:

```python
@triton.jit
def triton_kernel(out_ptr0, in_ptr0, in_ptr1, N: tl.constexpr):
    idx = tl.arange(0, N)
    x = tl.load(in_ptr0 + idx)
    y = tl.load(in_ptr1 + idx)
    ret = x // y
    tl.store(out_ptr0 + idx, ret)
```

### 2.4. Special Restrictions

Compared to GPU, Ascend A3 lacks support for uint8, uint16, uint32, and uint64.