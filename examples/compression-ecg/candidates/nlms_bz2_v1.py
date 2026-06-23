"""
nlms_bz2_v1 — per-channel best-of-four encoding.

Adds NLMS-4 (order=4, mu=0.1) first-difference prediction as an extra option
alongside the champion's varzz and nibble. For records with irregular rhythm
(e.g. MIT-BIH 108, 230) the adaptive predictor shrinks residuals, improving
bz2 BWT matching. Best-of-four guarantees no regression on records where NLMS
does not help.

NLMS is losslessly invertible: the decode re-runs the same forward pass using
quantised residuals so encoder and decoder weights stay in sync.

Byte layout:
  ECG1 header (10B) | n_chan uint32 | per-channel: [uint8 flag][uint32 clen][data]

Flag values:
  0 = varzz (raw delta)
  1 = nibble (raw delta)
  2 = varzz (NLMS residual)
  3 = nibble (NLMS residual)
"""
import bz2
import struct

import numpy as np

MAGIC = b'ECG1'
HEAD = 10
_MU = 0.1
_ORDER = 4
_EPS = 1e-6


def _zigzag(d):
    d32 = d.astype(np.int32)
    return np.where(d32 >= 0, d32 * 2, -d32 * 2 - 1).astype(np.uint32)


def _unzigzag(z):
    z32 = z.astype(np.int32)
    return np.where(z32 & 1, -(z32 >> 1) - 1, z32 >> 1).astype(np.int16)


def _varzz_pack(zzag):
    t0 = zzag < 128
    t1 = (zzag >= 128) & (zzag < 32640)
    t2 = zzag >= 32640
    n = len(zzag)
    sizes = np.ones(n, dtype=np.intp)
    sizes[t1] = 2
    sizes[t2] = 3
    off = np.empty(n + 1, dtype=np.intp)
    off[0] = 0
    np.cumsum(sizes, out=off[1:])
    out = np.zeros(int(off[-1]), dtype=np.uint8)
    if t0.any():
        out[off[:-1][t0]] = zzag[t0].astype(np.uint8)
    if t1.any():
        p = off[:-1][t1]
        v = zzag[t1].astype(np.uint32) - 128
        out[p] = (0x80 + (v >> 8)).astype(np.uint8)
        out[p + 1] = (v & 0xFF).astype(np.uint8)
    if t2.any():
        p = off[:-1][t2]
        v = zzag[t2]
        out[p] = np.uint8(0xFF)
        out[p + 1] = (v >> 8).astype(np.uint8)
        out[p + 2] = (v & 0xFF).astype(np.uint8)
    return bytes(out)


def _varzz_unpack(data, n):
    mv = memoryview(data)
    zzag = np.empty(n, dtype=np.uint32)
    pos = 0
    for i in range(n):
        b0 = mv[pos]
        if b0 < 0x80:
            zzag[i] = b0
            pos += 1
        elif b0 < 0xFF:
            zzag[i] = 128 + (((b0 & 0x7F) << 8) | mv[pos + 1])
            pos += 2
        else:
            zzag[i] = (mv[pos + 1] << 8) | mv[pos + 2]
            pos += 3
    return zzag


def _nibble_pack(zzag_arr):
    out = bytearray()
    n = len(zzag_arr)
    i = 0
    while i < n:
        z = int(zzag_arr[i])
        if i + 1 < n:
            z2 = int(zzag_arr[i + 1])
            if z < 8 and z2 < 8:
                out.append((z << 3) | z2)
                i += 2
                continue
        if z < 128:
            out.append(0x40 + z)
        elif z < 32640:
            v = z - 128
            out.append(0xC0 + (v >> 8))
            out.append(v & 0xFF)
        else:
            out.append(0xFF)
            out.append(z >> 8)
            out.append(z & 0xFF)
        i += 1
    return bytes(out)


def _nibble_unpack(data, n):
    mv = memoryview(data)
    zzag = np.empty(n, dtype=np.uint32)
    pos = 0
    i = 0
    while i < n:
        b = mv[pos]
        if b < 0x40:
            zzag[i] = (b >> 3) & 0x7
            i += 1
            if i < n:
                zzag[i] = b & 0x7
                i += 1
            pos += 1
        elif b < 0xC0:
            zzag[i] = b - 0x40
            i += 1
            pos += 1
        elif b < 0xFF:
            zzag[i] = 128 + (((b - 0xC0) << 8) | mv[pos + 1])
            i += 1
            pos += 2
        else:
            zzag[i] = (mv[pos + 1] << 8) | mv[pos + 2]
            i += 1
            pos += 3
    return zzag


def _nlms_fwd(diff_ch):
    """NLMS encode: returns int16 residuals. Weight updates use the quantised
    residual so encode and decode states stay identical."""
    n = len(diff_ch)
    res = np.empty(n, dtype=np.int16)
    w = np.zeros(_ORDER, dtype=np.float64)
    x = np.zeros(_ORDER, dtype=np.float64)
    d_int = diff_ch.astype(np.int32)
    for i in range(n):
        pred = int(round(float(np.dot(w, x))))
        r = (int(d_int[i]) - pred + 32768) % 65536 - 32768
        res[i] = r
        norm = float(np.dot(x, x)) + _EPS
        w += (float(_MU) / norm) * float(r) * x
        x[1:] = x[:-1]
        x[0] = float(d_int[i])
    return res


def _nlms_inv(res_ch):
    """NLMS decode: recover first-differences from residuals."""
    n = len(res_ch)
    diff = np.empty(n, dtype=np.int16)
    w = np.zeros(_ORDER, dtype=np.float64)
    x = np.zeros(_ORDER, dtype=np.float64)
    r_int = res_ch.astype(np.int32)
    for i in range(n):
        pred = int(round(float(np.dot(w, x))))
        d = (int(r_int[i]) + pred + 32768) % 65536 - 32768
        diff[i] = d
        norm = float(np.dot(x, x)) + _EPS
        w += (float(_MU) / norm) * float(r_int[i]) * x
        x[1:] = x[:-1]
        x[0] = float(d)
    return diff


def encode(blob):
    assert blob[:4] == MAGIC
    n_chan, n_samp = struct.unpack_from('<HI', blob, 4)
    sig = np.frombuffer(blob[HEAD:], dtype='<i2').reshape(n_chan, n_samp)

    d = sig.astype(np.int64)
    diff = np.empty_like(d)
    diff[:, 0] = d[:, 0]
    diff[:, 1:] = np.diff(d, axis=1)
    diff = ((diff + 32768) % 65536 - 32768).astype('<i2')

    chan_parts = []
    for c in range(n_chan):
        dc = diff[c]
        zzag = _zigzag(dc)
        c_vz = bz2.compress(_varzz_pack(zzag), 9)
        c_nb = bz2.compress(_nibble_pack(zzag), 9)
        res = _nlms_fwd(dc)
        zz_r = _zigzag(res)
        c_nvz = bz2.compress(_varzz_pack(zz_r), 9)
        c_nnb = bz2.compress(_nibble_pack(zz_r), 9)
        _, flag, data = min(
            (len(c_vz), 0, c_vz),
            (len(c_nb), 1, c_nb),
            (len(c_nvz), 2, c_nvz),
            (len(c_nnb), 3, c_nnb),
        )
        chan_parts.append(struct.pack('<BI', flag, len(data)) + data)

    return blob[:HEAD] + struct.pack('<I', n_chan) + b''.join(chan_parts)


def decode(blob):
    header = blob[:HEAD]
    assert header[:4] == MAGIC
    n_chan, n_samp = struct.unpack_from('<HI', header, 4)

    pos = HEAD + 4
    channels = []
    for _ in range(n_chan):
        flag = blob[pos]
        clen = struct.unpack_from('<I', blob, pos + 1)[0]
        pos += 5
        data = bz2.decompress(blob[pos:pos + clen])
        pos += clen
        if flag in (0, 2):
            zzag = _varzz_unpack(data, n_samp)
        else:
            zzag = _nibble_unpack(data, n_samp)
        vals = _unzigzag(zzag)
        if flag >= 2:
            vals = _nlms_inv(vals)
        channels.append(vals)

    diff = np.stack(channels, axis=0).astype(np.int64)
    sig = np.cumsum(diff, axis=1)
    sig = ((sig + 32768) % 65536 - 32768).astype('<i2')
    return header + sig.tobytes()
