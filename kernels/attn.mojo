from std.gpu import block_idx, global_idx, lane_id, thread_idx, WARP_SIZE
from std.gpu.primitives import warp
from std.math import cos, exp, fma, log, rsqrt, sin
from max.gpu.memory import AddressSpace
from max.gpu.sync import barrier
from layout import TileTensor, TensorLayout, row_major, stack_allocation
from layout.tensor_core import mma

comptime f32 = DType.float32
comptime HD = 256
comptime NQH = 16
comptime NKVH = 4
comptime KVT = DType.float32
comptime KVPAGE = 128
comptime KVPSH = 7
comptime KVPAD = 0
comptime KVHSTR = KVPAGE * HD + KVPAD
comptime TCAP = 1 << 24


@always_inline
def kv_off[NAT: Int, HD_: Int = HD, NKVH_: Int = NKVH](t: Int, att_i: Int, kvh: Int) -> Int:
    return (((t >> KVPSH) * NAT + att_i) * NKVH_ + kvh) * (KVPAGE * HD_ + KVPAD) + (t & (KVPAGE - 1)) * HD_


def amar_head_rmsnorm[
    XLayout: TensorLayout, GLayout: TensorLayout
](
    X: TileTensor[f32, XLayout, MutAnyOrigin],
    G: TileTensor[f32, GLayout, MutAnyOrigin],
    eps: Float32,
):
    comptime assert X.flat_rank == 2 and G.flat_rank == 1
    var h = block_idx.x
    var d = thread_idx.x
    var v = rebind[Scalar[f32]](X[h, d])
    var ssq = warp.sum(v * v)
    var sums = stack_allocation[f32, address_space = AddressSpace.SHARED](
        row_major[HD // WARP_SIZE]()
    )
    if lane_id() == 0:
        sums[d // WARP_SIZE] = rebind[sums.ElementType](ssq)
    barrier()
    var total: Float32 = 0
    comptime for w in range(HD // WARP_SIZE):
        total += rebind[Scalar[f32]](sums[w])
    X[h, d] = rebind[X.ElementType](
        v * rsqrt(total / Float32(HD) + eps) * rebind[Scalar[f32]](G[d])
    )


@always_inline
def attn_head_span[
    QLayout: TensorLayout, KLayout: TensorLayout,
    QsL: TensorLayout, ScL: TensorLayout, RdL: TensorLayout, NAT: Int, HD_: Int = HD, NKVH_: Int = NKVH
](
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Kc: TileTensor[KVT, KLayout, MutAnyOrigin],
    Vc: TileTensor[KVT, KLayout, MutAnyOrigin],
    mut qs: TileTensor[f32, QsL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    mut scores: TileTensor[f32, ScL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    mut red: TileTensor[f32, RdL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    qrow: Int, kvh: Int, t_lo: Int, t_hi: Int, tid: Int, lane: Int, scale: Float32, att_i: Int,
) -> SIMD[f32, 4]:
    comptime assert Q.flat_rank == 2 and Kc.flat_rank == 1 and Vc.flat_rank == 1
    comptime assert qs.flat_rank == 1 and scores.flat_rank == 1 and red.flat_rank == 1
    comptime assert HD_ % WARP_SIZE == 0
    var wave = tid // WARP_SIZE
    if tid < HD_:
        qs[tid] = rebind[qs.ElementType](Q[qrow, tid])
    barrier()
    var qv = qs.vectorize[8]()
    var kp = Kc.ptr
    var vp = Vc.ptr
    var m_run = Float32(-3.4e38)
    var l_run = Float32(0)
    var o = Float32(0)
    var t0 = t_lo
    while t0 < t_hi:
        barrier()
        var s = Float32(-3.4e38)
        if tid < HD_:
            var t = t0 + tid
            if t < t_hi:
                var kb = kv_off[NAT, HD_, NKVH_](t, att_i, kvh)
                var Kr = TileTensor(kp.unsafe_offset(kb), row_major[HD_]()).vectorize[8]()
                var acc: Float32 = 0
                for d8 in range(HD_ // 8):
                    var k8 = rebind[SIMD[KVT, 8]](Kr[d8]).cast[f32]()
                    var q8 = rebind[SIMD[f32, 8]](qv[d8])
                    comptime for j in range(8):
                        acc += q8[j] * k8[j]
                s = acc * scale
            scores[tid] = rebind[scores.ElementType](s)
            var wmax = warp.max(s)
            if lane == 0:
                red[wave] = rebind[red.ElementType](wmax)
        barrier()
        var cmax = Float32(-3.4e38)
        comptime for w in range(HD_ // WARP_SIZE):
            var sc = rebind[Scalar[f32]](red[w])
            if sc > cmax:
                cmax = sc
        var m_new = max(m_run, cmax)
        var alpha = exp(m_run - m_new)
        barrier()
        if tid < HD_:
            var e = exp(s - m_new)
            scores[tid] = rebind[scores.ElementType](e)
            var wsum = warp.sum(e)
            if lane == 0:
                red[wave] = rebind[red.ElementType](wsum)
        barrier()
        var csum = Float32(0)
        comptime for w in range(HD_ // WARP_SIZE):
            csum += rebind[Scalar[f32]](red[w])
        l_run = l_run * alpha + csum
        m_run = m_new
        o = o * alpha
        if tid < HD_:
            var n = t_hi - t0
            if n > HD_:
                n = HD_
            var tt = 0
            while tt + 8 <= n:
                var v = InlineArray[Float32, 8](uninitialized=True)
                var sc = InlineArray[Float32, 8](uninitialized=True)
                comptime for j in range(8):
                    v[j] = vp[unsafe_offset=kv_off[NAT, HD_, NKVH_](t0 + tt + j, att_i, kvh) + tid].cast[f32]()
                    sc[j] = rebind[Scalar[f32]](scores[tt + j])
                comptime for j in range(8):
                    o += sc[j] * v[j]
                tt += 8
            while tt < n:
                o += rebind[Scalar[f32]](scores[tt]) * vp[unsafe_offset=kv_off[NAT, HD_, NKVH_](t0 + tt, att_i, kvh) + tid].cast[f32]()
                tt += 1
        t0 += HD_
    return SIMD[f32, 4](m_run, l_run, o, 0)


@always_inline
def attn_head_body[
    QLayout: TensorLayout, KLayout: TensorLayout, OLayout: TensorLayout,
    QsL: TensorLayout, ScL: TensorLayout, RdL: TensorLayout, NAT: Int
](
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Kc: TileTensor[KVT, KLayout, MutAnyOrigin],
    Vc: TileTensor[KVT, KLayout, MutAnyOrigin],
    mut O: TileTensor[f32, OLayout, MutAnyOrigin],
    mut qs: TileTensor[f32, QsL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    mut scores: TileTensor[f32, ScL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    mut red: TileTensor[f32, RdL, MutUntrackedOrigin, address_space = AddressSpace.SHARED],
    qrow: Int, kvh: Int, T: Int, tid: Int, lane: Int, scale: Float32, att_i: Int,
):
    comptime assert O.flat_rank == 2
    var res = attn_head_span[NAT=NAT](Q, Kc, Vc, qs, scores, red, qrow, kvh, 0, T, tid, lane, scale, att_i)
    if tid < HD:
        var inv = 1 / res[1]
        O[qrow, tid] = rebind[O.ElementType](res[2] * inv)




def amar_attn_decode[
    QLayout: TensorLayout, KLayout: TensorLayout, OLayout: TensorLayout, NAT: Int
](
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Kc: TileTensor[KVT, KLayout, MutAnyOrigin],
    Vc: TileTensor[KVT, KLayout, MutAnyOrigin],
    O: TileTensor[f32, OLayout, MutAnyOrigin],
    t_len: Int32,
    scale: Float32,
    att_i: Int32,
):
    comptime assert Q.flat_rank == 2 and Kc.flat_rank == 1 and O.flat_rank == 2
    var h = Int(block_idx.x)
    var r = Int(block_idx.y)
    var tid = Int(thread_idx.x)
    var kvh = h // (NQH // NKVH)
    var T = Int(t_len) + r
    var qrow = r * NQH + h
    var qs = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[HD]())
    var scores = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[HD]())
    var red = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[HD // WARP_SIZE]())
    var O_ = O
    attn_head_body[NAT=NAT](Q, Kc, Vc, O_, qs, scores, red, qrow, kvh, T, tid, Int(lane_id()), scale, Int(att_i))


def amar_gate_mul[
    XLayout: TensorLayout, GLayout: TensorLayout
](
    X: TileTensor[f32, XLayout, MutAnyOrigin],
    Gate: TileTensor[f32, GLayout, MutAnyOrigin],
    n: Int32,
):
    comptime assert X.flat_rank == 1 and Gate.flat_rank == 1
    var i = global_idx.x
    if i >= Int(n):
        return
    var g = rebind[Scalar[f32]](Gate[i])
    X[i] = rebind[X.ElementType](
        rebind[Scalar[f32]](X[i]) * (1 / (1 + exp(-g)))
    )


def amar_gate_mul_cast[
    XLayout: TensorLayout, GLayout: TensorLayout, OLayout: TensorLayout
](
    X: TileTensor[f32, XLayout, MutAnyOrigin],
    Gate: TileTensor[f32, GLayout, MutAnyOrigin],
    O: TileTensor[DType.bfloat16, OLayout, MutAnyOrigin],
    n: Int32,
):
    comptime assert X.flat_rank == 1 and Gate.flat_rank == 1 and O.flat_rank == 1
    var i = global_idx.x
    if i >= Int(n):
        return
    var g = rebind[Scalar[f32]](Gate[i])
    O[i] = rebind[O.ElementType](
        (rebind[Scalar[f32]](X[i]) * (1 / (1 + exp(-g)))).cast[
            DType.bfloat16
        ]()
    )


comptime NROT = 64
comptime YARN_LOW = Float32(14.0)
comptime YARN_HIGH = Float32(22.0)
comptime FREQ_BASE = Float32(1e7)
comptime FREQ_SCALE = Float32(0.25)
comptime MSCALE = Float32(1.1386294361119891)


def amar_qgate_split[
    FLayout: TensorLayout, QLayout: TensorLayout, GLayout: TensorLayout
](
    Qfull: TileTensor[f32, FLayout, MutAnyOrigin],
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Gate: TileTensor[f32, GLayout, MutAnyOrigin],
):
    comptime assert Qfull.flat_rank == 2 and Q.flat_rank == 2 and Gate.flat_rank == 1
    var h = block_idx.x
    var r = Int(block_idx.y)
    var d = thread_idx.x
    Q[r * NQH + h, d] = rebind[Q.ElementType](Qfull[r, h * 2 * HD + d])
    Gate[r * NQH * HD + h * HD + d] = rebind[Gate.ElementType](
        Qfull[r, h * 2 * HD + HD + d]
    )


def amar_rope_yarn[
    XLayout: TensorLayout
](
    X: TileTensor[f32, XLayout, MutAnyOrigin],
    pos: Int32,
    nh: Int32,
):
    comptime assert X.flat_rank == 2
    var h = block_idx.x
    var r = Int(block_idx.y)
    var j = thread_idx.x
    var theta_ex = Float32(Int(pos) + r) * exp(
        Float32(-2 * j) / Float32(NROT) * log(FREQ_BASE)
    )
    var theta_in = FREQ_SCALE * theta_ex
    var ramp = (Float32(j) - YARN_LOW) / max(YARN_HIGH - YARN_LOW, 0.001)
    ramp = min(max(ramp, 0), 1)
    var theta = theta_in * (1 - ramp) + theta_ex * ramp
    var c = cos(theta) * MSCALE
    var s = sin(theta) * MSCALE
    var row = r * Int(nh) + h
    var x0 = rebind[Scalar[f32]](X[row, j])
    var x1 = rebind[Scalar[f32]](X[row, j + NROT // 2])
    X[row, j] = rebind[X.ElementType](x0 * c - x1 * s)
    X[row, j + NROT // 2] = rebind[X.ElementType](x0 * s + x1 * c)


def amar_kv_append[
    CLayout: TensorLayout, NLayout: TensorLayout, NAT: Int
](
    Cache: TileTensor[KVT, CLayout, MutAnyOrigin],
    New: TileTensor[f32, NLayout, MutAnyOrigin],
    t_idx: Int32,
    att_i: Int32,
):
    comptime assert Cache.flat_rank == 1 and New.flat_rank == 2
    var h = block_idx.x
    var r = Int(block_idx.y)
    var d = thread_idx.x
    var t = Int(t_idx) + r
    var cb = kv_off[NAT](t, Int(att_i), Int(h)) + Int(d)
    Cache.ptr[unsafe_offset=cb] = rebind[Scalar[KVT]](
        rebind[Scalar[f32]](New[r * NKVH + h, d]).cast[KVT]()
    )


comptime PA_TK = 16
comptime PA_ROWS = 2
comptime PA_KS = HD + 4


def amar_attn_prefill[
    QLayout: TensorLayout, KLayout: TensorLayout, OLayout: TensorLayout, NAT: Int
](
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Kc: TileTensor[KVT, KLayout, MutAnyOrigin],
    Vc: TileTensor[KVT, KLayout, MutAnyOrigin],
    O: TileTensor[f32, OLayout, MutAnyOrigin],
    pos: Int32,
    m: Int32,
    scale: Float32,
    att_i: Int32,
):
    comptime assert Q.flat_rank == 2 and Kc.flat_rank == 1 and Vc.flat_rank == 1 and O.flat_rank == 2
    var kvh = Int(block_idx.x)
    var tile = Int(block_idx.y)
    var tid = Int(thread_idx.x)
    var wave = tid // WARP_SIZE
    var lane = tid % WARP_SIZE
    var M = Int(m)
    var P = Int(pos)
    var head = kvh * (NQH // NKVH) + wave % (NQH // NKVH)
    var r = tile * PA_ROWS + wave // (NQH // NKVH)
    var valid = r < M
    var qrow = r * NQH + head
    var T = P + r + 1
    var t_blk = P + min(tile * PA_ROWS + PA_ROWS, M)
    var j = lane % PA_TK
    var dpart = lane // PA_TK

    var ks = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[PA_TK, PA_KS]())
    var vs = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[PA_TK, HD]())
    var qs = stack_allocation[f32, address_space = AddressSpace.SHARED](row_major[PA_ROWS * (NQH // NKVH), HD]())
    var ksv = ks.vectorize[1, 8]()
    var vsv = vs.vectorize[1, 8]()
    var qsv = qs.vectorize[1, 8]()
    var Qv = Q.vectorize[1, 8]()
    var O_ = O

    if valid:
        qsv[wave, lane] = rebind[qsv.ElementType](Qv[qrow, lane])
    var m_run = Float32(-3.4e38)
    var l_run = Float32(0)
    var o = SIMD[f32, 8](0)
    var lp = tid // 16
    var lc = (tid % 16) * 2
    var t0 = 0
    while t0 < t_blk:
        barrier()
        var p = t0 + lp
        if p < t_blk:
            var pb = kv_off[NAT](p, Int(att_i), kvh)
            var Kr = TileTensor(Kc.ptr.unsafe_offset(pb), row_major[HD]()).vectorize[8]()
            var Vr = TileTensor(Vc.ptr.unsafe_offset(pb), row_major[HD]()).vectorize[8]()
            ksv[lp, lc] = rebind[ksv.ElementType](rebind[SIMD[KVT, 8]](Kr[lc]).cast[f32]())
            ksv[lp, lc + 1] = rebind[ksv.ElementType](rebind[SIMD[KVT, 8]](Kr[lc + 1]).cast[f32]())
            vsv[lp, lc] = rebind[vsv.ElementType](rebind[SIMD[KVT, 8]](Vr[lc]).cast[f32]())
            vsv[lp, lc + 1] = rebind[vsv.ElementType](rebind[SIMD[KVT, 8]](Vr[lc + 1]).cast[f32]())
        else:
            ksv[lp, lc] = rebind[ksv.ElementType](SIMD[f32, 8](0))
            ksv[lp, lc + 1] = rebind[ksv.ElementType](SIMD[f32, 8](0))
            vsv[lp, lc] = rebind[vsv.ElementType](SIMD[f32, 8](0))
            vsv[lp, lc + 1] = rebind[vsv.ElementType](SIMD[f32, 8](0))
        barrier()
        var part: Float32 = 0
        comptime for d8 in range(HD // 16):
            var q8 = rebind[SIMD[f32, 8]](qsv[wave, dpart * (HD // 16) + d8])
            var k8 = rebind[SIMD[f32, 8]](ksv[j, dpart * (HD // 16) + d8])
            comptime for i in range(8):
                part += q8[i] * k8[i]
        part += warp.shuffle_xor(part, UInt32(PA_TK))
        var s = Float32(-3.4e38)
        if valid and t0 + j < T:
            s = part * scale
        var tmax = warp.max(s)
        if tmax > Float32(-3.4e38):
            var m_new = max(m_run, tmax)
            var alpha = exp(m_run - m_new)
            var pj = exp(s - m_new)
            var psum = pj if dpart == 0 else Float32(0)
            l_run = l_run * alpha + warp.sum(psum)
            o = o * alpha
            comptime for jj in range(PA_TK):
                var pb = warp.shuffle_idx(pj, UInt32(jj))
                var v8 = rebind[SIMD[f32, 8]](vsv[jj, lane])
                o = fma(v8, SIMD[f32, 8](pb), o)
            m_run = m_new
        t0 += PA_TK
    if valid:
        var inv = 1 / l_run
        comptime for i in range(8):
            O_[qrow, lane * 8 + i] = rebind[O_.ElementType](o[i] * inv)


comptime f16 = DType.float16
comptime PW_WAVES = 4
comptime PW_THREADS = PW_WAVES * WARP_SIZE
comptime PW_GQ = NQH // NKVH
comptime PW_ROWS = PW_WAVES * 16 // PW_GQ
comptime PW_TK = 16
comptime PW_QS = HD + 8
comptime PW_VS = PW_TK + 8
comptime PW_PS = Float32(32768.0)


def amar_attn_prefill_wmma[
    QLayout: TensorLayout, KLayout: TensorLayout, OLayout: TensorLayout, NAT: Int
](
    Q: TileTensor[f32, QLayout, MutAnyOrigin],
    Kc: TileTensor[KVT, KLayout, MutAnyOrigin],
    Vc: TileTensor[KVT, KLayout, MutAnyOrigin],
    O: TileTensor[f32, OLayout, MutAnyOrigin],
    pos: Int32,
    m: Int32,
    scale: Float32,
    att_i: Int32,
):
    comptime assert Q.flat_rank == 2 and Kc.flat_rank == 1 and Vc.flat_rank == 1 and O.flat_rank == 2
    var kvh = Int(block_idx.x)
    var tile = Int(block_idx.y)
    var tid = Int(thread_idx.x)
    var wave = tid // WARP_SIZE
    var lane = tid % WARP_SIZE
    var h = lane % 16
    var half = lane // 16
    var M = Int(m)
    var P = Int(pos)
    var ai = Int(att_i)
    var row0 = tile * PW_ROWS
    var t_blk = P + min(row0 + PW_ROWS, M)
    var wrow = row0 + wave * (16 // PW_GQ)
    var r = wrow + h // PW_GQ
    var valid = r < M
    var qrow = r * NQH + kvh * PW_GQ + h % PW_GQ
    var wave_on = wrow < M
    var wlim = P + min(wrow + 16 // PW_GQ - 1, M - 1)
    var lim = P + r

    var qs = stack_allocation[f16, address_space = AddressSpace.SHARED](row_major[PW_WAVES * 16, PW_QS]())
    var ks = stack_allocation[f16, address_space = AddressSpace.SHARED](row_major[PW_TK, PW_QS]())
    var vt = stack_allocation[f16, address_space = AddressSpace.SHARED](row_major[HD, PW_VS]())
    var qsv = qs.vectorize[1, 8]()
    var ksv = ks.vectorize[1, 8]()
    var vtv = vt.vectorize[1, 8]()
    var Qv = Q.vectorize[1, 8]()
    var O_ = O

    comptime for s in range(PW_WAVES * 16 * HD // 8 // PW_THREADS):
        var v = tid + s * PW_THREADS
        var qi = v // (HD // 8)
        var c = v % (HD // 8)
        var rr = row0 + qi // PW_GQ
        var x = SIMD[f16, 8](0)
        if rr < M:
            x = rebind[SIMD[f32, 8]](Qv[rr * NQH + kvh * PW_GQ + qi % PW_GQ, c]).cast[f16]()
        qsv[qi, c] = rebind[qsv.ElementType](x)

    var m_run = Float32(-3.4e38)
    var l_run = Float32(0)
    var acc = InlineArray[SIMD[f32, 8], HD // 16](fill=SIMD[f32, 8](0))
    var t0 = 0
    while t0 < t_blk:
        barrier()
        comptime for s in range(PW_TK * HD // 8 // PW_THREADS):
            var v = tid + s * PW_THREADS
            var key = v // (HD // 8)
            var c = v % (HD // 8)
            var p = t0 + key
            var x = SIMD[f16, 8](0)
            if p < t_blk:
                var Kr = TileTensor(Kc.ptr.unsafe_offset(kv_off[NAT](p, ai, kvh)), row_major[HD]()).vectorize[8]()
                x = rebind[SIMD[KVT, 8]](Kr[c]).cast[f16]()
            ksv[key, c] = rebind[ksv.ElementType](x)
        comptime for s in range(PW_TK * HD // 8 // PW_THREADS):
            var v = tid + s * PW_THREADS
            var key = v % PW_TK
            var c = v // PW_TK
            var p = t0 + key
            var x = SIMD[f16, 8](0)
            if p < t_blk:
                var Vr = TileTensor(Vc.ptr.unsafe_offset(kv_off[NAT](p, ai, kvh)), row_major[HD]()).vectorize[8]()
                x = rebind[SIMD[KVT, 8]](Vr[c]).cast[f16]()
            comptime for i in range(8):
                vt[c * 8 + i, key] = rebind[vt.ElementType](x[i])
        barrier()
        if wave_on and t0 <= wlim:
            var s0 = SIMD[f32, 8](0)
            var s1 = SIMD[f32, 8](0)
            comptime for c in range(HD // 16):
                var a = rebind[SIMD[f16, 8]](ksv[h, 2 * c]).join(rebind[SIMD[f16, 8]](ksv[h, 2 * c + 1]))
                var b = rebind[SIMD[f16, 8]](qsv[wave * 16 + h, 2 * c]).join(rebind[SIMD[f16, 8]](qsv[wave * 16 + h, 2 * c + 1]))
                var t = SIMD[f32, 8](0)
                comptime if c % 2 == 0:
                    mma(t, a, b, s0)
                    s0 = t
                else:
                    mma(t, a, b, s1)
                    s1 = t
            var sc = (s0 + s1) * scale
            var mx = Float32(-3.4e38)
            comptime for i in range(8):
                if valid and t0 + 2 * i + half <= lim:
                    mx = max(mx, sc[i])
            mx = max(mx, warp.shuffle_xor(mx, UInt32(16)))
            var m_new = max(m_run, mx)
            var alpha = exp(m_run - m_new)
            var pv = SIMD[f32, 8](0)
            comptime for i in range(8):
                if valid and t0 + 2 * i + half <= lim:
                    pv[i] = exp(sc[i] - m_new)
            var ps = pv.reduce_add()
            ps += warp.shuffle_xor(ps, UInt32(16))
            l_run = l_run * alpha + ps
            m_run = m_new
            var bf = SIMD[f16, 16](0)
            comptime for i in range(8):
                var own = (pv[i] * PW_PS).cast[f16]()
                var oth = (warp.shuffle_xor(pv[i], UInt32(16)) * PW_PS).cast[f16]()
                bf[2 * i] = own if half == 0 else oth
                bf[2 * i + 1] = oth if half == 0 else own
            comptime for dt in range(HD // 16):
                var a = rebind[SIMD[f16, 8]](vtv[dt * 16 + h, 0]).join(rebind[SIMD[f16, 8]](vtv[dt * 16 + h, 1]))
                var t = SIMD[f32, 8](0)
                mma(t, a, bf, acc[dt] * alpha)
                acc[dt] = t
        t0 += PW_TK
    if valid:
        var inv = 1 / (l_run * PW_PS)
        comptime for dt in range(HD // 16):
            comptime for i in range(8):
                O_[qrow, dt * 16 + 2 * i + half] = rebind[O_.ElementType](acc[dt][i] * inv)
