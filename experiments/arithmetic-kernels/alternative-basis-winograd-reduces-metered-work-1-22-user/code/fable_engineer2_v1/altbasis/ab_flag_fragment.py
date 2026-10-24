

# BEGIN FABLE-ENGINEER2 --altbasis (E2-AB, 2026-09-24): alternative-basis in-place tree Winograd (Karstadt-Schwartz-type change of basis,
# derived: A's a21 slot holds S1 = a21 + a22, B's b12 slot holds T3 = b22 - b12 at every level; 3 + 3 core adds, 6 to decode into
# (C11, C12, D = m5 + m4, C22); inverse C21 = C22 - D per level on the C tree's level-1 products; certified vs float64 A@B at depths 1-6,
# fable_engineer2_v1/altbasis/ab_certificate.py). New functions only; the engineer's _ipt_* trees, regions, caches and depth rule are reused
# unchanged; the IPT dispatchers are wrapped and route to the alt-basis variants while _AB_ON. Same op counts as the tree kernel; not
# bit-identical (different sums, rounding level). Stack AFTER --ipt.
_AB_ON = True
_AB_VIEWS = _CapLRU()
_CAP_BY_ID[id(_AB_VIEWS)] = 480
_AB_OLD_PPC = _packed_product_cached
_AB_OLD_READ5 = _packed_read5
_AB_OLD_CP = _cp_d6_shared
_AB_OLD_BB = _bb_product
_AB_OLD_W5 = _w5_port_product_body


def _ab_tree_views(kind, L, rows, cols, T):
    key = (kind, L, rows, cols, id(T))
    found = _AB_VIEWS.get(key)
    if found is not None:
        return found
    pairs = []
    for j in range(2, L + 1):
        ax = L - j
        if kind == 0:     # A: q21 (chunk 4) <- q21 + q22 (chunk 6), all other levels at data chunks 0,2,4,6
            idx = [slice(0, 7, 2)] * L
            lo = list(idx); lo[ax] = 4; hi = list(idx); hi[ax] = 6
        elif kind == 1:   # B: q12 (chunk 1) <- q22 (chunk 3) - q12, all other levels at data chunks 0..3
            idx = [slice(0, 4)] * L
            lo = list(idx); lo[ax] = 1; hi = list(idx); hi[ax] = 3
        else:             # C: level-1 axis all 7 products, deeper levels at data chunks 0..3; c21 (chunk 1) <- c22 (chunk 3) - c21
            idx = [slice(0, 4)] * L; idx[L - 1] = slice(None)
            lo = list(idx); lo[ax] = 1; hi = list(idx); hi[ax] = 3
        pairs.append((T[tuple(lo)], T[tuple(hi)]))
    return _cache_put(_AB_VIEWS, key, pairs)


def _ipt_forward_a_ab(a, L, m, k):
    TA, X1, A02, _keep = _ipt_side(0, L, m, k)
    h = _BH_HOLD.append
    u = 1 << L
    Aq = _ipt_bits(a, L, m // u, k // u)
    A0, A1 = fnp.unstack(Aq, axis=0)
    (a11, a12), (a21, a22) = fnp.unstack(A0, axis=0), fnp.unstack(A1, axis=0)
    h((A0, A1, a11, a12, a21, a22))
    X = X1[1]
    first = fnp.moveaxis(A0, 0, 2 * (L - 1))
    h(first); h(fnp.copyto(A02, first)); h(fnp.copyto(X[6], a22)); h(fnp.add(a21, a22, out=X[4]))
    for lo, hi in _ab_tree_views(0, L, m, k, TA):
        h(fnp.add(lo, hi, out=lo))
    for j in range(1, L + 1):
        X = X1[j]
        h(fnp.subtract(X[4], X[0], out=X[5])); h(fnp.subtract(X[2], X[5], out=X[3])); h(fnp.subtract(X[6], X[5], out=X[1]))
    return TA


def _ipt_forward_b_ab(b, L, k, n):
    TB, Y1, B02, _keep = _ipt_side(1, L, k, n)
    h = _BH_HOLD.append
    u = 1 << L
    Bq = _ipt_bits(b, L, k // u, n // u)
    Bj0, Bj1 = fnp.unstack(Bq, axis=1)
    (b11, b21), (b12, b22) = fnp.unstack(Bj0, axis=0), fnp.unstack(Bj1, axis=0)
    h((Bj0, Bj1, b11, b12, b21, b22))
    Y = Y1[1]
    first = fnp.moveaxis(Bj0, 0, 2 * (L - 1))
    h(first); h(fnp.copyto(B02, first)); h(fnp.copyto(Y[3], b22)); h(fnp.subtract(b22, b12, out=Y[1]))
    for lo, hi in _ab_tree_views(1, L, k, n, TB):
        h(fnp.subtract(hi, lo, out=lo))
    for j in range(1, L + 1):
        Y = Y1[j]
        h(fnp.add(Y[1], Y[0], out=Y[5])); h(fnp.subtract(Y[5], Y[2], out=Y[6])); h(fnp.subtract(Y[3], Y[5], out=Y[4]))
    return TB


def _ipt_leaf_unwind_ab(TA, TB, out, L, m, n):
    TC, Z1, _pair, _keep = _ipt_side(2, L, m, n)
    h = _BH_HOLD.append
    h(fnp.matmul(TA, TB, out=TC))
    for j in range(L, 1, -1):
        Z = Z1[j]
        h(fnp.add(Z[0], Z[5], out=Z[5])); h(fnp.add(Z[0], Z[2], out=Z[0])); h(fnp.add(Z[5], Z[4], out=Z[5]))
        h(fnp.add(Z[5], Z[3], out=Z[2])); h(fnp.add(Z[5], Z[1], out=Z[3])); h(fnp.add(Z[4], Z[6], out=Z[1]))
    for lo, hi in _ab_tree_views(2, L, m, n, TC):
        h(fnp.subtract(hi, lo, out=lo))
    u = 1 << L
    Cq = _ipt_bits(out, L, m // u, n // u)
    Z = Z1[1]
    C0, C1 = fnp.unstack(Cq, axis=0)
    (tl, tr), (bl, br) = fnp.unstack(C0, axis=0), fnp.unstack(C1, axis=0)
    h((C0, C1, tl, tr, bl, br))
    h(fnp.add(Z[0], Z[5], out=Z[5])); h(fnp.add(Z[0], Z[2], out=tl)); h(fnp.add(Z[5], Z[4], out=Z[5]))
    h(fnp.add(Z[5], Z[3], out=tr)); h(fnp.add(Z[5], Z[1], out=br)); h(fnp.add(Z[4], Z[6], out=Z[4])); h(fnp.subtract(br, Z[4], out=bl))
    return out


def _ipt_product_ab(a, b, out, L):
    m, k, n = int(a.shape[-2]), int(a.shape[-1]), int(b.shape[-1])
    TA = _ipt_forward_a_ab(a, L, m, k)
    TB = _ipt_forward_b_ab(b, L, k, n)
    _ipt_leaf_unwind_ab(TA, TB, out, L, m, n)
    _BH_HOLD.clear()
    return out


def _cp_d6_shared(a, b, out):
    # colpack's two six-level packets with ONE alt-basis A tree
    m, k, n = int(a.shape[0]), int(a.shape[1]), int(b.shape[1])
    if not (_AB_ON and 4096 < n and str(a.dtype) == str(b.dtype) == str(out.dtype) == 'float32'
            and _ipt_fits(6, m, k, 4096) and _ipt_fits(6, m, k, n - 4096)):
        return _AB_OLD_CP(a, b, out)
    TA = _ipt_forward_a_ab(a, 6, m, k)
    for j0, j1 in ((0, 4096), (4096, n)):
        bj, oj = b[:, j0:j1], out[:, j0:j1]
        _BH_HOLD.append((bj, oj))
        TB = _ipt_forward_b_ab(bj, 6, k, j1 - j0)
        _ipt_leaf_unwind_ab(TA, TB, oj, 6, m, j1 - j0)
    _BH_HOLD.clear()
    return out


def _bb_product(As, Bs, outs, L):
    P = len(As)
    m, k, n = int(As[0].shape[0]), int(As[0].shape[1]), int(Bs[0].shape[1])
    region = _IPT_REGION.get(L)
    u = 1 << L
    fits = (_AB_ON and region is not None and _SCRATCH is not None and not (m % u or k % u or n % u)
            and 7 ** L * P * (m // u) * (k // u) <= region[0] and 7 ** L * P * (k // u) * (n // u) <= region[1]
            and 7 ** L * P * (m // u) * (n // u) <= region[2]
            and all(tuple(x.shape) == (m, k) and str(x.dtype) == 'float32' for x in As)
            and all(tuple(x.shape) == (k, n) and str(x.dtype) == 'float32' for x in Bs)
            and all(tuple(x.shape) == (m, n) and str(x.dtype) == 'float32' for x in outs))
    if not fits:
        return _AB_OLD_BB(As, Bs, outs, L)
    TA, XA, perA, _ka = _ipt_side_p(0, L, P, m, k)
    TB, XB, perB, _kb = _ipt_side_p(1, L, P, k, n)
    TC, XC, perC, _kc = _ipt_side_p(2, L, P, m, n)
    h = _BH_HOLD.append
    for p in range(P):
        X, A02 = perA[p]
        Aq = _ipt_bits(As[p], L, m // u, k // u)
        A0, A1 = fnp.unstack(Aq, axis=0)
        (a11, a12), (a21, a22) = fnp.unstack(A0, axis=0), fnp.unstack(A1, axis=0)
        h((A0, A1, a11, a12, a21, a22))
        first = fnp.moveaxis(A0, 0, 2 * (L - 1))
        h(first); h(fnp.copyto(A02, first)); h(fnp.copyto(X[6], a22)); h(fnp.add(a21, a22, out=X[4]))
        Y, B02 = perB[p]
        Bq = _ipt_bits(Bs[p], L, k // u, n // u)
        Bj0, Bj1 = fnp.unstack(Bq, axis=1)
        (b11, b21), (b12, b22) = fnp.unstack(Bj0, axis=0), fnp.unstack(Bj1, axis=0)
        h((Bj0, Bj1, b11, b12, b21, b22))
        first = fnp.moveaxis(Bj0, 0, 2 * (L - 1))
        h(first); h(fnp.copyto(B02, first)); h(fnp.copyto(Y[3], b22)); h(fnp.subtract(b22, b12, out=Y[1]))
    for lo, hi in _ab_tree_views(0, L, m, k, TA):
        h(fnp.add(lo, hi, out=lo))
    for lo, hi in _ab_tree_views(1, L, k, n, TB):
        h(fnp.subtract(hi, lo, out=lo))
    for p in range(P):
        X, _A02 = perA[p]
        h(fnp.subtract(X[4], X[0], out=X[5])); h(fnp.subtract(X[2], X[5], out=X[3])); h(fnp.subtract(X[6], X[5], out=X[1]))
        Y, _B02 = perB[p]
        h(fnp.add(Y[1], Y[0], out=Y[5])); h(fnp.subtract(Y[5], Y[2], out=Y[6])); h(fnp.subtract(Y[3], Y[5], out=Y[4]))
    for j in range(2, L + 1):
        X = XA[j]
        h(fnp.subtract(X[4], X[0], out=X[5])); h(fnp.subtract(X[2], X[5], out=X[3])); h(fnp.subtract(X[6], X[5], out=X[1]))
        Y = XB[j]
        h(fnp.add(Y[1], Y[0], out=Y[5])); h(fnp.subtract(Y[5], Y[2], out=Y[6])); h(fnp.subtract(Y[3], Y[5], out=Y[4]))
    h(fnp.matmul(TA, TB, out=TC))
    for j in range(L, 1, -1):
        Z = XC[j]
        h(fnp.add(Z[0], Z[5], out=Z[5])); h(fnp.add(Z[0], Z[2], out=Z[0])); h(fnp.add(Z[5], Z[4], out=Z[5]))
        h(fnp.add(Z[5], Z[3], out=Z[2])); h(fnp.add(Z[5], Z[1], out=Z[3])); h(fnp.add(Z[4], Z[6], out=Z[1]))
    for lo, hi in _ab_tree_views(2, L, m, n, TC):
        h(fnp.subtract(hi, lo, out=lo))
    for p in range(P):
        Z, _none = perC[p]
        Cq = _ipt_bits(outs[p], L, m // u, n // u)
        C0, C1 = fnp.unstack(Cq, axis=0)
        (tl, tr), (bl, br) = fnp.unstack(C0, axis=0), fnp.unstack(C1, axis=0)
        h((C0, C1, tl, tr, bl, br))
        h(fnp.add(Z[0], Z[5], out=Z[5])); h(fnp.add(Z[0], Z[2], out=tl)); h(fnp.add(Z[5], Z[4], out=Z[5]))
        h(fnp.add(Z[5], Z[3], out=tr)); h(fnp.add(Z[5], Z[1], out=br)); h(fnp.add(Z[4], Z[6], out=Z[4])); h(fnp.subtract(br, Z[4], out=bl))
    _BH_HOLD.clear()
    return outs


def _w5_port_product_body(a, b, out, views, levels, cache):
    m, k, n = int(a.shape[-2]), int(a.shape[-1]), int(b.shape[-1])
    if not (_AB_ON and _ipt_ok(a, b, out, levels) and tuple(cache._shape) == (7,) * levels + (m >> levels, k >> levels)):
        return _AB_OLD_W5(a, b, out, views, levels, cache)
    if cache._leaf is None:
        TA = _ipt_forward_a_ab(a, levels, m, k)
        cached = fnp.empty(cache._shape, dtype=fnp.float32)
        cache._own_leaf(cached, cached)
        _BH_HOLD.append(fnp.copyto(cached, TA))
    TB = _ipt_forward_b_ab(b, levels, k, n)
    _ipt_leaf_unwind_ab(cache._leaf, TB, out, levels, m, n)
    _BH_HOLD.clear()
    return out


def _packed_product_cached(a, b, out, views, levels):
    if _AB_ON and _ipt_ok(a, b, out, levels):
        return _ipt_product_ab(a, b, out, levels)
    return _AB_OLD_PPC(a, b, out, views, levels)


def _packed_read5(a, b, out, views):
    if _AB_ON and _ipt_ok(a, b, out, 5):
        return _ipt_product_ab(a, b, out, 5)
    return _AB_OLD_READ5(a, b, out, views)
# END FABLE-ENGINEER2 --altbasis
