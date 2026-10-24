"""Fixed D6 diagonal refinement of the retained 256-row covariance strips.

Outer 256-row off-diagonal rectangles remain whole.  Each diagonal block uses
the source-priced partition (128,64,64), with every diagonal tile computed in
full.  This preserves the mathematical symmetric product, not FP32 bytes.
"""

_PSD_PARENT_SYM_UPPER = _sym_upper
_PSD_DIAGONAL = (128, 64, 64)
_PSD_SHAPES = ((256, 1024, 768), (256, 1024, 512), (256, 1024, 256),
               (128, 1024, 256), (64, 1024, 128), (64, 1024, 64))


def _psd_sym_tile(A, B, out, row, rows, col, cols, diagonal):
    # All operands and output are external to the packed arena.  Finish both
    # copies before this helper releases the tile or the next core uses scratch.
    keep = []
    a = A[row:row + rows, :]
    b = B[:, col:col + cols]
    part = fnp.empty((rows, cols), dtype=fnp.float32)
    keep.extend((a, b, part))
    _ipt_product_ab(a, b, part, 6)
    upper = out[row:row + rows, col:col + cols]
    keep.extend((upper, fnp.copyto(upper, part)))
    skip = rows if diagonal else 0
    if cols > skip:
        lower = out[col + skip:col + cols, row:row + rows]
        off = part[:, skip:]
        off_t = off.T
        keep.extend((lower, off, off_t, fnp.copyto(lower, off_t)))


def _psd_sym_upper(A, B):
    if not (_AB_ON and _WINOGRAD
            and len(A.shape) == len(B.shape) == 2
            and tuple(A.shape) == tuple(B.shape) == (1024, 1024)
            and str(A.dtype) == str(B.dtype) == 'float32'
            and all(_ipt_fits(6, m, k, n) for m, k, n in _PSD_SHAPES)):
        return _PSD_PARENT_SYM_UPPER(A, B)
    out = fnp.empty((1024, 1024), dtype=fnp.float32)
    for start in (0, 256, 512):
        end = start + 256
        _psd_sym_tile(A, B, out, start, 256, end, 1024 - end, False)
    for block in (0, 256, 512, 768):
        start = block
        for rows in _PSD_DIAGONAL:
            _psd_sym_tile(A, B, out, start, rows, start, block + 256 - start, True)
            start += rows
    return out


_sym_upper = _psd_sym_upper

# Exactly the selected layout's missing public side keys.  Existing setup reads
# this global dynamically; every original key and all cache capacities remain.
_PB_SINGLE = (
    (0, 6, 64, 1024), (0, 6, 128, 1024), (0, 6, 256, 1024),
    (1, 6, 1024, 64), (1, 6, 1024, 128), (1, 6, 1024, 256),
    (1, 6, 1024, 768),
    (2, 6, 64, 64), (2, 6, 64, 128), (2, 6, 128, 256),
    (2, 6, 256, 256), (2, 6, 256, 512), (2, 6, 256, 768),
) + tuple(_PB_SINGLE)
