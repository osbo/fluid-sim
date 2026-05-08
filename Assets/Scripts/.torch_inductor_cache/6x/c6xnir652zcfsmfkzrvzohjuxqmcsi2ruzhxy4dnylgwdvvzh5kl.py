
import triton
import triton.language as tl
from triton.compiler.compiler import AttrsDescriptor

from torch._inductor.runtime import triton_helpers, triton_heuristics
from torch._inductor.runtime.triton_helpers import libdevice, math as tl_math
from torch._inductor.runtime.hints import AutotuneHint, ReductionHint, TileHint, instance_descriptor, DeviceProperties

@triton_heuristics.reduction(
    size_hints=[65536, 128],
    reduction_hint=ReductionHint.DEFAULT,
    filename=__file__,
    triton_meta={'signature': {0: '*fp32', 1: '*fp32', 2: '*fp32', 3: '*fp32', 4: '*fp32', 5: 'i32', 6: 'i32'}, 'device': DeviceProperties(type='cuda', index=0, cc=89, major=8, regs_per_multiprocessor=65536, max_threads_per_multi_processor=1536, multi_processor_count=142), 'constants': {}, 'configs': [AttrsDescriptor(divisible_by_16=(0, 1, 2, 3, 4, 5), equal_to_1=())]},
    inductor_meta={'autotune_hints': set(), 'kernel_name': 'triton_red_fused__softmax_add_eq_masked_fill_mul_32', 'mutated_arg_names': [], 'no_x_dim': False, 'num_load': 8, 'num_reduction': 1, 'backend_hash': 'EE1FF1A692BB318A52D1FC9AAB9D4731B4C6A59706D9DFCBED88CECB030EA339', 'are_deterministic_algorithms_enabled': False, 'assert_indirect_indexing': True, 'autotune_local_cache': True, 'autotune_pointwise': True, 'autotune_remote_cache': None, 'force_disable_caches': False, 'dynamic_scale_rblock': True, 'max_autotune': False, 'max_autotune_pointwise': False, 'min_split_scan_rblock': 256, 'spill_threshold': 16, 'store_cubin': False}
)
@triton.jit
def triton_(in_ptr0, in_ptr1, in_ptr2, in_ptr3, out_ptr1, xnumel, rnumel, XBLOCK : tl.constexpr, RBLOCK : tl.constexpr):
    xnumel = 55808
    rnumel = 65
    xoffset = tl.program_id(0) * XBLOCK
    xindex = xoffset + tl.arange(0, XBLOCK)[:, None]
    xmask = xindex < xnumel
    rbase = tl.arange(0, RBLOCK)[None, :]
    x0 = xindex % 64
    x2 = (xindex // 512)
    x4 = xindex
    _tmp15 = tl.full([XBLOCK, RBLOCK], float("-inf"), tl.float32)
    for roffset in range(0, rnumel, RBLOCK):
        rindex = roffset + rbase
        rmask = rindex < rnumel
        r3 = rindex
        tmp0 = tl.load(in_ptr0 + (r3 + (65*x0) + (4160*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp3 = tl.load(in_ptr1 + (r3 + (65*x4)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp8 = tl.load(in_ptr2 + (r3 + (65*x0) + (4160*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp9 = tl.load(in_ptr3 + (3 + (4*r3) + (260*x0) + (16640*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp1 = 0.0
        tmp2 = tmp0 == tmp1
        tmp4 = 0.25
        tmp5 = tmp3 * tmp4
        tmp6 = tl.full([1, 1], 3, tl.int32)
        tmp7 = tmp6 == tmp6
        tmp10 = tl.where(tmp7, tmp8, tmp9)
        tmp11 = tmp5 + tmp10
        tmp12 = float("-inf")
        tmp13 = tl.where(tmp2, tmp12, tmp11)
        tmp14 = tl.broadcast_to(tmp13, [XBLOCK, RBLOCK])
        tmp16 = triton_helpers.maximum(_tmp15, tmp14)
        _tmp15 = tl.where(rmask & xmask, tmp16, _tmp15)
    tmp15 = triton_helpers.max2(_tmp15, 1)[:, None]
    for roffset in range(0, rnumel, RBLOCK):
        rindex = roffset + rbase
        rmask = rindex < rnumel
        r3 = rindex
        tmp17 = tl.load(in_ptr0 + (r3 + (65*x0) + (4160*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp20 = tl.load(in_ptr1 + (r3 + (65*x4)), rmask & xmask, eviction_policy='evict_first', other=0.0)
        tmp25 = tl.load(in_ptr2 + (r3 + (65*x0) + (4160*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp26 = tl.load(in_ptr3 + (3 + (4*r3) + (260*x0) + (16640*x2)), rmask & xmask, eviction_policy='evict_last', other=0.0)
        tmp18 = 0.0
        tmp19 = tmp17 == tmp18
        tmp21 = 0.25
        tmp22 = tmp20 * tmp21
        tmp23 = tl.full([1, 1], 3, tl.int32)
        tmp24 = tmp23 == tmp23
        tmp27 = tl.where(tmp24, tmp25, tmp26)
        tmp28 = tmp22 + tmp27
        tmp29 = float("-inf")
        tmp30 = tl.where(tmp19, tmp29, tmp28)
        tmp31 = tmp30 - tmp15
        tmp32 = tl_math.exp(tmp31)
        tl.store(out_ptr1 + (r3 + (65*x4)), tmp32, rmask & xmask)
