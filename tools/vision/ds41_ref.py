#!/usr/bin/env python3
"""Reference dumps for the DeepSeek V4.1 image tower gate (docs: the vision adapter gate).

Three stages, each with the smallest dependency set, so they run where the packages are:

  images      numpy + Pillow     writes the fixed synthetic image set (PNG) and cases.txt
  preprocess  numpy + Pillow     resize rule + resample + normalise + patchify -> NAME.pixels.u8, NAME.patches.f32
  encode      numpy              tower + aligner + special rows from the vision GGUF -> NAME.hidden.f32, NAME.rows.f32
  upstream    torch+transformers the same dumps from the upstream processor and model (see the note below)

`encode` is an independent FP32 implementation of the graph in numpy (its own GGUF parser, its own formulas): it
checks the engine's wiring, it is NOT the upstream code. Every choice the checkpoint does not state is a named
option below with the adapter's default; `upstream` exists to replace those defaults with facts. It needs a
transformers build that ships the `deepseek_v41` model code and was written without access to that code, so its
attribute probing is best effort and it has never been run.

All dumps are little-endian raw arrays; cases.txt lists one image per line:
  name width height resized_w resized_h grid_h grid_w span_rows graph_only
"""
import argparse
import hashlib
import math
import os
import struct
import sys
import time
from concurrent.futures import ThreadPoolExecutor

import numpy as np

# ---- options the checkpoint does not state (defaults = the adapter's recipe) -------------------------------------


def add_recipe(p):
    p.add_argument("--mean", default="0.5,0.5,0.5")
    p.add_argument("--std", default="0.5,0.5,0.5")
    p.add_argument("--filter", default="bicubic", choices=["bilinear", "bicubic", "lanczos"])
    p.add_argument("--gate-second", action="store_true", help="second half of mlp.w1 outputs is the SiLU gate")
    p.add_argument("--rope-adjacent", action="store_true", help="rotate pairs (2i, 2i+1) instead of (i, i+D/2)")
    p.add_argument("--aligner-act", default="gelu", choices=["gelu", "gelu_tanh", "silu"])
    p.add_argument("--unshuffle-col-major", action="store_true", help="aligner slot = dx*r+dy instead of dy*r+dx")
    p.add_argument("--no-last-newline", action="store_true", help="no row-end embedding after the last grid row")


# ---- GGUF (v3) ---------------------------------------------------------------------------------------------------

_SCALAR = {0: "<B", 1: "<b", 2: "<H", 3: "<h", 4: "<I", 5: "<i", 6: "<f", 7: "<?", 10: "<Q", 11: "<q", 12: "<d"}


class Gguf:
    def __init__(self, path):
        self.data = np.memmap(path, dtype=np.uint8, mode="r")
        self.pos = 0
        if bytes(self.data[:4]) != b"GGUF":
            raise ValueError("not a GGUF file")
        self.pos = 4
        version, = self._unpack("<I")
        if version != 3:
            raise ValueError("unsupported GGUF version %d" % version)
        n_tensors, n_kv = self._unpack("<QQ")
        self.meta = {}
        for _ in range(n_kv):
            key = self._text()
            kind, = self._unpack("<I")
            self.meta[key] = self._value(kind)
        infos = []
        for _ in range(n_tensors):
            name = self._text()
            n_dims, = self._unpack("<I")
            dims = self._unpack("<%dQ" % n_dims)
            kind, offset = self._unpack("<IQ")
            infos.append((name, dims, kind, offset))
        align = int(self.meta.get("general.alignment", 32))
        base = (self.pos + align - 1) // align * align
        self.tensors = {name: (dims, kind, base + offset) for name, dims, kind, offset in infos}

    def _unpack(self, fmt):
        size = struct.calcsize(fmt)
        out = struct.unpack(fmt, bytes(self.data[self.pos:self.pos + size]))
        self.pos += size
        return out

    def _text(self):
        n, = self._unpack("<Q")
        s = bytes(self.data[self.pos:self.pos + n]).decode("utf-8")
        self.pos += n
        return s

    def _value(self, kind):
        if kind == 8:
            return self._text()
        if kind == 9:
            item, n = self._unpack("<IQ")
            return [self._value(item) for _ in range(n)]
        return self._unpack(_SCALAR[kind])[0]

    def digest(self):
        """SHA-256 of the whole file (computed once)."""
        if getattr(self, "_digest", None) is None:
            h = hashlib.sha256()
            for start in range(0, self.data.shape[0], 64 << 20):
                h.update(self.data[start:start + (64 << 20)])
            self._digest = h.hexdigest()
        return self._digest

    def f32(self, name):
        """Tensor as FP32 in the source framework's shape (GGUF dimensions reversed)."""
        dims, kind, offset = self.tensors[name]
        shape = tuple(int(d) for d in reversed(dims))
        count = int(np.prod(shape))
        if kind == 0:
            a = np.frombuffer(self.data, dtype="<f4", count=count, offset=offset)
        elif kind == 1:
            a = np.frombuffer(self.data, dtype="<f2", count=count, offset=offset).astype(np.float32)
        elif kind == 30:  # BF16: the high half of the FP32 pattern
            a = (np.frombuffer(self.data, dtype="<u2", count=count, offset=offset).astype(np.uint32) << 16).view(np.float32)
        else:
            raise ValueError("%s: unsupported tensor type %d" % (name, kind))
        return np.array(a, dtype=np.float32).reshape(shape)


def model_config(g):
    a = "deepseek4-vision."
    if g.meta.get("general.architecture") != "deepseek4-vision":
        raise ValueError("general.architecture is not deepseek4-vision")
    keys = {"layers": "block_count", "width": "embedding_length", "mlp": "feed_forward_length",
            "heads": "attention.head_count", "proj": "projection_length", "patch": "patch_size",
            "down": "downsample_ratio", "max_tokens": "image.max_tokens", "min_pixels": "image.min_pixels",
            "theta": "rope.freq_base", "eps": "attention.layer_norm_rms_epsilon"}
    return {k: g.meta[a + v] for k, v in keys.items()}


# ---- preprocessing -----------------------------------------------------------------------------------------------


def smart_resize(height, width, factor, min_pixels, max_pixels):
    h_bar = round(height / factor) * factor
    w_bar = round(width / factor) * factor
    if h_bar * w_bar > max_pixels:
        beta = math.sqrt(height * width / max_pixels)
        h_bar = max(factor, math.floor(height / beta / factor) * factor)
        w_bar = max(factor, math.floor(width / beta / factor) * factor)
    elif h_bar * w_bar < min_pixels:
        beta = math.sqrt(min_pixels / (height * width))
        h_bar = math.ceil(height * beta / factor) * factor
        w_bar = math.ceil(width * beta / factor) * factor
    return w_bar, h_bar


def read_cases(folder):
    cases = []
    with open(os.path.join(folder, "cases.txt")) as f:
        for line in f:
            t = line.split()
            if t and not t[0].startswith("#"):
                cases.append([t[0]] + [int(x) for x in t[1:]])
    return cases


def write_cases(folder, cases):
    with open(os.path.join(folder, "cases.txt"), "w", newline="\n") as f:
        f.write("# name width height resized_w resized_h grid_h grid_w span_rows graph_only\n")
        for c in cases:
            f.write(" ".join(str(x) for x in c) + "\n")


def synthetic(name, w, h):
    """Deterministic integer images (no file or network source)."""
    y, x = np.mgrid[0:h, 0:w].astype(np.int64)
    if name.startswith("grad"):
        r, g, b = (x * 255) // max(w - 1, 1), (y * 255) // max(h - 1, 1), ((x + y) * 255) // max(w + h - 2, 1)
    elif name.startswith("checker"):
        k = ((x // 17) + (y // 23)) % 2
        r, g, b = k * 230 + 12, (1 - k) * 200 + (x % 29), (x * 7 + y * 13) % 256
    elif name.startswith("text"):  # dark strokes on a light page: thin horizontal runs with gaps
        line = (y % 24 < 9) & (y % 24 > 2)
        stroke = line & (((x * 2654435761 + (y // 24) * 40503) >> 7) % 5 < 3) & (x % 11 != 0)
        v = np.where(stroke, 24, 238)
        r, g, b = v, v, v + (x % 3)
    elif name.startswith("noise"):
        v = (x * 73856093) ^ (y * 19349663) ^ ((x * y) * 83492791)
        r, g, b = v % 256, (v >> 8) % 256, (v >> 16) % 256
    else:  # rings
        d = (x - w // 2) ** 2 + (y - h // 2) ** 2
        r, g, b = (d // 97) % 256, (d // 41) % 256, (x * 3 + y * 5) % 256
    return np.stack([r, g, b], axis=-1).astype(np.uint8)


IMAGE_SET = [  # name, width, height: minimum, a 4:3 photo size, the token cap, tiny, 8:1, odd
    ("grad_min", 546, 546), ("rings_4x3", 1008, 756), ("checker_tiny", 16, 16), ("text_wide", 1600, 200),
    ("noise_odd", 517, 389), ("checker_cap", 1344, 1344),
]


def cmd_images(args):
    from PIL import Image
    os.makedirs(args.out, exist_ok=True)
    cases = []
    for name, w, h in IMAGE_SET:
        Image.fromarray(synthetic(name, w, h), "RGB").save(os.path.join(args.out, name + ".png"), optimize=False)
        cases.append([name, w, h, 0, 0, 0, 0, 0, 0])
    # Graph-only case: a grid below the minimum size, so the slow host reference can run the real weights quickly.
    Image.fromarray(synthetic("rings_graph", 168, 126), "RGB").save(os.path.join(args.out, "rings_graph.png"))
    cases.append(["rings_graph", 168, 126, 0, 0, 0, 0, 0, 1])
    write_cases(args.out, cases)
    print("images: %d written to %s" % (len(cases), args.out))


def cmd_preprocess(args):
    from PIL import Image
    mean = np.array([float(v) for v in args.mean.split(",")], dtype=np.float32)
    std = np.array([float(v) for v in args.std.split(",")], dtype=np.float32)
    resample = {"bilinear": Image.BILINEAR, "bicubic": Image.BICUBIC, "lanczos": Image.LANCZOS}[args.filter]
    cell = args.patch * args.downsample
    cases = read_cases(args.out)
    for c in cases:
        name, graph_only = c[0], c[8]
        im = Image.open(os.path.join(args.out, name + ".png")).convert("RGB")
        w, h = im.size
        tw, th = (w, h) if graph_only else smart_resize(h, w, cell, args.min_pixels, args.max_tokens * cell * cell)
        if tw % cell or th % cell or (tw // cell) * (th // cell) > args.max_tokens:
            raise ValueError("%s: %dx%d does not fit the token limit" % (name, tw, th))
        if (tw, th) != (w, h):
            im = im.resize((tw, th), resample)
        px = np.asarray(im, dtype=np.uint8)
        norm = (px.astype(np.float32) * np.float32(1.0 / 255.0) - mean) / std  # FP32, the engine's operation order
        gh, gw = th // args.patch, tw // args.patch
        # [gh][py][gw][px][c] -> rows in raster order, features (channel, y, x)
        patches = norm.reshape(gh, args.patch, gw, args.patch, 3).transpose(0, 2, 4, 1, 3).reshape(gh * gw, -1)
        px.tofile(os.path.join(args.out, name + ".pixels.u8"))
        np.ascontiguousarray(patches, dtype="<f4").tofile(os.path.join(args.out, name + ".patches.f32"))
        mh, mw = gh // args.downsample, gw // args.downsample
        c[1:8] = [w, h, tw, th, gh, gw, mh * mw + (mh - 1 if args.no_last_newline else mh) + 2]
        print("preprocess %-14s %4dx%-4d -> %4dx%-4d grid %3dx%-3d rows %4d" % (name, w, h, tw, th, gh, gw, c[7]))
    write_cases(args.out, cases)
    import PIL
    print("pillow", PIL.__version__, "numpy", np.__version__)


# ---- encoder -----------------------------------------------------------------------------------------------------


def rms_norm(x, weight, eps):
    return x / np.sqrt(np.mean(x.astype(np.float64) ** 2, axis=-1, keepdims=True) + eps).astype(np.float32) * weight


def silu(x):
    return x / (1.0 + np.exp(-x))


def erf(x):  # Abramowitz-Stegun 7.1.26 is too coarse for a gate; use math.erf elementwise
    return np.vectorize(math.erf, otypes=[np.float64])(x)


def act(kind, x):
    x = x.astype(np.float64)
    if kind == "gelu":
        y = 0.5 * x * (1.0 + erf(x * 0.7071067811865476))
    elif kind == "gelu_tanh":
        y = 0.5 * x * (1.0 + np.tanh(0.7978845608028654 * (x + 0.044715 * x ** 3)))
    else:
        y = x / (1.0 + np.exp(-x))
    return y.astype(np.float32)


def rope(v, cos, sin, adjacent):
    """v [N][H][D]; cos/sin [N][D/2]; pair i is (i, i+D/2) or (2i, 2i+1)."""
    out = np.empty_like(v)
    half = v.shape[-1] // 2
    a, b = (v[..., 0::2], v[..., 1::2]) if adjacent else (v[..., :half], v[..., half:])
    ra, rb = a * cos[:, None, :] - b * sin[:, None, :], b * cos[:, None, :] + a * sin[:, None, :]
    if adjacent:
        out[..., 0::2], out[..., 1::2] = ra, rb
    else:
        out[..., :half], out[..., half:] = ra, rb
    return out


# A saved residual stream is only as good as the computation that made it. The key names everything the stream
# depends on; a state with another key (or none) is refused, never mixed into a new run.
STATE_VERSION = "ds41-ref-state-1"
STATE_SECONDS = 10.0  # least time between two saves


def state_key(g, cfg, patches, gh, gw, args):
    h = hashlib.sha256()
    tower = ",".join("%s=%r" % (k, cfg[k]) for k in ("layers", "width", "heads", "mlp", "eps", "theta"))
    text = "%s|%s|%s|grid=%dx%d|gate_second=%d|rope_adjacent=%d|" % (
        STATE_VERSION, g.digest(), tower, gh, gw, bool(args.gate_second), bool(args.rope_adjacent))
    h.update(text.encode("utf-8"))
    h.update(np.ascontiguousarray(patches, dtype="<f4").tobytes())
    return h.hexdigest()


def save_state(path, x, layer, key):
    np.savez(path + ".tmp.npz", x=x, layer=layer, key=np.array(key))
    os.replace(path + ".tmp.npz", path + ".npz")


def load_state(path, key, shape, layers):
    """(x, first layer) of a state saved by the same computation; ValueError for anything else."""
    with np.load(path + ".npz", allow_pickle=False) as state:
        names = set(state.files)
        if names != {"x", "layer", "key"}:
            raise ValueError("%s.npz is not a state of this tool version: remove it to start over" % path)
        saved, x, layer = str(state["key"]), state["x"], state["layer"]
    if saved != key:
        raise ValueError("%s.npz is from another computation (weights, patches, grid or tower options differ): "
                         "remove it to start over" % path)
    if layer.shape != () or layer.dtype.kind not in "iu" or not 0 < int(layer) < layers:
        raise ValueError("%s.npz: layer outside 1..%d" % (path, layers - 1))
    if x.shape != tuple(shape) or x.dtype != np.float32 or not np.isfinite(x).all():
        raise ValueError("%s.npz: the saved stream is not a finite float32 %s array" % (path, tuple(shape)))
    return x, int(layer)


def encode_one(g, cfg, patches, gh, gw, args, checkpoint=None):
    L, W, H, M, R = cfg["layers"], cfg["width"], cfg["heads"], cfg["mlp"], cfg["down"]
    D, N, eps = W // H, gh * gw, float(cfg["eps"])
    x = patches @ g.f32("vision.patch_embed.proj.weight").T + g.f32("vision.patch_embed.proj.bias")
    # 2D rotary angles: D/4 frequencies per axis, row angles then column angles
    nf = D // 4
    inv = (1.0 / np.power(np.float64(cfg["theta"]), (2.0 * np.arange(nf, dtype=np.float32) / np.float32(D // 2)).astype(np.float64))).astype(np.float32)
    rows = (np.arange(N) // gw).astype(np.float32)
    cols = (np.arange(N) % gw).astype(np.float32)
    ang = np.concatenate([rows[:, None] * inv[None, :], cols[:, None] * inv[None, :]], axis=1).astype(np.float64)
    cos, sin = np.cos(ang).astype(np.float32), np.sin(ang).astype(np.float32)
    scale = np.float32(1.0 / math.sqrt(D))
    # A long image may not fit one time-limited run: the residual stream is saved between layers and resumed.
    first, saved = 0, time.time()
    key = state_key(g, cfg, patches, gh, gw, args) if checkpoint else None
    if checkpoint and os.path.exists(checkpoint + ".npz"):
        x, first = load_state(checkpoint, key, x.shape, L)
        print("  resumed at layer %d" % first)
    pool = ThreadPoolExecutor(max_workers=min(H, os.cpu_count() or 1))
    for l in range(first, L):
        p = "vision.blocks.%d." % l
        h = rms_norm(x, g.f32(p + "norm1.weight"), eps)
        qkv = h @ g.f32(p + "attn.wqkv.weight").T + g.f32(p + "attn.wqkv.bias")
        q = rope(qkv[:, :W].reshape(N, H, D), cos, sin, args.rope_adjacent)
        k = rope(qkv[:, W:2 * W].reshape(N, H, D), cos, sin, args.rope_adjacent)
        v = qkv[:, 2 * W:].reshape(N, H, D)
        o = np.empty((N, H, D), dtype=np.float32)

        def attend(head):  # numpy releases the interpreter lock inside these calls: one head per thread
            s = (q[:, head, :] @ k[:, head, :].T) * scale
            s -= s.max(axis=1, keepdims=True)
            np.exp(s, out=s)
            s /= s.sum(axis=1, keepdims=True)
            o[:, head, :] = s @ v[:, head, :]

        list(pool.map(attend, range(H)))
        x = x + o.reshape(N, W) @ g.f32(p + "attn.wo.weight").T + g.f32(p + "attn.wo.bias")
        h = rms_norm(x, g.f32(p + "norm2.weight"), eps)
        m = h @ g.f32(p + "mlp.w1.weight").T
        gate, up = (m[:, M:], m[:, :M]) if args.gate_second else (m[:, :M], m[:, M:])
        x = x + (silu(gate) * up) @ g.f32(p + "mlp.w2.weight").T
        if checkpoint and l + 1 < L and time.time() - saved >= STATE_SECONDS:
            save_state(checkpoint, x.astype(np.float32, copy=False), l + 1, key)
            saved = time.time()
    pool.shutdown()
    if checkpoint and os.path.exists(checkpoint + ".npz"):
        os.remove(checkpoint + ".npz")
    hidden = rms_norm(x, g.f32("vision.norm.weight"), eps).astype(np.float32)

    # 3x3 pixel unshuffle in the layout of torch pixel_unshuffle on [C][H][W]: feature c*R*R + dy*R + dx
    mh, mw = gh // R, gw // R
    t = hidden.reshape(mh, R, mw, R, W)  # [my][dy][mx][dx][c]
    t = t.transpose(0, 2, 4, 3, 1) if args.unshuffle_col_major else t.transpose(0, 2, 4, 1, 3)
    merged = np.ascontiguousarray(t).reshape(mh * mw, W * R * R)
    y = merged @ g.f32("aligner.w1.weight").T + g.f32("aligner.w1.bias")
    y = act(args.aligner_act, y) @ g.f32("aligner.w2.weight").T + g.f32("aligner.w2.bias")
    y = y.astype(np.float32).reshape(mh, mw, -1)
    out = [g.f32("image_start")[None, :]]
    for r in range(mh):
        out.append(y[r])
        if r + 1 < mh or not args.no_last_newline:
            out.append(g.f32("image_newline")[None, :])
    out.append(g.f32("image_end")[None, :])
    return hidden, np.concatenate(out, axis=0).astype(np.float32)


def cmd_encode(args):
    g = Gguf(args.model)
    cfg = model_config(g)
    print("tower", cfg)
    for c in read_cases(args.out):
        name, gh, gw = c[0], c[5], c[6]
        if args.only and name not in args.only.split(","):
            continue
        patches = np.fromfile(os.path.join(args.out, name + ".patches.f32"), dtype="<f4").reshape(gh * gw, -1)
        t0 = time.time()
        hidden, rows = encode_one(g, cfg, patches, gh, gw, args, os.path.join(args.out, name + ".resume") if args.resume else None)
        if rows.shape[0] != c[7]:
            raise ValueError("%s: %d rows, cases.txt says %d" % (name, rows.shape[0], c[7]))
        if not args.no_write:
            np.ascontiguousarray(hidden, dtype="<f4").tofile(os.path.join(args.out, name + ".hidden.f32"))
            np.ascontiguousarray(rows, dtype="<f4").tofile(os.path.join(args.out, name + ".rows.f32"))
        # Row norms next to the learned rows' norms: a plausibility figure for the recipe options, not a gate.
        norms = np.linalg.norm(rows.astype(np.float64), axis=1)
        image = np.sort(norms[1:-1])
        print("encode %-14s patches %5d rows %5d  %.1f s  hidden rms %.4f  row L2 median %.3f max %.3f (start %.3f end %.3f)" % (
            name, gh * gw, rows.shape[0], time.time() - t0, float(np.sqrt(np.mean(hidden.astype(np.float64) ** 2))),
            float(image[len(image) // 2]), float(image[-1]), float(norms[0]), float(norms[-1])))
        sys.stdout.flush()


# ---- upstream (never run: see the module note) -------------------------------------------------------------------


def cmd_upstream(args):
    try:
        import torch
        import transformers
        from PIL import Image
    except ImportError as e:
        sys.exit("upstream: needs torch, transformers (with the deepseek_v41 model code) and Pillow: %s" % e)
    try:
        import importlib
        importlib.import_module("transformers.models.deepseek_v41")
    except ImportError:
        sys.exit("upstream: transformers %s has no deepseek_v41 model code" % transformers.__version__)
    processor = transformers.AutoProcessor.from_pretrained(args.model_dir)
    model = transformers.AutoModel.from_pretrained(args.model_dir, torch_dtype=torch.float32)
    model.eval()
    image_processor = getattr(processor, "image_processor", processor)
    print("processor", type(image_processor).__name__, getattr(image_processor, "to_dict", dict)())
    for c in read_cases(args.out):
        name = c[0]
        if c[8]:
            continue
        inputs = image_processor(images=Image.open(os.path.join(args.out, name + ".png")).convert("RGB"), return_tensors="pt")
        for key, value in inputs.items():
            if hasattr(value, "numpy"):
                a = value.to(torch.float32).numpy()
                print(name, "processor output", key, a.shape)
                np.ascontiguousarray(a, dtype="<f4").tofile(os.path.join(args.out, "%s.upstream.%s.f32" % (name, key)))
        with torch.no_grad():
            features = model.get_image_features(**inputs)
        a = (features[0] if isinstance(features, (list, tuple)) else features).to(torch.float32).numpy()
        print(name, "image features", a.shape)
        np.ascontiguousarray(a.reshape(-1, a.shape[-1]), dtype="<f4").tofile(os.path.join(args.out, name + ".upstream.rows.f32"))


def main():
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    sub = ap.add_subparsers(dest="cmd", required=True)
    p = sub.add_parser("images")
    p.add_argument("--out", required=True)
    p.set_defaults(fn=cmd_images)
    p = sub.add_parser("preprocess")
    p.add_argument("--out", required=True)
    p.add_argument("--patch", type=int, default=14)
    p.add_argument("--downsample", type=int, default=3)
    p.add_argument("--min-pixels", type=int, default=295936)
    p.add_argument("--max-tokens", type=int, default=1024)
    add_recipe(p)
    p.set_defaults(fn=cmd_preprocess)
    p = sub.add_parser("encode")
    p.add_argument("--out", required=True)
    p.add_argument("--model", required=True, help="the vision GGUF")
    p.add_argument("--only", default="", help="comma-separated case names")
    p.add_argument("--no-write", action="store_true", help="print the figures only")
    p.add_argument("--resume", action="store_true", help="save the state between layers and continue a stopped run")
    add_recipe(p)
    p.set_defaults(fn=cmd_encode)
    p = sub.add_parser("upstream")
    p.add_argument("--out", required=True)
    p.add_argument("--model-dir", required=True, help="upstream checkpoint directory")
    p.set_defaults(fn=cmd_upstream)
    args = ap.parse_args()
    args.fn(args)


if __name__ == "__main__":
    main()
