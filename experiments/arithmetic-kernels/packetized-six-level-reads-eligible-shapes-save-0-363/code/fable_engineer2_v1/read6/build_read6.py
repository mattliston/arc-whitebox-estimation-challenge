#!/usr/bin/env python3
"""TAG fable-engineer2 (E2-R6 build): --read6 = SIX-LEVEL READS. Appends to a built candidate (stack it AFTER every fragment that
redefines _mm). Level 6 runs inside read5's packets (one level-4 slot per packet; all level-5/6 arrays inside read5's own child
regions of the arena, so the 3.9e8-float arena is respected), for reads whose m, k, n divide by 64 and whose price favours it:
exact steady-state bill change dB = -0.128235 mkn + 23.447 (mk + kn) + 16.411 mn (derived from the op structure; matches in-situ
measurement to the flop) plus MU x platform seconds dT = 1.35 dU + 220 x 0.41 ms, dU fitted on 30 in-situ reads (read6/fit_read6_rule.py).
Only those reads change (rounding-level: one more Winograd level); every other op is untouched. Frames of up to _READ6_CAP shapes
are cached under the LRU cap machinery (~170 views each).
usage: build_read6.py <in.py> <out.py> <preset: q (MU 0.35 Gflop/s) | h (MU 0.15 Gflop/s)>"""
import sys
from pathlib import Path
PRESET = {"q": 350000000.0, "h": 150000000.0}
FRAGMENT = r'''

# BEGIN FABLE-ENGINEER2 SIX-LEVEL READS (E2-R6, build_read6.py preset {preset}, MU {mu:.3g} flops per platform-second)
_READ6_CAP = 12
_READ6_CA = (157351936, 216358912)
_READ6_CB = (216358912, 275365888)
_READ6_CC = (275365888, 282741760)
# read layout exactly as read5 (_packed_frame(4) + _bh_forward with copies kept); then, for each of the 7 level-4 slots (one slot per
# packet, the only size that fits the arena at k = 8192), the level-5 operands are formed as full 7-slot stacks (copies of the three
# plain quadrants + the four Winograd sums), level 6 runs once over the whole stacks (4 sums per side, 5 matmuls, 7-op unwind), and
# the level-5 unwind writes the level-4 output slot. All level-5/6 arrays live in read5's child regions [157351936, 282741760):
# A5+A6 in the A region, B5+B6 in the B region, P6 in the C region, P5 in the dead A6 region. Needs m, k, n divisible by 64.
_READ6_FRAMES = _CapLRU()
_CAP_BY_ID[id(_READ6_FRAMES)] = _READ6_CAP
_READ6_CA = (157351936, 216358912)
_READ6_CB = (216358912, 275365888)
_READ6_CC = (275365888, 282741760)


def _read6_frames(views, m, k, n, leaf_a, leaf_b, leaf):
    key = (id(views), m, k, n)
    found = _READ6_FRAMES.get(key)
    if found is not None:
        return found
    arena = _VIEW_SPECS[id(views)][0]
    r5, i5, c5 = m // 32, k // 32, n // 32
    r6, i6, c6 = m // 64, k // 64, n // 64
    na5, nb5, np5 = 7 ** 4 * r5 * i5, 7 ** 4 * i5 * c5, 7 ** 4 * r5 * c5
    na6, nb6, np6 = 7 ** 5 * r6 * i6, 7 ** 5 * i6 * c6, 7 ** 5 * r6 * c6
    a0, a1 = _READ6_CA
    b0, b1 = _READ6_CB
    c0, c1 = _READ6_CC
    assert na5 + na6 <= a1 - a0 and nb5 + nb6 <= b1 - b0 and np6 <= c1 - c0 and np5 <= na6, (m, k, n)
    L5 = (1, 7, 7, 7, 7)
    L6 = (1, 7, 7, 7, 7, 7)
    A5 = _read5_view(arena, a0, a0 + na5, L5 + (r5, i5))
    A6 = _read5_view(arena, a0 + na5, a0 + na5 + na6, L6 + (r6, i6))
    B5 = _read5_view(arena, b0, b0 + nb5, L5 + (i5, c5))
    B6 = _read5_view(arena, b0 + nb5, b0 + nb5 + nb6, L6 + (i6, c6))
    P6 = _read5_view(arena, c0, c0 + np6, L6 + (r6, c6))
    P5 = _read5_view(arena, a0 + na5, a0 + na5 + np5, L5 + (r5, c5))
    a5s, b5s, p5s = fnp.unstack(A5, axis=1), fnp.unstack(B5, axis=1), fnp.unstack(P5, axis=1)
    a6s, b6s, p6s = fnp.unstack(A6, axis=2), fnp.unstack(B6, axis=2), fnp.unstack(P6, axis=2)
    X = (A5[..., :r6, :i6], A5[..., :r6, i6:], A5[..., r6:, :i6], A5[..., r6:, i6:])
    Y = (B5[..., :i6, :c6], B5[..., :i6, c6:], B5[..., i6:, :c6], B5[..., i6:, c6:])
    Z = (P5[..., :r6, :c6], P5[..., :r6, c6:], P5[..., r6:, :c6], P5[..., r6:, c6:])
    x = (A6[:, :, 4:7], B6[:, :, 4:7], P6[:, :, 4:7])
    packets = []
    for p in range(7):
        a, b, out = leaf_a[p:p + 1], leaf_b[p:p + 1], leaf[p:p + 1]
        packets.append(((a[..., :r5, :i5], a[..., :r5, i5:], a[..., r5:, :i5], a[..., r5:, i5:]),
                        (b[..., :i5, :c5], b[..., :i5, c5:], b[..., i5:, :c5], b[..., i5:, c5:]),
                        (out[..., :r5, :c5], out[..., :r5, c5:], out[..., r5:, :c5], out[..., r5:, c5:])))
    found = (a5s, b5s, p5s, a6s, b6s, p6s, X, Y, Z, x, packets, (A5, A6, B5, B6, P6, P5))
    return _cache_put(_READ6_FRAMES, key, found)


def _read6_leaf_packets(m, k, n, views, leaf_a, leaf_b, leaf):
    h = _BH_HOLD.append
    a5s, b5s, p5s, a6s, b6s, p6s, X, Y, Z, x, packets, _full = _read6_frames(views, m, k, n, leaf_a, leaf_b, leaf)
    X11, X12, X21, X22 = X
    Y11, Y12, Y21, Y22 = Y
    for (a11, a12, a21, a22), (b11, b12, b21, b22), (TL, TR, BL, BR) in packets:
        h(fnp.copyto(a5s[0], a11)); h(fnp.copyto(a5s[1], a12)); h(fnp.copyto(a5s[3], a22))
        h(fnp.add(a21, a22, out=a5s[4])); h(fnp.subtract(a5s[4], a11, out=a5s[5]))
        h(fnp.subtract(a11, a21, out=a5s[6])); h(fnp.subtract(a12, a5s[5], out=a5s[2]))
        h(fnp.copyto(b5s[0], b11)); h(fnp.copyto(b5s[1], b21)); h(fnp.copyto(b5s[2], b22))
        h(fnp.subtract(b12, b11, out=b5s[4])); h(fnp.subtract(b22, b5s[4], out=b5s[5]))
        h(fnp.subtract(b22, b12, out=b5s[6])); h(fnp.subtract(b5s[5], b21, out=b5s[3]))
        h(fnp.add(X21, X22, out=a6s[4])); h(fnp.subtract(a6s[4], X11, out=a6s[5]))
        h(fnp.subtract(X11, X21, out=a6s[6])); h(fnp.subtract(X12, a6s[5], out=a6s[2]))
        h(fnp.subtract(Y12, Y11, out=b6s[4])); h(fnp.subtract(Y22, b6s[4], out=b6s[5]))
        h(fnp.subtract(Y22, Y12, out=b6s[6])); h(fnp.subtract(b6s[5], Y21, out=b6s[3]))
        h(fnp.matmul(X11, Y11, out=p6s[0])); h(fnp.matmul(X12, Y21, out=p6s[1]))
        h(fnp.matmul(a6s[2], Y22, out=p6s[2])); h(fnp.matmul(X22, b6s[3], out=p6s[3]))
        h(fnp.matmul(x[0], x[1], out=x[2]))
        p0, p1, p2, p3, p4, p5, p6 = p6s
        tl, tr, bl, br = Z
        h(fnp.add(p0, p1, out=tl)); h(fnp.add(p0, p5, out=p1)); h(fnp.add(p1, p6, out=p0)); h(fnp.add(p1, p4, out=p5))
        h(fnp.add(p5, p2, out=tr)); h(fnp.subtract(p0, p3, out=bl)); h(fnp.add(p0, p4, out=br))
        q0, q1, q2, q3, q4, q5, q6 = p5s
        h(fnp.add(q0, q1, out=TL)); h(fnp.add(q0, q5, out=q1)); h(fnp.add(q1, q6, out=q0)); h(fnp.add(q1, q4, out=q5))
        h(fnp.add(q5, q2, out=TR)); h(fnp.subtract(q0, q3, out=BL)); h(fnp.add(q0, q4, out=BR))


def _packed_read6(a, b, out, views):
    levels = 4
    m, k, n = int(a.shape[-2]), int(a.shape[-1]), int(b.shape[-1])
    assert int(b.shape[-2]) == k and tuple(out.shape) == (m, n)
    assert m % 64 == k % 64 == n % 64 == 0
    forward, leaf_a, leaf_b, leaf, backward = _packed_frame(levels, m, k, n, views)
    _bh_forward(a, b, forward, m, k, n, levels + 1, False, False)
    _read6_leaf_packets(m, k, n, views, leaf_a, leaf_b, leaf)
    _bh_backward(backward, out, m, n)
    _BH_HOLD.clear()
    return out

_READ6_MU = {mu}
_READ6_COEF = (0.0254, -0.0178, 0.0060, 0.0436)   # added user CPU per read: a (mk+kn)/1e6 + b mn/1e6 + c mkn/1e9 + d (seconds)
_READ6_CHOICE = {{}}


def _read6_take(m, k, n):
    key = (m, k, n)
    found = _READ6_CHOICE.get(key)
    if found is None:
        if m % 64 or k % 64 or n % 64 or not (0 < m <= 1024 and 0 < n <= 1024 and 1024 < k <= 8192):
            found = False
        else:
            c = _READ6_COEF
            db = -0.128235 * m * k * n + 23.447 * (m * k + k * n) + 16.411 * m * n
            du = c[0] * (m * k + k * n) / 1e6 + c[1] * m * n / 1e6 + c[2] * m * k * n / 1e9 + c[3]
            found = db + _READ6_MU * (1.35 * du + 220 * 0.41e-3) < 0
        _READ6_CHOICE[key] = found
    return found


_R6_MM = _mm


def _mm(a, b):
    if _WINOGRAD and len(a.shape) == 2 and len(b.shape) == 2 and str(a.dtype) == 'float32' and str(b.dtype) == 'float32':
        m, k, n = int(a.shape[0]), int(a.shape[1]), int(b.shape[1])
        if _read6_take(m, k, n) and _rule_depth('read', m, k, n) == 5:
            return _packed_read6(a, b, fnp.empty((m, n), dtype=fnp.float32), _SCRATCH[2])
    return _R6_MM(a, b)
# END FABLE-ENGINEER2 SIX-LEVEL READS
'''
if __name__ == "__main__":
    src = Path(sys.argv[1]).read_text(); out = Path(sys.argv[2]); preset = sys.argv[3]
    for need in ("\ndef _packed_read5(", "\ndef _read5_view(", "\nclass _CapLRU(dict):", "\ndef _cache_put(", "\ndef _mm(a, b):", "_PACKED_READ = (_PACKED_READ[:16]"):
        assert need in src, f"base lacks {need.strip()[:40]!r}"
    assert "_READ6_MU" not in src, "base already has --read6"
    assert not out.exists(), f"refusing to overwrite {out}"
    out.write_text(src.rstrip("\n") + "\n" + FRAGMENT.format(preset=preset, mu=PRESET[preset]))
    print(f"--read6 preset {preset} (MU {PRESET[preset]:.3g}): {sys.argv[1]} -> {sys.argv[2]}")
