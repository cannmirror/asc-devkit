# L0C Buffer到Global Memory数据搬运

## 产品支持情况

|产品|是否支持|
|--------|--------|
|Ascend 950PR/Ascend 950DT|√|

## 功能说明

头文件为：`#include "tensor_api/tensor.h"`

Tensor API通过`Copy`接口统一执行不同通路数据搬运。该接口用于将L0C Buffer中的矩阵计算结果搬运到Global Memory。L0C Buffer中的数据通常为`Mmad`的输出，数据格式为NZ。搬运到Global Memory时，接口会根据目的张量布局自动选择NZ到ND、NZ到DN或NZ到NZ的随路格式转换。

L0C Buffer到Global Memory搬运支持不量化输出、float到half或bfloat16_t的直接转换输出，以及配合标量或张量量化参数的随路量化输出。随路Relu、channel split和量化舍入方式通过`CopyL0C2GMTrait`配置；Mmad与Fixpipe细粒度并行相关的`unitFlag`通过`FixpipeParams`配置。

随路量化、随路Relu、随路格式转换、随路通道拆分以及随路通道合并的有效组合、中间数据类型和数据路径如下图所示。图中的F32到F16、F32到BF16为非量化模式，仅进行cast；其余路径为随路scalar或tensor量化模式。

针对Ascend 950PR/Ascend 950DT：

**图1** L0C2GM流程图

![](../figures/l0c2gm_flowchart-68.png "L0C2GM流程图-68")

## 函数原型

- 执行L0C Buffer到Global Buffer的非量化搬运。

```cpp
template <typename AtomType, typename DstTensor, typename SrcTensor>
__aicore__ inline void Copy(const CopyAtom<AtomType>& atomCopy, const DstTensor& dst, const SrcTensor& src)
```

- 执行L0C Buffer到Global Buffer的量化搬运。

```cpp
template <typename AtomType, typename DstTensor, typename SrcTensor, typename QuantParam,
    Std::enable_if_t<IsCopyQuantParamV<QuantParam>, int> Enable>
__aicore__ inline void Copy(const CopyAtom<AtomType>& atomCopy, const DstTensor& dst, const SrcTensor& src,
    const QuantParam& quant)
```

- 使用默认trait构造搬运原子对象。

```cpp
template <typename CopyOperationType>
__aicore__ inline constexpr auto MakeCopy(const CopyOperationType& copyOperation)
```

- 使用指定trait构造搬运原子对象。

```cpp
template <typename CopyOperationType, typename CopyTraitType>
__aicore__ inline constexpr auto MakeCopy(const CopyOperationType& copyOperation, const CopyTraitType& copyTrait)
```

## 参数说明

**表1** `Copy`接口参数说明

|参数名|输入/输出|描述|
|--------|--------|--------|
|`atomCopy`|输入|搬运原子对象，可由`MakeCopy(CopyL0C2GM{})`或`MakeCopy(CopyL0C2GM{}, CopyL0C2GMTraitDefault{})`构造。|
|`dst`|输出|目的张量，存储位置为`Location::GM`。支持`ND`、`DN`和`NZ`数据格式。数据格式为ND时使能NZ2ND，数据格式为DN时使能NZ2DN，数据格式为NZ时执行NZ2NZ。|
|`src`|输入|源张量，存储位置为`Location::L0C`，数据格式为`NZ`，通常为`Mmad`的计算结果。|
|`quant`|输入|可选量化参数。传入`uint64_t`时表示scalar量化参数；传入张量时表示tensor量化参数，张量通常位于L1 Buffer，元素类型为`uint64_t`。|
|`fixpipeParams`|输入|可选搬运参数，类型为`FixpipeParams`，通过`MakeCopy(CopyL0C2GM{}).with(fixpipeParams)`绑定到atom。未绑定时使用默认值。|

**表2** `MakeCopy`接口参数说明

| 参数名 | 输入/输出 | 描述 |
| :--- | :---: | :--- |
| `copyOperation` | 输入 | 搬运操作对象。L0C Buffer到Global Memory搬运取`CopyL0C2GM{}`。 |
| `copyTrait` | 输入 | 搬运trait对象。L0C Buffer到Global Memory搬运默认取`CopyL0C2GMTraitDefault{}`。 |

### CopyL0C2GMTrait说明

`CopyL0C2GMTrait`用于配置L0C Buffer到Global Memory搬运的静态特性。

```cpp
struct CopyL0C2GMTrait {
    RoundMode roundMode = RoundMode::DEFAULT;
    bool enableRelu = false;
    bool enableChannelSplit = false;
};
```

|成员|默认值|描述|
|--------|--------|--------|
|`roundMode`|`RoundMode::DEFAULT`|舍入模式。`RoundMode::HYBRID`仅在源类型为`float`、目的类型为`hifloat8_t`的量化输出场景支持。|
|`enableRelu`|`false`|是否使能随路Relu。|
|`enableChannelSplit`|`false`|是否使能F32 Channel Split。只支持NZ格式输出且源类型和目的类型均为`float`场景。|

使用自定义trait的示例：

```cpp
constexpr CopyL0C2GMTrait l0c2gmTrait = {
    RoundMode::DEFAULT,
    false,
    true
};

struct CopyL0C2GMTraitCustom {
    using TraitType = CopyL0C2GMTrait;
    static constexpr const TraitType value = l0c2gmTrait;
};
```

### FixpipeParams说明

`FixpipeParams`用于配置运行时搬运参数。

```cpp
struct FixpipeParams {
    uint8_t unitFlag = 0;
    bool subBlockId = false;
};
```

|成员|默认值|描述|
|--------|--------|--------|
|`unitFlag`|`0`|控制Mmad指令和Fixpipe指令的细粒度并行。`0`表示不使能；`2`表示使能且执行后不复位单元标记位；`3`表示使能且执行后复位单元标记位。使能时，`MmadParams`和`FixpipeParams`中的`unitFlag`需要配套设置为`2`或`3`。|
|`subBlockId`|`false`|在启用单目标模式时指示目标UB的编号，L0C Buffer到Global Memory数据搬运时该参数无效。|

## 数据类型

L0C Buffer到Global Memory搬运根据是否传入量化参数自动选择量化模式。

|源张量类型（L0C Buffer）|目的张量类型（Global Memory）|调用形式|说明|
|--------|--------|--------|--------|
|`int32_t`|`int8_t`、`uint8_t`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。|
|`float`|`int8_t`、`uint8_t`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。|
|`float`|`fp8_e4m3fn_t`、`hifloat8_t`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。`hifloat8_t`支持`RoundMode::DEFAULT`和`RoundMode::HYBRID`。|
|`int32_t`|`half`、`bfloat16_t`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。|
|`float`|`half`|`Copy(atom, dst, src)`|直接转换输出，对应F32到F16。|
|`float`|`bfloat16_t`|`Copy(atom, dst, src)`|直接转换输出，对应F32到BF16。|
|`float`|`half`、`bfloat16_t`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。|
|`int32_t`|`int32_t`|`Copy(atom, dst, src)`|不量化输出。|
|`float`|`float`|`Copy(atom, dst, src)`|不量化输出。|
|`float`|`float`|`Copy(atom, dst, src, quant)`|scalar或tensor量化输出。|

不传入`quant`时，接口选择不量化或直接转换模式；传入`uint64_t`时选择scalar量化模式；传入张量时选择tensor量化模式。

## 返回值说明

`Copy`无返回值。`MakeCopy`返回`CopyAtom`对象。

## API映射关系

与built-in接口映射关系：

L0C Buffer到Global Memory搬运接口是在built-in接口`asc_copy_l0c2gm`的基础上进行抽象封装实现的，其对应的底层built-in接口为：

```cpp
__aicore__ inline void asc_copy_l0c2gm(__gm__ bfloat16_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ half* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ float8_e4m3_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ float8_e5m2_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ hifloat8_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ int8_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ uint8_t* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ float* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ bfloat16_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ half* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ float8_e4m3_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ float8_e5m2_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ hifloat8_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ int8_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ uint8_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ int32_t* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ void* dst_addr, __cc__ float* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
__aicore__ inline void asc_copy_l0c2gm(__gm__ void* dst_addr, __cc__ int32_t* src_addr,
    uint16_t n_size, uint16_t m_size,
    uint32_t loop_dst_stride, uint16_t loop_src_stride,
    uint8_t l2_cache_ctl, uint8_t clip_relu_pre, uint8_t unit_flag_ctl,
    uint64_t quant_pre, uint8_t relu_pre, bool split_en,
    bool NZ2ND_en, uint64_t quant_post, uint8_t relu_post,
    bool clip_relu_post, uint8_t eltwise_op, bool eltwise_antq_en,
    bool C0_pad_en, bool broadcast_en, bool NZ2DN_en);
```

## 约束说明

- 源L0C Buffer NZ地址要求64字节对齐。目的ND/DN地址要求1字节对齐，目的NZ地址要求32字节对齐。
- 当搬运的M方向大小、N方向大小为0时，底层搬运指令不会执行。
- N方向大小取值范围为`[0, 4095]`。目的矩阵为NZ输出时，通常要求N方向大小为16的倍数；使能`enableChannelSplit`且输出类型为`float`时，N方向大小需要为8的倍数。
- tensor量化参数张量应位于L1 Buffer，元素类型为`uint64_t`，地址要求32字节对齐。详细约束参见[随路量化](quant_pre.md)。
- 目的地址写入区域不能重叠。若目的地址存在重叠写入，硬件不保证写入顺序。
- 使能`unitFlag`时，需要配合`Mmad`同时使能。
- 使用`RoundMode::HYBRID`时，源类型必须为`float`，目的类型必须为`hifloat8_t`。
- `enableChannelSplit`仅在源类型和目的类型均为`float`，且目的格式为`NZ`时生效。详细约束参见[F32 Channel Split](f32_channel_split.md)。
- Channel Merge为硬件自动使能，不能通过参数配置。详细约束参见[Int8/Int4 Channel Merge](int8_int4_channel_merge.md)。

## 关键特性

L0C Buffer到Global Memory搬运涉及[随路量化](quant_pre.md)、[随路Relu](relu_pre.md)、[F32 Channel Split](f32_channel_split.md)和[Int8/Int4 Channel Merge](int8_int4_channel_merge.md)等关键特性。

## 调用示例

### 不量化输出

```cpp

#include "tensor_api/tensor.h"

using namespace AscendC::Te;

__aicore__ inline void CopyL0CToGM()
{
    auto l0c = MakeTensor(MakeMemPtr(l0cAddr), MakeFrameLayout<NZLayoutPtn, 16>(m, n));
    auto gm = MakeTensor(MakeMemPtr(gmAddr), MakeFrameLayout<NDExtLayoutPtn>(m, n));

    FixpipeParams params;
    auto atom = MakeCopy(CopyL0C2GM{}).with(params);
    Copy(atom, gm, l0c);
}
```

### scalar量化输出

```cpp
#include "tensor_api/tensor.h"

using namespace AscendC::Te;
__aicore__ inline void CopyL0CToGM()
{
    auto l0c = MakeTensor(MakeMemPtr(l0cAddr), MakeFrameLayout<NZLayoutPtn, 16>(m, n));
    auto gm = MakeTensor(MakeMemPtr(gmAddr), MakeFrameLayout<NDExtLayoutPtn>(m, n));

    uint64_t quant = 1;
    auto atom = MakeCopy(CopyL0C2GM{}).with(FixpipeParams{});
    Copy(atom, gm, l0c, quant);
}
```

### tensor量化输出

```cpp
#include "tensor_api/tensor.h"

using namespace AscendC::Te;

__aicore__ inline void CopyL0CToGM()
{
    auto l0c = MakeTensor(MakeMemPtr(l0cAddr), MakeFrameLayout<NZLayoutPtn, 16>(m, n));
    auto gm = MakeTensor(MakeMemPtr(gmAddr), MakeFrameLayout<NDExtLayoutPtn>(m, n));
    auto quant = MakeTensor(MakeMemPtr(l1QuantAddr), MakeFrameLayout<NDExtLayoutPtn>(1, n));

    auto atom = MakeCopy(CopyL0C2GM{}).with(FixpipeParams{});
    Copy(atom, gm, l0c, quant);
}
```
