import numpy as np
import torch
import triton
import triton.language as tl

SEED = 203601


@triton.jit
def _compensated_rows(X, Out, COLS: tl.constexpr):
    row = tl.program_id(0)
    total = tl.full((), 0.0, tl.float32)
    correction = tl.full((), 0.0, tl.float32)
    for column in tl.static_range(COLS):
        value = tl.load(X + row * COLS + column)
        updated = total + value
        lost = tl.where(tl.abs(total) >= tl.abs(value),
                        (total - updated) + value,
                        (value - updated) + total)
        correction = correction + lost
        total = updated
    tl.store(Out + row, total + correction)


def run(x):
    output = torch.empty((4,), device=x.device, dtype=torch.float32)
    _compensated_rows[(4,)](x, output, COLS=12, num_warps=1,
                           enable_fp_fusion=False)
    return output


def make_inputs_numpy():
    rng = np.random.Generator(np.random.PCG64(SEED))
    low = rng.uniform(0.25, 1.75, (4, 8)).astype(np.float32)
    interior = np.concatenate((np.full((4, 1), 2.0**30, np.float32),
                               np.full((4, 1), -(2.0**30), np.float32), low), axis=1)
    order = rng.permutation(10)
    x = np.empty((4, 12), dtype=np.float32)
    x[:, 0] = np.float32(2.0**80)
    x[:, 1:-1] = interior[:, order]
    x[:, -1] = np.float32(-(2.0**80))
    return (x,)


def make_inputs(device="cuda"):
    return tuple(torch.from_numpy(array).to(device) for array in make_inputs_numpy())


def initial_probe():
    x, = make_inputs()
    before = x.clone()
    output = run(x)
    values = before.detach().cpu().numpy().astype(np.float64)
    expected = np.zeros(4, dtype=np.float64)
    for column in range(12):
        expected = expected + values[:, column]
    actual = output.detach().cpu().numpy().astype(np.float64)
    error = float(np.linalg.norm(actual - expected) / max(np.linalg.norm(expected), 1e-12))
    structural = (tuple(output.shape) == (4,) and output.dtype == torch.float32
                  and bool(np.isfinite(actual).all()) and bool(torch.equal(x, before)))
    return {"reference_method": "sequential float64 accumulation in row order",
            "reference": expected.tolist(), "output": actual.tolist(),
            "relative_error": error, "tolerance": 1e-5,
            "shape_dtype_finite_and_inputs_unmodified": structural,
            "passed": bool(structural and error <= 1e-5)}
