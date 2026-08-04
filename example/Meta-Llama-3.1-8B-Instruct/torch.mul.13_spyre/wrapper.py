"""SIGNATURE + wrapper + reference oracle + input generator for
``torch.mul.13_spyre``.

Structurally identical to ``torch.mul.12_spyre`` — same shapes, strides,
and kernel body, just a distinct traced call site (see ``triton_kernel.py``
for the exact source path). See ``torch.mul.12_spyre/wrapper.py`` for the
full derivation of the reference oracle and device-layout reasoning; this
file duplicates it verbatim.

Caller-side settings recap:

- logical ``x``: ``[1, 32, 1, 128]`` f16; logical ``y``: ``[1, 1, 1,
  128]`` f16, broadcast over ``x``'s head dim; logical output: same shape
  as ``x``.
- device shapes: ``in_ptr0`` ``[32, 1, 2, 1, 64]``, ``in_ptr1`` ``[1, 1,
  2, 1, 64]``, ``out_ptr0`` ``[1, 1, 2, 32, 64]``.
- ``xnumel = 4096``, ``spyre_grid = (32,)``, one program per head.
"""

import numpy as np
import torch

from . import triton_kernel


# ---------------------------------------------------------------------------
# SIGNATURE — dtype per @triton.jit arg, taken from the decorator's
# ``triton_meta['signature']`` in output_code.py.
# ---------------------------------------------------------------------------

SIGNATURE = {
    "in_ptr0":  "*fp16",
    "in_ptr1":  "*fp16",
    "out_ptr0": "*fp16",
    "xnumel":   "i32",
    "XBLOCK":   "i32",
}


# ---------------------------------------------------------------------------
# Launch parameters, tags/doc, from the traced ``.run(...)`` call and
# ``spyre_grid`` (see original meta.py's VARIANTS["default"]).
# ---------------------------------------------------------------------------

TAGS = ["descriptor-load-static", "descriptor-store-static", "program-id-1d"]

SUMMARY = (
    "Broadcasting `out = x * y` on Meta-Llama-3.1-8B-Instruct's "
    "traced `torch.mul.13` op (structurally identical to "
    "`torch.mul.12`): `y` broadcast over `x`'s 32-wide head axis, "
    "one program per head."
)

DOC = (
    "Multiplies a logical `[1, 32, 1, 128]` f16 tensor `x` by a "
    "logical `[1, 1, 1, 128]` f16 tensor `y` broadcast over `x`'s "
    "head dim; same kernel body, shapes, and strides as "
    "`torch.mul.12_spyre` (see that example's `doc` for the full "
    "device-layout explanation), just a distinct traced call site."
)

CONSTEXPR = ["XBLOCK"]
XNUMEL = 4096
XBLOCK = 128
GRID = (32,)

DISTRIBUTION_LOOP = False  # see torch.mul.12_spyre/wrapper.py

OUTPUT_KEY = "out_ptr0"


# ---------------------------------------------------------------------------
# Wrapper — launches the traced kernel on real tensors.
# ---------------------------------------------------------------------------

def mul(
    in_ptr0: torch.Tensor,
    in_ptr1: torch.Tensor,
    kernel_fn=triton_kernel.triton_unk_fused_mul_0,
) -> torch.Tensor:
    """Multiplies `in_ptr0` (device-layout shape `[32, 1, 2, 1, 64]`) by
    `in_ptr1` broadcast over the head axis (device-layout shape
    `[1, 1, 2, 1, 64]`), storing into a differently-laid-out output
    `[1, 1, 2, 32, 64]` (head axis moved front-to-back). See
    `torch.mul.12_spyre/wrapper.py` for the full derivation."""
    out_ptr0 = torch.empty(
        (1, 1, 2, 32, 64), dtype=in_ptr0.dtype, device=in_ptr0.device
    )
    kernel_fn[GRID](in_ptr0, in_ptr1, out_ptr0, XNUMEL, XBLOCK=XBLOCK)
    return out_ptr0


# ---------------------------------------------------------------------------
# Reference (NumPy oracle) + input maker — preserved from the original
# meta.py for standalone verification independent of the wrapper above.
# ---------------------------------------------------------------------------

def make_inputs(xnumel: int = XNUMEL, XBLOCK: int = XBLOCK, **_unused) -> dict:
    """Build pointer-tensor inputs for the kernel (see
    ``torch.mul.12_spyre/wrapper.py`` for the full rationale).
    """
    del xnumel, XBLOCK
    rng = np.random.default_rng(0)
    in_ptr0 = rng.standard_normal((32, 1, 2, 1, 64)).astype(np.float16)
    in_ptr1 = rng.standard_normal((1, 1, 2, 1, 64)).astype(np.float16)
    out_ptr0 = np.zeros((1, 1, 2, 32, 64), dtype=np.float16)
    return {"in_ptr0": in_ptr0, "in_ptr1": in_ptr1, "out_ptr0": out_ptr0}


def run(inputs: dict) -> np.ndarray:
    """NumPy oracle: identical derivation to ``torch.mul.12_spyre/wrapper.py``.
    """
    x = inputs["in_ptr0"].astype(np.float32)
    y = inputs["in_ptr1"].astype(np.float32)

    x = x.reshape(32, 2, 64)
    x = np.transpose(x, (1, 0, 2))  # -> (2, 32, 64)

    y = y.reshape(2, 64)

    result = x * y[:, None, :]
    result = result.reshape(1, 1, 2, 32, 64)
    return result.astype(np.float16)
