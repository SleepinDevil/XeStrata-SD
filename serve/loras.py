# SPDX-FileCopyrightText: 2026 MistVVK and the XeStrata contributors
# SPDX-License-Identifier: LGPL-3.0-or-later
"""serve/loras.py - the adapters an image model can apply: its LoRA folder's files, and a request's "lora" field and
prompt tags checked against them (the image engine reads and applies them: src/image/image_lora.cpp).

The files are read by their headers only (a safetensors' JSON, a GGUF's metadata and tensor infos): each tensor's name
and shape and the file's string metadata.  A key is brought to the DiT's name the way the engine brings it (split_key:
the file's prefix off, ".weight" off, the role's suffix off), and a file is this model's when every weight it changes
is one the DiT's products take (TARGETS: the names of qi_dit.cpp's, moss_dit.cpp's and mf_dit.cpp's
build_lora_targets, written here a second time; the record's check sets them against the probe's `map` on the models,
name for name), in a form the engine applies today: a plain LoRA or LoKr (a DoRA: a plain LoRA with a dora_scale over
the weight's rows, ComfyUI's weight_decompose), not a LoHa, GLoRA, OFT or a whole weight's difference, and no text
encoder's weight.  The engine refuses those when it binds a set (QiDit::set_loras, MossDit::set_loras,
MfDit::set_loras), so no image is made with part of a file.

A listing entry - ImageGen.defaults' "loras" (the engine's capabilities: /health's image_defaults and image_models,
/v1/models' image model):
  name      the file without its extension; a subfolder's is its path there ("style/gouache")
  path      the same with the extension, relative to the folder (never an absolute path)
  rank      the highest rank of its weights
  scale     the strength its metadata recommends (recommended_strength_model, ...), else 1.0
  trigger   its trigger words (modelspec.trigger_phrase, ss_trigger_words, ...), else None
  targets   the kinds of weights it changes ("attn.to_q", "img_mlp.gate_layer", "modulation.1")
  size_mib  the file's size

A request's adapters come from the "lora" field - a list of {"name", "scale"} or one such object (vLLM-Omni's shape), a
name alone, or one of those as JSON text (a multipart form's field) - and from the prompt's tags, <lora:name:0.8> in
A1111's and Forge's form, in the positive prompt and the negative one.  "local_path" names a file inside the folder,
and no other path is taken (a path is not a capability).  A text encoder's adapter is not applied (the human's
decision of 2026-10-29): "scale_text" and a tag's third field, A1111's text encoder's weight, are taken as the
engine's other unknown fields are, ignored.  A name the listing does not have is refused where the field
gives it, and taken out of the prompt with a warning where a tag gives it (the response's strata.lora_unknown and the
server's log; the human's decision of 2026-10-29, as A1111 and Forge do).  A model whose DiT takes no adapter at all
takes neither the field nor a tag: both are refused, so no image is made without what was asked for.

The folder is the config's "lora_dir" (setup writes it: <data>/models/loras), else "loras" beside the DiT's file.  Its
listing is kept CACHE_S seconds and read again at once when the folder's mtime changes: /health asks for it with each
page load.
"""
from __future__ import annotations

import collections
import json
import math
import re
import struct
import time
from pathlib import Path
from urllib.parse import quote

MAX_LORA = 4                       # the most adapters one request stacks
SCALE_MIN, SCALE_MAX = -2.0, 2.0   # a request's strength
CACHE_S = 10.0                     # how long a listing is kept before the folder is read again
EXTS = (".safetensors", ".gguf")
MAX_HEADER = 64 << 20              # the longest header read (a safetensors' JSON is a file's tensors; a GGUF's too)
TAG = re.compile(r"<lora:([^<>:]+)(?::([^<>:]+))?(?::([^<>:]+))?>", re.IGNORECASE)
FAMILY_NAMES = {"qwen-image": "Qwen-Image-2.1", "moss-image": "MOSS-Image", "mage-flow": "Mage-Flow",
                "hunyuan-image-3": "HunyuanImage 3.0"}

# The weights adapters may take, by the name a file's key is left with after split_key: the DiTs' target tables
# (src/image/qi_dit.cpp's, moss_dit.cpp's and mf_dit.cpp's build_lora_targets write these names).  "{b}" is a block's
# number - the same names for every block, so a listing needs no block count.  Qwen-Image-2.1's MLP's first weight is
# one [gate | up] on the GPU: a file may name it fused (gate_up, ComfyUI's and a GGUF's form) or as diffusers' two
# halves (gate_layer is its rows [0, inter), proj the rest).  MOSS-Image's text embedder holds one qkv of three C-row
# weights (one name on the file's side), and up and gate apart on the file's side where the GPU has one [up | gate].
# Mage-Flow's and MageTrail's blocks are the same 14 weights (the two streams' modulations, the attention's projections,
# the MLPs); MageTrail's low-rank modulation is F32 and the engine binds no adapter to it (set_loras says so).
_QWEN_BLOCKS = ("attn.to_q", "attn.to_k", "attn.to_v", "attn.to_out.0", "img_mlp.gate_up", "img_mlp.gate_layer",
                "img_mlp.proj", "img_mlp.out")
_MOSS_TEXT_BLOCKS = ("qkv", "proj", "ffn_up_gate", "ffn_up", "ffn_gate", "ffn_down")
_MOSS_BLOCKS = ("proj.q", "proj.k", "proj.v", "proj.o", "proj.ffn_up_gate", "proj.ffn_up", "proj.ffn_gate",
                "proj.ffn_down")
_MOSS_OUTSIDE = ("video_embedder", "time_embedding.0", "time_embedding.2", "shared_block_modulation",
                 "video_head_modulation", "final_linear_video", "text_embedder.proj")
_MAGE_BLOCKS = ("attn.to_q", "attn.to_k", "attn.to_v", "attn.add_q_proj", "attn.add_k_proj", "attn.add_v_proj",
                "attn.to_out.0", "attn.to_add_out", "img_mlp.net.0.proj", "img_mlp.net.2", "txt_mlp.net.0.proj",
                "txt_mlp.net.2", "img_mod.1", "txt_mod.1")
_MAGE_OUTSIDE = ("img_in", "txt_in", "time_text_embed.timestep_embedder.linear_1",
                 "time_text_embed.timestep_embedder.linear_2", "norm_out.linear", "proj_out")
TARGETS: dict[str, tuple[str, ...]] = {
    "qwen-image": ("img_in", "time_text_embed.timestep_embedder.linear_1",
                   "time_text_embed.timestep_embedder.linear_2", "modulation.1", "norm_out.linear", "proj_out",
                   "txt_in.in_layer", "txt_in.out_layer") + tuple("transformer_blocks.{b}." + n for n in _QWEN_BLOCKS),
    "moss-image": (_MOSS_OUTSIDE + tuple("text_embedder.blocks.{b}." + n for n in _MOSS_TEXT_BLOCKS) +
                   tuple("layers.{b}." + n for n in _MOSS_BLOCKS)),
    "mage-flow": (_MAGE_OUTSIDE + tuple("transformer_blocks.{b}." + n for n in _MAGE_BLOCKS)),
}


def _target_pattern(name: str) -> re.Pattern[str]:
    """A TARGETS name as the pattern a file's key is matched with ("{b}" a block's number)."""
    return re.compile("^" + re.escape(name).replace(r"\{b\}", r"\d+") + "$")


_MATCH = {family: tuple(_target_pattern(n) for n in names) for family, names in TARGETS.items()}

# A file's key -> the DiT's weight and the tensor's role, as the engine reads them (src/image/image_lora.cpp's
# split_key): the longest prefix first, ".weight" off every form but PEFT's bare lora_A and lora_B, then the role's
# suffix, longest first too.  sd-scripts' keys write the module's dots as underscores (lora_unet_...), and these models
# name no weight that way.
PREFIXES = ("model.diffusion_model.", "diffusion_model.", "transformer.", "lora_unet_")
ROLES = (
    (".lora_A.default", "lora_A"), (".lora_B.default", "lora_B"),
    (".lora.down", "lora_A"), (".lora.up", "lora_B"),
    (".lora_A", "lora_A"), (".lora_B", "lora_B"),
    (".lora_down", "lora_A"), (".lora_up", "lora_B"),
    (".lora_mid", "lora_mid"), (".lora_linear_layer.down", "lora_A"), (".lora_linear_layer.up", "lora_B"),
    (".alpha", "alpha"), (".dora_scale", "dora_scale"),
    (".lokr_w1_a", "lokr_w1_a"), (".lokr_w1_b", "lokr_w1_b"), (".lokr_w2_a", "lokr_w2_a"), (".lokr_w2_b", "lokr_w2_b"),
    (".lokr_w1", "lokr_w1"), (".lokr_w2", "lokr_w2"), (".lokr_t2", "lokr_t2"),
    (".hada_w1_a", "hada_w1_a"), (".hada_w1_b", "hada_w1_b"), (".hada_w2_a", "hada_w2_a"), (".hada_w2_b", "hada_w2_b"),
    (".hada_t1", "hada_t1"), (".hada_t2", "hada_t2"),
    (".oft_blocks", "oft_blocks"), (".rescale", "rescale"),
    (".a1", "a1"), (".a2", "a2"), (".b1", "b1"), (".b2", "b2"),
    (".diff_b", "diff_b"), (".diff", "diff"), (".set_weight", "set_weight"),
    (".w_norm", "w_norm"), (".b_norm", "b_norm"),
    (".reshape_weight", "reshape_weight"),
)
# The strength a file's metadata may recommend, and the words it may name a trigger with (kohya's and peft's saves
# carry no strength; civitai's, SimpleTuner's and ai-toolkit's may recommend one).
STRENGTH_KEYS = ("recommended_strength_model", "recommended_strength", "ss_strength", "modelspec.strength")
TRIGGER_KEYS = ("modelspec.trigger_phrase", "trigger_phrase", "trigger", "trigger_words", "ss_trigger_words")


class LoraError(ValueError):
    """A request's adapters that cannot be taken (the image endpoint's 400)."""


def split_key(raw: str) -> tuple[str, str]:
    """A key as a file writes it -> (the DiT's weight's name, the tensor's role); ("", "") for a key of no role (a
    file's own: a quantization's, a config's)."""
    s, kohya = raw, False
    for p in PREFIXES:
        if s.startswith(p):
            kohya = p == "lora_unet_"
            s = s[len(p):]
            break
    if s.endswith(".weight"):
        s = s[: -len(".weight")]
    role = ""
    for suffix, r in ROLES:
        if s.endswith(suffix):
            s, role = s[: -len(suffix)], r
            break
    if kohya:
        s = s.replace("_", ".")
    return s, role


def form_of(roles) -> str:
    """The form a weight's tensors are in, as the engine's kind_of reads them: lora, lokr, loha, glora, oft, diff; ""
    when they are none of those."""
    for role, form in (("lora_A", "lora"), ("lora_B", "lora"), ("lokr_w1", "lokr"), ("lokr_w2", "lokr"),
                       ("lokr_w1_a", "lokr"), ("lokr_w2_a", "lokr"), ("hada_w1_a", "loha"), ("hada_w2_a", "loha"),
                       ("a1", "glora"), ("b1", "glora"), ("oft_blocks", "oft"), ("diff", "diff"),
                       ("set_weight", "diff")):
        if role in roles:
            return form
    return ""


def _lokr_rank(roles: dict[str, tuple[int, ...]]) -> tuple[int, str]:
    """A LoKr weight's tensors -> (the factorization's rank, "") or (0, why they make no Kronecker product): its
    two matrices whole (lokr_w1 and lokr_w2) or each from two factors (lokr_w1_a [rows][rank] and lokr_w1_b
    [rank][cols]), w2's under a Tucker core (lokr_t2, a linear product's: a kernel of 1 x 1).  The rank is the one
    ComfyUI divides the file's alpha by (w2's factors' rows, else w1's); the engine reads the tensors the same way
    (src/image/image_lora.cpp's make_lokr)."""
    rank = 0
    for name in ("w1", "w2"):
        whole, fa, fb = f"lokr_{name}", f"lokr_{name}_a", f"lokr_{name}_b"
        if whole in roles:   # the whole matrix: a Tucker core beside w2 stays unread, as ComfyUI leaves it
            if fa in roles or fb in roles:
                return 0, f"both {whole} and its factors {fa}/{fb}"
            if len(roles[whole]) != 2:
                return 0, f"{whole} must be a matrix"
            continue
        if fa not in roles or fb not in roles:
            return 0, f"a LoKr weight needs {whole} or both {fa} and {fb}"
        a, b = roles[fa], roles[fb]
        if len(a) != 2 or len(b) != 2:
            return 0, f"{fa} and {fb} must be matrices"
        if name == "w2" and "lokr_t2" in roles:
            t2 = roles["lokr_t2"]
            if not (len(t2) == 2 or (len(t2) == 4 and t2[2] == 1 and t2[3] == 1)):
                return 0, "a LoKr Tucker core with a convolution's kernel dimensions"
            if a[0] != t2[0] or b[0] != t2[1]:
                return 0, f"the Tucker core is {t2[0]} x {t2[1]}; w2_a's rows {a[0]}, w2_b's {b[0]}"
        elif a[1] != b[0]:
            return 0, f"{fb} is {b[0]} x {b[1]}, not the rank its {fa} has ({a[1]})"
        rank = b[0]
    return rank, ""


def is_text_encoder(key: str) -> bool:
    """A weight of the text encoder rather than the DiT (the engine refuses these when it binds a set)."""
    return key.startswith(("lora_te", "text_encoder", "te."))


def is_training_aid(key: str) -> bool:
    """SimpleTuner's auxiliary projector: trained beside the adapter, not one of the model's weights."""
    return "crepa_projector" in key


def kind_of(name: str) -> str:
    """The kind of weight a target's name is, a block's without its number: "transformer_blocks.7.attn.to_q" ->
    "attn.to_q", "layers.3.proj.q" -> "proj.q", "text_embedder.blocks.1.qkv" -> "qkv", "modulation.1" as it is."""
    return re.sub(r"^(?:transformer_blocks|layers|text_embedder\.blocks)\.\d+\.", "", name)


def encode_path(path: str) -> str:
    """A file's path as a request line word (IMG's LORA:<strength>:<path>): the line is split on whitespace, so the
    separators a path may hold - a space, a '#' - are written %XX; the engine decodes them (strata_image.cpp's
    read_lora).  A colon and the path's own slashes stay as they are."""
    return quote(path, safe="/\\:")


# ----------------------------------------------------------------------------------------------- the files' headers
def _gguf_string(f, limit: int) -> str:
    n = struct.unpack("<Q", f.read(8))[0]
    if n > limit:
        raise ValueError("a string of the header is too long")
    return f.read(n).decode("utf-8", "replace")


def _gguf_value(f, kind: int, depth: int = 0):
    """One GGUF metadata value skipped (a string's read: the listing wants those), of its type's number."""
    if kind in (0, 1, 7):                       # u8, i8, bool
        return f.read(1)
    if kind in (2, 3):                          # u16, i16
        return f.read(2)
    if kind in (4, 5, 6):                       # u32, i32, f32
        return f.read(4)
    if kind in (10, 11, 12):                    # u64, i64, f64
        return f.read(8)
    if kind == 8:                               # string
        return _gguf_string(f, MAX_HEADER)
    if kind == 9:                               # array: its elements' type, its count, its values
        if depth > 4:
            raise ValueError("an array inside an array")
        inner, n = struct.unpack("<IQ", f.read(12))
        for _ in range(n):
            _gguf_value(f, inner, depth + 1)
        return None
    raise ValueError(f"a metadata field of type {kind}")


def _gguf_header(f) -> tuple[dict[str, tuple[int, ...]], dict[str, str]]:
    f.seek(4)
    version = struct.unpack("<I", f.read(4))[0]
    if version not in (2, 3):
        raise ValueError(f"a GGUF of version {version}")
    n_tensors, n_kv = struct.unpack("<QQ", f.read(16))
    if n_tensors > (1 << 24) or n_kv > (1 << 24):
        raise ValueError("a header with more tensors than a model has")
    meta: dict[str, str] = {}
    for _ in range(n_kv):
        key = _gguf_string(f, MAX_HEADER)
        kind = struct.unpack("<I", f.read(4))[0]
        value = _gguf_value(f, kind)
        if kind == 8:
            meta[key] = value
    tensors: dict[str, tuple[int, ...]] = {}
    for _ in range(n_tensors):
        name = _gguf_string(f, MAX_HEADER)
        n_dims = struct.unpack("<I", f.read(4))[0]
        if n_dims > 4:
            raise ValueError(f"{name}: more than four dimensions")
        dims = struct.unpack("<" + "Q" * n_dims, f.read(8 * n_dims))
        f.read(4 + 8)                           # the tensor's type; its offset in the data
        tensors[name] = tuple(int(d) for d in reversed(dims))   # [rows, columns], the engine's order
    return tensors, meta


def read_header(path: Path) -> tuple[dict[str, tuple[int, ...]], dict[str, str]]:
    """A safetensors' or a GGUF's header -> (its tensors' shapes as [rows, columns], its string metadata).  The data is
    not read.  ValueError for a file of neither form."""
    with open(path, "rb") as f:
        if f.read(4) == b"GGUF":
            return _gguf_header(f)
        f.seek(0)
        head = f.read(8)
        if len(head) < 8:
            raise ValueError("shorter than a header")
        n = struct.unpack("<Q", head)[0]
        if n < 2 or n > MAX_HEADER:
            raise ValueError("not a safetensors header")
        raw = f.read(n)
        if len(raw) < n:
            raise ValueError("shorter than its header")
    head = json.loads(raw)
    if not isinstance(head, dict):
        raise ValueError("not a safetensors header")
    meta = head.pop("__metadata__", None)
    tensors: dict[str, tuple[int, ...]] = {}
    for name, t in head.items():
        shape = t.get("shape") if isinstance(t, dict) else None
        if not isinstance(shape, list) or not all(isinstance(x, int) for x in shape):
            raise ValueError(f"{name}: no shape")
        tensors[name] = tuple(shape)
    if not isinstance(meta, dict):
        meta = {}
    return tensors, {str(k): str(v) for k, v in meta.items()}


# --------------------------------------------------------------------------------------------------- the folder
def _finite(value) -> float | None:
    """A number, or a metadata value's text (a safetensors' fields are strings), or None."""
    if isinstance(value, str):
        try:
            value = float(value.strip())
        except ValueError:
            return None
    if isinstance(value, bool) or not isinstance(value, (int, float)):
        return None
    v = float(value)
    return v if math.isfinite(v) else None


def _recommended(meta: dict[str, str]) -> float:
    """The strength a file's metadata recommends, else 1.0 (the engine's default: alpha / rank at a request's 1)."""
    for key in STRENGTH_KEYS:
        v = _finite(meta.get(key))
        if v is not None and SCALE_MIN <= v <= SCALE_MAX:
            return v
    return 1.0


def _trigger(meta: dict[str, str]) -> str | None:
    for key in TRIGGER_KEYS:
        v = (meta.get(key) or "").strip()
        if v:
            return v
    return None


class Folder:
    """One image model's adapter folder: the files its DiT takes, as the listing, and the lookup a request's names go
    through.  Read once per CACHE_S seconds, and at once when the folder's mtime changes."""

    def __init__(self, cfg: dict):
        self.family = cfg.get("family") or "qwen-image"
        self.takes = self.family in TARGETS
        given = cfg.get("lora_dir")
        if isinstance(given, str) and given:
            self.dir = Path(given)
        else:   # "loras" beside the DiT's file (a folder of shards: beside the folder)
            dit = cfg.get("diffusion_model")
            self.dir = (Path(dit).parent if isinstance(dit, str) and dit else Path(".")) / "loras"
        self._listing: list[dict] = []
        self._by_name: dict[str, dict] = {}
        self._by_path: dict[str, dict] = {}
        self.skipped: dict[str, str] = {}   # a file that is not this model's, and why (a request's error says so)
        self._mtime: int | None = None
        self._read = 0.0
        self._scan(force=True)

    def __repr__(self) -> str:
        return f"Folder({self.family}, {str(self.dir)!r}, {len(self._listing)} adapters)"

    def _scan(self, force: bool = False) -> None:
        try:
            mtime = self.dir.stat().st_mtime_ns if self.dir.is_dir() else None
        except OSError:
            mtime = None
        if not force and mtime == self._mtime and time.monotonic() - self._read < CACHE_S:
            return
        self._mtime, self._read = mtime, time.monotonic()
        made: list[dict] = []
        skipped: dict[str, str] = {}
        if self.takes and mtime is not None:
            for p in sorted(self.dir.rglob("*")):
                parts = p.relative_to(self.dir).parts
                if p.suffix.lower() not in EXTS or not p.is_file() or any(x.startswith(".") for x in parts):
                    continue
                rel = "/".join(parts)
                name = rel[: -len(p.suffix)]
                try:
                    entry = self._entry(p, rel, name)
                except (OSError, ValueError, struct.error) as exc:
                    skipped[name] = f"its header could not be read ({exc})"
                    continue
                if isinstance(entry, str):
                    skipped[name] = entry
                    continue
                made.append(entry)
        # the same stem twice (a.safetensors beside a.gguf): each keeps its extension
        repeated = collections.Counter(x["name"] for x in made)
        self._listing, self._by_name, self._by_path = [], {}, {}
        for entry in made:
            if repeated[entry["name"]] > 1:
                entry = {**entry, "name": entry["path"]}
            self._listing.append(entry)
            self._by_name[entry["name"]] = entry
            self._by_path[entry["path"]] = entry
        self.skipped = skipped

    def _entry(self, path: Path, rel: str, name: str) -> dict | str:
        """One file's listing entry, or why this model does not take it."""
        tensors, meta = read_header(path)
        weights: dict[str, dict[str, tuple[int, ...]]] = {}
        for raw, shape in tensors.items():
            key, role = split_key(raw)
            if not role or is_training_aid(key):
                continue
            weights.setdefault(key, {})[role] = shape
        if not weights:
            return "it holds no adapter tensors"
        targets: set[str] = set()
        rank = 0
        for key, roles in sorted(weights.items()):
            form = form_of(roles)
            if form not in ("lora", "lokr"):
                return f"{key}: a {form or 'non-LoRA'} adapter, which the image engine applies not yet"
            if "dora_scale" in roles and form != "lora":
                return f"{key}: a DoRA (dora_scale) on a {form} adapter, which the image engine applies not yet"
            if is_text_encoder(key):
                return f"{key}: a text encoder's weight, which the image engine applies not yet"
            if not any(m.match(key) for m in _MATCH[self.family]):
                return f"{key} is not one of this image model's weights"
            if form == "lokr":
                r, why = _lokr_rank(roles)
                if why:
                    return f"{key}: {why}"
                rank = max(rank, r)
                targets.add(kind_of(key))
                continue
            a, b = roles.get("lora_A"), roles.get("lora_B")
            if a is None or b is None:
                return f"{key}: a LoRA weight needs both lora_A (down) and lora_B (up)"
            if len(a) != 2 or len(b) != 2:
                return f"{key}: lora_A and lora_B must be matrices"
            if b[1] != a[0]:
                return f"{key}: lora_B is {b[0]} x {b[1]}, not the rank its lora_A has ({a[0]})"
            if "dora_scale" in roles and tuple(roles["dora_scale"]) != (b[0],):
                # the engine's DoRA scales the weight's output rows, c = dora_scale / (|W| a row + eps)
                if tuple(roles["dora_scale"]) == (a[1],):
                    return (f"{key}: a DoRA (dora_scale) over the weight's columns, which the engine's DoRA does "
                            f"not take (it scales a product's rows)")
                return f"{key}: dora_scale is neither the weight's rows nor its columns"
            rank = max(rank, a[0])
            targets.add(kind_of(key))
        return {"name": name, "path": rel, "rank": rank, "scale": _recommended(meta), "trigger": _trigger(meta),
                "targets": sorted(targets), "size_mib": round(path.stat().st_size / 1048576, 1)}

    def listing(self) -> list[dict]:
        """This model's adapters, each a listing entry (a copy: a caller may not change the kept one)."""
        self._scan()
        return [dict(e) for e in self._listing]

    def find(self, name: str) -> dict | None:
        """The adapter a request's name is, or None (see skipped for why a file of the folder is not one)."""
        self._scan()
        return self._by_name.get(name.strip())

    def file_of(self, entry: dict) -> str:
        """The file a listing entry names: an absolute path (the engine reads it from another process, whose working
        directory is not this one's)."""
        return str(self.dir.absolute() / entry["path"])

    def local(self, local_path: str) -> tuple[dict | None, str]:
        """A request's local_path -> (the listing entry, "") or (None, why it is not taken).  Only a file inside the
        folder is taken: the path is resolved - a link's target too - and must stay there."""
        try:
            root = self.dir.resolve()
        except OSError:
            return None, "the LoRA folder could not be read"
        p = Path(local_path)
        try:
            full = (p if p.is_absolute() else root / p).resolve()
        except (OSError, RuntimeError):
            return None, "the path could not be read"
        if root not in full.parents:
            return None, "it is not inside the model's LoRA folder"
        if not full.is_file():
            return None, "it is not a file inside the model's LoRA folder"
        rel = full.relative_to(root).as_posix()
        self._scan()
        entry = self._by_path.get(rel)
        if entry is not None:
            return entry, ""
        return None, self.skipped.get(rel[: -len(full.suffix)], "it is not an adapter this model applies")


_FOLDERS: dict[tuple[str, str], Folder] = {}


def folder(cfg: dict) -> Folder:
    """The folder of `cfg`'s image model, kept: a server asks for it with each request and /health."""
    fam = cfg.get("family") or "qwen-image"
    given = cfg.get("lora_dir")
    dirname = given if isinstance(given, str) and given else str(
        (Path(cfg["diffusion_model"]).parent if isinstance(cfg.get("diffusion_model"), str)
         and cfg["diffusion_model"] else Path(".")) / "loras")
    key = (str(Path(dirname).absolute()), fam)
    f = _FOLDERS.get(key)
    if f is None:
        f = _FOLDERS[key] = Folder(cfg)
    return f


# ------------------------------------------------------------------------------------------------- a request's
def _no_loras(f: Folder) -> str:
    name = FAMILY_NAMES.get(f.family, f.family)
    return f"lora: {name} takes no adapters (its DiT has no adapter path in the image engine)"


def _unknown(f: Folder) -> str:
    names = [e["name"] for e in f.listing()]
    if not names:
        return "the model's LoRA folder holds no file its DiT takes"
    return "the model's adapters are " + ", ".join(names[:6]) + (f" (and {len(names) - 6} more)" if len(names) > 6
                                                                 else "")


def _strength(value, where: str, default: float) -> float:
    """A strength (or a form field's text, or a tag's) from SCALE_MIN to SCALE_MAX; `default` when none."""
    if value is None:
        return default
    v = _finite(value)
    if v is None or not SCALE_MIN <= v <= SCALE_MAX:
        raise LoraError(f"{where}: a number from {SCALE_MIN:g} to {SCALE_MAX:g}")
    return v


def _items(value) -> list:
    """A "lora" field as the adapters' list: a list or one object, or one of those as JSON text (a form's field), or a
    name alone."""
    if isinstance(value, str):
        text = value.strip()
        if text.startswith(("[", "{")):
            try:
                value = json.loads(text)
            except ValueError:
                raise LoraError('lora: a JSON list of {"name", "scale"} or one such object') from None
        else:
            return [text] if text else []
    if value is None:
        return []
    if isinstance(value, dict):
        return [value]
    if isinstance(value, (list, tuple)):
        return list(value)
    raise LoraError('lora: a list of {"name", "scale"} or one such object')


def one(item, f: Folder) -> dict:
    """One adapter a request names -> {"name", "path", "scale"} ("path": its file, absolute)."""
    if isinstance(item, str):
        item = {"name": item}
    if not isinstance(item, dict):
        raise LoraError('lora: an object {"name": "gouache", "scale": 0.8} (a string is a name alone)')
    name, local = item.get("name"), item.get("local_path")
    entry, why = None, ""
    if local is not None:
        if not isinstance(local, str) or not local.strip():
            raise LoraError("lora: local_path: a file's path inside the model's LoRA folder")
        entry, why = f.local(local)
        if entry is None:
            raise LoraError(f"lora: local_path {local!r}: {why}")
    elif isinstance(name, str) and name.strip():
        entry = f.find(name)
        if entry is None:
            raise LoraError(f"lora: {name.strip()!r}: {f.skipped.get(name.strip()) or _unknown(f)}")
    else:
        raise LoraError('lora: each adapter needs a "name" (one the model lists) or a "local_path"')
    use = {"name": entry["name"], "path": f.file_of(entry),
           "scale": _strength(item.get("scale"), f"lora: {entry['name']}: scale", 1.0)}
    return use


def limit(uses: list[dict]) -> None:
    """At most MAX_LORA adapters stack in one request."""
    if len(uses) > MAX_LORA:
        raise LoraError(f"lora: at most {MAX_LORA} adapters at once ({len(uses)} are named)")


def field(value, f: Folder) -> list[dict]:
    """A request's "lora" field -> the adapters it asks for (one()'s dicts, in the order given); LoraError for a name
    the model does not list, a repeat, more than MAX_LORA, or a strength outside SCALE_MIN..SCALE_MAX."""
    items = _items(value)
    if not items:
        return []
    if not f.takes:
        raise LoraError(_no_loras(f))
    out: list[dict] = []
    seen: set[str] = set()
    for item in items:
        use = one(item, f)
        if use["name"] in seen:
            raise LoraError(f"lora: {use['name']!r} is named twice")
        seen.add(use["name"])
        out.append(use)
    limit(out)
    return out


def strip_tags(text: str, f: Folder) -> tuple[str, list[dict], list[str]]:
    """A prompt's <lora:name:weight> tags out of `text` -> (the text, the adapters the tags name in order - the first
    naming of a name wins, one()'s dicts - and the names the model does not list, which are left out and said in the
    response).  <lora:name:weight:weight> is A1111's text encoder's weight: not applied, and taken as the engine's other
    unknown fields are (the human's decision of 2026-10-29).  A weight that is not a number, or a tag on a model that
    takes no adapter at all: LoraError."""
    if "<" not in text:
        return text, [], []
    found = list(TAG.finditer(text))
    if not found:
        return text, [], []
    if not f.takes:
        raise LoraError(_no_loras(f) + ": take the prompt's tag out, or name another image model")
    uses: list[dict] = []
    unknown: list[str] = []
    for m in found:
        name = m.group(1).strip()
        entry = f.find(name)
        scale = _strength(m.group(2), f"<lora:{name}:weight>", 1.0)
        if entry is None:
            unknown.append(name)
            continue
        if any(u["name"] == entry["name"] for u in uses):
            continue
        uses.append({"name": entry["name"], "path": f.file_of(entry), "scale": scale})
    return TAG.sub("", text), uses, unknown
