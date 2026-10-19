"""nnU-Net model folder -> a torch network that runs fp16 on MPS, plus the sliding window."""
from __future__ import annotations

import queue
import threading
import warnings
from pathlib import Path

import numpy as np
import torch

from .errors import ModelNotFound, UnsupportedModel
from .shuffleup import surgered_state, swap_transposed

DTYPES = {"fp32": torch.float32, "fp16": torch.float16, "bf16": torch.bfloat16}
ACCUMULATE = ("auto", "device", "host")

# Fallback reserve for weights + one patch's activations when nothing has been measured yet,
# from E1/E2 on torch 2.13: fp16 nnU-Net, 112x112x128 patch, K=118 -> 4.3 GB driver-allocated;
# 128^3, K=25 -> 2.5 GB. One constant cannot fit both, which is why the real decision is made
# from a measurement of the first patch (see TorchModel._sliding_window); this is only used
# when a caller asks for a decision before any patch has run.
DEFAULT_ACTIVATION_RESERVE_GB = 4.5


def device_working_set_bytes(device: torch.device) -> int | None:
    """What the framework currently holds on ``device`` (weights, activations, cache)."""
    if device.type == "mps":
        return int(torch.mps.driver_allocated_memory())
    if device.type == "cuda":
        return int(torch.cuda.memory_reserved(device))
    return None


def host_memory_health() -> int | None:
    """macOS ``kern.memorystatus_level``: the percentage of memory the kernel considers free.
    Lower than "available" suggests, because it accounts for what is already paged out."""
    import platform
    import subprocess
    if platform.system() != "Darwin":
        return None
    try:
        out = subprocess.run(["sysctl", "-n", "kern.memorystatus_level"], capture_output=True, text=True, timeout=5)
        return int(out.stdout.strip())
    except Exception:
        return None


def host_available_bytes() -> int | None:
    """Memory the OS could hand out now without swapping, or None if unknown.

    psutil when present; else ``/proc/meminfo`` MemAvailable on Linux (the kernel's own estimate,
    and where the CUDA path runs); else, on macOS, free + inactive + speculative pages from
    ``vm_stat`` - what the kernel will reclaim without paging out.
    """
    try:
        import psutil
        return int(psutil.virtual_memory().available)
    except Exception:
        pass
    try:                                    # Linux, where the CUDA path actually runs
        with open("/proc/meminfo") as f:
            for line in f:
                if line.startswith("MemAvailable:"):
                    return int(line.split()[1]) * 1024
    except OSError:
        pass
    import platform
    import subprocess
    if platform.system() != "Darwin":
        return None
    try:
        out = subprocess.run(["vm_stat"], capture_output=True, text=True, timeout=5).stdout
        pages = {}
        for line in out.splitlines():
            if ":" not in line:
                continue
            k, v = line.split(":", 1)
            v = v.strip().rstrip(".")
            if v.isdigit():
                pages[k.strip()] = int(v)
        page = 16384 if platform.machine() == "arm64" else 4096
        got = sum(pages.get(k, 0) for k in ("Pages free", "Pages inactive", "Pages speculative"))
        return int(got * page) if got else None
    except Exception:
        return None


def device_budget_bytes(device: torch.device, *, host_headroom_gb: float = 3.0,
                        unified_fraction: float = 0.5) -> int | None:
    """Allocatable bytes for a big buffer on ``device`` right now, or None if unknown.

    CUDA: the card's free memory - a discrete pool, so it is exactly the budget.

    **MPS is unified memory**, so ``recommended_max_memory()`` is a hardware ceiling, not
    availability: a GPU allocation consumes the same RAM the OS is using, and taking the
    ceiling drives the machine into swap (measured 2026-08-22 - a 9 GB budget on a 16 GB M2
    Air pushed ``kern.memorystatus_level`` to 10 % and tripped the bench guard). So the MPS
    budget is the *smaller* of the Metal ceiling (honoring
    PYTORCH_MPS_HIGH_WATERMARK_RATIO, which is what actually caps allocations) and what the
    host can spare, keeping ``host_headroom_gb`` for everything else.
    """
    import os
    # "or None if unknown" includes "this backend is not present on this machine": a budget
    # query must not raise just because a caller named a device the host does not have.
    if device.type == "cuda":
        if not torch.cuda.is_available():
            return None
        free, _total = torch.cuda.mem_get_info(device)
        return int(free)
    if device.type != "mps" or not torch.backends.mps.is_available():
        return None
    rec = float(torch.mps.recommended_max_memory())
    ratio = os.environ.get("PYTORCH_MPS_HIGH_WATERMARK_RATIO")
    cap = rec * float(ratio) if ratio else rec
    device_left = max(0.0, cap - torch.mps.driver_allocated_memory())
    host = host_available_bytes()
    if host is None:
        return int(device_left)
    # Only a fraction of "available" is durably ours: on a machine with pages already swapped
    # out, reclaiming inactive pages pushes other processes' memory to swap, and the swapping is
    # the thing that hurts. Measured 2026-08-22: a snapshot showing 6.9 GB available let the
    # policy take a 1.6 GB accumulator on device at K=118, after which the machine swapped at
    # 4.9 GB/min. Taking the budget is what destroys the budget, on unified memory.
    return int(min(device_left, max(0.0, (host - host_headroom_gb * 1e9) * unified_fraction)))


#: The share of a device's measured free memory the ranked encoder sizes its slab to. The
#: encode runs where the logits are, beside the resident model, and its working-set bound
#: (``rankfield.slab_bytes``) counts live tensors, not what the allocator keeps: on MPS the
#: pool grew in ~1 GiB heaps to 1.5-2.2x the bound (2026-09-23, K=118 and K=25 fields, slabs
#: of 0.46-2.95 GiB bound). Half the measurement keeps the pool inside it.
RANKED_ENCODE_BUDGET_FRACTION = 0.5
#: ...and no more than rankfield's own small default (None = ``DEFAULT_MEMORY_BUDGET``, 1 GiB),
#: because more bought nothing. Same process, conditions alternated, warm-up discarded, M2
#: 16 GB: K=118 at 236x167x167 took 5.6 / 5.5 / 5.7 s at 7 / 15 / 30 planes and 8.1 s at 45
#: (memory pressure); K=25 at 472x334x334 took 32.7 / 34.7 / 40.8 s at 5 / 11 / 22 planes.
#: The per-slab launches are noise beside the per-voxel selection work. So the measurement
#: only ever SHRINKS the slab, on a device too full for the default. Unmeasured on CUDA,
#: where launches are relatively dearer: this is the number to lift there if one says so.
RANKED_ENCODE_BUDGET_CEILING: int | None = None


def reusable_cache_bytes(device) -> int:
    """Bytes torch's allocator holds on ``device`` for tensors that no longer exist - memory
    this process already has, which its next allocations take before asking the device or
    the host for more. 0 where there is no such pool (cpu) or no backend.

    MPS: what the driver holds less what live tensors hold. CUDA: reserved less allocated
    (``mem_get_info``'s free leaves the reserved cache out, as the MPS reading counts it in)."""
    device = torch.device(device)
    if device.type == "mps" and torch.backends.mps.is_available():
        return max(0, int(torch.mps.driver_allocated_memory() - torch.mps.current_allocated_memory()))
    if device.type == "cuda" and torch.cuda.is_available():
        return max(0, int(torch.cuda.memory_reserved(device) - torch.cuda.memory_allocated(device)))
    return 0


def ranked_encode_budget(device) -> int:
    """Bytes the ranked encoder may size its slab to on ``device``: a share of what it can
    take right now, capped at rankfield's own default, which is also the answer where the
    budget is unknown (cpu, or no backend). Adapts to the machine and never changes a byte of
    the field, so a caller records it beside the accumulator placement, not as a deviation.

    What it can take is the device's fresh budget PLUS torch's reusable cache: the encode
    runs right after the network, whose freed activations sit in that cache, and its slab is
    carved from them before anything new is asked of the host. Counting the cache as used
    read ZERO on an M2 after ``lung_vessels``' fine network (2026-09-23: the driver held 3.1
    GiB, 2.5-2.8 of it reusable; the host had 2.6 GiB available, under the 3 GiB headroom),
    so every such encode ran one plane a slab - harmless while rankfield's selection was the
    cost, 2.09 s against 0.75 s once its Metal kernel made the selection cheap."""
    from .ranked import DEFAULT_MEMORY_BUDGET
    ceiling = DEFAULT_MEMORY_BUDGET if RANKED_ENCODE_BUDGET_CEILING is None else RANKED_ENCODE_BUDGET_CEILING
    free = device_budget_bytes(torch.device(device))
    if free is None:
        return DEFAULT_MEMORY_BUDGET
    free += reusable_cache_bytes(device)
    # a full device still encodes, a plane at a time (rankfield's floor), rather than refusing
    return max(1, min(ceiling, int(free * RANKED_ENCODE_BUDGET_FRACTION)))


CUDA_AUTO_BATCH = 4


def choose_batch(policy, *, device: torch.device, on_device: bool, held_bytes: int | None,
                 budget_bytes: int | None, accumulator_bytes: int) -> tuple[int, str]:
    """Patches per forward pass. An int is taken as given; ``"auto"`` decides from measurements.

    Batch 1 is the measured optimum on Apple silicon (one patch saturates a bandwidth-bound
    GPU). On CUDA, measured on an A10 in one container with alternated conditions: batch 2 is
    12 % faster than 1 with no warmup cost, batch 4 is 18 % faster in steady state but its
    first use of a patch shape pays ~7 s of cuDNN autotuning - still a net win for a whole-body
    job, where five parts share one shape. Activations scale about linearly with batch, so
    the rule is: CUDA, accumulator on the device, and ``CUDA_AUTO_BATCH`` x the measured
    working set still fits beside the accumulator with margin.

    The 0.5 GB margin is flat, and nothing has measured it against a failure. On 2026-09-11 a
    CADS ResEnc-L checkpoint in fp32 (192^3 patch, K=18) on a 22 GiB A10 ran out of memory,
    apparently at batch 4. It has not been reproduced, and ``batch_choice``, which holds the
    figures this decided from, reaches no log and no provenance, so there is nothing yet to
    size a proportional margin by. The fallback absorbs a miss instead: an out-of-memory error
    at a batch above 1 is retried at batch 1 on the device before the accumulator moves to the
    host (``TorchModel._sliding_window_with_fallback``).
    """
    if policy != "auto":
        b = max(1, int(policy))
        return b, f"batch {b} (requested)"
    if device.type != "cuda":
        return 1, "batch 1: not CUDA (1 is the measured optimum on Apple silicon)"
    if not on_device:
        return 1, "batch 1: accumulator is on the host, so the device-side batched loop does not apply"
    if held_bytes is None or budget_bytes is None:
        return 1, "batch 1: no memory measurement available"
    need = CUDA_AUTO_BATCH * held_bytes + accumulator_bytes
    if need + int(0.5e9) <= budget_bytes + held_bytes:      # budget was measured with b=1 already held
        return CUDA_AUTO_BATCH, (f"batch {CUDA_AUTO_BATCH}: {CUDA_AUTO_BATCH}x the measured {held_bytes / 1e9:.2f} GB "
                                 f"working set + {accumulator_bytes / 1e9:.2f} GB accumulator fits in "
                                 f"{(budget_bytes + held_bytes) / 1e9:.2f} GB")
    return 1, (f"batch 1: {CUDA_AUTO_BATCH}x the measured {held_bytes / 1e9:.2f} GB working set would not fit "
               f"beside the {accumulator_bytes / 1e9:.2f} GB accumulator in {(budget_bytes + held_bytes) / 1e9:.2f} GB")


def choose_accumulate(policy: str, *, device: torch.device, K: int, shape, bytes_per_element: int = 2,
                      activation_reserve_gb: float = DEFAULT_ACTIVATION_RESERVE_GB,
                      host_headroom_gb: float = 3.0, measured: bool = False,
                      safety_fraction: float = 0.25, min_host_health: int = 35) -> tuple[bool, str]:
    """Where the sliding-window accumulator lives. Returns ``(on_device, why)``.

    The accumulator is ``K`` channels plus a weight map at the *padded model grid*: on a
    16 GB Apple machine at K=118 that is 1.6 GB and does not fit beside the network, but on
    a 64 GB Mac or a CUDA card with headroom it does - and on-device accumulation is worth
    ~25 % of the per-patch time (`medseg/docs/backend-decision.md` E2-accum). So this is a runtime
    decision from the actual budget, never a hard-coded default. ``"device"`` / ``"host"``
    force it; a forced ``"device"`` that OOMs still falls back, with a warning.
    """
    if policy not in ACCUMULATE:
        raise ValueError(f"accumulate must be one of {ACCUMULATE}; got {policy!r}")
    n = 1
    for d in shape:
        n *= int(d)
    need = int((K + 1) * n * bytes_per_element)
    if policy == "host":
        return False, f"forced host (accumulator would be {need / 1e9:.2f} GB)"
    if device.type == "cpu":
        return False, "cpu device: accumulator is already in host memory"
    budget = device_budget_bytes(device, host_headroom_gb=host_headroom_gb)
    if policy == "device":
        return True, f"forced device ({need / 1e9:.2f} GB accumulator, {budget / 1e9:.2f} GB free)" if budget else "forced device"
    if budget is None:
        return False, "no device budget reported"
    if device.type == "mps":
        health = host_memory_health()
        if health is not None and health < min_host_health:
            return False, (f"host memory is already tight (kern.memorystatus_level {health}% < "
                           f"{min_host_health}%): on unified memory a device accumulator would come "
                           f"out of the same pool and push the machine into swap")
    if measured:
        # The network is already resident, so `budget` is what is genuinely left; reserve only a
        # margin for per-patch transients the caching allocator has not yet settled.
        held = device_working_set_bytes(device) or 0
        margin = max(int(0.5e9), int(safety_fraction * held))
        fits = need + margin <= budget
        return fits, (f"{'fits' if fits else 'does not fit'}: accumulator {need / 1e9:.2f} GB + margin "
                      f"{margin / 1e9:.2f} GB vs {budget / 1e9:.2f} GB free on {device} "
                      f"(measured: network holds {held / 1e9:.2f} GB)")
    reserve = int(activation_reserve_gb * 1e9)
    fits = need + reserve <= budget
    return fits, (f"{'fits' if fits else 'does not fit'}: accumulator {need / 1e9:.2f} GB + estimated reserve "
                  f"{reserve / 1e9:.1f} GB vs {budget / 1e9:.2f} GB free on {device} (unmeasured)")


def inverse_perm(perm) -> tuple:
    """The permutation that undoes ``perm``."""
    out = [0] * len(perm)
    for i, p in enumerate(perm):
        out[p] = i
    return tuple(out)


def canonical_spacing(spacing_t, fwd) -> tuple:
    """Plans spacing (expressed in the transpose_forward frame) mapped back to
    canonical (z, y, x) axis order: transposed axis ``k`` IS canonical axis
    ``fwd[k]``, so its spacing lands at index ``fwd[k]``."""
    out = [0.0] * len(fwd)
    for k, sp in zip(fwd, spacing_t):
        out[k] = float(sp)
    return tuple(out)


def checkpoint_name(folder, folds) -> str:
    """Which checkpoint file to load from the requested folds.

    nnU-Net writes ``checkpoint_final.pth`` when training ends and
    ``checkpoint_best.pth`` at the best validation epoch, and a published model
    may ship either: every TotalSegmentator, MOOSE and MRSegmentator asset ships
    ``final``, while TotalVibeSegmentator's body-region and vertebra models ship
    only ``best``. Prefer ``final`` - it is what nnU-Net's own predictor defaults
    to, so preferring it keeps the common case byte-identical - and fall back to
    ``best`` rather than dying inside nnU-Net on a bare file-not-found.
    """
    root = Path(folder)
    dirs = [root / f"fold_{f}" for f in folds]
    for name in ("checkpoint_final.pth", "checkpoint_best.pth"):
        if dirs and all((d / name).is_file() for d in dirs):
            return name
    have = sorted({f"{d.name}/{c.name}" for d in dirs if d.is_dir()
                   for c in d.glob("checkpoint_*.pth")})
    raise ModelNotFound(
        f"{root.name}: no checkpoint_final.pth or checkpoint_best.pth in every "
        f"requested fold ({', '.join(d.name for d in dirs)}); found "
        + (", ".join(have) if have else "no checkpoint_*.pth at all"))


def window_tiles(extent_zyx, patch, transpose_forward=(0, 1, 2), step: float = 0.5) -> int:
    """How many patches the sliding window runs over an input of ``extent_zyx`` (model grid).

    What :meth:`TorchModel.predict_logits` does, counted rather than run: the input is permuted
    into the network's axis order (``patch`` is stated in that order), padded up to the patch
    where it is shorter, and tiled by nnU-Net's own step rule. The body envelope asks this,
    not the box's volume, whether a crop saves any network time (see
    :func:`~haversack.envelope.worth_cropping`).

    A 2D model's patch has two entries: nnU-Net runs every slice of the first network axis
    through a 2D window over the other two, so that axis multiplies the count unpadded.
    """
    from nnunetv2.inference.sliding_window_prediction import compute_steps_for_sliding_window
    size = [int(extent_zyx[a]) for a in transpose_forward]
    patch = [int(p) for p in patch]
    n = 1
    if len(patch) == len(size) - 1:
        n, size = size[0], size[1:]
    size = [max(s, p) for s, p in zip(size, patch)]
    for s in compute_steps_for_sliding_window(size, patch, step):
        n *= len(s)
    return n


def available_folds(folder, folds) -> tuple:
    """The requested folds, restricted to the ``fold_*`` directories that exist.

    TotalSegmentator ships fold_0 only, so ``folds=(0,)`` is the right default - but a stock
    nnU-Net result folder may hold any subset (the knee reference model ships only fold_1).
    ``folds="all"`` takes whatever is on disk. A folder holding only ``fold_all``
    (nnU-Net's ``--fold all`` layout - how MOOSE ships) satisfies any request, since
    that single model was trained on all the data. Asking for numeric folds that are
    all missing is otherwise an error naming what is there, rather than nnU-Net's
    bare file-not-found.
    """
    root = Path(folder)
    have = sorted(int(p.name.split("_")[1]) for p in root.glob("fold_*")
                  if p.is_dir() and p.name.split("_")[-1].isdigit())
    has_all = (root / "fold_all").is_dir()   # nnU-Net's --fold all layout (MOOSE ships these)
    if not have and not has_all:
        raise ModelNotFound(f"no fold_* directory in {root}")
    if folds is None or (isinstance(folds, str) and folds == "all"):
        return tuple(have) or ("all",)
    want = [int(f) for f in ((folds,) if isinstance(folds, int) else folds)]
    keep = [f for f in want if f in have]
    if not keep:
        if has_all:
            # fold_all is the model trained on ALL data - it subsumes any
            # numeric fold request when it is the only thing on disk
            return ("all",)
        raise ModelNotFound(f"{root.name}: requested fold(s) {want} not present; have {have}")
    return tuple(keep)


class TorchModel:
    """One nnU-Net configuration folder (``{trainer}__{plans}__{config}``) on torch.

    Uses nnU-Net's own predictor to build the architecture from ``plans.json`` and load
    the checkpoints (so tiling, gaussian and fold handling stay nnU-Net's), then:
    ``ShuffleUp3d`` surgery (exact; lets the decoder run in half precision on MPS),
    ``dtype``, and a sliding-window loop with two accumulator
    placements, chosen at run time from the device's actual free memory
    (``accumulate="auto"``, or force with ``"device"`` / ``"host"``):

    * **device** - accumulate on the GPU. Fastest; needs ``(K + 1) * voxels * 2`` bytes
      beside the network (1.6 GB at K=118 for a chest at 3 mm). The right choice on a
      large Mac or a CUDA card with headroom.
    * **host** - accumulate in host memory, with the fp16 add on a worker thread while the
      GPU computes the next patch: bit-identical to nnU-Net's loop and ~25 % faster than it,
      and it keeps whole-body inference inside a modest GPU budget.
    """

    def __init__(self, folder, *, folds=(0,), device="auto", dtype: str = "fp16", channels_last: bool = False,
                 allow_transpose: bool = False,
                 surgery: bool = True, accumulate: str = "auto", step_size: float = 0.5,
                 activation_reserve_gb: float = DEFAULT_ACTIVATION_RESERVE_GB, batch_size="auto",
                 defer_device: bool = False):
        from nnunetv2.inference.predict_from_raw_data import nnUNetPredictor
        from nnunetv2.inference.sliding_window_prediction import compute_gaussian

        from .resample import resolve_device
        self.folder = Path(folder)
        self.device = resolve_device(device)
        self.dtype = DTYPES[dtype]
        if accumulate not in ACCUMULATE:
            raise ValueError(f"accumulate must be one of {ACCUMULATE}; got {accumulate!r}")
        self.accumulate = accumulate
        self.activation_reserve_gb = float(activation_reserve_gb)
        # Patches per forward pass: an int, or "auto" (decided per volume after the first patch
        # from measured memory - see choose_batch). Only the device-side accumulate batches;
        # the host path keeps its per-patch pipeline.
        self.batch_size = batch_size
        self.batch_choice = None
        self.accumulate_choice = None                       # set per volume in predict_logits
        from .trainers import ensure_trainer
        ensure_trainer(self.folder)                       # shim custom trainers (e.g. SkeletonRecall)
        # Quiet two things nnunetv2 says on every non-CUDA run that mean nothing here: it
        # print()s "perform_everything_on_device=True is only supported for cuda devices" even
        # when handed False (the accumulator placement is haversack's own policy, `accumulate`),
        # and warns "Detected old nnU-Net plans format" for every TotalSegmentator checkpoint,
        # which it then reconstructs fine.
        import contextlib
        import io
        with contextlib.redirect_stdout(io.StringIO()), warnings.catch_warnings():
            warnings.filterwarnings("ignore", message="Detected old nnU-Net plans format")
            # nnunetv2 imports every trainer module while looking for the checkpoint's, and
            # the Primus/EVA ones import timm, whose hrnet decorates with the deprecated
            # torch.jit.interface (torch >= 2.14 warns once). Not our code, not our model.
            warnings.filterwarnings("ignore", category=FutureWarning, message=".*torch.jit.interface.*")
            p = nnUNetPredictor(tile_step_size=step_size, use_gaussian=True, use_mirroring=False,
                                perform_everything_on_device=False, device=self.device, verbose=False,
                                allow_tqdm=False)
            use = available_folds(self.folder, folds)
            p.initialize_from_trained_model_folder(str(self.folder), use_folds=use,
                                                   checkpoint_name=checkpoint_name(self.folder, use))
        self.predictor = p
        self.plans = p.plans_manager.plans
        self.dataset_json = p.dataset_json
        self.label_manager = p.label_manager
        self.K = int(p.label_manager.num_segmentation_heads)
        self.patch = tuple(int(x) for x in p.configuration_manager.patch_size)
        # nnU-Net permutes the spatial axes before preprocessing (transpose_forward), and
        # configuration_manager.spacing and patch_size are expressed in that permuted frame.
        # haversack keeps everything OUTSIDE the network in canonical (z, y, x) order: spacing_zyx
        # is mapped back to canonical here, and predict_logits permutes the tensor into the
        # transposed frame only around the network itself (kernel anisotropy must see the
        # axis order it was trained on), permuting the logits straight back. self.patch stays
        # in the transposed frame - it is only ever applied to the permuted tensor.
        self.transpose_forward = tuple(int(i) for i in p.plans_manager.transpose_forward)
        self.transpose_backward = inverse_perm(self.transpose_forward)
        declared_bwd = tuple(int(i) for i in getattr(p.plans_manager, "transpose_backward",
                                                     self.transpose_backward))
        if declared_bwd != self.transpose_backward:
            raise UnsupportedModel(
                f"{self.folder.name}: plans transpose_backward {declared_bwd} is not the "
                f"inverse of transpose_forward {self.transpose_forward}")
        if len(p.configuration_manager.spacing) != 3:
            # a 2d configuration: nnU-Net keeps each image's own slice spacing, which a spacing
            # fixed at load cannot state (it came out 0 here, a division by zero downstream)
            raise UnsupportedModel(f"{self.folder.name}: a 2d configuration "
                                   "(needs each image's own slice spacing and a slice-wise loop)")
        self.spacing_zyx = canonical_spacing(p.configuration_manager.spacing,
                                             self.transpose_forward)
        if self.transpose_forward != (0, 1, 2) and not allow_transpose:
            # The transposed path is implemented and spec-tested. It has since been
            # checked against nnU-Net's own predictor on ONE model
            # (dentalsegmentator:base: 99.86 % of voxels, Dice 0.999 on the large
            # structures, in both stored orientations), which is evidence for that
            # model rather than confirmation of the path - so the gate stays and the
            # opt-in is per run. Do not remove it on the strength of one model.
            raise UnsupportedModel(
                f"{self.folder.name}: plans set transpose_forward={self.transpose_forward}. "
                "haversack implements transposed models but confirms them one at a time "
                "against an external oracle - pass allow_transpose=True (CLI: "
                "--allow-transpose; server: haversack serve --allow-transpose) to run this "
                "model, and treat the output as pending confirmation.")
        self.fold_params = list(p.list_of_parameters)
        # Everything up to here is CPU work (checkpoint read, architecture build, surgery) and
        # safe to do on a helper thread. The device move is deliberately separate: a helper
        # thread copying weights to the GPU contends with a running prediction - measured on
        # an A10 at batch 4, prefetching whole models cost more network time than it saved.
        self.net = p.network.eval()
        # nnU-Net wraps the network in torch.compile when its nnUNet_compile variable is set, and
        # the wrapper prefixes `_orig_mod.` to every module and state-dict name - names no
        # checkpoint uses. So the surgery's mapping and every fold load address the module inside
        # it, as nnU-Net's own fold loop does (2026-10-18: found by review; addressing the wrapper
        # failed every surgered model under compile, single folds included).
        self._module = getattr(self.net, "_orig_mod", self.net)
        self.n_swapped = swap_transposed(self._module) if surgery else 0
        if self.n_swapped:
            # The surgery was built from the weights the network holds, which are fold 0's; every
            # fold's checkpoint still names ConvTranspose3d tensors. Map each into the surgered
            # network's names once, here, with the rest of the CPU work (2026-10-18: before this,
            # every fold after the first raised, so no multi-fold model ran with surgery on). The
            # predictor's own list is replaced too: it describes the network it holds, and keeping
            # the old dicts alive beside the new ones would hold the transposed weights twice.
            self.fold_params = [surgered_state(s, self._module) for s in self.fold_params]
            p.list_of_parameters = self.fold_params
        self._held = 0          # the fold the network holds: nnU-Net's initialize loaded fold 0
        self.net.to(self.dtype)
        self.channels_last = channels_last
        self._gaussian_cpu = compute_gaussian(self.patch, sigma_scale=1. / 8, value_scaling_factor=10,
                                              device=torch.device("cpu"))
        self.gaussian = None
        self._on_device = False
        if not defer_device:
            self.to_device()

    def to_device(self) -> "TorchModel":
        """Move the network to ``self.device``. Idempotent; call from the thread that predicts."""
        if not self._on_device:
            self.net.to(self.device)
            # Off by default (2026-09-27): channels_last_3d made the sliding window slower on both
            # devices measured - organs model (831) at 1.5 mm on an A10, 6.84 s vs 4.33 s; total_fast
            # (836) at 3 mm on an M2, 20.7 s vs 17.6 s - same tiles, fp16, labels within fp16 rounding.
            if self.channels_last:
                self.net.to(memory_format=torch.channels_last_3d)
            self.gaussian = self._gaussian_cpu.to(self.device)
            self._on_device = True
        return self

    # -- normalization (nnU-Net plans) ------------------------------------------
    @property
    def normalization_schemes(self) -> tuple[str, ...]:
        return tuple(self.predictor.configuration_manager.normalization_schemes)

    def intensity_properties(self, channel: int = 0) -> dict:
        return self.plans.get("foreground_intensity_properties_per_channel", {}).get(str(channel), {})

    @property
    def use_mask_for_norm(self):
        return getattr(self.predictor.configuration_manager, "use_mask_for_norm", None)

    def resampling(self, kind: str) -> dict:
        """The plans' resampling for ``kind`` - ``"data"`` (the input) or ``"probabilities"``
        (the logits, at export) - as ``{"order", "order_z", "force_separate_z"}``; see
        :func:`haversack.preprocess.nnunet_resampling`."""
        from .preprocess import nnunet_resampling_from_config
        return nnunet_resampling_from_config(self.predictor.configuration_manager.configuration, kind,
                                             self.folder.name)

    # -- sliding window ------------------------------------------------------------
    def _load_fold(self, i: int) -> None:
        """Make the network hold fold ``i``. A no-op for the fold it already holds, so a
        single-fold model never reloads, and a multi-fold one pays one copy per fold per volume
        (a call ends holding the last fold, so the next starts by loading fold 0 again)."""
        if i == self._held:
            return
        self._held = None       # a load that raises leaves the network holding no known fold
        # copies into the existing tensors, which keep their dtype and device: no cast after it
        self._module.load_state_dict(self.fold_params[i])
        self._held = i

    def tiles(self, extent_zyx) -> int:
        """Patches :meth:`predict_logits` runs, per fold, over an input of ``extent_zyx``."""
        return window_tiles(extent_zyx, self.patch, self.transpose_forward,
                            self.predictor.tile_step_size)

    @torch.inference_mode()
    def predict_logits(self, x: torch.Tensor, *, report=None) -> torch.Tensor:
        """``(C, Z, Y, X)`` preprocessed float tensor -> ``(K, Z, Y, X)`` logits (fp16).

        The accumulator's placement follows ``self.accumulate`` and the device's free
        memory at this moment (see :func:`choose_accumulate`); the choice, and why, is
        recorded in ``self.accumulate_choice``.

        ``report`` is an optional :class:`~haversack.progress.Reporter`; it is ticked once per patch,
        which is both the progress granularity and the only point a run can be cancelled. It is
        passed in rather than held on the model, because models are shared through the cache.
        """
        from acvl_utils.cropping_and_padding.padding import pad_nd_image

        self.to_device()
        x = x.to(self.dtype)
        transposed = self.transpose_forward != (0, 1, 2)
        if transposed:
            # the network's kernel anisotropy matches the frame it was trained on
            x = x.permute((0, *(f + 1 for f in self.transpose_forward))).contiguous()
        padded, revert = pad_nd_image(x, self.patch, "constant", {"value": 0}, True, None)
        slicers = self.predictor._internal_get_sliding_window_slicers(padded.shape[1:])
        total = None
        for i in range(len(self.fold_params)):
            self._load_fold(i)
            acc = self._sliding_window_with_fallback(padded, slicers, report=report)
            total = acc if total is None else total.add_(acc)
        if len(self.fold_params) > 1:
            total /= len(self.fold_params)
        if self.device.type == "cuda":
            torch.cuda.synchronize()
        elif self.device.type == "mps":
            torch.mps.synchronize()
        out = total[(slice(None), *revert[1:])]
        if transposed:
            out = out.permute((0, *(b + 1 for b in self.transpose_backward))).contiguous()
        return out

    def _patch(self, padded: torch.Tensor, sl):
        pred = self.net(padded[sl][None].to(self.device))[0]
        pred *= self.gaussian
        return pred

    def _sliding_window_with_fallback(self, padded: torch.Tensor, slicers, *, report=None) -> torch.Tensor:
        """:meth:`_sliding_window`, stepped down when it runs out of memory with the accumulator on
        the device: a batch above 1 is retried at 1 on the device, and batch 1 with the
        accumulator on the host. A forced ``"device"`` falls back the same way.

        **Each retry runs after the ``except`` block, never inside it.** While an exception is
        handled, its traceback references every frame between here and the failed allocation, and
        each frame its locals - the device accumulator, the batched input, the activations. Until
        2026-09-11 the host retry ran inside the handler, so ``empty_cache()`` could release none
        of that and the retry ran beside it: on Modal, a CADS ResEnc-L checkpoint in fp32 on a
        22 GiB A10 raised on an 864 MiB allocation with 19.08 GiB still allocated by PyTorch
        (the PyTorch FAQ: "My out of memory exception handler can't allocate memory"). So the
        handler keeps strings and ints and nothing else: holding the exception, its traceback, or
        anything reached through them pins the failed attempt again. ``tests/test_oom_fallback.py``
        checks with weak references.

        The step to batch 1 before the host is there because batch 1 on the device is what the
        measured placement policy approved; only the batch above it rests on an estimate (see
        :func:`choose_batch`). An error in the first patch is raised as it is: no policy has
        decided anything yet, and every fallback would run that same patch the same way first.
        """
        retry: dict = {}
        failed: list[str] = []
        while True:
            # this attempt's choices, not the previous volume's: the model is shared through the cache
            self.accumulate_choice = self.batch_choice = None
            try:
                return self._sliding_window(padded, slicers, report=report, **retry)
            except RuntimeError as e:          # torch.OutOfMemoryError is one; MPS raises a bare RuntimeError
                on_device = bool(self.accumulate_choice and self.accumulate_choice["on_device"])
                if not on_device or "memory" not in str(e).lower():
                    # raised in here, a retry's error was chained to the one before; now it is not
                    for f in failed:
                        e.add_note(f"haversack: this was a retry - an earlier attempt ran out of memory at {f}")
                    raise
                batch = self.batch_choice["batch"] if self.batch_choice else 1
                oom = " ".join(str(e).split())
                failed.append(f"batch {batch}, accumulator on {self.device}: {oom}")
            # `e` is unbound here, and the failed attempt's tensors are garbage with it
            if self.device.type == "mps":
                torch.mps.empty_cache()
            elif self.device.type == "cuda":
                torch.cuda.empty_cache()
            if batch > 1:
                warnings.warn(f"batch {batch} ran out of memory on {self.device} ({oom}); retrying at batch 1",
                              stacklevel=2)
                retry = {"batch": 1, "reason": f"batch 1: batch {batch} ran out of memory ({oom})"}
            else:
                warnings.warn(f"on-device accumulation ran out of memory ({oom}); falling back to host", stacklevel=2)
                retry = {"force_host": True,
                         "reason": f"forced host after an out-of-memory fallback ({'; '.join(failed)})"}

    def _sliding_window(self, padded: torch.Tensor, slicers, *, force_host: bool = False,
                        batch: int | None = None, reason: str = "", report=None) -> torch.Tensor:
        """Placement is decided after the *first* patch has run, from what the network actually
        holds on the device - no extra compute, and no guessing at an activation reserve that
        varies 2 GB between models.

        ``force_host`` and ``batch`` are the out-of-memory fallback's overrides of the two
        policies, and ``reason`` is recorded in place of the policy's why (see
        :meth:`_sliding_window_with_fallback`)."""
        K, shape = self.K, padded.shape[1:]
        with torch.inference_mode():
            # In a list that _accumulate empties, so that nothing here keeps it once it is added
            # (see _accumulate). It stays alive until then on purpose: the memory reads below are
            # taken with it resident, and choose_accumulate and choose_batch decide from them.
            first = [self._patch(padded, slicers[0])]
        if force_host:
            on_device, why = False, reason or "forced host after an out-of-memory fallback"
        else:
            on_device, why = choose_accumulate(self.accumulate, device=self.device, K=K, shape=shape,
                                               activation_reserve_gb=self.activation_reserve_gb, measured=True)
        self.accumulate_choice = {"on_device": on_device, "why": why}
        held = device_working_set_bytes(self.device)
        budget = device_budget_bytes(self.device) if on_device else None
        n = 1
        for d in shape:
            n *= int(d)
        if batch is not None and on_device:
            b, bwhy = batch, reason
        else:
            b, bwhy = choose_batch(self.batch_size, device=self.device, on_device=on_device, held_bytes=held,
                                   budget_bytes=budget, accumulator_bytes=(K + 1) * n * 2)
        self.batch_choice = {"batch": b, "why": bwhy}
        return self._accumulate(padded, slicers, first, on_device, batch=b, report=report)

    @torch.inference_mode()
    def _accumulate(self, padded: torch.Tensor, slicers, first: list[torch.Tensor], on_device: bool,
                    batch: int = 1, report=None) -> torch.Tensor:
        """``first`` is the output of the first patch, which :meth:`_sliding_window` ran to
        measure the device, as the only item of a list that this pops.

        A list, and not the tensor, because an argument stays referenced for the whole call. Until
        2026-09-11 ``first`` was the tensor, and the ``del first`` here dropped only this frame's
        name: the caller's local still bound it, and so did the ``args`` tuple of the
        inference-mode wrapper around this method. So the first patch's output - a view of the
        network's whole output, K x patch x dtype, about 510 MB for an fp32 K=18 model at a 192^3
        patch - stayed on the device for the whole loop. ``tests/test_first_patch_release.py``
        checks with a weak reference.
        """
        K, shape = self.K, padded.shape[1:]
        if on_device:
            acc = torch.zeros((K, *shape), dtype=torch.half, device=self.device)
            n_pred = torch.zeros(shape, dtype=torch.half, device=self.device)
            acc[slicers[0]] += first.pop()
            n_pred[slicers[0][1:]] += self.gaussian
            rest = slicers[1:]
            B = batch
            if B == 1:
                for i, sl in enumerate(rest):
                    if report is not None:
                        report.tick(i + 1, len(slicers))    # the cancellation point
                    pred = self._patch(padded, sl)
                    acc[sl] += pred
                    n_pred[sl[1:]] += self.gaussian
                    # Unbound here, and not when the next _patch returns: until 2026-09-11 each
                    # patch's output - K x patch x dtype, about 510 MB for an fp32 K=18 model at a
                    # 192^3 patch - was still on the device during the next forward pass, one more
                    # than _sliding_window measured the working set with. Checked by weak reference
                    # in tests/test_patch_output_release.py, as are the two loops below.
                    del pred
            else:
                data = padded.to(self.device)
                for i in range(0, len(rest), B):
                    if report is not None:
                        report.tick(min(i + B, len(rest)) + 1, len(slicers))
                    group = rest[i:i + B]
                    x = torch.stack([data[sl] for sl in group])          # (b, C, *patch)
                    preds = self.net(x)
                    preds *= self.gaussian                                # broadcasts over the batch
                    for pred, sl in zip(preds, group):
                        acc[sl] += pred
                        n_pred[sl[1:]] += self.gaussian
                    # pred too: the loop leaves it on the batch's last row, a view that keeps the
                    # whole batch's storage, so until 2026-09-11 `del preds` freed nothing and the
                    # next batch ran beside all B of this one's outputs
                    del x, preds, pred
            torch.div(acc, n_pred, out=acc)
            # Checked here too since 2026-10-05: until then only the host path was, so a NaN or an
            # fp16 overflow accumulated on the device reached the labels unremarked. On MPS the
            # check costs about 8 MB; the message has no "memory" in it, so the fallback re-raises
            # it rather than retrying on the host.
            if not all_finite(acc):
                raise RuntimeError("non-finite logits after accumulation")
            return acc
        acc = torch.zeros((K, *shape), dtype=torch.half)
        n_pred = torch.zeros(shape, dtype=torch.half)
        gauss_cpu = self._gaussian_cpu
        q: queue.Queue = queue.Queue(maxsize=2)
        err: list = []

        def worker():
            with torch.inference_mode():
                try:
                    while True:
                        item = q.get()
                        if item is None:
                            q.task_done(); break
                        host, sl = item
                        acc[sl] += host
                        n_pred[sl[1:]] += gauss_cpu
                        q.task_done()
                except Exception as e:                                 # pragma: no cover
                    err.append(e)

        t = threading.Thread(target=worker, daemon=True)
        t.start()
        q.put((first.pop().to("cpu"), slicers[0]))
        try:
            for i, sl in enumerate(slicers[1:]):
                if report is not None:
                    report.tick(i + 1, len(slicers))                   # the cancellation point
                pred = self._patch(padded, sl)
                q.put((pred.to("cpu"), sl))                            # the copy is cheap; the add overlaps the next forward
                del pred                                               # the device tensor: see the batch-1 loop above
        finally:
            q.put(None)                                                # never leave the worker parked on get()
            t.join()
        if err:
            raise err[0]
        torch.div(acc, n_pred, out=acc)
        if not all_finite(acc):
            raise RuntimeError("non-finite logits after accumulation")
        return acc


def all_finite(t: torch.Tensor) -> bool:
    """``bool(torch.isfinite(t).all())`` without the temporary.

    On the CPU ``torch.isfinite`` materializes full-size intermediates before ``.all()`` reduces
    them: on a 755 MB fp16 accumulator (K=18, a 256 x 256 x 320 grid) peak RSS grew 1696 MB, 2.25x
    the tensor, and on the fp32 tensor of the same shape 1722 MB (torch 2.14, Apple M2,
    2026-10-05). The host accumulator is K x the padded model grid, so the check put a GB-scale
    transient on top of a CPU run's peak (a sliding window over that grid: 3.05 GB, 2.07 GB
    without it). A max and a min reduce to scalars and propagate NaN, and an
    infinity is itself an extreme, so the two extremes are finite exactly when every element
    is: the same answer for NaN, +inf and -inf at any position, in every float dtype
    (``tests/test_all_finite.py``), with peak RSS growing 1 MB."""
    if t.numel() == 0:
        return True                    # isfinite(empty).all() is True; amax of nothing raises
    return bool(torch.isfinite(t.amax()) & torch.isfinite(t.amin()))


# re-exported so callers keep importing it from here
from .tasks import resolve_model_folder  # noqa: E402,F401
