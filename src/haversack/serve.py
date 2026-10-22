"""The REST job protocol over a Segmenter - run segmentations for remote callers.

This is the seam the toolkit's remote consumers share (medseg/docs/slicer-modal-design.md in
the medseg workspace): a 3D Slicer panel, a CLI on another machine, a notebook. The
contract is deliberately small:

    GET    /v1/health              who am I - version, device, task count
    GET    /v1/version             what's deployed - contract, package + weights versions
    GET    /v1/tasks               task names
    GET    /v1/tasks/{task}        describe: structures, modality, weights
    POST   /v1/jobs                task + input (+ options JSON) -> {id}; the input is a
                                   `source` list - one entry for most tasks, one
                                   PER DECLARED ROLE for a multi-input model,
                                   each {"kind": "upload"} (the
                                   default; multipart part "file") or {"kind": "idc",
                                   "crdc_series_uuid": ...} (the server fetches from
                                   the public IDC buckets; needs the idc extra). A bare
                                   multipart file remains valid shorthand forever. Kind
                                   "url" is reserved for the authenticated tier.
                                   {"kind": "result", "id": "<key>"} names a result THIS
                                   server computed, by the `key` its job reports - so one
                                   job's labels are another's mask. Its identity is the
                                   referenced output's content digest, resolved here at
                                   submit; a result that is not there is refused with a
                                   409 naming what to compute first.
                                   `deliverables` (a form field of its own, a JSON list)
                                   names what is rendered beside the labels - "preview",
                                   "statistics"; [] for none; absent, this deployment's
                                   set, which is also the most one may name. Never part
                                   of the result's key: declining a preview recomputes
                                   nothing, and a cache hit renders what its list names
                                   and the stored result lacks.
    GET    /v1/jobs                brief status of every known job
    GET    /v1/inputs/{digest}     whether this server already holds that content
    POST   /v1/inputs             store a multi-file input (a DICOM series) as
                                   one tree - several parts, or a zip; returns
                                   its digest. `from_job=<id>` instead promotes
                                   that job's result into the store, so one job's
                                   output can be another's input without the
                                   bytes routing through the client
    A finished job reports `outputs` - the content digest of what it produced -
    and that digest is the ETag on the result, so If-None-Match gets a 304.
    PUT    /v1/inputs/{digest}     store it (preload). Content whose format
                                   cannot be identified is REFUSED, not stored:
                                   a blob nothing can open is a job that was
                                   always going to fail, so it fails here. The digest in the URL is
                                   CHECKED against the bytes, never trusted; a
                                   source may then be {"kind":"input","sha256":...}
                                   instead of re-sending. No route hands input
                                   bytes back.
    Cache-Control: no-cache on a submit (or an authorized labels GET) means "do not
    serve me a stored result" - RFC 9111, so the recompute is still published. An
    engine may decline to be served from cache at all; VoxTell does, because its
    free-text prompts make the key space unbounded.

    GET    /v1/jobs/{id}           full status; includes result metadata once done,
                                   its `key` (the handle for the stored result) and a
                                   `links` object - follow those rather than building
                                   path-surface URLs client-side
    GET    /v1/jobs/{id}/events    Server-Sent Events: status snapshots until terminal
    GET    /v1/jobs/{id}/result    the label volume (.nii.gz)
    DELETE /v1/jobs/{id}           cancel an active job / delete a finished one

Jobs run through :class:`LocalExecutor`: a **bounded FIFO** ahead of one dispatcher
thread per server. The per-device lock in :mod:`haversack.job` already makes concurrent
runs safe; what it does not give is order (lock wake-ups are not FIFO), bounds,
introspection, or instant cancel-while-queued - the queue exists for those four
things and nothing more. Its records are **durable** (:mod:`haversack.jobstore`, a sqlite
file in the workdir): a restart re-queues work rather than dropping it, because a job
is content-keyed and idempotent, and it reclaims the directories no record owns -
which is only answerable because records now outlive the process. `keep_finished`
bounds what memory holds; `jobs_ttl_h` bounds how long a record lasts. Live objects -
cancel tokens, SSE subscriber queues - stay in memory and are rebuilt from the store
at startup. Read the store without a server using ``tools/jobs.py``.
Progress events are idempotent state
snapshots, which is what makes the SSE stream robust - a dropped connection needs no
replay, just a resubscribe or a fall back to polling the same JSON. A ``prepare`` job
reports through the same ``progress`` object: stage ``weights``, one part per model,
bytes received as ``step`` / ``n_steps``, so a client draws the download the way it
draws the sliding window.

Task names at this boundary are catalog names only - the in-process API's freedom to
take a model-folder path does not cross the wire, so a served deployment never treats
server-readable directories as runnable tasks. ``POST /v1/tasks`` is reserved for a
future privileged install/register endpoint (weights by URL or upload into a
content-addressed store); nothing else may squat on that route, and no weight fetching
by URL happens anywhere in serve until it lands with its own auth.

Every input resolves to a content identity - an upload to its sha256, an IDC series to
its immutable crdc UUID (the reserved ``series_instance_uid`` form, with an optional
``idc_version`` defaulting to the latest data release, will resolve to one at submit) -
and the job's ``input_identity`` is the ordered tuple of them:
the key a future result cache will use. IDC fetches happen at dispatch, as a visible
"fetch" progress stage, so submits stay tiny and a 429 never wastes an upload.

FastAPI and uvicorn live behind the ``serve`` extra; nothing here imports them until
:func:`create_app` runs. Computation needs a bearer token; reads never do. The
command line always has one - given, or generated and left in a file only that user
can read - and ``--no-token`` runs open, on purpose, with no guards of any kind: an
open server is open to whatever reaches the port, including through a proxy or tunnel
in front of a loopback bind. The authenticated deployment is the Modal one, where the
platform supplies both the queue (spawn + autoscaler) and the auth (proxy tokens).
"""
import json
import hashlib
import sys
import os
import re
import shutil
import threading
import time
import uuid
from collections import deque
from dataclasses import asdict, dataclass, field
from pathlib import Path

from . import content
from .content import ContentStore, is_digest
from .jobstore import JobStore
from .errors import Cancelled, InputError, HaversackError, ResourceError
from .jobpolicy import (DELIVERABLES, INPUT_NOT_ON_HAND, RENDER_BUSY, fill_read_ahead,
                        missing_deliverables, pending_covers, prefetchable, record_inputs,
                        take_pre_read, refresh_cached_input, source_cache_key,
                        unkeyed_deliverables, wanted_deliverables)
from .progress import CancelToken, Reporter

ACTIVE = ("queued", "running")
ARTIFACT_PENDING_TTL = 900.0   # a pending marker older than this is a dead
                               # overlap thread's leavings (mirrors Modal's sweep)
#: Defined in jobpolicy; imported here so the wire vocabulary has one source.
from .jobpolicy import TERMINAL  # noqa: E402
RESULT_NAME = "labels.seg.nrrd"          # the information-preserving default artifact
#: An embedding job's output (2026-09-23): an embedding field, written by feldglas. A generation
#: holds exactly ONE primary output, labels or a field; the key keeps them apart (``result_key``'s
#: ``kind``), and every "is this entry there" question asks ``primary_output`` rather than
#: naming the labels file, so the lifetime code (leases, claims, pruning) is one code for both.
EMBEDDING_NAME = "embedding.zarr.zip"
#: A ranked job's output (2026-09-24): the task's ranked store - its output distribution on the
#: model grid, the field every restore and surface of its labels can be derived from (a duckn
#: zarr zip; haversack.ranked_output). A third primary output under the same lifetime rules.
RANKED_NAME = "rankfield.duckn.zip"
PRIMARY_NAMES = (RESULT_NAME, EMBEDDING_NAME, RANKED_NAME)
#: What each kind of job publishes, and the suffix a download of it is named with.
OUTPUT_OF_KIND = {"segment": RESULT_NAME, "embed": EMBEDDING_NAME, "rankfield": RANKED_NAME}
#: The kinds whose output is not a label map: no deliverables (a preview and statistics are of
#: labels), no label paths, no NIfTI conversion, and a status that says what the output is.
NOT_LABELS = ("embed", "rankfield")


def primary_output(where) -> "Path | None":
    """The primary output a generation directory holds (labels or a field), or None."""
    for name in PRIMARY_NAMES:
        p = Path(where) / name
        if p.exists():
            return p
    return None
#: The eventually-consistent artifacts, rendered after "done" is already served.
#: Named once: `put` has to know which files belong to the generation it replaces.
#: They are the files of `jobpolicy.DELIVERABLES` - the names a request asks for them
#: under (2026-09-20) - read from that table rather than written a second time.
ARTIFACT_NAMES = tuple(DELIVERABLES.values())
#: What is SERVED beside a result's labels: the URL's file name -> (the file in the
#: generation it is built from, the deliverable that file belongs to). ``meta.json`` is
#: built from the result record, which every entry has, so it names neither. The one
#: table both doors register from (2026-09-21) - the path surface, with its grid tokens,
#: and the job-scoped routes - each name under GET and HEAD alike, so a view added here
#: cannot come to exist at one door, or under one verb, and not the other.
ARTIFACT_VIEWS = {"meta.json": (None, None),
                  "preview.png": (DELIVERABLES["preview"], "preview"),
                  "statistics.json": (DELIVERABLES["statistics"], "statistics"),
                  "statistics.tsv": (DELIVERABLES["statistics"], "statistics")}
#: Which publication an entry holds. Written by `put` before the labels file, so an
#: entry that is visible at all has one, and checked by `add_artifact` so a worker
#: from an earlier publication cannot write into a later one.
GENERATION_NAME = ".generation"
#: The pointer file naming the generation an entry currently publishes. One
#: atomic rename of this file IS the publication.
CURRENT_NAME = "current"
from .sources import (FETCH_EPOCH,  # noqa: E402
                      CRDC_RE, IDC_BUCKETS, ResultSource,  # noqa: E402
                      check_identifier as _check_identifier,
                      fetch_recording_origin as _fetch_recording_origin,
                      registry as _source_registry)


_ALL_SOURCE_PREFIXES = frozenset(_source_registry())   # every source haversack knows


#: What the cache key carries for "this build could compute something different".
#:
#: It used to be ``__version__``, which meant every release threw the cache away -
#: three times in one day for 0.7.0, 0.7.1 and 0.7.2, none of which touched a
#: model, the pipeline or the encoding. A stored result costs GPU-minutes to make
#: and is content-addressed by everything that actually determines it: the input's
#: identity, the task, the options, and the weights versions. The build only needs
#: its own component for what those four do NOT capture.
#:
#: **Bump it when a build would compute different bytes from the same inputs** -
#: the pipeline's resampling, framing or restore; the label mapping; an engine's
#: own inference path; anything in `docs/` "Geometry facts". Do NOT bump it for a
#: release, a server change, a new source, a new catalog, or a bug fix that cannot
#: reach the arithmetic. When in doubt, bump: a wrong hit serves bytes that were
#: never computed from this build, and no one can tell by looking.
#:
#: 1 (2026-09-08): the first epoch. Everything before it was keyed on the release
#: number, so this bump invalidates the cache once and for the last time.
#: 2 (2026-09-08): a prefix fetch used to write every object under its basename, so
#: two objects sharing one (`case/a/IM.dcm` and `case/b/IM.dcm`) landed on the same
#: path and a slice of the series was lost. The result key holds the SOURCE
#: IDENTIFIER, not the bytes' digest, so the same `idc:`/`s3:`/`gs:` identifier now
#: computes from a complete series where it used to compute from a truncated one -
#: different bytes under an unchanged key, which is exactly what this exists for.
#: 3 (2026-09-11): the body envelope. Unset, `envelope_mm` meant a 20 mm crop and now
#: means the whole volume; `{"envelope_mm": 0}` ran inference cropped flush to the skin
#: and now runs the whole volume too, as `--envelope 0` always did; an envelope crop
#: narrower than the network's patch is grown to it with real voxels, where the sliding
#: window padded it with normalized 0 (the model's mean tissue); and a crop that saves no
#: tiles runs the whole volume. Each changes labels under an unchanged key.
#: 4 (2026-09-27, 0.15.0, the user's call): the reader. MONOCHROME1 and an unapplied
#: Modality LUT read as the values the file means, each frame of an Enhanced file with its
#: own rescale, a series of mixed rescales without wrapping; a decode that disagrees with
#: pydicom and a truncated .nii.gz are refused. The input copies re-fetch themselves
#: (READER_VERSION 4) but a result's key holds the source identifier, not the reader, so a
#: result computed from a misread input would be served on. Most results recompute to the
#: same bytes; none is served from a read this build would not make.
#:
#: 5 (2026-09-28, 0.16.0rc2, the user's call: one bump at the stable pin): every change since
#: 0.15.0 that moves labels under an unchanged key. The fused restore became labelfield's
#: (0.16.0rc1: a nearest coordinate exactly half a voxel past the last sample is outside) and
#: labelfield 0.1.3 applies crop offsets as exact integer steps; the network left
#: channels_last_3d (fp16 rounding); only TotalSegmentator's input is truncated to integers; a
#: TS cascade labels nothing outside its box; a native nnU-Net model is preprocessed in
#: nnU-Net's order with separate-z and restored as nnU-Net exports; TotalSegmentator's per-task
#: postprocessing runs. The restore is shared by every engine that grades one, so this is the
#: global epoch and not the nnU-Net engine's.
#:
#: 6 (2026-09-30, the user's call): a NIfTI input with both transforms is placed by its sform
#: (code not 0), as nibabel, TotalSegmentator and duckn place it, where SimpleITK took the qform
#: beside an MNI or aligned sform (io._nifti_placement). Keys do not hold the reader, so every
#: result recomputes once; only results from such files change.
#:
#: A change that only ONE engine's arithmetic sees bumps that engine's
#: ``Engine.cache_epoch`` instead (2026-09-12), so the other engines keep their results.
#:
#: Reproducibility, stated (2026-09-28): the same build on the same input is not bit-identical
#: across processes on CUDA. nnU-Net's predictor sets ``torch.backends.cudnn.benchmark=True``
#: for the process, so convolution algorithms are chosen per run, and the batch size and the
#: accumulator's placement follow free device memory. Measured: up to ~1400 of 418 M voxels
#: (about 3e-6, within 1e-5) differ between two runs of ``total`` on an A10. A hit serves a result
#: this build computed from these inputs; a recompute agrees with it to that tolerance, not to
#: the byte. On MPS, repeated runs matched exactly in the comparisons of 2026-09-27.
CACHE_EPOCH = "6"


def result_key(identity, task, options, weights_versions, epoch=None, kind: str = "segment") -> str:
    """The result-cache key: everything that determines the output bytes, up to the CUDA
    run-to-run variation :data:`CACHE_EPOCH` states (about 1e-5 of voxels).

    (input identity) x (task + options) x (weights versions) x (cache epoch) - the
    design's cache contract. Over-keying on an option that turns out inert only
    costs hits; under-keying would serve wrong bytes, so all options count. See
    :data:`CACHE_EPOCH` for the last component and when it moves.

    ``kind`` is what the job makes (2026-09-23): ``segment`` (labels, every key before that
    day) or ``embed`` (an embedding field). It joins the payload only when it is not
    ``segment``, so no existing key moves - and it must join then: ``ts.v2:total_fast`` is a
    task AND an encoder, and one key for both would hand a label map to a field's reader.
    """
    import hashlib
    body = {"identity": list(identity), "task": str(task),
            "options": {k: options[k] for k in sorted(options)},
            "weights": list(weights_versions),
            "haversack": epoch or CACHE_EPOCH}
    if kind != "segment":
        body["kind"] = str(kind)
    payload = json.dumps(body, sort_keys=True)
    return hashlib.sha256(payload.encode()).hexdigest()


def wants_no_cache(request) -> bool:
    """Whether the request asked not to be served a stored result.

    RFC 9111 `Cache-Control: no-cache` - "do not reuse a stored response" - which
    is exactly the lever a caller needs after the model behind a task changes
    without the cache key changing. Note it does NOT mean "do not store": the
    recomputed result is published as usual, so artifacts, `key` and `links`
    survive. `no-store` is a separate directive we deliberately do not implement.
    """
    raw = ""
    try:
        raw = request.headers.get("cache-control") or ""
    except Exception:
        return False
    return any(d.strip().lower() == "no-cache" for d in raw.split(","))


def _validate_request(seg, task, sources: list, options: dict, *,
                      declared: dict | None = None) -> list:
    """Check a submit against what the task itself declares.

    ``declared``, when a dict is passed, is filled ``{role: its inputs[] entry}`` from the
    same ``describe()`` the binding was made against - so a caller that needs what a role
    TAKES (a ``result:`` reference is checked against the role's ``kind``) reads the
    declaration this function read, and does not describe the task a second time.

    Two things, both answerable before any work starts: the options are validated
    against the task's published parameter schema (the same declaration that
    generates the schema clients read, so the advertised contract and the
    enforced one cannot drift), and the sources are bound to the task's declared
    inputs **by name**.

    Returns the ``[(role, source), ...]`` binding in the model's channel order.
    Nothing consumes the ordering yet - no engine accepts more than one input -
    but the refusal a multi-input task gets is now the accurate one, naming the
    roles it wanted.

    A task whose spec cannot be resolved at all is left alone deliberately: that
    is the worker's error to raise, with the worker's context, and guessing at it
    here would turn a clear downstream failure into a confusing 422.
    """
    from fastapi import HTTPException      # an extra, so imported at call time

    from .engines.registry import ENGINES, NNUNETV2
    from .errors import RequestError
    from .schemas import (bind_sources, declared_inputs, validate_options,
                          wire_params)
    try:
        desc = seg.describe(task) or {}
    except Exception:
        # A task whose own metadata is unreadable - a truncated dataset.json, a
        # half-written bundle. Fall through to the pre-existing contract (one
        # image, no option schema to check against) so the job dispatches and the
        # WORKER reports the real error with its context, which is what this
        # function's docstring promises. Returning an empty binding instead made
        # submit die on idents[0] with an opaque 500, and leaked the job dir.
        desc, unknown = {}, True
    else:
        unknown = False
    eng = ENGINES.get(desc.get("engine") or NNUNETV2) or ENGINES[NNUNETV2]
    try:
        if not unknown:
            validate_options(wire_params(eng.parameters, eng.processing_knobs), options)
            # ...and against what the task's installed models HAVE: a schema cannot say
            # which folds or configurations a checkpoint ships (2026-09-26)
            asks = getattr(seg, "option_problem", None)
            problem = asks(task, options) if asks is not None else None
            if problem:
                raise RequestError("invalid_parameter", problem[1], parameter=problem[0])
        inputs = declared_inputs(desc)
        if declared is not None:
            declared.update({str(i.get("name")): i for i in inputs or []})
        return bind_sources(sources, inputs,
                            multi_input=eng.multi_input, task=task)
    except RequestError as e:
        raise HTTPException(422, e.detail) from e


def engine_serves_from_cache(task) -> bool:
    """Whether this task's ENGINE allows a stored result to be served.

    An engine whose request space is unbounded (VoxTell's free text) sets this
    False: the lookup would almost never hit, and the entries only evict results
    that do get re-read. Routed by the task's grammar, the same way the worker
    dispatch resolves an engine, so no catalog is needed here.
    """
    try:
        from .engines.registry import engine_for_task
        return bool(engine_for_task(task).serve_from_cache)
    except Exception:
        return True                    # unknown engine: behave as before


def resource_links(task, identity, options, *, preview=False, statistics=False) -> dict:
    """The path-surface URLs for a finished result - ``{}`` when it is not
    path-addressable.

    The one place this URL grammar is written. Clients should follow these
    rather than assembling paths from a task name and an identity: the infix
    for grid variants, which identities are addressable at all (a single
    source identity, not an upload's sha256), and which options keep a result
    addressable are all decisions the server owns and can change.

    **A content digest is never path-addressable** (decided 2026-09-20, here and nowhere
    else): not an upload's, not a stored input's, and not a ``result:`` reference's - whose
    identity IS the referenced output's digest, so that referring to a result and sending
    its bytes are one request. A path names a result by an identifier that stays put and
    can be keyed with no lookup; a result's key can be republished with other bytes, so a
    ``/v1/result/<key>/<task>/...`` would need the result cache read on every anonymous
    probe, and nothing single-input consumes a label map yet. It is asked of
    ``content.is_digest`` rather than of the ``sha256:`` spelling: that test let
    ``sha256-tree:`` through - an uploaded DICOM series referred to by digest - and minted
    ``/v1/sha256-tree/<hex>/...`` links no route has ever served.
    """
    ident = list(identity or [])
    if len(ident) != 1 or ":" not in str(ident[0]) or is_digest(ident[0]):
        return {}                       # content digests and multi-source: job-scoped only
    opts = options or {}
    tok = next((t for t, o in GRID_TOKENS.items() if o == opts), None)
    if opts and tok is None:
        return {}                       # non-menu options have no path form
    infix = f"_{tok}" if tok else ""
    prefix, one = str(ident[0]).split(":", 1)
    base = f"/v1/{prefix}/{one}/{task}"
    links = {"labels": f"{base}/labels{infix}.seg.nrrd",
             "meta": f"{base}/meta{infix}.json"}
    if preview:
        links["preview"] = f"{base}/preview{infix}.png"
    if statistics:
        links["statistics"] = f"{base}/statistics{infix}.tsv"
    return links


#: An embedding's options as they appear in its path, as ``GRID_TOKENS`` are a label map's
#: (2026-09-24): ``embedding.zarr.zip`` for the defaults, ``embedding_int8.zarr.zip`` for int8
#: tokens. The menu is ``encoders.serving.OPTIONS``, and nothing outside it has a path.
EMBEDDING_TOKENS = {"int8": {"int8": True}}


def embedding_links(encoder, identity, options) -> dict:
    """The path-surface URL of a finished embedding - ``{}`` when it has none. The same rule
    of addressability as :func:`resource_links` (one source identity, never a content digest,
    options on the menu); the one place this grammar is written, for the listing and anyone
    else, so a client follows links instead of assembling them."""
    ident = list(identity or [])
    if len(ident) != 1 or ":" not in str(ident[0]) or is_digest(ident[0]):
        return {}
    opts = options or {}
    tok = next((t for t, o in EMBEDDING_TOKENS.items() if o == opts), None)
    if opts and tok is None:
        return {}
    infix = f"_{tok}" if tok else ""
    prefix, one = str(ident[0]).split(":", 1)
    return {"embedding": f"/v1/{prefix}/{one}/{encoder}/embedding{infix}.zarr.zip"}


def ranked_links(task, identity, options) -> dict:
    """The path-surface URL of a finished ranked store - ``{}`` when it has none: one source
    identity, never a content digest, and no options (a store takes none). The one place this
    grammar is written, as :func:`embedding_links` is for fields."""
    ident = list(identity or [])
    if len(ident) != 1 or ":" not in str(ident[0]) or is_digest(ident[0]) or options:
        return {}
    prefix, one = str(ident[0]).split(":", 1)
    return {"rankfield": f"/v1/{prefix}/{one}/{task}/{RANKED_NAME}"}


def weights_versions_of(segmenter, task) -> list:
    """The key's model component, from the install sidecars via describe(), plus the
    task's engine's own cache epoch when it declares one (``Engine.cache_epoch``).
    "unknown" when nothing better exists - documented, never guessed.

    The one door every result key's weights pass through (Modal's
    ``_fresh_weights_versions`` wraps it), which is why the engine epoch joins here and
    not at each ``result_key`` call site. An entry that names the model folder it
    resolved (``model``: its task states a trainer/plans choice, as ts.v3's do) adds it,
    because one dataset's sidecar covers every folder in it (2026-09-21). A task that states
    its tile step (``step_size``, ts.v3's 0.8) adds ``step=<value>`` the same way, and a cascade
    its crop rule (``crop=upstream``, 2026-09-22), which moved every cascade's labels and no
    other task's. A task stating auxiliary classes adds ``auxiliary=0`` (2026-09-22): its
    results used to carry them as unnamed values, and now map them to 0 as upstream does. A
    task whose catalog states its model's orientation adds ``orient=<code>`` (MOOSE,
    2026-09-26), and one whose catalog states its model's folds adds ``folds=0,1,...`` (LNQ,
    2026-10-22)."""
    try:
        d = segmenter.describe(task)
        entries = d.get("weights_installed") or []
        out = [f"{e.get('id')}={e.get('version') or e.get('sha256') or 'unknown'}"
               + (f"/{e['model']}" if e.get("model") else "")
               for e in entries] or ["unknown"]
        if d.get("step_size") is not None:
            out.append(f"step={d['step_size']:g}")
        if d.get("folds"):
            # the ensemble a catalog states its model is (LNQ, 2026-10-22): a task stating none
            # runs fold 0, as every key before it did, and adds nothing
            out.append("folds=" + ",".join(str(f) for f in d["folds"]))
        if d.get("crop"):
            out.append(f"crop={d['crop']}")
        if d.get("auxiliary"):
            out.append("auxiliary=0")
        if d.get("model_orientation") not in (None, "native"):
            # the orientation a catalog STATES its model was trained in (MOOSE's manifest,
            # 2026-09-26): until then every MOOSE model got the input's own axis order, and on
            # LPS DICOM the RAS-trained ones mirrored their labels. Only a stated reorientation
            # adds this - "native" is what every model got before - so no other key moves.
            out.append(f"orient={d['model_orientation']}")
    except Exception:
        out = ["unknown"]
    return out + _engine_epoch(segmenter, task)


def versions_for(segmenter, task, kind: str = "segment") -> list:
    """The key's weights component for a job of ``kind``: ``weights_versions_of`` for a
    segmentation, the encoder's own (``encoders.serving.field_versions``) for an embedding job.
    The ONE place the choice is made, so submit, publication's re-key and every executor key
    an embedding job alike (a re-key through the segmentation's door would publish the field
    under a key nobody asks for - the _EngineShim lesson of 2026-09-12)."""
    if kind == "embed":
        from .encoders.serving import field_versions
        return field_versions(segmenter, task)
    if kind == "rankfield":
        # the task's own model identity, as its labels key on, plus what a store's bytes are
        # written in (ranked_output.ranked_tag: rankfield's format, duckn's seg, our rules)
        from .ranked_output import ranked_tag
        return weights_versions_of(segmenter, task) + [ranked_tag()]
    return weights_versions_of(segmenter, task)


def installed_versions(segmenter, task) -> list | None:
    """The weights versions this server would run for canonical ``task``, one per weights
    entry ``describe()`` reports - or None when it cannot say (nothing installed yet, or an
    entry with no version sidecar). None is "unknown", never "anything": every catalog's
    own ``ensure`` refuses to let an unknown installed tag satisfy a pin, and so does the
    wire (2026-09-12)."""
    try:
        entries = segmenter.describe(task).get("weights_installed") or []
    except Exception:
        return None
    versions = [e.get("version") for e in entries]
    return versions if versions and all(versions) else None


def run_name(task: str, version: str | None) -> str:
    """The name a worker hands the catalog: the canonical task, re-pinned when the caller
    pinned it. The wire keys and routes on the canonical name, but the catalog is where a
    pin is enforced (install that version, or refuse), so the pin has to arrive there -
    dropping it here is how a pinned submit used to run whatever was installed."""
    return f"{task}@{version}" if version else task


def split_run_name(name: str) -> tuple:
    """``run_name``'s inverse: ``(task, version or None)``. Split at the LAST ``@``, as
    ``EcosystemCatalog.resolve`` does, so a worker that must hand the version on itself
    (the MONAI adapter) parses a pin exactly as the catalog that enforces it would."""
    task, sep, version = str(name).rpartition("@")
    return (task, version) if sep and task and version else (str(name), None)


def _engine_epoch(segmenter, task) -> list:
    """``["<engine>@epoch=<n>"]`` for an engine that declares a cache epoch, else nothing,
    so an engine that never bumps keeps exactly the keys it always had.

    Only "there is no such engine" means no epoch. Anything else - above all a
    segmenter-shaped object with no ``engine_for`` - raises: a silent ``[]`` on one side
    of the API/worker handshake is a key the other side never computes, which is how
    Modal's _EngineShim briefly published FastSurfer results nowhere (2026-09-12)."""
    try:
        eng = segmenter.engine_for(task)
    except LookupError:
        return []
    ep = getattr(eng, "cache_epoch", None)
    return [f"{eng.name}@epoch={ep}"] if ep else []


#: Reserved in a path component on SOME platform, so reserved on ALL of them.
#: POSIX forbids only the separator and NUL; Windows adds ``< > : " | ? *`` - and
#: the colon is the one that matters, because every key these stores are handed
#: contains one (``idc:<uuid>``, ``sha256:<hex>``, ``sha256-tree:<hex>``). There it
#: is the Alternate Data Stream separator and illegal in a filename, so the store
#: layer could never have worked on Windows.
#:
#: Applied uniformly rather than per-platform on purpose. A conditional rule makes
#: the same key map to different paths on different hosts, which quietly costs the
#: store its portability - a copied volume, a restored backup, a bind mount from
#: another OS. "Works on my machine" should not be a property of a layout.
RESERVED_PATH_CHARS = '<>:"|?*\\/\x00'


def safe_path_component(key: str) -> str:
    """``key`` as a filename that is legal on every platform we target.

    Percent-encoded rather than hashed, so the cache stays one you can ``ls``:
    finding a poisoned entry by eye and removing it by name is a real debugging
    move that hashed names would take away. Reversible and injective - ``%`` is
    escaped first, or a literal ``%3A`` and an encoded ``:`` would collide.
    """
    out = key.replace("%", "%25")
    # Uppercase letters are escaped too, so two identifiers that differ only in case
    # (hf, zenodo, openneuro and tcia identifiers are case-sensitive) cannot share an
    # entry on a case-insensitive filesystem - macOS's default, where the two would
    # otherwise map to one directory and the second job would get the first's bytes.
    # ASCII only: a code point above 0xFF would need three hex digits and collide with a
    # two-digit escape followed by a literal digit ("A3" vs "\u0413")
    out = "".join("%%%02X" % ord(c) if (c.isupper() and c.isascii()) else c for c in out)
    for c in RESERVED_PATH_CHARS:
        out = out.replace(c, "%%%02X" % ord(c))
    return out


class SeriesCache:
    """Series-keyed staging for fetched inputs: one directory per series under
    ``root``, committed by a ``.done`` marker holding the entry's byte count,
    evicted least-recently-used past ``budget_bytes``. One writer per series
    ever; readers wait on the marker. This is what lets several tasks on the
    same image download the series once.

    Two files carry all the meaning, and the DIRECTORY carries none:

    ``.owner``   the claim, published by one ``os.link`` so it names its owner
                 from the instant it exists (see :meth:`_claim`). Present
                 without ``.done`` means a writer is mid-flight, and the entry
                 is never read.
    ``.done``    committed, and readable.

    A bare directory with neither is abandoned scaffolding that the next writer
    simply claims inside. That used to be an *ownerless claim* - the one state
    the protocol could not identify, and the reason it grew an mtime-based
    freshness heuristic, an owner re-read immediately before the reclaim rename,
    and an extension counter. A claim whose writer died is reclaimed after
    ``claim_timeout``; a claim whose writer is still alive is never reclaimed,
    because two writers on one path produce a mixed series."""

    MARKER = ".done"
    GRAVEYARD = ".graveyard"
    #: Where `_claim` stages its token before linking it. NOT inside the entry:
    #: `_writer_alive` walks the entry with rglob and stats what it finds, so a
    #: temp file appearing and vanishing at that level made a LIVE writer read as
    #: dead (86 of 3000 calls; 3 of 24 runs then reclaimed and deleted a live
    #: writer mid-fetch). Same filesystem as the entries, because a hard link
    #: cannot cross one.
    CLAIMS = ".claims"

    def __init__(self, root, fetch_fn, *, budget_bytes: int = 8 << 30,
                 claim_timeout: float = 180.0):
        self.root = Path(root)
        self.root.mkdir(parents=True, exist_ok=True)
        self.fetch = fetch_fn                  # fetch_fn(series, entry_dir) -> content dir
        self.budget = int(budget_bytes)
        self.claim_timeout = float(claim_timeout)
        self._lock = threading.Lock()          # eviction + pin bookkeeping
        self._pins: dict = {}                  # entry name -> refcount
        #: Where a dropped entry goes before deletion. A DIRECTORY, not a name
        #: convention: an entry's name comes from its cache key, so any pattern
        #: that means "discarded" to us can also be a real key - `s3:b/x.stale1`
        #: is a legal object. Two bugs came from matching names in this namespace
        #: (a glob that deleted live entries, then a narrowed regex that deleted
        #: live *claims*), and a separate directory ends the class rather than
        #: narrowing it again.
        self.graveyard = self.root / self.GRAVEYARD
        self.claims = self.root / self.CLAIMS
        self.sweep_stale()                     # a crash between rename and delete
        #: Debris only appears when a process dies between the rename into the
        #: graveyard and the delete, so sweeping at construction cleaned up after
        #: the LAST crash - and a server that stays up for weeks never swept
        #: again, letting its own crashes accumulate unbounded. _evict re-sweeps
        #: on this interval instead: no thread, no timer, just the eviction pass
        #: that already runs after commits.
        self._last_sweep = time.monotonic()

    def _entry(self, series: str) -> Path:
        # Keys become directory names. Filesystem-safe keys keep their readable
        # verbatim name (a cache you can ls); anything else - separators, dot
        # names, absurd lengths, and on Windows the reserved characters - maps to
        # a deterministic hash, so identifiers with slashes (DOIs, org/name ids)
        # or colons (every content digest) are safe by construction rather than
        # forbidden.
        # A FETCHED entry carries the epoch of the code that downloaded it, so a build
        # that would download different bytes cannot reuse what an older one left. That
        # is not the same question as the result cache's epoch, and bumping that one
        # answered only half of it: 2 was set because the old flattener could drop a
        # slice of a series, which invalidated every stored RESULT while leaving the
        # truncated INPUT marked complete under its own identifier - so an upgraded
        # server missed the result, reused the bad input, and recomputed from it. The
        # corrected download never ran (2026-09-09).
        #
        # In the key rather than in the marker, exactly as `result_key` does it: an old
        # entry becomes unreachable instead of needing a new predicate threaded through
        # the claim protocol, and LRU or `cache clean inputs` reclaims it in time.
        #
        # Content-addressed entries are EXEMPT and must stay so: an upload is named by
        # the digest of its own bytes, nothing here fetched it, and there is nothing to
        # re-fetch it from - epoching those would strand them permanently.
        #
        # The input copy's reader version joins it for the same reason (2026-09-25): an entry
        # keeps the COPY instead of the fetched bytes (docs/input-copy.md), so a reader that
        # would produce another copy from the same bytes must not find the old one - it fetches
        # again. Content-addressed entries have no source to refetch from: a stale copy there
        # reads as absent (``_stale_copy``), and the client sends the bytes again.
        from .input_copy import READER_VERSION
        epoch = f"e{FETCH_EPOCH}.r{READER_VERSION}"
        name = safe_path_component(series if is_digest(series) else f"{epoch}!{series}")
        # ".graveyard" would BE the graveyard: the reclaim then renames that
        # directory into itself, fails with EINVAL, and the single dispatcher
        # thread loops forever. No production key can spell it (every one carries
        # a ":" which escapes), but the namespace is shared with our own
        # directory, so the reservation is explicit.
        if (name not in (".", "..", self.GRAVEYARD, self.CLAIMS)
                and 0 < len(name) <= 200):
            return self.root / name
        import hashlib
        stamp = series if is_digest(series) else f"{epoch}!{series}"
        d = self.root / ("h_" + hashlib.sha256(stamp.encode()).hexdigest()[:32])
        return d

    def has(self, series: str) -> bool:
        entry = self._entry(series)
        return (entry / self.MARKER).exists() and not self._stale_copy(entry)

    def path(self, series: str) -> Path:
        """What a committed entry holds for the reader (valid only when has()): its input copy
        when it has one (docs/input-copy.md), else the content directory as fetched."""
        return self._content(self._entry(series))

    @staticmethod
    def _content(entry: Path) -> Path:
        from .input_copy import copy_path
        copy = copy_path(entry)
        return copy if copy.is_file() else entry / "series"

    def _reclaim(self, entry: Path) -> None:
        """Move an entry nobody can read into the graveyard and delete it (cache-internal: the
        policy of discarding an input a job still wants is jobpolicy's alone)."""
        try:
            self.graveyard.mkdir(parents=True, exist_ok=True)
            grave = self.graveyard / f"{entry.name}-{os.getpid()}-{time.time_ns()}"
            entry.rename(grave)
        except OSError:
            return
        shutil.rmtree(grave, ignore_errors=True)

    @staticmethod
    def _stale_copy(entry: Path) -> bool:
        """An entry whose input copy another reader version wrote: its original is gone, so it
        cannot be redone - the entry counts as absent (a fetch is fetched again; an upload,
        with nothing to fetch it from, answers input_gone)."""
        from .input_copy import copy_path, stale
        copy = copy_path(entry)
        return copy.is_file() and stale(copy)

    def _transcode(self, series: str, entry: Path, dest) -> Path:
        """The input copy of what was just stored, and the original removed - one form per
        entry. Before the commit, inside the writer's claim: the original exists only here, as
        the transcoder's input. A ``result:`` reference is a label map (its names and codes live
        in its file) and is never transcoded; an input the reader refuses, or whose copy fails
        its read-back, keeps its original and is read (and refused) as it always was."""
        from .input_copy import transcode
        from .sources import ResultSource, read_input_record
        if str(series).startswith(ResultSource.prefix + ":"):
            return Path(dest)
        rec = read_input_record(entry) or {}
        digest = series if is_digest(series) else (rec.get("content") or {}).get("digest")
        copy = transcode(dest, entry, source=None if is_digest(series) else series,
                         source_digest=digest)
        if copy is None:
            return Path(dest)
        original = entry / "series"
        if original.exists():
            shutil.rmtree(original)
        return copy

    def entry(self, series: str) -> Path:
        """The entry directory itself - where a fetch's sidecars live."""
        return self._entry(series)

    def pin(self, series: str) -> None:
        """Protect an in-use entry from LRU eviction - the marker mtime ages
        for a whole run, so without a pin the CURRENT job's input can be
        evicted mid-read under budget pressure. Refcounted; pair with unpin
        in a finally."""
        name = self._entry(series).name
        with self._lock:
            self._pins[name] = self._pins.get(name, 0) + 1

    def unpin(self, series: str) -> None:
        name = self._entry(series).name
        with self._lock:
            n = self._pins.get(name, 0) - 1
            if n <= 0:
                self._pins.pop(name, None)
            else:
                self._pins[name] = n

    #: The claim. Its presence means "a writer holds this entry"; its CONTENT is
    #: that writer's identity. Both arrive in one operation - see :meth:`_claim`.
    CLAIM = ".owner"

    def _claim(self, entry: Path, *, marker=None) -> str | None:
        """Take the claim on ``entry``, or None if another writer holds it.

        The claim and its identity arrive TOGETHER. The token is written to a
        private temp file inside the entry first, and one ``os.link`` publishes
        it; link is atomic and fails with EEXIST when the claim is taken, so the
        instant a claim becomes visible it already names its owner.

        That is the whole point. The old protocol claimed by ``mkdir`` and wrote
        ``.owner`` afterwards, leaving a window where a claim existed that nobody
        could identify - and ``_owner_of`` returning None could not tell a writer
        that crashed before naming itself from a successor two statements in.
        Every guard around the reclaim path existed to paper over that window:
        an mtime-based freshness heuristic, a re-read of the owner immediately
        before the rename, an extension counter. The window is now gone rather
        than guarded, so the directory's own existence carries no meaning at all -
        only this file and ``.done`` do.

        ``os.link`` is used rather than ``os.symlink``, which has the same
        atomic-create-with-payload property, because symlinks need Developer Mode
        or SeCreateSymbolicLinkPrivilege on Windows while hard links do not. The
        temp file lives inside the entry so it cannot land on another filesystem,
        which a hard link may not cross.
        """
        entry.mkdir(parents=True, exist_ok=True)
        claim = entry / self.CLAIM
        token = uuid.uuid4().hex
        self.claims.mkdir(parents=True, exist_ok=True)
        tmp = self.claims / token
        try:
            tmp.write_text(token, encoding="utf-8")
            try:
                os.link(tmp, claim)
            except FileExistsError:
                return None                # another writer got there first
            except OSError:
                # A filesystem with no hard links (FAT32, some network mounts).
                # Degrade to exclusive-create then write: still one writer, but
                # the token lands a syscall late, so an EMPTY claim is possible.
                # `_owner_of` treats that as a live claim being established and
                # refuses to reclaim it - failing safe costs a retry, the other
                # way costs a mixed series.
                try:
                    fd = os.open(claim, os.O_CREAT | os.O_EXCL | os.O_WRONLY, 0o644)
                except FileExistsError:
                    return None
                except OSError:
                    return None            # read-only cache root: never claim
                with os.fdopen(fd, "w") as f:
                    f.write(token)
            try:
                if (marker or (entry / self.MARKER)).exists():
                    # Committed under us between the caller's marker check and
                    # this claim. Release it: re-fetching over a finished entry
                    # would replace good bytes and reset their LRU age for nothing.
                    claim.unlink(missing_ok=True)
                    return None
                # We hold the claim on an entry with no marker, so anything
                # already in it is a previous attempt that never completed -
                # untrusted by definition. Clear it, or this writer's output is
                # that attempt's leftovers PLUS ours, committed as one complete
                # series. The old protocol got this free: the directory WAS the
                # claim, so stale scaffolding blocked the claim instead of being
                # adopted.
                for stale in entry.iterdir():
                    if stale == claim:
                        continue
                    if stale.is_dir() and not stale.is_symlink():
                        shutil.rmtree(stale, ignore_errors=True)
                    else:
                        stale.unlink(missing_ok=True)
            except OSError:
                # The claim is already published, so a failure here has to take
                # it back. Falling through to the outer handler returned None
                # with our token still linked: a claim nobody held, `staging()`
                # true, and the key dead until the timeout reclaimed it (found
                # 2026-09-06 by probing an entry that is writable but not
                # readable - the link succeeds and the iterdir raises).
                claim.unlink(missing_ok=True)
                return None
            return token
        except OSError:
            return None                    # cannot write into the entry at all
        finally:
            tmp.unlink(missing_ok=True)

    def _owner_of(self, entry: Path) -> str | None:
        """The claim's owner, or None when there is NO claim.

        The distinction the old layout could not draw: None now means unclaimed,
        never "claimed by someone we cannot name". The one exception is the
        no-hard-link fallback in :meth:`_claim`, where an empty file is a claim
        mid-establishment; it reads as a live claim so nothing reclaims it.
        """
        try:
            return (entry / self.CLAIM).read_text(encoding="utf-8") or "<establishing>"
        except FileNotFoundError:
            return None                    # genuinely unclaimed
        except OSError:
            # A claim we cannot READ is still a claim. Returning None here said
            # "unclaimed", and the waiter's `break` skipped its sleep and retook
            # the claim immediately - 6399 attempts and 95% of a core in three
            # seconds, on the single dispatcher thread, forever. The trigger is
            # ordinary: under umask 077 the claim is mode 0600 and os.link
            # preserves it, so any second uid on a shared cache root span.
            return "<unreadable>"

    def _teardown_claim(self, entry: Path, token: str) -> None:
        """Remove a failed claim - only while this writer still owns it.

        An absent or different claim means someone else reclaimed the path, and
        deleting by bare path would destroy THEIR staging. Under the linked claim
        a missing file can no longer mean "our own owner write failed", because
        the token is written before the claim exists at all: it means the claim
        is not ours any more. Refuse either way."""
        try:
            if (entry / self.CLAIM).read_text(encoding="utf-8") != token:
                return                     # reclaimed by a successor: not ours
        except OSError:
            return                         # cannot prove ownership: never delete
        shutil.rmtree(entry, ignore_errors=True)

    def _hb_start(self, entry: Path, token: str | None = None):
        """Tick the claim's mtime while the fetch runs. _writer_alive reads
        file mtimes as the heartbeat, but a fetch that buffers in memory
        (IDC reads whole objects before writing) is disk-silent for minutes -
        long enough to be declared dead while alive. The ticker makes
        liveness mean process-liveness, which is what reclaim must key on."""
        stop = threading.Event()
        beat = entry / self.CLAIM          # a FILE: _writer_alive scans files
                                           # (rglob), a directory utime is
                                           # invisible to it
        def tick():
            while not stop.wait(min(10.0, self.claim_timeout / 6)):
                try:
                    # Stop the moment this is no longer OUR claim. The ticker
                    # holds a PATH, not a handle: after a reclaim renamed the
                    # entry aside and re-created it, a writer still stuck inside
                    # fetch_fn went on touching its SUCCESSOR's claim file every
                    # 10s, so if the successor then died nothing ever aged it out
                    # and the key became permanently unfetchable. hb.set() cannot
                    # help - it runs when fetch_fn returns, which is exactly what
                    # a hung writer never does.
                    if token is not None and self._owner_of(entry) != token:
                        return
                    os.utime(beat if beat.exists() else entry)
                except OSError:
                    return

        threading.Thread(target=tick, name="haversack-claim-hb", daemon=True).start()
        return stop

    def _writer_alive(self, entry: Path) -> bool:
        """A live writer keeps producing files - the newest mtime under the
        entry is its heartbeat. A timeout alone proves nothing about death."""
        try:
            newest = max((f.stat().st_mtime for f in entry.rglob("*")),
                         default=entry.stat().st_mtime)
        except OSError:
            return False
        return (time.time() - newest) < self.claim_timeout

    def staging(self, series: str) -> bool:
        """Is a writer mid-flight on this series?

        The CLAIM answers it, not the directory: a bare directory with neither
        claim nor marker is abandoned scaffolding that anyone may take over.
        """
        e = self._entry(series)
        return (e / self.CLAIM).exists() and not (e / self.MARKER).exists()

    def get_or_fetch(self, series: str, *, check=None, credentials=None,
                     fetch=None) -> Path:
        """Return the series content directory, fetching if needed (blocking).
        ``check`` is called while waiting on another writer; raise from it to
        cancel the wait.

        ``fetch`` overrides how the content is produced for this call only, so a
        caller that ALREADY has the bytes - an upload being adopted into the
        content store - reuses this method's claim, wait-on-another-writer and
        commit rather than growing a second copy of them. Two callers storing the
        same content at once behave exactly like two jobs fetching one series:
        the first writes, the second waits and then finds it there."""
        while True:
            entry = self._entry(series)
            marker = entry / self.MARKER
            if marker.exists():
                try:
                    os.utime(marker)           # LRU touch
                except FileNotFoundError:      # evicted between check and touch
                    continue                   # reclaim on the next pass
                except OSError:
                    pass                       # read-only cache, or another uid owns the
                                               # marker: the LRU loses a touch, that is all.
                                               # `continue` here spins the one dispatcher
                                               # thread forever at 100% CPU.
                if self._stale_copy(entry):
                    # A content-addressed entry holding another reader version's copy (a fetched
                    # one never meets it: the version is in its name). Nobody can read it - has()
                    # says absent - so the caller is storing those bytes again: the dead entry is
                    # reclaimed as a dead writer's is, and the store proceeds.
                    self._reclaim(entry)
                    continue
                return self._content(entry)
            token = self._claim(entry, marker=marker)
            if token is None:
                # Another writer holds it. Wait on the MARKER, and let the owner
                # tell us what is happening - it is always readable now, so the
                # states are exact rather than inferred: a claim that is present
                # and unchanged, a claim that changed hands, or no claim at all.
                deadline = time.time() + self.claim_timeout
                extensions = handovers = 0
                while not marker.exists():
                    owner_before = self._owner_of(entry)
                    if owner_before is None:
                        break                  # claim released: retake it on the next pass
                    if time.time() > deadline:
                        # Read the owner BEFORE the liveness check, which walks a
                        # staging tree that can hold thousands of files - the
                        # window between its verdict and the rename below is wide.
                        if self._writer_alive(entry):
                            if extensions < 3:
                                # slow but alive: extend rather than destroy. A
                                # timeout teardown of a LIVE writer aliases two
                                # writers onto one path and they destroy each
                                # other's work.
                                extensions += 1
                                deadline = time.time() + self.claim_timeout
                            else:
                                # STILL alive after 4x claim_timeout: give up
                                # loudly. A live writer is NEVER reclaimed - a
                                # round-4 probe showed the reclaim committing a
                                # MIXED series (two writers' slices in one entry)
                                # as complete. One writer per series is the
                                # invariant; the waiter fails retryably instead.
                                raise ResourceError(
                                    f"staging of {series!r} has been held for "
                                    f"{4 * self.claim_timeout:.0f}s by a writer that is "
                                    "still alive; giving up rather than risk a mixed "
                                    "series - retry later")
                        elif handovers >= self.MAX_HANDOVERS:
                            raise ResourceError(
                                f"staging of {series!r} changed hands "
                                f"{handovers} times without completing; giving up "
                                "rather than wait indefinitely - retry later")
                        elif (self._owner_of(entry) != owner_before
                              and handovers < self.MAX_HANDOVERS):
                            # A handover is PROGRESS, not the writer being slow,
                            # so it must not spend the slow-writer budget - three
                            # legitimate handovers used to exhaust it and the next
                            # live writer produced a "held for 720s" error whose
                            # number was arbitrary, since each handover had reset
                            # the deadline.
                            #
                            # But it needs a ceiling of its own. Without one this
                            # branch reset the deadline unconditionally, and a
                            # claim that keeps appearing to change hands - a
                            # thrashing pool of writers, or an owner read that is
                            # never twice the same - waits here forever, on the
                            # single dispatcher thread, with no error and no exit.
                            handovers += 1
                            # It changed hands while we were walking the tree.
                            # Whoever holds it now is not who we judged dead, so
                            # wait on them rather than destroy their work. This
                            # comparison is now decisive: under the old layout a
                            # successor was ownerless for two statements and read
                            # as None on both sides of the check.
                            deadline = time.time() + self.claim_timeout
                        else:
                            # Dead, and still the same claim. Rename aside first
                            # so the old writer's paths stop aliasing our reclaim,
                            # then delete.
                            try:
                                self.graveyard.mkdir(parents=True, exist_ok=True)
                                # pid and nanoseconds, like discard(): a one-second
                                # stamp collides when two processes reclaim together
                                grave = self.graveyard / (f"{entry.name}-{os.getpid()}"
                                                          f"-{time.time_ns()}")
                                entry.rename(grave)
                            except OSError:
                                break      # cannot move it aside; let the wait retry
                            shutil.rmtree(grave, ignore_errors=True)
                            break
                    if check is not None:
                        check()
                    time.sleep(0.2)
                # Every exit from that loop retries the claim, and a break skips
                # the sleep above. One unsleeping retry path was enough to spin
                # this thread - the single dispatcher - at 95% of a core
                # indefinitely, so the pause is here rather than on each break.
                time.sleep(0.05)
                continue
            hb = self._hb_start(entry, token)
            try:
                fn = fetch or self.fetch
                dest = Path(fn(series, entry, credentials=credentials)
                            if credentials is not None else fn(series, entry))
                dest = self._transcode(series, entry, dest)
                self._commit(entry, key=series, token=token)
                return dest
            except BaseException:
                self._teardown_claim(entry, token)
                raise
            finally:
                hb.set()

    def prefetch(self, series: str) -> bool:
        """Claim + fetch + commit without blocking on other writers. False if
        already present, claimed elsewhere, or the fetch failed."""
        entry = self._entry(series)
        if (entry / self.MARKER).exists():
            return False                       # already here
        token = self._claim(entry)
        if token is None:
            return False                       # claimed elsewhere, or just committed
        hb = self._hb_start(entry, token)
        try:
            dest = self.fetch(series, entry)
            self._transcode(series, entry, dest if dest is not None else entry / "series")
            self._commit(entry, key=series, token=token)
            return True
        except Exception:
            self._teardown_claim(entry, token)
            return False
        finally:
            hb.set()

    def _commit(self, entry: Path, key: str | None = None,
                token: str | None = None) -> None:
        if token is not None:
            try:
                if (entry / self.CLAIM).read_text(encoding="utf-8") != token:
                    raise ResourceError(
                        f"claim for {key or entry.name!r} was reclaimed while "
                        "fetching; discarding this writer's result")
            except OSError:
                # Under the linked claim this is no longer "our own write failed"
                # - the token exists before the claim does. The claim is gone,
                # so this entry was reclaimed and these bytes are orphaned.
                raise ResourceError(
                    f"claim for {key or entry.name!r} no longer exists; "
                    "discarding this writer's result") from None
        # budget = content bytes; bookkeeping dotfiles (.owner/.key/.done)
        # stay out of the arithmetic
        size = sum(f.stat().st_size for f in entry.rglob("*")
                   if f.is_file() and not f.name.startswith("."))
        if key is not None and entry.name != key:
            (entry / ".key").write_text(key, encoding="utf-8")   # readable name for hashed entries
        (entry / self.MARKER).write_text(str(size), encoding="utf-8")
        self._evict(keep={entry.name})

    def discard(self, series: str) -> bool:
        """Drop a committed, unpinned entry so the next fetch re-reads the source.

        Refuses in the two cases where dropping it would break someone: a PIN
        means someone is reading those bytes right now, and a missing marker means
        another writer holds the claim and owns the directory. Returns whether it
        dropped anything, so a caller can say so rather than assume.

        "Someone is reading" covers the read-ahead only because
        :func:`haversack.jobpolicy.fill_read_ahead` pins for the duration of its
        read. It did not always: a committed entry is unpinned between the writer
        releasing its claim and the job that wants it taking one, the read-ahead
        read in exactly that window, and this method would happily rename a DICOM
        series into the graveyard and delete it while ImageSeriesReader was still
        walking the directory. The guarantee here is only as good as that pin.

        Callers discard BEFORE taking their own pin. Doing it after would make a
        job refuse its own refresh, since the pin count cannot say who holds it.
        """
        entry = self._entry(series)
        with self._lock:
            if entry.name in self._pins:
                return False               # someone is reading it
            if not (entry / self.MARKER).exists():
                return False               # a claim in flight, or nothing there
            try:
                self.graveyard.mkdir(parents=True, exist_ok=True)
                aside = self.graveyard / f"{entry.name}-{os.getpid()}-{time.time_ns()}"
                os.replace(entry, aside)
            except OSError:
                # a read-only cache root, or the entry moved under us. discard()
                # answers a question - "did anything get dropped" - and must not
                # raise out of it, which would fail the job.
                return False
        shutil.rmtree(aside, ignore_errors=True)
        return True

    def sweep_stale(self) -> None:
        """Empty the graveyard: entries a crash left between the rename and the
        delete. They carry no marker, so the LRU skips them forever."""
        # Everything under the graveyard, and NOTHING outside it. No name in the
        # entry namespace is inspected, because no name there can be trusted to
        # mean "discarded": entry names come from cache keys. An earlier build's
        # leftovers (`<entry>.stale<digits>`) are deliberately not swept - the
        # predicate that would find them, "has no .done marker", is also the exact
        # definition of a claim another process is fetching into right now.
        if not self.graveyard.is_dir():
            return
        for d in self.graveyard.iterdir():
            shutil.rmtree(d, ignore_errors=True) if d.is_dir() else d.unlink(missing_ok=True)

    #: How many times the claim may change hands under one waiter before it
    #: gives up. Each handover is real progress, so this is generous - but it is
    #: a CEILING, because the branch that counts them also resets the deadline.
    MAX_HANDOVERS = 10

    #: How often _evict re-sweeps the graveyard. Long, because debris is
    #: crash-only: the cost of sweeping late is bounded disk, and the cost of
    #: sweeping often is an iterdir on every eviction pass.
    SWEEP_INTERVAL = 300.0

    def _maybe_sweep(self) -> None:
        now = time.monotonic()
        with self._lock:
            if now - self._last_sweep < self.SWEEP_INTERVAL:
                return
            self._last_sweep = now         # claimed under the lock: one sweeper
        self.sweep_stale()                 # outside it: rmtree must not block readers

    def _evict(self, keep) -> None:
        self._maybe_sweep()
        with self._lock:
            protected = set(keep) | set(self._pins)
            entries, kept_bytes = [], 0
            for e in self.root.iterdir():
                if e in (self.graveyard, self.claims):
                    continue                   # ours, not an entry
                m = e / self.MARKER
                if not m.exists():
                    continue                   # a writer mid-flight: never touch
                try:
                    mtime, size = m.stat().st_mtime, int(m.read_text(encoding="utf-8") or 0)
                except (OSError, ValueError):
                    continue
                if e.name in protected:
                    kept_bytes += size
                else:
                    entries.append((mtime, size, e))
            total = kept_bytes + sum(sz for _, sz, _ in entries)
            for _, size, e in sorted(entries, key=lambda t: t[0]):
                if total <= self.budget:
                    break
                shutil.rmtree(e, ignore_errors=True)
                total -= size


def _read_image(path):
    from . import io as nio
    return nio.read_image(path)


class ReadAhead:
    """At most one pre-read image, keyed by series: the prefetch thread fills
    it after staging bytes, the next run pops it. Capacity 1 by design - a
    full CT is ~1 GB of RAM and one-ahead is the pipeline's depth. The image
    is task-independent (stored orientation, IPP-corrected geometry via
    :func:`haversack.io.read_image`); the pipeline applies each task's own
    reorientation exactly as it does for any caller-held image."""

    def __init__(self, read_fn=None):
        self.read = read_fn or _read_image
        self._lock = threading.Lock()
        self._key = None
        self._image = None

    def fill(self, series: str, path) -> bool:
        try:
            img = self.read(path)
        except Exception:
            return False
        with self._lock:
            self._key, self._image = series, img
        return True

    def has(self, key: str) -> bool:
        with self._lock:
            return self._key == key

    def pop(self, key: str):
        with self._lock:
            if self._key == key:
                img, self._key, self._image = self._image, None, None
                return img
            return None


#: ``GET /v1/segmentations``: rows per page. The maximum is what one request may make the
#: server read - two small files a row - and it mirrors ``/v1/segments``. On a Modal volume
#: a cold row is ~49 ms of round trips serially and ~2.3 ms on ``LIST_WORKERS`` threads, so
#: a full page of 1000 is a little over two seconds there the first time and far less after.
LIST_LIMIT_DEFAULT = 100
LIST_LIMIT_MAX = 1000
#: How many ``identity=`` values one listing request may carry. Each costs a key per served
#: task per path-addressable option set, looked up by name (~200 stats on a full catalog).
LIST_IDENTITIES_MAX = 100
#: Threads a listing reads entries on. Reading a Modal volume is cheap per BYTE and dear per
#: FILE (measured 2026-09-20 on a 2,083-entry cache: the first read of any file ~24 ms
#: whatever its size, a stat 0.4 ms): a serial walk took 161 s, the same walk on 32 threads
#: 4.5 s. It is round trips, not data, so the threads wait and do not compute. The listing
#: itself, deployed over that cache the same day: a scan of all 2,083 entries 3.5 s, 4.2 s and
#: 9.7 s cold on three containers, 0.3-0.5 s once remembered (``ListingMemo``).
LIST_WORKERS = 32
#: The most entries read under one hold of the executor's view lock (see
#: ``ResultCache.list``): on Modal a volume reload waits for that hold to end, and every
#: lookup waits behind the reload, so a hold is bounded - ~0.6 s cold at the rates above.
LIST_CHUNK = 256


def encode_cursor(position, scope: str | None = None) -> str:
    """The listing's position ``(pointer mtime in ns, key)`` as the opaque token the wire
    carries. Versioned, so the server may change what a position is: a client only ever
    hands back what it was given. ``scope`` names the listing and filters it was issued for
    (2026-09-26): a position is a place in ONE ordered set, and handed to another listing -
    another kind, another ``task`` - it answered a silently wrong page."""
    import base64
    body = [1, int(position[0]), str(position[1])] + ([str(scope)] if scope else [])
    raw = json.dumps(body, separators=(",", ":"))
    return base64.urlsafe_b64encode(raw.encode("utf-8")).decode("ascii").rstrip("=")


def decode_cursor(token: str, scope: str | None = None) -> tuple:
    """``encode_cursor``'s inverse; ValueError for anything this server did not issue, or
    issued for another listing than ``scope`` (a cursor from before scopes names none, and
    is taken as it always was)."""
    import base64
    import binascii
    try:
        pad = "=" * (-len(token) % 4)
        got = json.loads(base64.b64decode(token + pad, altchars=b"-_", validate=True))
    except (binascii.Error, ValueError, UnicodeDecodeError) as e:
        raise ValueError("not a cursor") from e
    if (not isinstance(got, list) or len(got) not in (3, 4) or got[0] != 1
            or isinstance(got[1], bool) or not isinstance(got[1], int)
            or not isinstance(got[2], str) or not got[2]):
        raise ValueError("not a cursor")
    if len(got) == 4 and scope is not None and got[3] != scope:
        raise ValueError("another listing's cursor")
    return got[1], got[2]


class ListingMemo:
    """What a listing row takes from ``meta.json``, remembered per PUBLICATION: in memory,
    bounded, never written to disk.

    ``meta.json`` never changes for a generation, and on a Modal volume reading it again is
    the expensive half of a row (see ``LIST_WORKERS``). A long-lived server therefore keeps
    what it parsed, under the stamp of the pointer that named the generation - the mtime of
    ``<key>/current``, which only a publication moves (see ``ResultCache._stamp``).

    **This is not an index** (the user's decision, 2026-09-20: no identity -> key index,
    "one more thing to keep in sync"), and the difference is who is believed. An index
    answers "which entries exist, which match" by itself, so every put, eviction and delete
    by ANY process or container must reach it, and a missed one makes it silently wrong. The
    memo answers nothing by itself: every listing still enumerates the cache and stats every
    pointer, the filesystem alone says what exists and what is current, and a remembered row
    is used only while its pointer's stamp is the one it was read under. A memo that is
    empty, lost to a restart, evicted or never consulted costs time - seconds, on the
    parallel scan - and never an answer. ``capacity`` rows, least recently used first out:
    the default is ten times the largest cache seen so far (2,083 entries) at well under a
    kilobyte a row, about 20 MB at the very worst in a container that has 2 GB.
    """

    def __init__(self, capacity: int = 20000):
        from collections import OrderedDict
        self.capacity = int(capacity)
        self._rows = OrderedDict()
        self._lock = threading.Lock()          # the listing reads on a pool of threads

    def get(self, key: str, stamp: int):
        """``(directory name, fields)`` read under exactly this pointer stamp, else None."""
        with self._lock:
            hit = self._rows.get(key)
            if hit is None or hit[0] != stamp:
                return None
            self._rows.move_to_end(key)
            return hit[1], hit[2]

    def put(self, key: str, stamp: int, where: str, fields: dict) -> None:
        with self._lock:
            self._rows[key] = (stamp, where, fields)
            self._rows.move_to_end(key)
            while len(self._rows) > self.capacity:
                self._rows.popitem(last=False)

    def drop(self, key: str) -> None:
        with self._lock:
            self._rows.pop(key, None)

    def __len__(self) -> int:
        with self._lock:
            return len(self._rows)


class ResultCache:
    """REQUEST-keyed store of finished results: <root>/<key>/labels.seg.nrrd +
    result.json + meta.json (the readable key components - a cache you can ls).
    LRU by directory mtime, count-bounded; results are ~MBs so the bound is
    generous by default.

    The key is :func:`result_key` - a digest of the REQUEST (identity x task x
    options x weights x version), not of the bytes. That distinction matters now
    that content addressing exists next door: :mod:`haversack.content` keys on what
    the bytes ARE, this keys on what was asked for. A finished job publishes the
    content digest of its output in ``outputs``, which is what an ETag and a
    chained input refer to."""

    def __init__(self, root, *, keep: int = 500):
        self.root = Path(root).expanduser()
        self.root.mkdir(parents=True, exist_ok=True)
        self.keep = int(keep)

    #: How long a reader's LEASE lasts: a generation - or a legacy flat entry - that was
    #: handed to a reader survives for this long after the LAST time it was, whatever else
    #: happens to the key. Counting generations was the wrong rule and this replaced it:
    #: "keep the current one and its predecessor" is safe only while publications are
    #: rarer than reads, and two publications in a row deleted a generation a reader had
    #: selected and not yet opened (2026-09-09). Measured from the reader rather than the
    #: writer, and visible to another process because it is on disk rather than in memory.
    #:
    #: The lease is the mtime of a file of its own (``LEASE_NAME``), and EVERY cleanup path
    #: asks it - pruning, the ceiling, eviction. It used to be the directory's mtime, which
    #: also moves when a generation is created or an artifact lands, so nothing could tell
    #: "published recently" from "handed to a reader recently": the ceiling, needing
    #: something to reclaim, reclaimed the second, and a legacy flat entry was judged by
    #: a third timestamp that no read ever touched (2026-09-10).
    #:
    #: Generous, because the cost of being wrong is asymmetric: a stale directory holds
    #: disk until the next publication, a deleted one fails a request that was already
    #: served.
    GENERATION_GRACE_S = 900
    #: A ceiling on generations NOBODY holds: a key republished faster than the lease and
    #: never read keeps at most this many. A held generation is never a candidate. The
    #: ceiling used to take the oldest RECENT generations, and a generation is recent
    #: precisely because a reader just resolved it - so this many publications inside one
    #: lease deleted the result a reader had selected and not yet opened (2026-09-10).
    #: Held generations are bounded instead by the lease, which expires, and by what a
    #: publication costs, which is a whole segmentation.
    MAX_GENERATIONS = 16
    #: The lease file, inside the directory whose files a reader was handed.
    LEASE_NAME = ".lease"
    #: The entry's lock: readers hold it shared while they acquire a path, reclamation
    #: holds it exclusive while it decides and moves. See ``_entry_lock``.
    LOCK_NAME = ".lock"
    #: ``<key>/.writer-<gen>``: a writer's claim on the generation it is publishing, locked
    #: from before its staging exists until its pointer names it. See ``_claim``.
    CLAIM_PREFIX = ".writer-"
    #: Where reclamation moves a directory while it asks its second question.
    TOMB_PREFIX = ".reclaim-"

    def _generation_dir(self, key: str, gen: str) -> Path:
        return self.root / key / f"g-{gen}"

    def _staging_dir(self, key: str, gen: str) -> Path:
        """Where a generation is ASSEMBLED, under a name pruning does not recognize.

        A writer used to build straight into `g-<gen>`, where a concurrent publication of
        the same key saw an old generation and deleted it mid-assembly - the writer then
        failed on its own labels file. Staging is renamed into place only once complete,
        so an unfinished generation is never a pruning candidate and a published one is
        never unfinished. Whether it is still being written is its writer's claim to say;
        its age says nothing (see ``_claim``).
        """
        return self.root / key / f"s-{gen}"

    def _resolve(self, key: str, *, lease: bool = True) -> Path | None:
        """The directory holding the generation that is current NOW, or None.

        Everything a reader needs is inside it, which is the point: labels, metadata and
        artifacts are published as one directory and referred to by one pointer, so no
        reader can be handed a pair from two publications and no writer can land a file
        in a generation that is not its own. Replacing files in place could not offer
        that however carefully it was ordered - a review demonstrated both halves, a
        reader seeing new metadata beside old labels, and an artifact worker overtaken
        mid-copy writing into the result that replaced it (2026-09-09).

        A flat entry from before this change is still readable, so an existing cache
        keeps answering; the next publication of that key replaces it with a generation.

        With ``lease`` (the default) the reader's lease is taken BEFORE the answer is
        final: the directory is leased and then checked, so a generation reclaimed in
        between is noticed here - the lease lands nowhere, or the labels are gone - and
        the pointer is read again, instead of a path being handed out that no cleanup
        knows anyone holds. A legacy flat entry is leased the same way, in its own
        directory, because that is where cleanup looks: the read used to touch the key
        directory while cleanup judged the labels file (2026-09-10). ``list`` passes
        False - it hands out no path, and it used to renew every entry's lease per call.
        """
        import contextlib
        d = self.root / key
        # the pointer, the lease and the check are ONE acquisition: see _entry_lock
        with (self._entry_lock(key, shared=True) if lease else contextlib.nullcontext()):
            for _ in range(8):                 # a publication can land between any two reads
                try:
                    gen = (d / CURRENT_NAME).read_text(encoding="utf-8").strip()
                except OSError:
                    where = d                  # a legacy flat entry, or nothing at all
                else:
                    where = self._generation_dir(key, gen)
                if primary_output(where) is None:
                    if where == d:
                        return None
                    continue                   # the pointer moved on, or dangles: ask again
                if lease and not self._take_lease(where):
                    continue                   # reclaimed before the lease could land
                if primary_output(where) is not None:
                    return where
            return None

    def _entry_lock(self, key: str, *, shared: bool):
        """Exclusion between a reader's ACQUISITION and reclamation, on one entry. Readers
        hold ``<key>/.lock`` shared from reading the pointer until their lease has landed;
        pruning and eviction hold it exclusive while they decide and move.

        Moving a directory aside and asking again (``_reclaim``) narrowed that
        check-then-act to one move and one move back - and in that instant a path a reader
        had already been handed did not exist: FileNotFoundError, reproduced by review
        (2026-09-10). Under the lock no reclamation decides while a reader is between the
        pointer and its lease, and a lease that landed first is seen, so nothing is ever
        moved and then put back. The second question stays for where no lock can be
        taken - no locking facility, a lock file this process cannot open, a lock that
        does not reach across hosts on a shared volume.

        Yields whether exclusion is really held. The lock file is checked to still be the
        entry's once it is locked: eviction moves a whole entry, lock file included, and a
        lock on a file that has left is a lock on nothing.
        """
        import contextlib
        import os
        from . import filelock
        path = self.root / key / self.LOCK_NAME

        def _open():
            for flags in (os.O_CREAT | os.O_RDWR, os.O_RDONLY):   # a read-only cache: shared
                try:
                    return os.open(path, flags, 0o644)
                except OSError:
                    continue
            return None

        @contextlib.contextmanager
        def held():
            fd = None
            if filelock.SUPPORTED:
                for _ in range(8):
                    fd = _open()
                    if fd is None:
                        break                  # no entry at all: nothing to exclude
                    try:
                        filelock.lock(fd, shared=shared)
                    except OSError:
                        os.close(fd)
                        fd = None
                        break                  # this filesystem does not lock
                    try:
                        mine, now = os.fstat(fd), os.stat(path)
                        if (mine.st_dev, mine.st_ino) == (now.st_dev, now.st_ino):
                            break
                    except OSError:
                        pass                   # the entry moved while this waited
                    os.close(fd)
                    fd = None
            try:
                yield fd is not None
            finally:
                if fd is not None:
                    os.close(fd)               # closing releases the lock
        return held()

    def _take_lease(self, where: Path) -> bool:
        """Lease ``where`` to a reader, now. False only when ``where`` is gone: a lease
        this process cannot WRITE - a read-only cache, a file another uid owns - lets the
        read proceed unleased, as every read did before leases existed."""
        try:
            (where / self.LEASE_NAME).touch()
        except FileNotFoundError:
            return False
        except OSError:
            pass
        return True

    def _leased(self, where: Path) -> bool:
        """Was a path under ``where`` handed to a reader within the lease?"""
        import time as _time
        try:
            age = _time.time() - (where / self.LEASE_NAME).stat().st_mtime
        except OSError:
            return False
        return age < self.GENERATION_GRACE_S

    def _claim(self, d: Path, gen: str):
        """Claim generation ``gen`` of the entry at ``d`` for this writer: the claim's
        open descriptor - locked where a lock can be taken - or None when not even the
        file can be written.

        Staging used to be judged dead once its directory had been quiet for the lease.
        An mtime says when something last changed, not whether its writer is alive: one
        long copy, a suspended process or a closed laptop lid leaves a live writer
        looking exactly like a dead one, and a publication of the same key then deleted
        its work under it (2026-09-10). The kernel releases a lock when its holder dies,
        so being able to take it is proof - see ``_writer_gone``.

        Locked BEFORE anything is written into it: a pruner that can read which host took
        a claim therefore always finds it held, and one that reads nothing cannot tell
        whose it is and leaves it alone. Where no lock can be taken the claim is KEPT,
        marked ``unlocked``: it cannot prove its writer's death, but it still says a
        writer is there, which eviction and the ceiling must see. The first version
        removed it, and a lockless writer's staging then looked like nobody's - so
        eviction took the entry it was publishing into (2026-09-10, reproduced by review).
        """
        import os
        from . import filelock
        path = d / f"{self.CLAIM_PREFIX}{gen}"
        try:
            fd = os.open(path, os.O_CREAT | os.O_EXCL | os.O_RDWR, 0o644)
        except OSError:
            return None
        locked = False
        if filelock.SUPPORTED:
            try:
                locked = filelock.lock(fd, blocking=False)
            except OSError:
                locked = False                 # this filesystem does not lock
        try:
            os.write(fd, f"{_host_identity()}\n{os.getpid()}\n"
                         f"{'locked' if locked else 'unlocked'}\n".encode("utf-8"))
        except OSError:
            pass                               # an empty claim is unverifiable: still kept
        return fd

    def _release(self, d: Path, gen: str, fd) -> None:
        """Give up a claim: once the pointer names the generation, or once a failed
        publication has removed what it built. Closed before it is unlinked, because
        Windows will not delete an open file."""
        import os
        if fd is None:
            return
        try:
            os.close(fd)
        finally:
            try:
                (d / f"{self.CLAIM_PREFIX}{gen}").unlink()
            except OSError:
                pass

    def _writer_gone(self, d: Path, gen: str):
        """Is the writer of ``gen`` PROVABLY dead?

        None when nothing claims ``gen`` - a publication that finished, or one from before
        claims existed. True only when this host takes the lock the writer held, which the
        kernel releases when the writer dies. False when the writer is alive - and also
        when nothing here can say: a claim from another host (an advisory lock need not
        reach across machines sharing a volume), a claim its writer could not lock, a
        filesystem without locks, a claim that cannot be read. Only True licenses
        reclaiming anything.
        """
        import os
        from . import filelock
        try:
            fd = os.open(d / f"{self.CLAIM_PREFIX}{gen}", os.O_RDWR)
        except FileNotFoundError:
            return None
        except OSError:
            return False
        try:
            try:
                lines = os.read(fd, 512).decode("utf-8", "replace").split("\n")
            except OSError:
                return False
            if (not filelock.SUPPORTED or lines[0] != _host_identity()
                    or (len(lines) > 2 and lines[2] == "unlocked")):
                return False
            try:
                if not filelock.lock(fd, blocking=False):
                    return False
            except OSError:
                return False
            filelock.unlock(fd)
            return True
        finally:
            os.close(fd)

    def _reclaim(self, p: Path, needed) -> bool:
        """Delete the directory ``p`` unless ``needed`` says it is in use - asked before,
        and asked AGAIN once ``p`` has been moved out of reach, where a yes puts it back.
        Returns whether ``p`` is gone.

        Deciding "nobody holds this" and then deleting it is a check-then-act: a reader
        can take its lease in between, be told its path is good, and lose it. Once ``p``
        is out of reach, a reader that has not leased yet cannot find it - its lease lands
        nowhere and it reads the pointer again - and one that leased before the move is
        what the second question sees. What is left is the instant between the move and
        the move back, for a reader that opens its file exactly then.
        """
        import os
        import shutil
        import time as _time
        if needed(p):
            return False
        tomb = p.parent / f"{self.TOMB_PREFIX}{_time.time_ns()}-{os.getpid()}-{p.name}"
        try:
            os.rename(p, tomb)
        except OSError:
            return False                       # gone already, or another pruner moved it
        if needed(tomb):
            try:
                os.rename(tomb, p)
            except OSError:
                pass                           # never deleted here: see _sweep_tombs
            return False
        shutil.rmtree(tomb, ignore_errors=True)
        return True

    def _reclaim_flat(self, d: Path) -> bool:
        """A legacy flat entry's files, unless a reader holds them - the same two
        questions as ``_reclaim``. The labels file moves first because it is what
        ``_resolve`` gates on: once it is out of reach the entry is invisible."""
        import os
        import time as _time
        labels = d / RESULT_NAME
        if self._leased(d):
            return False
        tomb = d / f"{self.TOMB_PREFIX}{_time.time_ns()}-{os.getpid()}-{RESULT_NAME}"
        try:
            os.rename(labels, tomb)
        except OSError:
            return False
        if self._leased(d):
            try:
                os.rename(tomb, labels)
            except OSError:
                pass
            return False
        for p in (tomb, *(d / n for n in ("result.json", "meta.json", GENERATION_NAME,
                                           *ARTIFACT_NAMES, self.LEASE_NAME))):
            try:
                p.unlink()
            except OSError:
                pass
        return True

    def _sweep_tombs(self, parent: Path) -> None:
        """Remove what a failed move-back left in ``parent``. Aged by the birth in its
        NAME, and only past the lease: renaming keeps a directory's mtime, so a tomb one
        instant old can look ancient; and whoever holds a tomb leased it before it moved -
        nobody can find it afterwards - so past the lease, nobody does."""
        import shutil
        import time as _time
        try:
            tombs = [p for p in parent.iterdir() if p.name.startswith(self.TOMB_PREFIX)]
        except OSError:
            return
        now = _time.time_ns()
        for p in tombs:
            try:
                born = int(p.name[len(self.TOMB_PREFIX):].split("-", 1)[0])
            except ValueError:
                continue
            if (now - born) / 1e9 < self.GENERATION_GRACE_S:
                continue
            if p.is_dir():
                shutil.rmtree(p, ignore_errors=True)
            else:
                try:
                    p.unlink()
                except OSError:
                    pass

    def _key_in_use(self, where: Path) -> bool:
        """Is anything in the entry at ``where`` still held - a reader's lease on its
        legacy flat files or on any generation, or a writer not provably dead?

        Staging counts on its own, claimed or not: staging nobody claims - a build from
        before claims - is unknown ownership, protected on this path as it is from
        pruning. Eviction used to look only for claims it could verify, so a writer that
        could not lock had its entry taken from under it (2026-09-10)."""
        if self._leased(where):
            return True
        try:
            children = list(where.iterdir())
        except OSError:
            return False
        for c in children:
            if c.name.startswith("g-") and self._leased(c):
                return True
            if c.name.startswith("s-") and self._writer_gone(where, c.name[2:]) is not True:
                return True
            if (c.name.startswith(self.CLAIM_PREFIX)
                    and self._writer_gone(where, c.name[len(self.CLAIM_PREFIX):]) is not True):
                return True
        return False

    def _stamp(self, key: str, probe: bool = False) -> int | None:
        """When the entry at ``key`` was PUBLISHED, in ns - the listing's clock - or None
        when ``key`` publishes nothing. One stat and no content read, which is the point:
        on a Modal volume a stat is 0.4 ms and the first read of any file ~24 ms.
        ``probe`` is for a COMPUTED name, which usually does not exist (an identity filter
        derives every task's key to find the few that were run): the key directory is asked
        first, so a miss is one failed stat and not two (9,400 names, measured: 1.7 s).

        It is the mtime of the POINTER, ``<key>/current``, and no other file would do. A
        publication writes the pointer under a temporary name and renames it into place
        (``put``); a rename is atomic and keeps the mtime the file was written with. So a
        stat meets the previous pointer or the new one, never a missing or half-written
        file, and under a REpublication (``Cache-Control: no-cache``) the entry's time moves
        exactly once, at the instant its content does - to a time later than every position
        a reader paging toward older entries can hold. Nothing else writes the file. A read
        leases a file of its own inside the generation and touches the KEY directory for
        the LRU - whose mtime is therefore the last READ, and would reorder the listing
        under traffic; an artifact lands inside the generation directory; pruning removes
        generations and never the pointer. ``meta.json``'s ``computed`` is a job's START on
        its worker's clock and needs a content read besides. A legacy flat entry has no
        pointer: its labels file, which ``put`` also placed by rename, stands in.
        """
        import os
        d = self.root / key
        if probe:
            try:
                os.stat(d)
            except OSError:
                return None
        for name in (CURRENT_NAME, RESULT_NAME):
            try:
                return os.stat(d / name).st_mtime_ns
            except OSError:
                continue
        return None

    def _names(self) -> list:
        """The name of everything under the root that may be an entry, from ONE directory
        listing and no stat: what is not an entry has no stamp (``_stamp``). A dotfile is a
        tomb mid-reclamation or a probe. The directory is closed before returning - on a
        Modal volume an open directory refuses the volume's next reload."""
        import os
        try:
            with os.scandir(self.root) as it:
                return [e.name for e in it if not e.name.startswith(".")]
        except OSError:
            return []

    def _fields(self, key: str, stamp: int, memo=None):
        """What ``meta.json`` says of the entry ``key`` published at ``stamp``:
        ``(directory, fields, remembered)``, or None when there is no readable entry. Two
        content reads - the pointer and ``meta.json`` - or none, when ``memo`` remembers
        this publication (see ``ListingMemo``)."""
        hit = memo.get(key, stamp) if memo is not None else None
        if hit is not None:
            d = self.root / key
            return (d / hit[0] if hit[0] else d), hit[1], True
        return self._read_fields(key, stamp, memo)

    def _read_fields(self, key: str, stamp: int, memo=None):
        d = self.root / key
        where = self._resolve(key, lease=False)    # ONE resolution; hands out no path
        if where is None:
            return None
        try:
            meta = json.loads((where / "meta.json").read_text(encoding="utf-8"))
        except FileNotFoundError:
            meta = {}                          # an entry from before meta.json: still listed
        except (OSError, ValueError):
            return None
        if not isinstance(meta, dict):
            return None
        fields = {k: meta.get(k) for k in ("task", "identity", "options", "computed")}
        if meta.get("kind") not in (None, "segment"):
            fields["kind"] = meta["kind"]      # a field says what it is; a segmentation's fields are as they were
        # Remembered under the stamp the CALLER saw. If a publication landed between that
        # stat and this read, what was read belongs to the new pointer and is filed under
        # the old one's stamp - which no stat will ever return again, so it is never
        # found, only evicted. (Re-checking the stamp here was a stat a row for nothing.)
        if memo is not None:
            memo.put(key, stamp, where.name if where != d else "", fields)
        return where, fields, False

    def _row(self, key: str, stamp: int, found, memo=None) -> dict | None:
        """The listing's row for an entry ``_fields`` found. A REMEMBERED generation that
        pruning has since taken is read again - not dropped from the listing, and not
        answered from memory."""
        where, fields, remembered = found
        row = self._row_at(key, stamp, where, fields)
        if row is None and remembered:
            memo.drop(key)
            again = self._read_fields(key, stamp, memo)
            row = self._row_at(key, stamp, again[0], again[1]) if again is not None else None
        return row

    def _row_at(self, key: str, stamp: int, where: Path, fields: dict) -> dict | None:
        """A row from what ``meta.json`` said and what only the directory can say now - the
        labels' size, and which artifacts have arrived (they do, after "done"): stats, no
        content. None when the labels are gone."""
        import os
        try:
            size = os.stat(primary_output(where) or where / RESULT_NAME).st_size
        except OSError:
            return None
        task, identity, options = fields.get("task"), fields.get("identity"), fields.get("options")
        row = {"key": key, "task": task, "identity": identity, "options": options,
               "computed": fields.get("computed"), "published": stamp / 1e9, "bytes": size}
        if fields.get("kind") not in (None, "segment"):
            row["kind"] = fields["kind"]       # an embedding job's field: said, and never linked as labels
            return row
        if resource_links(task, identity, options):    # asked first: two stats saved a row
            row["links"] = resource_links(task, identity, options,
                                          preview=(where / "preview.png").exists(),
                                          statistics=(where / "statistics.json").exists())
        return row

    def list(self, *, keys=None, limit: int | None = None, after=None, accept=None,
             match=None, memo=None, hold=None, workers: int | None = None) -> tuple:
        """Completed segmentations, newest PUBLISHED first: ``(rows, position)``, where
        ``position`` resumes the listing after the last entry this call looked at - pass it
        back as ``after`` - and is None when nothing is left. A row is the readable meta of
        an entry, its size, when it was published, and its path-surface links when it has
        any (``resource_links``). No index anywhere (decided 2026-09-20): three stateless
        mechanisms, each from a measurement of what a Modal volume charges for (a directory
        listing of 2,083 names 0.03 s, a stat 0.4 ms, the FIRST read of a file ~24 ms
        whatever its size).

        1. ``keys`` - a filter by identity is COMPUTED, not searched. The caller derives
           the key of every result it could mean (``serve.result_key``; the route does it
           per served task and path-addressable option set) and only those names are
           stat'ed: no directory listing, and no entry read that is not returned.
        2. Order and paging come from NAMES and STATS - the pointer's mtime, ``_stamp`` -
           and content is read only for the entries of the page asked for. ``after`` is a
           position ``(stamp, key)``, not an offset, so a page is the same page whatever
           was published since the one before it: a new entry sorts ahead of every
           position already handed out. There is no cap: the listing used to keep the
           newest 500 and say nothing of the rest.
        3. ``match`` / ``accept`` - a filter that needs CONTENT (a task) reads every entry
           until the page is full, ``workers`` at a time, because the cost is round trips
           and they overlap; ``memo`` spares a long-lived server the re-read.

        ``match(fields)`` is asked of what ``meta.json`` says alone (``task``, ``identity``,
        ``options``, ``computed``), BEFORE the entry's files are stat'ed; ``accept(row)`` of
        the finished row. Both in the calling thread and outside any hold. The split is a
        measurement (Modal, 2026-09-20): with every row remembered, a scan of 2,083 entries
        for a task none of them had was still 1.5 s, all of it stats - a stat is 0.23 ms
        there and, unlike a read, barely overlaps (0.11 ms on 32 threads) - and three of a
        row's four stats are for its size and artifacts, which a refused row never shows.
        While every row is accepted a page reads exactly its own entries; after the first
        refusal the scan reads ``LIST_CHUNK`` at a time, so at most one chunk is read beyond
        the page (and remembered, where there is a memo).

        ``hold`` is a callable returning a context manager that is held around EVERY batch
        of reads, and only around them. On Modal it is the api container's view lock,
        shared (``modal_app._cache_view``): a volume reload hides the whole volume from the
        container's other threads while it runs, and this method's readers ARE other
        threads. The arrangement is safe because a batch's threads are started inside the
        hold and the hold is not left until every one of them has finished (``each``) - so
        no read of this listing can overlap a reload, which needs the lock exclusive - and
        it is per batch rather than per listing because a cold scan is seconds long: a
        reload waits at most ``CACHE_RELOAD_WAIT_S`` for readers, and lookups queue behind
        a waiting reload. Between two batches the view may be reloaded; an entry that went
        in between reads as gone and is skipped, one that arrived is newer than this
        listing, and a republished one moved its stamp, so the memo does not vouch for it.
        """
        import contextlib
        import os
        from concurrent.futures import ThreadPoolExecutor, wait
        hold = hold or contextlib.nullcontext
        workers = LIST_WORKERS if workers is None else int(workers)
        pool = []                              # started on first need, joined before return

        def order(position):                   # newest first; the key makes it total
            return -position[0], position[1]

        def each(fn, items) -> list:
            """``fn`` over ``items`` in order, under ONE hold that outlasts every call."""
            with hold():
                if len(items) < 4 or workers < 2:
                    return [fn(x) for x in items]
                if not pool:
                    pool.append(ThreadPoolExecutor(max_workers=workers,
                                                   thread_name_prefix="haversack-list"))
                futures = []
                try:
                    for x in items:
                        futures.append(pool[0].submit(fn, x))
                finally:
                    wait(futures)              # even when a submit failed: see ``hold``
                return [f.result() for f in futures]

        try:
            if keys is None:
                with hold():
                    names = self._names()
            else:                              # names the caller computed: never a path
                names = [k for k in dict.fromkeys(map(str, keys))
                         if k and not k.startswith(".") and os.sep not in k
                         and not (os.altsep and os.altsep in k)]
            computed = keys is not None
            # The stats go a CHUNK at a time too, each under its own hold. They went as one
            # batch, so one hold outlasted every name: 1.9 s of the 2.0 s a reload waits on a
            # cache of 2,083, and a refusal - then 503s for everybody else - from an identity
            # filter at its documented maximum (~18,800 derived keys). Found by an adversarial
            # pass on the merge, 2026-09-21; `_list_cache` already promised what this now does.
            stamps = []
            for j in range(0, len(names), LIST_CHUNK):
                stamps += each(lambda k: self._stamp(k, probe=computed), names[j:j + LIST_CHUNK])
            found = sorted(((t, k) for k, t in zip(names, stamps) if t is not None), key=order)
            if after is not None:
                found = [c for c in found if order(c) > order(after)]
            rows, i, clean = [], 0, True
            while i < len(found) and (limit is None or len(rows) < limit):
                need = len(found) - i if limit is None else limit - len(rows)
                chunk = found[i:i + (min(need, LIST_CHUNK) if clean else LIST_CHUNK)]
                said = each(lambda c: self._fields(c[1], c[0], memo), chunk)
                wanted = [(c, f) for c, f in zip(chunk, said)
                          if f is not None and (match is None or match(f[1]))]
                built = dict(zip((c for c, _ in wanted),
                                 each(lambda cf: self._row(cf[0][1], cf[0][0], cf[1], memo),
                                      wanted)))
                for c in chunk:
                    if limit is not None and len(rows) >= limit:
                        break                  # read ahead of the page: remembered, not sent
                    i += 1
                    row = built.get(c)
                    if row is not None and (accept is None or accept(row)):
                        rows.append(row)
                    else:
                        clean = False
            return rows, (found[i - 1] if 0 < i < len(found) else None)
        finally:
            for p in pool:
                p.shutdown(wait=True)

    def get(self, key: str):
        """``(labels path, result)`` for what ``key`` publishes now, leased - or None.

        The LRU touch is best effort, and on its own. A cache this process cannot WRITE - a
        read-only filesystem (EROFS), a directory another uid owns (EPERM) - is a supported
        way to read one: ``_take_lease`` and ``_entry_lock`` both allow for it, and
        ``SeriesCache`` has treated its own touch this way all along. There the LRU loses a
        touch, that is all. The touch used to share one ``try`` with the read of
        ``result.json``, so a refused touch SKIPPED the read and every hit came back with
        ``{}`` for its result (found 2026-09-20, from a listing smoked over a cache mounted
        read-only). Nothing failed, which is what made it a defect. The ETag fell back from
        the content digest to the key, so a client holding those very bytes downloaded them
        again; a ``result:<key>`` reference was refused as ``result_unreadable``, with the
        advice to recompute a result that was fine; and the job result route, which takes
        an entry only when its digest is the job's (``same_output``), fell through to the
        job's own scratch copy - a 410 "purged" once that was gone, with the bytes sitting
        in the entry.

        ``{}`` means what ``same_output`` always took it to mean: a ``result.json`` that is
        missing, unreadable, or not what ``put`` writes (bad JSON, bytes that are not UTF-8,
        anything but an object).
        """
        g = self._resolve(key)
        if g is None:
            return None
        try:
            os.utime(self.root / key)          # LRU touch
        except OSError:
            pass                               # not ours to write: read on (see above)
        try:
            result = json.loads((g / "result.json").read_text(encoding="utf-8"))
        except (OSError, ValueError):          # ValueError: JSONDecodeError, UnicodeDecodeError
            result = {}
        return primary_output(g) or g / RESULT_NAME, result if isinstance(result, dict) else {}

    def adopt(self, key: str, gen: str, *, names=(), sizes=None) -> bool:
        """Make an existing, COMPLETE generation directory this entry's current one.

        `put` publishes what it assembles; this publishes what is already here. A copy of
        another host's publication can arrive in three ways - a crash between the rename
        and the pointer write, a second process placing the same generation, a pointer that
        moved back to a generation this host still holds - and in all three the directory
        is right and only the pointer is wrong. Without this the entry was a permanent miss
        on that host: every read re-downloaded, repaired, and still answered None, and on a
        compute server the miss became a recompute that overwrote the very generation an
        operator had just rolled back to (review, 2026-09-20).

        False unless every file named in ``names``, the two documents and the labels are
        present AND the right size: adopting on existence alone published a 0-byte labels
        file as a 200, which is precisely what a power loss leaves behind a rename on a
        journaled filesystem - the case this method was written for (review, 2026-09-20).
        ``sizes`` is the publisher's own record, ``{name: bytes}``; a file with no recorded
        size must merely be non-empty.
        """
        import os
        where = self._generation_dir(key, gen)
        # the publication's ONE primary output (labels or an embedding job's field), named by
        # the caller: always demanding the labels made a field entry un-adoptable, so the
        # repair this method exists for could never finish for one (2026-09-23)
        primaries = [n for n in names if n in PRIMARY_NAMES]
        if len(primaries) != 1:
            return False
        wanted = {"result.json", "meta.json", *names}
        sizes = sizes or {}
        for n in wanted:
            try:
                on_disk = (where / n).stat().st_size
            except OSError:
                return False
            if on_disk != sizes[n] if n in sizes else not on_disk:
                return False
        d = self.root / key
        tmp = d / f"{CURRENT_NAME}.{uuid.uuid4().hex[:8]}.tmp"
        try:
            tmp.write_text(gen, encoding="utf-8")
            os.replace(tmp, d / CURRENT_NAME)
        except OSError:
            Path(tmp).unlink(missing_ok=True)
            return False
        return True

    def published_result(self, key: str):
        """The current publication's result document, or None. Read without a lease: it
        hands out no path. The one question ``LocalExecutor._entry_holds`` asks, named so
        a cache whose entries are not directories can answer it too."""
        g = self._resolve(key, lease=False)
        if g is None:
            return None
        try:
            return json.loads((g / "result.json").read_text(encoding="utf-8"))
        except (OSError, json.JSONDecodeError):
            return None

    def generation(self, key: str) -> str | None:
        """Which publication the entry at ``key`` currently holds, or None."""
        try:
            return (self.root / key / CURRENT_NAME).read_text(encoding="utf-8").strip()
        except OSError:
            return None

    def put(self, key: str, labels_path, result: dict, meta: dict,
            preview_path=None, statistics_path=None, output_name: str = RESULT_NAME,
            generation=None, move: bool = False) -> str:
        """Publish one generation of a result, returning its generation token.

        The generation is assembled COMPLETE in a directory of its own and becomes
        visible by one atomic rename of the pointer file. Nothing is edited in place, so
        there is no window in which an entry is half-replaced, and an artifact worker for
        an earlier generation cannot reach this one - it writes into its own directory,
        which either still exists or does not.

        The writer holds a claim (``_claim``) from before its staging exists until the
        pointer names its generation. That is what tells a concurrent pruner the staging
        is still being written however quiet it has been, and what keeps the generation
        from being reclaimed in the instant between its rename and the pointer's. A
        publication that fails removes what it built itself - nobody else may.

        ``move`` hands over the source files instead of copying them, for a caller whose
        sources are temporary and on this same filesystem (``objectcache``'s fill, whose
        work directory lives inside this root). Copying meant a fill needed TWICE the
        result's size free - it failed on a disk with room for the result but not for two
        of it, measured on a 12 MB image (configuration sweep, 2026-09-20) - and it read
        and wrote every byte a second time.

        ``generation`` is for a copy of a publication made elsewhere (``objectcache``: the
        local copy keeps the store's token, which is how a hit is known to be current).
        FileExistsError when that generation is already here: another filler got there
        first, and its directory is not this call's to replace or remove.
        """
        import os
        import shutil
        d = self.root / key
        d.mkdir(parents=True, exist_ok=True)
        gen = generation or uuid.uuid4().hex
        if generation and self._generation_dir(key, gen).exists():
            raise FileExistsError(f"generation {gen} of {key} is already here")
        claim = self._claim(d, gen)
        if claim is None and generation and self._writer_gone(d, gen) is True:
            # a filler killed between its claim and its release leaves the claim behind,
            # and every later fill on this host then read "someone is placing it" and
            # missed - for ever on a host that never computes, because only a successful
            # put of this key prunes it (review, 2026-09-20). Death is proved the same way
            # everywhere else here: the lock its holder could not have released.
            import shutil
            shutil.rmtree(self._staging_dir(key, gen), ignore_errors=True)
            (d / f"{self.CLAIM_PREFIX}{gen}").unlink(missing_ok=True)
            claim = self._claim(d, gen)
        if generation and claim is None and (d / f"{self.CLAIM_PREFIX}{gen}").exists():
            # the claim file is O_EXCL: a concurrent copy of the same generation holds it
            raise FileExistsError(f"generation {gen} of {key} is being placed")
        placed = False
        g = self._staging_dir(key, gen)        # assembled here, renamed into place below
        try:
            g.mkdir()

            def _place(name: str, write) -> None:
                tmp = g / f"{name}.{uuid.uuid4().hex[:8]}.tmp"
                write(tmp)
                os.replace(tmp, g / name)

            def _take(src):                    # same filesystem: hand the file over
                return lambda t: os.replace(src, t)

            _place("result.json", lambda t: t.write_text(json.dumps(result), encoding="utf-8"))
            _place("meta.json", lambda t: t.write_text(json.dumps(meta, indent=2),
                                                       encoding="utf-8"))
            supplied = {"preview.png": preview_path, "statistics.json": statistics_path}
            for name in ARTIFACT_NAMES:
                src = supplied.get(name)
                if src and Path(src).exists():
                    _place(name, _take(src) if move
                           else (lambda t, s=src: shutil.copy2(s, t)))
            if output_name not in PRIMARY_NAMES:
                raise ValueError(f"{output_name!r} is not a primary output ({', '.join(PRIMARY_NAMES)})")
            _place(output_name, _take(labels_path) if move
                   else (lambda t: shutil.copy2(labels_path, t)))

            # complete: the staging directory becomes a generation, and then one rename of
            # the pointer makes it the entry. Nothing between those two is observable.
            os.replace(g, self._generation_dir(key, gen))
            placed = True
            tmp_ptr = d / f"{CURRENT_NAME}.{uuid.uuid4().hex[:8]}.tmp"
            tmp_ptr.write_text(gen, encoding="utf-8")
            os.replace(tmp_ptr, d / CURRENT_NAME)
        except BaseException:
            shutil.rmtree(g, ignore_errors=True)
            # only a generation this call renamed into place is its own to remove: with a
            # supplied token, a failed rename can mean ANOTHER copy's directory is there
            if placed and self.generation(key) != gen:
                shutil.rmtree(self._generation_dir(key, gen), ignore_errors=True)
            raise
        finally:
            self._release(d, gen, claim)
            try:
                # a publication that landed nothing leaves no entry: an empty directory
                # counts against the cache's bound and resolves to nothing (configuration
                # sweep, 2026-09-20 - a disk that ran out of space left one per attempt)
                if not placed and not any(d.iterdir()):
                    d.rmdir()
            except OSError:
                pass
        self._prune_generations(key, keep_gen=gen)
        self.evict()
        return gen

    def _prune_generations(self, key: str, *, keep_gen: str) -> None:
        """Drop what nobody can still be holding.

        Nothing is reclaimed that a reader holds (a lease: ``GENERATION_GRACE_S``), that
        a writer is still publishing (a claim that is alive, or cannot be proved dead),
        or that is current - asked of the POINTER as well as of ``keep_gen``, because
        another publication can replace this one before its pruner runs. Of the rest, a
        generation nobody has touched for the lease is stale, and the ceiling takes the
        oldest recent ones beyond ``MAX_GENERATIONS``. Every deletion goes through
        ``_reclaim``, which asks all of it again once the directory is out of reach.

        Staging is reclaimed only once its writer is PROVABLY dead, never for being old
        (``_writer_gone``); staging nobody claims - a build from before claims, or a
        filesystem without locks - is left where it is. A legacy flat entry is treated
        as a generation: kept while a reader holds it, aged out after that.

        All of it under the entry's lock, held exclusive - see ``_entry_lock``.
        """
        with self._entry_lock(key, shared=False):
            self._prune_locked(key, keep_gen=keep_gen)

    def _prune_locked(self, key: str, *, keep_gen: str) -> None:
        import shutil
        import time as _time

        d = self.root / key
        cutoff = _time.time() - self.GENERATION_GRACE_S

        def _mtime(p):
            try:
                return p.stat().st_mtime
            except OSError:
                return 0.0

        try:
            names = list(d.iterdir())
        except OSError:
            return
        # a dead writer's staging goes, and so does its claim, which would otherwise
        # read as "dead" forever while protecting nothing
        for c in names:
            if c.name.startswith(self.CLAIM_PREFIX):
                gen = c.name[len(self.CLAIM_PREFIX):]
                if self._writer_gone(d, gen) is True:
                    shutil.rmtree(self._staging_dir(key, gen), ignore_errors=True)
                    try:
                        c.unlink()
                    except OSError:
                        pass

        def held(gen: str):
            def ask(where: Path) -> bool:
                return (gen == keep_gen or self.generation(key) == gen
                        or self._leased(where) or self._writer_gone(d, gen) is False)
            return ask

        gens = sorted((p for p in names if p.name.startswith("g-") and p.is_dir()),
                      key=_mtime)
        free = [p for p in gens if not held(p.name[2:])(p)]
        stale = [p for p in free if _mtime(p) < cutoff]
        # the ceiling: oldest first, and only ever generations nobody holds
        recent = [p for p in free if p not in stale]
        overflow = recent[:max(0, len(gens) - len(stale) - self.MAX_GENERATIONS)]
        for p in stale + overflow:
            self._reclaim(p, held(p.name[2:]))
        # a flat entry from before generations existed: superseded the moment the pointer
        # names a generation, and held, like one, for as long as a reader's lease lasts
        if (d / RESULT_NAME).exists() and _mtime(d / RESULT_NAME) < cutoff:
            self._reclaim_flat(d)
        if any(p.name.startswith(self.TOMB_PREFIX) for p in names):
            self._sweep_tombs(d)

    def add_artifact(self, key: str, name: str, src_path, generation=None) -> bool:
        """Place an eventually-consistent artifact (preview.png, statistics.json) into
        the generation it was rendered for, atomically (temp + rename) - the overlap
        thread calls this after "done" has already been served.

        False when that generation is gone: superseded and pruned, or the whole entry
        evicted. Skipped, never recreated, and never written anywhere but its own
        generation's directory - so no ordering between this and :meth:`put` can put an
        artifact beside another publication's labels, in either direction. The version
        before generations checked a token and then copied, which left the copy itself
        unguarded in one direction and, once a check was added after the rename, let a
        late worker delete the artifact its successor had already placed.
        """
        if name in PRIMARY_NAMES:
            # a primary output is placed by `put` alone: an artifact of that name would give a
            # generation two, and `get` would answer with whichever it asks for first
            raise ValueError(f"{name!r} is a primary output, not an artifact")
        import os
        import shutil
        g = (self._generation_dir(key, generation) if generation
             else self._resolve(key, lease=False))    # a writer, not a reader: no lease
        if g is None or primary_output(g) is None:
            return False
        tmp = g / f"{name}.{uuid.uuid4().hex[:8]}.tmp"   # unique per writer
        shutil.copy2(src_path, tmp)
        try:
            os.replace(tmp, g / name)
        except OSError:                        # pruned between the check and the rename
            Path(tmp).unlink(missing_ok=True)
            return False
        return True

    def delete(self, key: str) -> bool:
        """Remove one entry; True if it existed. An explicit removal does not wait out
        leases: taking the entry away, from its readers too, is what was asked."""
        import shutil
        d = self.root / key
        if not d.is_dir():
            return False
        shutil.rmtree(d, ignore_errors=True)
        return True

    def evict(self) -> None:
        """Keep at most ``keep`` entries, least recently used first - except one a reader
        holds or a writer is still publishing. Eviction removes whole entries, and a read
        making an entry the most recently used protects it only until ``keep`` others
        have been touched, which a busy cache does inside one lease (2026-09-10). So
        ``keep`` is a target: an entry in use outlives it until its lease runs out, and the
        next least recently used goes in its place - an entry eviction may not take does
        not use up its turn, or the cache would grow past ``keep`` by one per such entry."""

        def _mtime(d):                         # entries can vanish between
            try:                               # iterdir and stat (concurrent
                return d.stat().st_mtime       # delete/evict); a raise here
            except OSError:                    # would fail the putting job
                return 0.0

        try:
            entries = list(self.root.iterdir())
        except OSError:
            return
        dirs = [d for d in entries if d.is_dir() and not d.name.startswith(".")]
        excess = len(dirs) - self.keep
        for d in sorted(dirs, key=_mtime):
            if excess <= 0:
                break
            # decided and moved under the entry's lock: no reader is mid-acquisition
            with self._entry_lock(d.name, shared=False):
                if self._reclaim(d, self._key_in_use):
                    excess -= 1
        if any(p.name.startswith(self.TOMB_PREFIX) for p in entries):
            self._sweep_tombs(self.root)


def _host_identity() -> str:
    """The host whose advisory locks this process can trust: its own.

    A writer's claim (``ResultCache._claim``) is an advisory lock the kernel releases
    when its holder dies, which makes "I can take it" proof of death - but only to a
    process under that kernel. On a volume several machines or containers mount, a lock
    need not reach from one to another, and there "I can take it" proves nothing. So a
    claim records the host that took it, and only that host concludes anything from it.
    Module-level so that a test can move a pruner to another host.
    """
    import socket
    return socket.gethostname()


class QueueFull(HaversackError):
    """The pending queue is at its bound; the caller should retry later."""


class ResultsNotVisible(HaversackError):
    """A result may exist, but this server's view of where it lives is stale and could
    not be refreshed: HTTP 503 with Retry-After, never a 404 or a 410.

    On Modal a view is refreshed by a volume reload, which is refused while any file on
    the volume is open in the container - as every streamed result is. A miss read from
    such a view said "purged" for 191 of 300 finished jobs (2026-09-19) whose entries the
    workers had committed. An executor that can tell a stale view from a current one
    raises this from ``confirm_absent``; one whose view is always current (a local
    filesystem) never does.
    """

#: seconds a client is told to wait before asking again after a ResultsNotVisible
NOT_VISIBLE_RETRY_AFTER_S = 5


def _local_scratch():
    """A container-LOCAL staging directory, deliberately not on any volume.

    Ingest hashes what it receives and then adopts the file into the content
    store. Staging that on a snapshot-consistent volume means a concurrent reload
    can truncate the very bytes being hashed - and guarding against it with the
    volume lock is worse than the disease on an async route: the lock would be
    held across an await on the NETWORK, so a second upload blocks the event loop
    acquiring it while the first waits to be resumed to release it. Neither
    request can finish.

    Staging locally removes the hazard instead of serializing around it. Nothing
    here needs to be visible to another container: only the adopt into the
    content store does, and that has its own lock and no awaits inside it.
    """
    import tempfile
    shm = Path("/dev/shm")
    return tempfile.mkdtemp(prefix="haversack-ingest-",
                            dir=str(shm) if shm.is_dir() else None)


def _write_guard(executor):
    """The guard a write into the job directory must hold.

    An executor backed by a snapshot-consistent volume exposes one: a concurrent
    reload elsewhere discards uncommitted writes, so a partially written file can
    be truncated under us - and this store then hashes the truncation. Hoisted
    into one helper because it was documented as mandatory on the upload path and
    then quietly skipped by the two new ingest routes.
    """
    import contextlib
    return getattr(executor, "volume_guard", None) or contextlib.nullcontext()


def _discard(jdir) -> None:
    """Drop a job directory nothing owns yet."""
    import shutil
    shutil.rmtree(jdir, ignore_errors=True)


def reference_input(staged):
    """The one image a multi-input job's artifacts render against.

    A preview and a statistics table need ONE image, and the sensible choice is
    the task's first declared channel. Shared with the Modal worker rather than
    written twice: the two sides had already picked differently (declared order
    here, client source order there), so the same request previewed a different
    channel depending on where it ran.
    """
    if isinstance(staged, dict):
        return next(iter(staged.values()), None)
    return staged


def stored_input_kind(store, digest: str) -> str | None:
    """The kind of content a stored input IS: ``labels`` for a label map with its names (a
    ``.seg.nrrd``, or any NRRD carrying segment fields - what ``POST /v1/inputs from_job=``
    promotes a result as), else ``image``; None when the entry cannot be looked at, which leaves
    the decision to the reader as before.

    A ``result:`` reference was checked against the role it is bound to from the day it existed;
    the same bytes named by their digest were not (2026-09-26, a black-box review): a
    segmentation stored with ``from_job`` ran through ``ts.v2:total_fast`` as its CT and came back
    ``done`` with 73 structures. Read from the stored entry's header, never from a name the
    caller chose: a label map is kept in its own file (``input_copy.wanted`` never transcodes one).
    """
    from .input_copy import _nrrd_header, is_copy
    from .labelmap import LABELS_KIND
    try:
        where = Path(store.resolve(digest))
        if where.is_dir() or is_copy(where):
            return "image"                 # a series, or an image decoded into its input copy
        with open(where, "rb") as f:
            nrrd = f.read(4) == b"NRRD"    # the content, not the name an upload was sent under
        if nrrd and any(k.startswith("segment") for k in _nrrd_header(where)):
            return LABELS_KIND
        return "image"
    except Exception:                      # noqa: BLE001 - unreadable here: the reader decides
        return None


_DIGEST_SPELLING = re.compile(r"(?i)(sha256|sha256-tree):([0-9a-f]+)")


def canonical_digest(value) -> str:
    """A content digest as the server keys it: the algorithm and hex in lower case. Hex is
    case-insensitive by definition, and ``sha256:<UPPER>`` was answered "not held" for content
    the server held (2026-09-26). Anything else is returned stripped, for ``is_digest`` to
    judge as before."""
    v = str(value or "").strip()
    return v.lower() if _DIGEST_SPELLING.fullmatch(v) else v


_PATH_TAIL = r"(?:/[^\s'\"()\[\],;]*)?"


def scrub_server_paths(text, roots) -> str:
    """``text`` with every path under one of ``roots`` cut to its last component.

    A job's ``error`` is the exception's own words, and those name the server's files - its
    work directory, the series cache, an input store's per-process view, a temporary file
    (2026-09-26, a black-box review). The name of the file is the useful part to a client; where
    this server keeps it is not the client's business. The full text stays in the server's log
    and its job store. Only paths under the roots given are touched, so an API route in a
    message (``/v1/jobs/...``) is left alone.
    """
    if not text:
        return text
    for root in sorted({str(r).rstrip("/") for r in roots if r and str(r) != "/"},
                       key=len, reverse=True):
        def _cut(m):
            p, tail = m.group(0), ""
            while p and p[-1] in ":.":     # sentence punctuation after a path
                p, tail = p[:-1], p[-1] + tail
            return (p.rstrip("/").rsplit("/", 1)[-1] or "<server>") + tail
        text = re.sub(re.escape(root) + _PATH_TAIL, _cut, text)
    return text


class _FileAt:
    """A one-entry "store" that resolves to a file already in hand, for
    :func:`stored_input_kind` on an upload."""

    def __init__(self, path):
        self.path = Path(path)

    def resolve(self, digest):
        return self.path


def upload_name(role: str, filename: str) -> str:
    """A multi-input upload's file name in the job dir: the role HEX-encoded, so it can
    be read back exactly. It was ``input_{role}_{name}``, matched by prefix, and a role is
    the model's own spelling - underscores included - so roles ``t1`` and ``t1_ce`` both
    matched ``input_t1_ce_...`` (review, 2026-09-19); a role with a ``/`` in it would
    have named a subdirectory."""
    return f"input_{role.encode('utf-8').hex()}_{Path(filename).name}"


def upload_role(name: str) -> str | None:
    """The role an :func:`upload_name` file was saved under, or None for any other name."""
    parts = name.split("_", 2)
    if len(parts) != 3 or parts[0] != "input":
        return None
    try:
        return bytes.fromhex(parts[1]).decode("utf-8")
    except ValueError:
        return None


def result_payload(seg, labels_path) -> dict:
    """A finished job's public result, built ONCE for both executors.

    They had drifted already - the Modal side reported `timings` and the local
    side did not - which is the same shape as the bug where an engine worker and
    the API disagreed about weights identity: two hand-written copies of one
    thing.

    `outputs` is new: the content digest of what the job produced. It is what
    lets a client skip re-downloading a result it already holds (it IS the
    ETag), and what lets one job's output become another's input without the
    bytes taking a round trip out through the client and back.
    """
    from .content import digest_file
    out = {"names": {int(k): v for k, v in seg.schema.names.items()},
           "volumes_ml": {k: round(float(v), 2) for k, v in seg.volumes_ml().items()},
           "provenance": seg.provenance}
    timings = getattr(seg, "timings", None)
    if timings:
        out["timings"] = {k: round(float(v), 3) for k, v in timings.items()}
    p = Path(labels_path) if labels_path is not None else None
    if p is not None and p.exists():
        out["outputs"] = [{"name": "labels", "sha256": digest_file(p),
                           "bytes": p.stat().st_size}]
    return out


def ranked_payload(seg, path) -> dict:
    """A finished ranked job's public result (``result.json``): the store's digest first, as every
    result's is (``etag_of``, ``same_output`` and ``result:`` read ``outputs[0]``), with ``kind:
    ranked`` so a reference cannot bind a store where an image or labels belong - and the run's
    names, volumes and provenance, which the store was computed with."""
    from .content import digest_file
    out = result_payload(seg, None)               # names, volumes, provenance, timings; no labels file
    p = Path(path)
    out["outputs"] = [{"name": "rankfield", "kind": "rankfield", "sha256": digest_file(p),
                       "bytes": p.stat().st_size}]
    return out


def etag_of(key: str, result=None) -> str:
    """The validator for a stored result.

    The CONTENT digest when we know it, so a client holding those exact bytes
    gets a 304 - and so two runs that produce identical bytes are identical to a
    cache. Falls back to the request key, which is what this always used to be:
    a fine validator for "the same request", but it changes when a weights
    version bumps even if the output does not.
    """
    outs = (result or {}).get("outputs") or []
    digest = outs[0].get("sha256") if outs else None
    return f'"{digest}"' if digest else f'"{key[:32]}"'


def body_etag(body: bytes) -> str:
    """The validator for an ARTIFACT beside a result - ``meta.json``, ``preview.png``,
    ``statistics.json`` / ``.tsv`` - the digest of the very bytes sent, in the labels'
    own spelling (``"sha256:<hex>"``).

    Until 2026-09-21 all four carried ``etag_of(key)``, the KEY-derived tag, under
    ``Cache-Control: public, max-age=3600``. A ``Cache-Control: no-cache`` recompute
    republishes under the same key, so one URL then served other bytes (a preview of
    8290 and then 8309 bytes, a ``volume_ml`` of 0.384 and then 0.512) under an
    unchanged STRONG validator, which RFC 9110 8.8.1 forbids: a cache revalidating its
    stored preview was told "not modified" about a picture of the previous labels - and
    the four URLs of one result shared the one value besides.

    Why the content and not the publication (a generation id plus the artifact's name,
    which needs no read): the read is already paid. Three of the four bodies are BUILT
    per request - ``meta.json`` from the result record, ``statistics.json``
    re-serialized, the ``.tsv`` derived from it - so a HEAD owes them to its
    ``Content-Length`` anyway, and the fourth is a PNG of kilobytes. A digest is also
    right where a generation's name is not: a legacy flat entry has no generation, a
    job's own copy is no publication at all, and two publications that render the same
    bytes ARE the same to a cache - the labels' tag has always said so. A file that
    goes from absent to present within a generation goes from 404 to 200: no tag was
    ever issued for the absence, so none can be stale.
    """
    import hashlib
    return f'"sha256:{hashlib.sha256(body).hexdigest()}"'


def answer_body(request, resp, headers: dict):
    """GET's 200, HEAD's 200 or either one's 304 for a response whose body is in hand.

    ``resp`` is the 200 a GET sends and ``headers`` its caching fields, ETag included.
    HEAD gets the same fields and the GET's ``Content-Length`` and ``Content-Type`` with
    no content (RFC 9110 9.3.2); a matching ``If-None-Match`` gets the 304 on either
    verb, as the labels do. One function, so the two verbs cannot come to disagree
    about a representation - the defect the labels' probe had until 2026-09-21."""
    from fastapi.responses import Response
    fresh = not_modified(request, headers["ETag"], headers)
    if fresh is not None:
        return fresh
    if request.method == "HEAD":
        head = Response(status_code=200, headers=headers)
        head.headers["content-length"] = str(len(resp.body))   # GET's, never the 0 of
        head.headers["content-type"] = resp.headers["content-type"]    # an empty body
        return head
    resp.headers.update(headers)
    return resp


def artifact_response(view: str, *, result=None, path=None):
    """The 200 a GET of one ``ARTIFACT_VIEWS`` name sends, its body in hand: the result
    record for ``meta.json``, else built from the generation's file at ``path``. In
    hand - never a ``FileResponse`` streamed at send time - because the validator is
    the digest of these bytes (``body_etag``) and a HEAD owes their length; the files
    are a PNG and a JSON of kilobytes. Blocking (it reads), so async routes call it off
    the loop; OSError when the file left between the look and the read."""
    from fastapi.responses import JSONResponse, Response
    if view == "meta.json":
        return JSONResponse(result or {})
    if view == "preview.png":
        return Response(Path(path).read_bytes(), media_type="image/png")
    stats = json.loads(Path(path).read_text(encoding="utf-8"))
    if view == "statistics.json":
        return JSONResponse(stats)
    from .statistics import statistics_tsv
    return Response(statistics_tsv(stats), media_type="text/tab-separated-values")


def same_output(own, published) -> bool:
    """Whether a published entry holds the bytes a job reported: both content digests
    known and equal. A missing digest is not a match - an entry whose result.json is
    unreadable reads as ``{}``, and a legacy entry may carry no ``outputs``, and the
    first version accepted both and served another publication's bytes as the job's
    (review, 2026-09-19)."""
    def digest(r):
        outs = (r or {}).get("outputs") or []
        return outs[0].get("sha256") if outs else None
    a = digest(own)
    return a is not None and a == digest(published)


#: what a 304 repeats from its 200, beside the ETag (RFC 9110 15.4.5; Date is the server's)
_NOT_MODIFIED_KEEPS = ("cache-control", "content-location", "expires", "vary")


def not_modified(request, etag: str, headers=None):
    """A 304 when the client already holds this exact content, else None.

    RFC 9110 conditional GET - the other half of an ETag we have been sending
    but never acting on. A label volume is megabytes and a Slicer client asks
    for the same one repeatedly.

    ``headers`` is what the 200 would have carried. RFC 9110 15.4.5: a 304 MUST repeat
    the 200's Cache-Control, Content-Location, Expires and Vary, and until 2026-09-21
    this sent the ETag alone, so the path surface's 304 dropped ``Cache-Control: public,
    max-age=3600`` and ``Vary: Prefer``. Nothing else crosses, and ``Preference-Applied``
    deliberately: the same section says SHOULD NOT for the rest, and a cache writes a
    304's fields onto EVERY stored response holding that validator (RFC 9111 4.3.4) -
    chosen by the ETag, not by the request's Prefer - so one ``wait=30`` echo would land
    on the variant stored for a plain GET. The echo is optional on any response (RFC
    7240 3). A 200 with none of the four (the job result route's) gets the 304 it
    always got.
    """
    from fastapi.responses import Response
    raw = ""
    try:
        raw = request.headers.get("if-none-match") or ""
    except Exception:
        return None
    if not raw:
        return None

    def opaque(tag: str) -> str:
        # RFC 9110 13.1.2: If-None-Match uses the WEAK comparison - two tags match when
        # their opaque parts do, whatever `W/` either wears (8.8.3.2). Until 2026-09-21
        # the strings were compared whole, so `W/"<our tag>"` - what a proxy that
        # re-embeds a body hands back, having weakened the tag as it must - was a 200
        # and the whole label volume again. The safe direction, and still wrong.
        tag = tag.strip()
        return tag[2:] if tag.startswith("W/") else tag

    tags = {opaque(t) for t in raw.split(",")}
    if opaque(etag) in tags or "*" in tags:
        kept = {k: v for k, v in (headers or {}).items()
                if k.lower() in _NOT_MODIFIED_KEEPS}
        return Response(status_code=304, headers={**kept, "ETag": etag})
    return None


def publish_completion(*, segmenter, task, identity, options, cache_key,
                       labels_path, input_image, artifacts, cache_enabled,
                       migrate_key, set_pending, clear_pending, put,
                       mark_done, start_worker, kind: str = "segment"):
    """The one correct publication order for a finished segmentation, shared
    by both executors so ordering fixes cannot drift apart (in the 2026-08-25
    review, C7 and C8 each had to be written twice):

      1. re-key: the job may have been keyed while weights versions were
         still "unknown" (first install); they are knowable now, so migrate
         the key and the single-flight marker together - otherwise the entry
         is orphaned and every later probe misses forever.
      2. load the artifact pair while the input is still staged - the only
         inline artifact cost (~0.3 s).
      3. pending marker BEFORE the entry is visible: a probe that finds the
         fresh entry with no artifact must read "pending", never a
         definitive absence it would treat as a 404.
      4. the cache put (the entry's labels file is its commit marker).
      5. done becomes observable.
      6. the artifact worker starts; a start failure clears pending and must
         never disturb the already-observable done.

    The environment differences (in-process set vs Dict markers, volume
    commits, _emit vs a state field) ride in the callables; the ORDER lives
    here. Returns (cache_key, pair)."""
    if cache_key:
        try:
            # the kind only when it is not a segmentation: that call stays exactly as it was
            fresh = result_key(identity, task, options, versions_for(segmenter, task, kind),
                               **({"kind": kind} if kind != "segment" else {}))
            if fresh != cache_key:
                migrate_key(cache_key, fresh)
                cache_key = fresh
        except Exception:
            pass
    pair = None
    if artifacts and cache_enabled and cache_key:
        try:
            from .preview import load_oriented_pair
            pair = load_oriented_pair(input_image, labels_path)
        except Exception:
            pair = None
    if pair is not None:
        set_pending(cache_key)
    generation = None
    if cache_enabled and cache_key:
        # the token identifying THIS publication; the artifact worker presents it
        # so a worker from an earlier one cannot write into this result
        generation = put(cache_key)
    mark_done()
    if pair is not None:
        try:
            start_worker(pair, cache_key, generation)
        except Exception:
            clear_pending(cache_key)
    return cache_key, pair


def artifact_overlap(pair, task, artifacts, *, preview_out, statistics_out,
                     place, finish, unavailable=None):
    """The overlap thread's body, shared by both executors: render and
    compute from the in-RAM pair (no input or disk dependence), hand each
    file to ``place(name, path) -> bool`` (atomic within the cache; False
    when the entry was evicted meanwhile - dropped, never recreated), and
    ALWAYS run ``finish(placed)`` - the pending-marker clear, plus any
    commit/logging the environment wants. ``placed`` is [(name, seconds)]
    for what actually landed.

    ``artifacts`` is what THIS job renders - its request's list held to the
    deployment's set (``jobpolicy.wanted_deliverables``) - and nothing outside it is
    rendered: a declined preview costs no render. The renderers live here, so the two
    names are spelled here too; the files they land as are ``jobpolicy.DELIVERABLES``'s,
    and a test drives each name of that table through this function.

    Each deliverable is rendered on its own (review, 2026-09-25): one ``try`` around both
    let a preview's failure cost the statistics too, and neither was said anywhere - the
    job kept linking both, and both 404ed. What did not render is handed to
    ``unavailable({name: why})`` BEFORE ``finish``, so a reader who sees no pending render
    also sees why."""
    from .jobpolicy import RENDER_EMPTY, RENDER_FAILED
    placed, failed = [], {}

    def one(name, render):
        # the seconds are the render's own: `place` can wait on a lock the
        # worker holds, and counting that wait here once passed a 2-minute
        # jobs-Dict sweep off as a 127 s preview (2026-09-19)
        t0 = time.time()
        try:
            out = render()
        except Exception as e:                 # noqa: BLE001 - said, never raised
            failed[name] = f"{RENDER_FAILED} ({type(e).__name__}: {e})"
            return
        dt = time.time() - t0
        if not out:
            failed[name] = RENDER_EMPTY
        elif place(DELIVERABLES[name], out):
            placed.append((name, dt))

    try:
        from .preview import render_preview
        from .statistics import compute_statistics
        if "preview" in artifacts:
            one("preview", lambda: render_preview(None, None, preview_out, title=task, pair=pair))
        if "statistics" in artifacts:
            one("statistics", lambda: compute_statistics(None, None, statistics_out, pair=pair))
    except Exception as e:                     # noqa: BLE001 - an import, say
        for name in artifacts:
            if name not in dict(placed):
                failed.setdefault(name, f"{RENDER_FAILED} ({type(e).__name__}: {e})")
    finally:
        try:
            if failed and unavailable is not None:
                unavailable(failed)
        finally:
            finish(placed)


@dataclass
class JobRecord:
    """Everything the server knows about one job. Mutated only under the executor's
    condition variable, except ``progress`` which is an atomic rebind (same contract
    as :class:`haversack.job.Job`)."""

    id: str
    task: str
    options: dict
    dir: Path
    input_path: Path
    kind: str = "segment"                         # or "prepare": install weights only
    state: str = "queued"
    created: float = field(default_factory=time.time)
    started: float | None = None
    finished: float | None = None
    progress: dict | None = None
    error: str | None = None
    result: dict | None = None                    # names / volumes_ml / provenance
    labels_path: Path | None = None
    source: list = field(default_factory=list)
    #: ``((role, path_or_None), ...)`` in the model's channel order, for a task
    #: that takes more than one input. Empty for the single-input case, which
    #: keeps using ``input_path``. Paths live here rather than on the ``source``
    #: entries because those are serialized to clients, and a server filesystem
    #: path is not theirs to see.
    input_paths: tuple = ()
    input_identity: tuple = ()
    cached: bool = False
    cache_key: str | None = None
    cancel_token: CancelToken = field(default_factory=CancelToken)
    subscribers: list = field(default_factory=list)   # (event_loop, asyncio.Queue)
    source_tokens: dict | None = None             # credentials in transit: never serialized
    #: `Cache-Control: no-cache` asked for a recompute. Carried to the FETCH as
    #: well as the result lookup: for a source whose identity is not
    #: version-pinned (`s3:`, `github:`), recomputing from a stale cached input
    #: answers the same wrong thing again, only slower.
    refresh_input: bool = False
    #: Set when a refresh was asked for and could not happen (the input was in
    #: use). Surfaced on the job so a caller can retry rather than trust a result
    #: computed from bytes it asked not to reuse.
    input_refresh_skipped: bool = False
    #: The weights version the caller pinned (`task@version`), or None. `task` stays
    #: canonical - it is what keys and routes - and the worker runs
    #: ``run_name(task, version)``, so the catalog installs that version or refuses it.
    version: str | None = None
    #: What this job renders beside its labels, in ``jobpolicy.DELIVERABLES`` order: the
    #: request's list, or the deployment's set when it named none (2026-09-20). On the
    #: record and NOT in ``options``, which are hashed into ``cache_key``: asking for a
    #: preview, or declining one, must never move a result's key.
    deliverables: tuple = ()
    #: ``{name: why}`` for what a cache hit's list named, the stored generation lacks,
    #: and this server could not render then - said on the job rather than left out of
    #: ``links`` without a word.
    deliverables_unavailable: dict | None = None
    #: Set, under the executor's condition variable, when publication has read the list:
    #: a submit that joins this flight may add to ``deliverables`` only before that.
    #: Runtime only - a restored job has not reached publication.
    deliverables_sealed: bool = False


class _PrepareDone(Exception):
    """Control-flow escape: a prepare job finished; skip the segment path."""


class TagsWithheld(Exception):
    """An input's tags are not handed back: a credential may have reached its bytes."""


class LocalExecutor:
    """A bounded FIFO of jobs ahead of one dispatcher thread.

    ``segmenter`` supplies the task catalog and, by default, the work itself;
    ``segment_fn`` overrides the work for tests (same signature as
    ``Segmenter.segment``). ``max_pending`` bounds the queue - submit past it raises
    :class:`QueueFull` (HTTP 429). Finished jobs and their files are kept until
    ``keep_finished`` more finish after them.
    """

    #: A cache hit renders what its result lacks (``_render_on_hit``): the 404 of a missing
    #: deliverable may advise a plain submit. Modal renders only where it computes.
    renders_on_hit = True

    #: ``kind=embed`` jobs run here (2026-09-23): in-process, on this server's device.
    embeds = True

    @property
    def ranked_stores(self) -> bool:
        """Whether ``kind=rankfield`` jobs run here (2026-09-24): in-process, when the packages a
        store is written with are installed (core; absent only in a lean install). Asked at the submit door, so a
        server without them refuses at once rather than failing a queued job."""
        from .ranked_output import store_extra_missing
        return not store_extra_missing()

    def __init__(self, segmenter, *, workdir, max_pending: int = 16,
                 keep_finished: int = 50, segment_fn=None, fetch_idc_fn=None,
                 cache_dir=None, keep_cached: int = 500,
                 input_cache_bytes: int = 8 << 30, read_fn=None, sources=None,
                 artifacts=("preview", "statistics"), jobs_ttl_h: float = 24.0, embed_fn=None,
                 result_store=None, sweep_interval_h: float = 24.0, dicom_withhold=()):
        self.segmenter = segmenter
        #: what ``dicom.json`` never hands back as a value: dicom-spec §5 groups and PS3.6
        #: keywords, each value present replaced by null (§4.3) - the operator's policy, checked
        #: here so a misspelled name stops the server rather than withholding nothing
        from duckn.dicom_tags import keywords_named
        keywords_named(dicom_withhold or ())
        self.dicom_withhold = tuple(dicom_withhold or ())
        self.workdir = Path(workdir)
        self.workdir.mkdir(parents=True, exist_ok=True)
        self.max_pending = int(max_pending)
        self.keep_finished = int(keep_finished)
        self._segment = segment_fn or segmenter.segment
        #: the embedding job's work (``encoders.pipeline.embed_file``'s signature); tests inject one
        self._encode = embed_fn
        self._fetch_idc = fetch_idc_fn or _fetch_idc_series
        self.sources = _source_registry(sources)
        if os.environ.get("HAVERSACK_INPUT_STORE", "").strip().lower() == "blobs":
            # step 6 of docs/cache-consolidation.md, behind its flag until it has soaked:
            # inputs as blobs + one ref each, read through views a pin holds (inputstore)
            from .inputstore import ServerInputs
            self.series_cache = ServerInputs(self.workdir / "input_store", self._fetch_source,
                                             budget_bytes=input_cache_bytes,
                                             legacy_root=self.workdir / "series_cache")
            self.content = self.series_cache
        else:
            self.series_cache = SeriesCache(self.workdir / "series_cache", self._fetch_source,
                                            budget_bytes=input_cache_bytes)
            # Uploads addressed by their own bytes, sharing the series cache's root,
            # budget and pin discipline - an entry is an entry whether a client sent
            # it or the server fetched it.
            self.content = ContentStore(self.series_cache)
        self.read_ahead = ReadAhead(read_fn)
        #: The deliverables this deployment renders: the default for a request that names
        #: none, and the ceiling for one that does (the submit door refuses a name
        #: outside it).
        self.artifacts = set(artifacts or ())
        # cache_key -> (owner jid, set at, names being rendered). The single flight of
        # the artifact path: one render per result at a time, whether it follows a
        # compute or a cache hit whose list the stored generation does not satisfy.
        self._artifacts_pending: dict = {}
        self.cache = ResultCache(cache_dir, keep=keep_cached) if cache_dir else None
        if result_store is not None:
            # the shared store is the authority and the local cache its read-through copy
            # (objectcache, 2026-09-19); a URL is opened and probed, a store object is used
            if self.cache is None:
                raise InputError("--result-store needs a local result cache in front of it; "
                                 "drop --no-result-cache")
            from .objectcache import SharedResultCache
            self._sweep_every = float(sweep_interval_h) * 3600
            try:
                self.cache = (SharedResultCache.open(result_store, self.cache)
                              if isinstance(result_store, str)
                              else SharedResultCache(result_store, self.cache))
            except InputError:
                raise                          # already names what to do about it
            except Exception as e:             # noqa: BLE001
                # a wrong bucket, absent credentials, DNS: one line naming the fix, like
                # every other startup failure, not a traceback from inside obstore
                raise InputError(
                    f"--result-store {result_store}: {type(e).__name__}: {e}; check the "
                    "bucket name and that credentials are in the environment "
                    "(AWS_ACCESS_KEY_ID / AWS_SECRET_ACCESS_KEY / AWS_ENDPOINT / "
                    "AWS_REGION for S3-compatible stores)") from None
        self._sweeper = None
        #: what the listing remembers of each publication's meta.json - see ListingMemo
        self._listing_memo = ListingMemo()
        # `result:<key>` - a result this server computed, as an input - resolves against
        # THIS executor's cache, so the executor builds that source; it is in nobody's
        # `default_sources()`. Added to whatever registry the operator chose, because it
        # names no repository they could have chosen: it is a capability of having a
        # result cache, and a server without one does not offer the kind at all.
        if self.cache is not None and ResultSource.prefix not in self.sources:
            self.sources[ResultSource.prefix] = ResultSource(self._result_entry)
        self._inflight: dict[str, str] = {}      # cache key -> active job id
        self._joiners: dict[str, int] = {}       # job id -> clients riding it besides the first
        self._cv = threading.Condition()
        self._pending: deque[str] = deque()
        self._jobs: dict[str, JobRecord] = {}
        self._done_order: deque[str] = deque()
        self._stop = False
        # Durable records. The in-memory structures above stay as the RUNTIME
        # view - they hold live objects (cancel tokens, SSE subscriber queues)
        # that cannot be written down - but they are derived: rebuilt from the
        # store at startup, and every mutation writes both inside one `_cv`
        # block so they move together. The store is authoritative across
        # restarts, memory within a run, and reconcile() is the defined point
        # where the two are reconciled rather than trusted to agree.
        self.jobs_db = JobStore(self.workdir / "jobs.db")
        self.jobs_ttl_s = float(jobs_ttl_h) * 3600.0
        self._restore()
        self._thread = threading.Thread(target=self._dispatch, name="haversack-serve", daemon=True)
        self._thread.start()
        # last, because it sweeps `cache`, which has to exist first
        if result_store is not None and getattr(self, "_sweep_every", 0) > 0:
            self._start_sweeper()

    # -- durability ---------------------------------------------------------
    def _persisted(self, rec: JobRecord) -> dict:
        """The writable view of a record.

        Three fields never go: `cancel_token` and `subscribers` are live
        objects, and `source_tokens` are per-request credentials the record
        itself marks "never serialized". What IS recorded is whether the job
        had any, because that decides whether it can be replayed after a
        restart or has to fail asking the caller to resubmit.
        """
        return {"id": rec.id, "task": rec.task, "state": rec.state, "kind": rec.kind,
                "options": rec.options, "cache_key": rec.cache_key,
                "created": rec.created, "started": rec.started,
                "finished": rec.finished, "error": rec.error, "result": rec.result,
                "cached": rec.cached, "source": rec.source,
                "input_identity": list(rec.input_identity),
                "input_path": str(rec.input_path) if rec.input_path else None,
                "input_paths": [[r, str(p) if p else None] for r, p in rec.input_paths],
                "labels_path": str(rec.labels_path) if rec.labels_path else None,
                "refresh_input": bool(rec.refresh_input),
                "input_refresh_skipped": bool(rec.input_refresh_skipped),
                "version": rec.version,
                # a list, so a job re-queued by a restart still declines what its
                # caller declined (an absent key is a record from before the list)
                "deliverables": list(rec.deliverables),
                "deliverables_unavailable": rec.deliverables_unavailable,
                "needed_credentials": bool(rec.source_tokens)}

    def _persist(self, rec: JobRecord) -> None:
        try:
            self.jobs_db.put(self._persisted(rec))
        except Exception:
            pass            # a bookkeeping failure must not fail a running job

    def _restore(self) -> None:
        """Rebuild the runtime view from the store, then delete what nothing owns.

        Two halves that only work together: a job directory is reclaimable
        exactly when no record refers to it, and that question is only
        answerable now that records survive the process. Before this, every
        directory from a previous run was stranded - nothing in memory knew it
        existed and nothing scanned the disk.
        """
        import shutil
        try:
            resumable = self.jobs_db.reconcile()
            known = {r["id"] for r in self.jobs_db.all(limit=10_000)}
        except Exception as e:
            # Booting matters more than restoring, so this is swallowed - but
            # not silently. Skipping restore also skips the sweep below, so a
            # store that cannot be read looks exactly like an empty one while
            # job directories quietly accumulate. Say so.
            import warnings
            warnings.warn(f"could not restore jobs from {self.jobs_db.path} ({e}); "
                          "queued work from the previous run is lost and orphaned "
                          "job directories were not reclaimed", stacklevel=2)
            return
        for r in resumable:
            rec = JobRecord(id=r["id"], task=r["task"], options=r.get("options") or {},
                            dir=self.workdir / r["id"],
                            input_path=Path(r["input_path"]) if r.get("input_path") else None,
                            kind=r.get("kind") or "segment",
                            source=r.get("source") or [],
                            input_identity=tuple(r.get("input_identity") or ()),
                            input_paths=tuple((a, Path(b) if b else None)
                                              for a, b in (r.get("input_paths") or [])),
                            cache_key=r.get("cache_key"), created=r.get("created") or time.time(),
                            refresh_input=bool(r.get("refresh_input")),
                            input_refresh_skipped=bool(r.get("input_refresh_skipped")),
                            version=r.get("version"),
                            # held to what THIS process renders; a record from before
                            # the list has none and gets the deployment's set
                            deliverables=(() if r.get("kind") in NOT_LABELS else
                                          wanted_deliverables(r.get("deliverables"),
                                                              self.artifacts)))
            self._jobs[rec.id] = rec
            self._pending.append(rec.id)
            # the single-flight marker, oldest first: without it a re-ask for the same
            # key after a restart starts a second job, and a DELETE cancels the wrong one
            # ...but not for a pinned job: whether its pin was verified is not recorded,
            # and a marker is only exact for one that was (see submit)
            if rec.cache_key and not rec.version and rec.cache_key not in self._inflight:
                self._inflight[rec.cache_key] = rec.id
        # Positively identify a job directory before removing it, rather than
        # removing whatever is not recognized. The workdir legitimately holds
        # other things - the series cache, and a result cache when one is
        # configured under it - and a deny-list deleted the result cache the
        # first time this ran. Never delete what you cannot name.
        import re
        looks_like_a_job = re.compile(r"[0-9a-f]{12}\Z")      # new_job_dir()'s ids
        for d in self.workdir.iterdir():
            if d.is_dir() and looks_like_a_job.match(d.name) and d.name not in known:
                shutil.rmtree(d, ignore_errors=True)

    def _fetch_source(self, key: str, entry, credentials=None):
        """Series-cache fetch dispatcher: keys are ``<prefix>:<identifier>``.
        The idc prefix routes through ``self._fetch_idc`` so the historical
        ``fetch_idc_fn`` injection seam keeps working. ``credentials`` is a
        per-request secret, forwarded and never stored."""
        prefix, ident = key.split(":", 1)
        if prefix == "idc":
            return self._fetch_idc(ident, entry)
        return _fetch_recording_origin(self.sources[prefix], ident, entry, credentials)

    def input_tags(self, prefix: str, ident: str, *, fetch: bool, select=None,
                   per_slice: bool = True) -> dict | None:
        """A hosted input's DICOM tags (``GET /v1/<prefix>/<identifier>/dicom.json``,
        2026-09-27): ``inputs.Input.tags`` of what this server holds, the operator's
        ``dicom_withhold`` applied. None when the input is not held and ``fetch`` is False
        (HEAD, which never fetches); fetched otherwise, into the same cache a job reads.

        Hosted sources only - an upload's tags are never handed back, as its bytes never are
        (the user's decision). And not bytes a credential may have reached: the cache files
        them under the source's identity whoever fetched them, so an entry whose record says a
        credential came with its fetch - or that predates the record saying so, from a source
        where one could reach private bytes - is refused with :class:`TagsWithheld`."""
        from .inputs import Input
        from .sources import read_input_record
        src = self.sources[prefix]
        key = source_cache_key({"kind": prefix, "id": ident}).key
        self.series_cache.pin(key)             # BEFORE the look: eviction skips a pin
        try:
            if self.series_cache.has(key):
                path = self.series_cache.path(key)
            elif not fetch:
                return None
            else:
                path = self.series_cache.get_or_fetch(key)
            record = read_input_record(self.series_cache.entry(key)) or {}
            said = record.get("credentialed")
            if said is True or (said is None
                                and getattr(src, "credentials_reach_private", False) is True):
                raise TagsWithheld(
                    f"{prefix}:{ident} was fetched with a credential"
                    + ("" if said is True else ", or before this server recorded whether it was")
                    + ": its content is not handed back to other callers")
            return Input(f"{prefix}:{ident}", path, record).tags(
                select=select, withhold=self.dicom_withhold or None, per_slice=per_slice)
        finally:
            self.series_cache.unpin(key)

    # -- intake --------------------------------------------------------------
    def new_job_dir(self) -> tuple[str, Path]:
        jid = uuid.uuid4().hex[:12]
        d = self.workdir / jid
        d.mkdir(parents=True, exist_ok=True)
        return jid, d

    @property
    def accepting(self) -> bool:
        with self._cv:
            return len(self._pending) < self.max_pending

    def submit(self, jid: str, jdir: Path, input_path, task: str, options: dict,
               *, source=None, identity: tuple = (), no_cache: bool = False,
               source_tokens: dict | None = None, inputs: tuple = (),
               refresh_input: bool = False, version: str | None = None,
               deliverables=None, kind: str = "segment") -> JobRecord:
        # `deliverables`: the request's list (None: it named none). It goes on the
        # record and is never seen by `result_key` below - rendering a preview, or
        # declining one, is not a different result (2026-09-20). An embedding job renders
        # none: a preview and statistics are of labels (2026-09-23).
        rec = JobRecord(id=jid, task=task, options=options, dir=jdir, input_path=input_path,
                        source=list(source or [{"kind": "upload"}]), input_identity=tuple(identity),
                        input_paths=tuple(inputs), source_tokens=source_tokens or None,
                        refresh_input=bool(refresh_input), version=version, kind=kind,
                        deliverables=(() if kind in NOT_LABELS
                                      else wanted_deliverables(deliverables, self.artifacts)))
        if self.cache is not None and identity:
            rec.cache_key = result_key(identity, task, options, versions_for(self.segmenter, task, kind),
                                       **({"kind": kind} if kind != "segment" else {}))
            if not no_cache:
                hit = self.cache.get(rec.cache_key)
                if hit is not None:
                    rec.labels_path, rec.result = Path(hit[0]), hit[1]
                    rec.state, rec.cached = "done", True
                    rec.started = rec.finished = time.time()
                    # a hit still honors the list: before the record is written or
                    # seen, so its first status already says what it could not deliver
                    self._render_on_hit(rec)
                    self._persist(rec)
                    with self._cv:
                        self._jobs[jid] = rec
                        self._done_order.append(jid)
                    self._emit(rec)
                    self._evict()
                    return rec
        with self._cv:
            # Ask twice, compute once - also when the asks overlap: an identical key
            # already in flight is joined, not duplicated (the path surface does the
            # same through find_inflight). The new job's directory is discarded.
            if rec.cache_key and not no_cache:
                other = self._jobs.get(self._inflight.get(rec.cache_key))
                # ...but only a flight fetched with the SAME source credentials: a caller
                # without them must not ride one that used somebody else's
                if (other is not None and other.state in ACTIVE
                        and (other.source_tokens or None) == (rec.source_tokens or None)):
                    import shutil
                    shutil.rmtree(jdir, ignore_errors=True)
                    self._joiners[other.id] = self._joiners.get(other.id, 0) + 1
                    # One flight, one render: what this caller asked for joins that
                    # job's list, never narrows it, and only while publication has not
                    # read it - after that the job's own `deliverables` says what it
                    # delivers, and a later ask is a cache hit, which renders the rest.
                    if not other.deliverables_sealed:
                        both = set(other.deliverables) | set(rec.deliverables)
                        if both != set(other.deliverables):
                            other.deliverables = wanted_deliverables(both, self.artifacts)
                            self._persist(other)
                    return other
            if len(self._pending) >= self.max_pending:
                raise QueueFull(f"queue is full ({self.max_pending} pending)")
            self._jobs[jid] = rec
            self._pending.append(jid)
            # A pin the route could not verify (it forced no_cache for it) is keyed on an
            # UNKNOWN installed version, and its marker let an unpinned ask of the same
            # bytes join it - inheriting a bad pin's failure, or a good pin's version
            # (review 2026-09-12). It gets a marker only once it re-keys on what it
            # actually installed (_migrate below), when joining it is exact.
            if rec.cache_key and not (version and no_cache):
                self._inflight[rec.cache_key] = jid
            # written inside the same _cv block as the in-memory insert, so the
            # durable record and the runtime view move together
            self._persist(rec)
            busy = any(r.state == "running" for r in self._jobs.values())
            self._cv.notify()
        self._emit(rec)
        if busy:
            self._prefetch_next()          # overlap this fetch with the running job
        return rec

    def submit_prepare(self, jid: str, jdir: Path, task: str) -> JobRecord:
        """Queue a weights-install job: same queue, no input, no cache."""
        rec = JobRecord(id=jid, task=task, options={}, dir=jdir, input_path=None,
                        kind="prepare", source=[])
        with self._cv:
            if len(self._pending) >= self.max_pending:
                raise QueueFull(f"queue is full ({self.max_pending} pending)")
            self._jobs[jid] = rec
            self._pending.append(jid)
            self._cv.notify()
        self._emit(rec)
        return rec

    # -- cache face (shared by the path surface and the public tier) ---------
    def cache_get(self, key: str):
        return self.cache.get(key) if self.cache is not None else None

    def _result_entry(self, key: str, *, fresh: bool = False):
        """The reader a :class:`~haversack.sources.ResultSource` resolves through: the
        LEASED lookup, so the generation it hands back outlives the copy a fetch makes of
        it whatever is published or evicted meanwhile (``GENERATION_GRACE_S``). ``fresh``
        means nothing here: a local filesystem is always the current view."""
        import contextlib
        return contextlib.nullcontext(self.cache_get(key))

    def find_inflight(self, key: str):
        with self._cv:
            jid = self._inflight.get(key)
            rec = self._jobs.get(jid) if jid else None
        return jid if rec is not None and rec.state in ACTIVE else None

    def cache_delete(self, key: str) -> bool:
        return self.cache.delete(key) if self.cache is not None else False

    def cache_list(self, *, keys=None, limit=None, after=None, accept=None,
                   match=None) -> tuple:
        """``ResultCache.list`` over this server's cache: ``(rows, position)``. The same
        call ModalExecutor answers over its volume, so the route is written once."""
        if self.cache is None:
            return [], None
        return self.cache.list(keys=keys, limit=limit, after=after, accept=accept,
                               match=match, memo=self._listing_memo)

    def artifact_state(self, key: str, name: str | None = None) -> str:
        """"pending" while the overlap thread is still placing this entry's
        artifacts; "absent" once it finished (or never ran) - at which point a
        missing artifact file is definitive.

        ``name`` asks about ONE deliverable: a render that was not asked for it will
        never place it, so its absence is definitive at once - a GET of a declined
        preview answers 404, not 202 until the statistics land (2026-09-20)."""
        with self._cv:
            cur = self._live_pending(key)
        if cur is None:
            return "absent"
        names = cur[2] if len(cur) > 2 else None
        return "pending" if name is None or pending_covers(names, name) else "absent"

    def _live_pending(self, key: str):
        """The pending marker for ``key`` - ``(owner, set at, names)`` - or None. Asked
        under ``_cv``. One older than ARTIFACT_PENDING_TTL is dropped here:
        a killed/hung overlap thread left its marker; without this the
        refuse-if-present set makes it immortal and every artifact GET
        202s forever (Modal has the same rule as a 900s Dict sweep)."""
        cur = self._artifacts_pending.get(key)
        if cur is not None and time.time() - cur[1] > ARTIFACT_PENDING_TTL:
            self._artifacts_pending.pop(key, None)
            return None
        return cur

    def _claim_pending(self, key: str, owner: str, names) -> bool:
        """Take the artifact path's single flight for ``key``; False when a live render
        holds it. Refuse-if-present, in one step under ``_cv``: since a cache hit renders
        too (2026-09-20) the claim is asked for from submit threads as well as the one
        dispatcher, and two asks of one key must not both start a render."""
        with self._cv:
            if self._live_pending(key) is not None:
                return False
            self._artifacts_pending[key] = (owner, time.time(), tuple(names))
            return True

    def _reference_on_hand(self, rec: JobRecord):
        """``(image, release)`` for the image a cache hit's deliverables render against -
        the task's first declared input, as ``reference_input`` has it - if this server
        holds it NOW; ``(None, release)`` when it does not. ``release`` lets go of the pin.

        Never a fetch. The labels are cached and a deliverable is light; a download to
        draw a preview of a result nobody is computing is a cost the caller did not ask
        for, under a queue slot no job holds - so an input that is gone is SAID to be
        gone (``deliverables_unavailable``), and `no-cache` is the caller's lever.
        """
        def nothing():
            pass
        entry = (rec.source or [{"kind": "upload"}])[0]
        kind = entry.get("kind", "upload")
        if kind == "upload":
            p = rec.input_paths[0][1] if rec.input_paths else rec.input_path
            return (Path(p) if p is not None and Path(p).exists() else None), nothing
        if kind == "input":
            digest = str(entry.get("id") or entry.get("sha256") or "")
            self.content.pin(digest)           # BEFORE the look: the store is LRU
            try:
                if self.content.has(digest):
                    return self.content.fast_path(digest), lambda: self.content.unpin(digest)
            except Exception:                  # noqa: BLE001 - unreadable is not on hand
                pass
            self.content.unpin(digest)
            return None, nothing
        sk = source_cache_key(entry)
        if sk is None or not sk.ident:
            return None, nothing
        self.series_cache.pin(sk.key)          # BEFORE the look: eviction skips a pin
        if self.series_cache.has(sk.key):
            return self.series_cache.path(sk.key), lambda: self.series_cache.unpin(sk.key)
        self.series_cache.unpin(sk.key)
        return None, nothing

    def _render_on_hit(self, rec: JobRecord) -> None:
        """A cache hit honors its request's list (2026-09-20).

        The labels are served as they are - same key, same generation, same ETag. What
        the list names and that generation lacks (the request that computed it declined
        it, or it never rendered) is rendered NOW, into that generation, through the
        path every artifact takes: the pending marker as the single flight, the overlap
        body, the cache's atomic ``add_artifact``. No second mechanism, so the routes
        that wait on a pending artifact, and the rule that an artifact never lands
        beside another publication's labels, hold for it unchanged.

        What cannot be rendered is recorded on the job with the reason: the input is no
        longer on this server, or a render of this result that does not include it is
        still running. ``links`` then leaves it out - said, never silently omitted.
        """
        if self.cache is None or not rec.cache_key or rec.labels_path is None:
            return
        labels = Path(rec.labels_path)
        missing = missing_deliverables(rec.deliverables, labels.parent)
        if not missing:
            return

        def ride(cur) -> None:
            # a render of this result is running: what it will place is on its way,
            # and what it will not cannot be started beside it (one flight per result)
            names = cur[2] if len(cur) > 2 else None
            rec.deliverables_unavailable = {
                d: RENDER_BUSY for d in missing if not pending_covers(names, d)} or None

        with self._cv:
            cur = self._live_pending(rec.cache_key)
        if cur is not None:
            return ride(cur)
        image, release = self._reference_on_hand(rec)
        if image is None:
            rec.deliverables_unavailable = {d: INPUT_NOT_ON_HAND for d in missing}
            return
        if not self._claim_pending(rec.cache_key, rec.id, missing):
            release()                          # another ask of this key claimed it first
            with self._cv:
                cur = self._live_pending(rec.cache_key)
            return ride(cur) if cur is not None else None
        # the generation the labels were read from: the render lands there or nowhere
        gen = labels.parent.name
        try:
            threading.Thread(target=self._hit_worker,
                             args=(rec, image, labels, gen[2:] if gen.startswith("g-") else None,
                                   missing, release),
                             name="haversack-artifacts", daemon=True).start()
        except Exception:                      # noqa: BLE001 - a hit is never failed by this
            release()
            self._release_pending(rec.cache_key, rec.id)

    def _release_pending(self, key: str, owner: str) -> None:
        """Only the owner clears: a duplicate flight's finish must not turn a sibling's
        still-pending artifacts into definitive 404s."""
        with self._cv:
            if self._artifacts_pending.get(key, (None,))[0] == owner:
                self._artifacts_pending.pop(key, None)

    def _hit_worker(self, rec: JobRecord, image, labels: Path, generation, names,
                    release) -> None:
        """A cache hit's render. The pair is loaded here rather than in ``submit`` - a
        read of two volumes has no place on a request's thread - and from then on it is
        ``_artifact_worker``, the same as after a compute."""
        try:
            try:
                from .preview import load_oriented_pair
                pair = load_oriented_pair(image, labels)
            except Exception:                  # noqa: BLE001 - best effort, as every artifact
                pair = None
            if pair is None:
                self._release_pending(rec.cache_key, rec.id)
                return
            self._artifact_worker(pair, rec.cache_key, rec.dir, rec.task, rec.id,
                                  generation, names)
        finally:
            release()

    # -- introspection -------------------------------------------------------
    def get(self, jid: str) -> JobRecord | None:
        with self._cv:
            return self._jobs.get(jid)

    def jobs(self) -> list[JobRecord]:
        with self._cv:
            return list(self._jobs.values())

    def position(self, jid: str) -> int | None:
        """0 = next to run; None once no longer queued."""
        with self._cv:
            try:
                return list(self._pending).index(jid)
            except ValueError:
                return None

    # -- control -------------------------------------------------------------
    def cancel(self, jid: str):
        """Cancel an active job; delete a finished one.

        Returns ``(state, deleted)`` - ``deleted`` is True only when a finished
        job's record and files were actually removed, never for a transition into
        ``cancelled``. ``(None, False)`` for an unknown job."""
        with self._cv:
            rec = self._jobs.get(jid)
            if rec is not None and rec.state in ACTIVE and self._joiners.get(jid, 0) > 0:
                # several clients ride this flight; one leaving must not end it for the
                # others - the last DELETE is the one that cancels
                self._joiners[jid] -= 1
                return "released", False
            if rec is None:
                stored = self._stored(jid)     # evicted from memory, still on record
                if stored is None:
                    return None, False
                import shutil
                shutil.rmtree(self.workdir / jid, ignore_errors=True)
                try:
                    self.jobs_db.drop(jid)
                except Exception:
                    pass
                return stored.get("state"), True
            if rec.state == "queued":
                self._pending.remove(jid)
                rec.state, rec.finished = "cancelled", time.time()
                self._persist(rec)
                self._done_order.append(jid)
                # compare-and-pop, same rule as the dispatcher's finally:
                # under duplicate flights the marker names the LATEST job
                if rec.cache_key and self._inflight.get(rec.cache_key) == jid:
                    self._inflight.pop(rec.cache_key, None)
                state = rec.state
            elif rec.state == "running":
                rec.cancel_token.cancel()      # honored at the next patch boundary
                state = rec.state
            else:
                self._jobs.pop(jid)
                self._rm(rec)
                try:
                    self.jobs_db.drop(jid)     # deleted means deleted, durably too
                except Exception:
                    pass
                return rec.state, True
        if state == "cancelled":
            self._emit(rec)
            self._requeue_positions()
        return state, False

    def _start_sweeper(self) -> None:
        """Reclaim the shared store's unreferenced bytes on a timer.

        `delete` removes an entry and leaves its bytes for a sweep (2026-09-20), and a
        republication leaves its predecessor's the same way - so a store that is never
        swept only grows. Nothing else runs it, and an operator who has to remember a cron
        line will not, so the server that writes to a store also tidies it.

        Deliberately dull: it sweeps with the shipped grace (a day) and expires nothing by
        age, so it can only remove bytes no entry refers to. A failure is reported and the
        loop continues - cleanup is not worth a server. The first sweep is one interval
        away, not at startup, because a fleet restarting together should not all sweep at
        once, and the interval is jittered for the same reason.
        """
        import random

        # Its own event, never `_cv`: `submit` notifies ONE waiter on `_cv`, and a sweeper
        # waiting there could take the wakeup meant for the dispatcher, leaving a job
        # queued until the next submit (2026-09-23). close() sets it.
        self._sweep_stop = threading.Event()

        def loop():
            while True:
                if self._sweep_stop.wait(self._sweep_every * random.uniform(0.9, 1.1)):
                    return
                try:
                    got = self.cache.sweep()
                    if got["deleted_blobs"] or got["expired_pointers"]:
                        print(f"[sweep] reclaimed {got['deleted_blobs']} object(s) from the "
                              "result store", file=sys.stderr, flush=True)
                except Exception as e:         # noqa: BLE001 - never worth the server
                    print(f"warning: the scheduled sweep of the result store failed: "
                          f"{type(e).__name__}: {e}", file=sys.stderr, flush=True)
        self._sweeper = threading.Thread(target=loop, name="haversack-sweep", daemon=True)
        self._sweeper.start()

    def close(self) -> None:
        with self._cv:
            self._stop = True
            self._cv.notify_all()
        if getattr(self, "_sweep_stop", None) is not None:
            self._sweep_stop.set()

    # -- SSE plumbing --------------------------------------------------------
    def subscribe(self, jid: str, loop, q) -> bool:
        with self._cv:
            rec = self._jobs.get(jid)
            if rec is None:
                return False
            rec.subscribers.append((loop, q))
            return True

    def unsubscribe(self, jid: str, loop, q) -> None:
        with self._cv:
            rec = self._jobs.get(jid)
            if rec is not None and (loop, q) in rec.subscribers:
                rec.subscribers.remove((loop, q))

    def _emit(self, rec: JobRecord) -> None:
        snap = self.status(rec)
        for loop, q in list(rec.subscribers):
            try:
                loop.call_soon_threadsafe(q.put_nowait, snap)
            except RuntimeError:               # loop already closed
                pass

    def _requeue_positions(self) -> None:
        with self._cv:
            queued = [self._jobs[j] for j in self._pending]
        for rec in queued:
            self._emit(rec)

    # -- the dispatcher ------------------------------------------------------
    def _refresh_input(self, rec, key: str, reporter, already: set | None = None,
                       *, kind: str | None = None, ident: str | None = None) -> None:
        """Drop a cached input when this job asked for a recompute.

        The rule itself lives in :func:`haversack.jobpolicy.refresh_cached_input`,
        because the Modal worker has to apply exactly the same one and used to
        carry its own copy of it. All that differs here is where the skip is
        recorded: a field on the job record, against an emit into the Modal jobs
        dict.
        """
        def mark_skipped():
            rec.input_refresh_skipped = True

        refresh_cached_input(key,
                             wanted=bool(getattr(rec, "refresh_input", False)),
                             cache=self.series_cache, read_ahead=self.read_ahead,
                             reporter=reporter, on_skipped=mark_skipped,
                             source=self.sources.get(kind) if kind else None,
                             identifier=ident,
                             already=already)

    def _from_store(self, entry, pinned: list):
        """Resolve an ``input`` source: content this server already holds.

        Nothing is fetched or copied - the bytes are in the store already, which
        is the whole point of referring by digest. Pinned like any other input,
        because the store is LRU and the entry could otherwise be evicted out
        from under a running job.
        """
        digest = str(entry.get("id") or entry.get("sha256") or "")
        self.content.pin(digest)
        pinned.append(digest)
        # Held NOW, after the pin (review, 2026-09-25): the submit checked, but the entry
        # can be evicted before dispatch, and a re-upload of the same bytes may be writing
        # it at this moment - resolving then handed the job a half-written series, whose
        # labels were published under the whole content's key.
        if not self.content.has(digest):
            raise InputError(f"{digest} is no longer held by this server (evicted after "
                             "the job was accepted); send the bytes again")
        return self.content.fast_path(digest)     # decoded copy when there is one

    def _stage_many(self, rec, entries, reporter, pinned: list) -> dict:
        """Stage every input of a multi-input job; returns ``{role: path}``.

        Fetches run sequentially inside this one dispatcher thread, each
        reporting its own ``fetch`` stage so a client can see which sequence is
        being pulled. The read-ahead cache stays out of this path deliberately:
        it holds one pre-read volume aimed at the NEXT job, and a multi-input job
        would evict it for a fraction of its own inputs.

        Uploads were already written at submit and arrive on ``rec.input_paths``;
        remote sources are fetched here, the same way and through the same
        pinned series cache as a single-input job.
        """
        staged = {}
        refreshed: set = set()             # one refresh per identifier, not per role
        by_role = {e.get("role"): e for e in entries}
        for role, path in rec.input_paths:
            entry = by_role.get(role) or {}
            kind = entry.get("kind", "upload")
            if kind == "upload":
                staged[role] = path
                continue
            if kind == "input":
                staged[role] = self._from_store(entry, pinned)
                continue
            sk = source_cache_key(entry)
            ident, key = sk.ident, sk.key
            self._refresh_input(rec, key, reporter, refreshed,   # BEFORE our own pin
                                kind=kind, ident=entry.get("id"))
            self.series_cache.pin(key)
            pinned.append(key)
            reporter.stage("fetch", f"{role} {ident[:8]}")
            staged[role] = self.series_cache.get_or_fetch(
                key, check=reporter.check,
                credentials=(rec.source_tokens or {}).get(kind))
            reporter.check()
        # the reference input: what previews and statistics render against
        rec.input_path = staged[rec.input_paths[0][0]]
        return staged

    def _run_encode(self, rec: JobRecord, reporter) -> tuple:
        """An embedding job's compute: the staged input FILE (the encoder reads it itself, by its
        own convention - a pre-read image is dropped, never used), the field written into the
        job's directory, and its published record. The field records the job's identity - the
        source identifier and the bytes' digest - not the scratch path the bytes sat at."""
        from .encoders.pipeline import embed_file
        from .encoders.serving import field_payload, input_record
        take_pre_read(self.read_ahead, rec.id, fresh_bytes_wanted=True)   # nothing lingers pinned
        path = Path(rec.input_path)
        identity = input_record(rec.input_identity[0] if rec.input_identity else None, path)
        if self._encode is None:
            # a server installs on first use (encoders.serving.ensure_weights); an injected
            # embed_fn brings its own
            from .encoders.serving import ensure_weights
            reporter.stage("weights", rec.task)
            ensure_weights(rec.task, progress=lambda m: reporter.stage("weights", m))
        reporter.stage("embed", rec.task)
        work = self._encode or embed_file
        report = work(rec.task, path, rec.dir / EMBEDDING_NAME, identity=identity,
                      device=self.segmenter.policy.get("device", "auto"),
                      int8=bool(rec.options.get("int8")), cancel=rec.cancel_token,
                      task_weights=getattr(getattr(self.segmenter, "weights", None), "root", None))
        out = Path(report["embedding"])
        return out, field_payload(report, out)

    def _run_ranked(self, rec: JobRecord, inp, entries, reporter) -> tuple:
        """A ranked job's compute (2026-09-24): the task's store, written into the job's
        directory through THIS server's warm Segmenter - the same models, device lock and
        cancellation a segmentation gets - and its published record. The store names its input by
        the job's identity (source identifier or digest), never the scratch path it sat at."""
        from .ranked_output import segment_to_store
        ident = rec.input_identity[0] if rec.input_identity else None
        source = ({"type": "image", "identifier": str(ident)} if ident else None)

        def run(image, task, **kw):
            return self._segment(image, task, cancel=rec.cancel_token, **kw)
        reporter.stage("rankfield", rec.task)
        seg, out = segment_to_store(inp, run_name(rec.task, rec.version), rec.dir / RANKED_NAME,
                                    case=rec.id, source=source, quiet=True, run=run,
                                    image_name=str(ident) if ident else None,
                                    progress=reporter)
        record_inputs(seg, entries, rec.input_identity, self.series_cache)
        return Path(out), ranked_payload(seg, out)

    def _dispatch(self) -> None:
        while True:
            with self._cv:
                while not self._pending and not self._stop:
                    self._cv.wait()
                if self._stop:
                    return
                jid = self._pending.popleft()
                rec = self._jobs[jid]
                rec.state, rec.started = "running", time.time()
                self._persist(rec)
            try:                           # nothing before the handler may kill
                self._emit(rec)            # the ONLY dispatcher thread
                self._requeue_positions()
                self._prefetch_next()      # the CPU downloader, parallel to this GPU job
            except Exception:
                pass
            pinned = []
            try:
                reporter = Reporter.of(progress=lambda p, r=rec: self._on_progress(r, p),
                                       cancel=rec.cancel_token)
                if rec.kind == "prepare":
                    reporter.stage("weights", rec.task)
                    # the install reports through the same reporter: one part per model,
                    # bytes received as step / n_steps, so a client's bar moves during the fetch
                    rec.result = self.segmenter.prepare(rec.task, progress=reporter)
                    reporter.check()
                    rec.state = "done"
                    self._persist(rec)
                    raise _PrepareDone
                entries = rec.source or [{"kind": "upload"}]
                if len(entries) > 1:
                    inp = self._stage_many(rec, entries, reporter, pinned)
                else:
                    src = entries[0]
                    kind = src.get("kind", "upload")
                    if kind == "input":
                        rec.input_path = inp = self._from_store(src, pinned)
                    elif kind != "upload":
                        sk = source_cache_key(src)
                        ident, key = sk.ident, sk.key
                        self._refresh_input(rec, key, reporter,   # BEFORE our own pin
                                            kind=kind, ident=src.get("id"))
                        self.series_cache.pin(key)
                        pinned.append(key)
                        if self.series_cache.has(key):
                            reporter.stage("fetch", "cached")
                        elif self.series_cache.staging(key):
                            reporter.stage("fetch", "prefetched")
                        else:
                            reporter.stage("fetch", ident[:13])
                        rec.input_path = self.series_cache.get_or_fetch(
                            key, check=reporter.check,
                            credentials=(rec.source_tokens or {}).get(kind))
                        reporter.check()
                        # A job that asked for fresh bytes never uses a pre-read
                        # image; the rule (and why the pop alone is not enough)
                        # is jobpolicy.take_pre_read's.
                        preread = take_pre_read(
                            self.read_ahead, key,
                            fresh_bytes_wanted=getattr(rec, "refresh_input", False))
                        if preread is not None:
                            reporter.stage("read", "preread")
                            inp = preread
                        else:
                            inp = rec.input_path
                    else:
                        # uploaded bytes are the job's own: nothing to be stale
                        preread = take_pre_read(self.read_ahead, rec.id,
                                                fresh_bytes_wanted=False)
                        if preread is not None:
                            reporter.stage("read", "preread")
                            inp = preread
                        else:
                            inp = rec.input_path
                if rec.kind == "embed":
                    rec.labels_path, rec.result = self._run_encode(rec, reporter)
                elif rec.kind == "rankfield":
                    rec.labels_path, rec.result = self._run_ranked(rec, inp, entries, reporter)
                else:
                    seg = self._segment(inp, run_name(rec.task, rec.version), progress=reporter,
                                        cancel=rec.cancel_token, **rec.options)
                    # what the result was computed FROM, and under what terms - the
                    # rights each fetch recorded beside its bytes, or "not
                    # determined" for an upload; the same rule the Modal worker applies
                    record_inputs(seg, entries, rec.input_identity, self.series_cache)
                    rec.labels_path = Path(seg.save(rec.dir / RESULT_NAME))
                    rec.result = result_payload(seg, rec.labels_path)
                (rec.dir / "result.json").write_text(json.dumps(rec.result), encoding="utf-8")

                def _migrate(old_key: str, new_key: str) -> None:
                    with self._cv:
                        if self._inflight.get(old_key) == rec.id:
                            self._inflight.pop(old_key, None)
                        if self._inflight.get(new_key) in (None, rec.id):
                            self._inflight[new_key] = rec.id   # never stomp a newer flight
                        rec.cache_key = new_key

                def _mark_done() -> None:
                    rec.state = "done"
                    if rec.progress is not None:
                        # the last snapshot, not the last stage's START: a done job kept
                        # saying `finalize` at 0.97 (2026-09-26)
                        rec.progress = {**rec.progress, "stage": "done", "detail": "",
                                        "fraction": 1.0}
                    self._persist(rec)

                with self._cv:
                    # What THIS job renders: read once, held again to what this process
                    # renders, and sealed - a submit that joined the flight may have
                    # added to the list up to here, and must not believe it did after.
                    wanted = wanted_deliverables(rec.deliverables, self.artifacts)
                    rec.deliverables, rec.deliverables_sealed = wanted, True
                    # no entry to render into (no result cache, or no identity to key
                    # one by): said before `done` is observable, so `links` never names
                    # what no door will serve (2026-09-21)
                    rec.deliverables_unavailable = unkeyed_deliverables(
                        wanted, rec.cache_key) or rec.deliverables_unavailable

                def _set_pending(key: str) -> None:
                    # refuse-if-present: a duplicate flight must not ACQUIRE
                    # ownership by stomping - it would then legally clear the
                    # marker while the sibling's overlap still renders, and
                    # probes would read a definitive 404 for artifacts that
                    # land seconds later. The owner's finish clears; then a
                    # later flight may set again.
                    self._claim_pending(key, rec.id, wanted)

                def _clear_pending(key: str) -> None:
                    self._release_pending(key, rec.id)

                def _start(pair, key: str, generation=None) -> None:
                    threading.Thread(target=self._artifact_worker,
                                     args=(pair, key, rec.dir, rec.task, rec.id, generation,
                                           wanted),
                                     name="haversack-artifacts", daemon=True).start()

                if rec.cancel_token.cancelled:
                    # cooperative cancellation is checked per patch; the restore and the
                    # save are not interruptible, so a DELETE that landed during them
                    # must still keep the entry from being (re)published
                    raise Cancelled("cancelled before publication")
                rec.cache_key, _ = publish_completion(
                    segmenter=self.segmenter, task=rec.task,
                    identity=rec.input_identity, options=rec.options,
                    cache_key=rec.cache_key, labels_path=rec.labels_path,
                    # the request's list, not the deployment's set: nothing it declined
                    # is rendered, and an empty list skips the pair load as well
                    input_image=reference_input(inp), artifacts=wanted,
                    cache_enabled=self.cache is not None,
                    migrate_key=_migrate,
                    set_pending=_set_pending,
                    clear_pending=_clear_pending,
                    put=lambda key: self._publish(rec, key),
                    mark_done=_mark_done, start_worker=_start, kind=rec.kind)
            except _PrepareDone:
                pass
            except Cancelled:
                rec.state = "cancelled"
                if rec.cache_key:
                    self._release_pending(rec.cache_key, rec.id)
            except Exception as e:             # noqa: BLE001 - reported to the client
                rec.state = "failed"
                rec.error = f"{type(e).__name__}: {e}"
                # whole here, and in the job store; a client's status gets it without the
                # server's paths (_client_error)
                print(f"[job {rec.id}] failed: {rec.error}", file=sys.stderr, flush=True)
                if rec.cache_key:
                    self._release_pending(rec.cache_key, rec.id)   # failed after pending add
            finally:
                for key in pinned:
                    self.series_cache.unpin(key)
                rec.finished = time.time()
                # the durable row is written once the outcome is complete - state, error
                # and finished together; written earlier it recorded every failure as
                # causeless and every job as unfinished, which is what a restart showed
                self._persist(rec)
                with self._cv:
                    self._done_order.append(rec.id)
                    # compare-and-pop: under duplicate flights for one key the
                    # marker names the LATEST job - popping unconditionally
                    # made probes 404 while the survivor still ran and left
                    # DELETE unable to cancel it
                    if rec.cache_key and self._inflight.get(rec.cache_key) == rec.id:
                        self._inflight.pop(rec.cache_key, None)
                self._emit(rec)
                self._evict()

    def _artifact_worker(self, pair, cache_key: str, jdir: Path, task: str,
                         owner: str, generation=None, names=None) -> None:
        """Post-completion artifacts via the shared overlap body; placement
        is the cache's atomic add_artifact, finish clears the pending marker
        only when this job still owns it. ``names`` is what this job renders - its
        request's list, or what a cache hit found missing; None is the deployment's
        set, which is all there was to render before requests could say."""

        def _finish(placed) -> None:
            self._release_pending(cache_key, owner)

        def _unavailable(failed: dict) -> None:
            with self._cv:
                rec = self._jobs.get(owner)
                if rec is None:
                    return
                rec.deliverables_unavailable = {**(rec.deliverables_unavailable or {}),
                                                **failed}
                self._persist(rec)
            self._emit(rec)

        artifact_overlap(
            pair, task, self.artifacts if names is None else names,
            preview_out=jdir / "preview.png",
            statistics_out=jdir / "statistics.json",
            place=lambda name, path: self.cache.add_artifact(
                cache_key, name, path, generation=generation),
            finish=_finish, unavailable=_unavailable)

    def _prefetch_next(self) -> None:
        """Best-effort: download the HEAD queued idc job's series into the
        series cache on a background thread while the GPU runs the current one.
        The fetch releases the GIL (Rust + file IO), so it costs the GPU loop
        nothing. The cache's atomic directory claim guarantees one writer per
        series; the dispatcher waits out an in-flight staging instead of racing
        it, and a failed staging leaves nothing behind, so the dispatcher falls
        back to its own fetch. This is the pre-loading half of the IO-prefetch
        pipeline - it hides the fetch; hiding the read is the follow-on."""
        with self._cv:
            nxt = self._jobs.get(self._pending[0]) if self._pending else None
        # Which jobs may be warmed - not a prepare, not multi-input, not one that
        # asked for fresh bytes, not an `input` source - is decided once, in
        # jobpolicy.prefetchable. The Modal worker's scan has to agree, and two
        # of those exclusions once existed here alone.
        if nxt is None or not prefetchable(
                state=nxt.state, kind=nxt.kind,
                refresh_input=getattr(nxt, "refresh_input", False),
                sources=nxt.source):
            return
        src = nxt.source[0] if nxt.source else {"kind": "upload"}
        kind = src.get("kind", "upload")
        sk = source_cache_key(src)
        if sk is not None and sk.ident:
            key = sk.key
            if self.series_cache.staging(key) or self.read_ahead.has(key):
                return                         # another writer, or already read

            def work():
                if self.series_cache.has(key) or self.series_cache.prefetch(key):
                    fill_read_ahead(key, cache=self.series_cache,
                                    read_ahead=self.read_ahead)
        elif kind == "upload" and nxt.input_path is not None:
            key, path = nxt.id, nxt.input_path      # local bytes: hide the read
            if self.read_ahead.has(key):
                return

            def work():
                fill_read_ahead(key, read_ahead=self.read_ahead, path=path)
        else:
            # An `input` source is resolved through the content store and has no
            # series to stage and no input_path yet, so there is nothing to
            # pre-read. It used to reach the upload branch with path=None and
            # kill this thread on `cache.pin(None)`.
            return

        def guarded():
            try:
                work()
            except Exception as e:             # best effort, and a daemon thread:
                                               # a failed pre-read must not raise
                                               # into threading.excepthook. Same
                                               # line the Modal worker prints, so
                                               # the two read alike in a log.
                print(f"[prefetch] failed: {e}", flush=True)

        threading.Thread(target=guarded, name="haversack-prefetch", daemon=True).start()

    def _on_progress(self, rec: JobRecord, p) -> None:
        rec.progress = asdict(p)
        self._emit(rec)

    # -- housekeeping --------------------------------------------------------
    def _evict(self) -> None:
        with self._cv:
            victims = []
            while len(self._done_order) > self.keep_finished:
                jid = self._done_order.popleft()
                rec = self._jobs.pop(jid, None)
                if rec is not None:
                    victims.append(rec)
        for rec in victims:
            self._rm(rec)          # its bytes; the RECORD outlives them
        self._reap()

    def _reap(self) -> None:
        """Drop terminal records past the TTL and the directories they owned.

        `keep_finished` bounds what MEMORY holds, and evicting from memory takes
        the job's bytes with it. This bounds how long the RECORD lasts, which is
        a different question - dropping the record on memory eviction would have
        made a busy server forget jobs within seconds, defeating the durability
        it just gained. So an evicted job keeps answering `/v1/jobs/{id}` from
        the store, with its result reported as gone rather than the id 404ing.
        Runs after each job, the same place and cadence as Modal's
        `_bound_jobs_store`.
        """
        import shutil
        try:
            for jid in self.jobs_db.reap(self.jobs_ttl_s):
                shutil.rmtree(self.workdir / jid, ignore_errors=True)
        except Exception:
            pass

    @staticmethod
    def _rm(rec: JobRecord) -> None:
        import shutil
        shutil.rmtree(rec.dir, ignore_errors=True)

    # -- the executor protocol create_app depends on -------------------------
    # (ModalExecutor in modal_app.py implements the same surface over Modal
    # primitives: new_job_dir, accepting, submit, status_of, statuses, cancel,
    # result_file, and supports_push=False for the SSE poll branch.)
    supports_push = True

    def _stored(self, jid: str) -> dict | None:
        """A terminal record from the store, for an id memory no longer holds."""
        try:
            r = self.jobs_db.get(jid)
        except Exception:
            return None
        return r if r and r.get("state") in TERMINAL else None

    def _private_roots(self) -> list:
        """Where this server keeps files: what a client-facing message never names."""
        import tempfile
        roots = [self.workdir, tempfile.gettempdir(), Path.home()]
        if self.cache is not None and getattr(self.cache, "root", None) is not None:
            roots.append(self.cache.root)
        out = []
        for r in roots:
            out.append(str(r))
            try:
                out.append(str(Path(r).resolve()))
            except OSError:
                pass
        return out

    def _client_error(self, text):
        return scrub_server_paths(text, self._private_roots())

    def status_of(self, jid: str) -> dict | None:
        rec = self.get(jid)
        if rec is not None:
            return self.status(rec)
        r = self._stored(jid)
        if r is None:
            return None
        # The durable record outlives the bytes: an evicted or pre-restart job keeps
        # answering, its result reported as gone rather than the id 404ing.
        # ...and gone means gone from BOTH places the result route looks: the job's copy
        # and its published entry (no lease - this hands out no path)
        gone = not (r.get("labels_path") and Path(r["labels_path"]).exists()) and not (
            r.get("cache_key") and self._entry_holds(r["cache_key"], r.get("result")))
        d = {"id": r["id"], "task": r.get("task"), "state": r.get("state"),
             "created": r.get("created"), "started": r.get("started"),
             "finished": r.get("finished"), "input_identity": r.get("input_identity") or [],
             "options": r.get("options") or {}, "cached": bool(r.get("cached")),
             "evicted": True, "result_available": not gone}
        if r.get("kind") in NOT_LABELS:
            # as the live status says it: without it the links door read an evicted field as a
            # segmentation and minted a task-named encoder's LABEL paths (review, 2026-09-23)
            d["kind"] = r["kind"]
        if r.get("input_refresh_skipped"):
            d["input_refresh_skipped"] = True
        if r.get("error"):
            d["error"] = self._client_error(r["error"])
        if r.get("result"):
            d["result"] = r["result"]
        if r.get("cache_key"):
            d["key"] = r["cache_key"]
        if r.get("deliverables") is not None:  # absent: a record from before the list
            d["deliverables"] = list(r["deliverables"])
        if r.get("deliverables_unavailable"):
            d["deliverables_unavailable"] = dict(r["deliverables_unavailable"])
        return d

    def statuses(self) -> list[dict]:
        """Every job this server knows: the ones in memory, then the terminal records the job
        store keeps for ids memory no longer holds - a restart's, or a finished job past
        ``--keep-finished`` - in the brief form, marked ``evicted`` as ``status_of`` marks
        them. Until 2026-09-26 the listing was memory's alone, so after a restart it was empty
        while each old job still answered by its id."""
        live = [self.status(r, brief=True) for r in self.jobs()]
        seen = {d["id"] for d in live}
        try:
            stored = self.jobs_db.all()
        except Exception:                  # noqa: BLE001 - the store is bookkeeping: list memory
            stored = []
        for r in stored:
            if r.get("id") in seen or r.get("state") not in TERMINAL:
                continue
            d = {"id": r["id"], "task": r.get("task"), "state": r.get("state"),
                 "created": r.get("created"), "started": r.get("started"),
                 "finished": r.get("finished"), "evicted": True}
            if r.get("error"):
                d["error"] = self._client_error(r["error"])
            if r.get("kind") in NOT_LABELS:
                d["kind"] = r["kind"]
            if r.get("cached"):
                d["cached"] = True
            live.append(d)
        return live

    def _publish(self, rec: JobRecord, key: str):
        """The cache put for a finished job; the publication's generation token.

        With a result STORE, a segmentation's task versions are recorded there too
        (``note_task``, step 4b): a read-only server with no weights installed derives the
        same key from them. After the put, and never at its expense - a job whose result is
        published is done whether or not the note could be written."""
        generation = self.cache.put(
            key, rec.labels_path, rec.result,
            {"identity": list(rec.input_identity), "task": rec.task,
             "options": rec.options, "computed": rec.started,
             "job": rec.id, **({"kind": rec.kind} if rec.kind in NOT_LABELS else {})},
            output_name=OUTPUT_OF_KIND.get(rec.kind, RESULT_NAME))
        # every kind notes what a reader keys it on (review, 2026-09-25): only a segmentation
        # did, so a read-only server reached a task's rank field only if a segmentation of
        # it had been published too, and an nnU-Net encoder's embedding never
        if rec.kind in ("segment", "rankfield") and hasattr(self.cache, "note_task"):
            try:
                self.cache.note_task(rec.task, versions_for(self.segmenter, rec.task),
                                     installed_versions(self.segmenter, rec.task))
            except Exception as e:             # noqa: BLE001 - see the docstring
                print(f"warning: could not record {rec.task}'s versions in the result store: "
                      f"{type(e).__name__}: {e}", file=sys.stderr, flush=True)
        if rec.kind == "embed" and hasattr(self.cache, "note_task"):
            try:
                self.cache.note_task(f"embed:{rec.task}",
                                     versions_for(self.segmenter, rec.task, "embed"))
            except Exception as e:             # noqa: BLE001
                print(f"warning: could not record {rec.task}'s versions in the result "
                      f"store ({type(e).__name__}: {e}); read-only servers will miss it "
                      "until the next publication records them", file=sys.stderr, flush=True)
        return generation

    def _entry_holds(self, key: str, result) -> bool:
        """Whether the entry at ``key`` holds this job's bytes - the result route's own
        test (``same_output``), read without a lease: this hands out no path."""
        if self.cache is None:
            return False
        published = self.cache.published_result(key)
        return published is not None and same_output(result, published)

    def result_file(self, jid: str):
        """(state, labels path or None); (None, None) for an unknown job. The
        path is None when the bytes are gone (job dir purged under a kept
        record) - callers must not assume done implies readable."""
        rec = self.get(jid)
        if rec is None:
            r = self._stored(jid)
            if r is None:
                return None, None
            p = r.get("labels_path")
            return r.get("state"), (Path(p) if p and Path(p).exists() else None)
        p = rec.labels_path
        return rec.state, (p if p is not None and Path(p).exists() else None)

    # -- serialization -------------------------------------------------------
    def status(self, rec: JobRecord, *, brief: bool = False) -> dict:
        d = {"id": rec.id, "task": rec.task, "state": rec.state,
             "created": rec.created, "started": rec.started, "finished": rec.finished}
        if rec.state == "queued":
            d["queue_position"] = self.position(rec.id)
        if rec.progress is not None:
            d["progress"] = rec.progress
        if rec.version:
            d["version"] = rec.version     # what the caller pinned; `task` is canonical
        if rec.error is not None:
            d["error"] = self._client_error(rec.error)
        if getattr(rec, "input_refresh_skipped", False):
            # the caller asked for a recompute from fresh bytes and did not get one
            d["input_refresh_skipped"] = True
        if not brief and rec.input_identity:
            d["input_identity"] = list(rec.input_identity)
        if not brief:
            # the handle for this result, and the options its URL form depends on
            if rec.cache_key:
                d["key"] = rec.cache_key
            if rec.options:
                d["options"] = dict(rec.options)
            if rec.kind != "prepare":
                # what this job renders beside its labels - beside `options`, never in
                # them - and what a cache hit could not, with the reason; `links` is
                # built from the two
                d["deliverables"] = list(rec.deliverables)
                if rec.deliverables_unavailable:
                    d["deliverables_unavailable"] = dict(rec.deliverables_unavailable)
        if rec.kind in NOT_LABELS:
            d["kind"] = rec.kind          # said only when it is not a segmentation: no status moves
        if rec.cached:
            d["cached"] = True
        if not brief and rec.state == "done" and rec.result is not None:
            d["result"] = rec.result
        return d


# The IDC fetch itself lives in haversack.sources.IDCSource; these two shims keep
# the historical seams - tests monkeypatch _idc_enabled, and _fetch_idc_series
# is the injectable default for LocalExecutor(fetch_idc_fn=...).
# (kept text below for context)
# The three public IDC buckets, probed in order (idc-open-data holds 99.5 % of
# series). If IDC ever adds a bucket, series in it will fail loudly below; the
# upgrade path is resolving per series via idc-index (`series_aws_url`), which we
# deliberately keep OUT of the server tier to stay dependency-light - see the
# 2026-08-24 three-bucket finding in the medseg design doc before re-deriving this.
def _idc_enabled() -> bool:
    try:
        import obstore  # noqa: F401
        return True
    except ImportError:
        return False


def _fetch_idc_series(series: str, jobdir: Path) -> Path:
    """Fetch one IDC series (see haversack.sources.IDCSource for the mechanics),
    recording its collection and license beside it."""
    from .sources import IDCSource
    return _fetch_recording_origin(IDCSource(), series, jobdir)

def _version() -> str:
    try:
        from . import __version__
        return __version__
    except Exception:
        return "unknown"


CONTRACT_VERSION = "1"          # the /v1 wire contract; bump only on a breaking change


def _pkg_info(name: str) -> dict | None:
    """Best-effort ``{version, commit?}`` for an installed distribution. The commit
    (from a VCS install's ``direct_url.json``) is what actually pins an engine
    package's rev - the version string alone doesn't. Returns None if not installed
    (engine packages live only in their own images)."""
    import importlib.metadata as im
    try:
        info = {"version": im.version(name)}
    except Exception:
        return None
    try:
        import json
        raw = im.distribution(name).read_text("direct_url.json")
        commit = ((json.loads(raw).get("vcs_info") or {}).get("commit_id")
                  if raw else None)
        if commit:
            info["commit"] = commit
    except Exception:
        pass
    return info


def _progress_headers(progress: dict | None, extra: dict | None = None) -> dict:
    """202 progress as headers, so HEAD probes and header-only clients see how
    far along a flight is (a HEAD response cannot carry a body)."""
    h = {"Retry-After": "10", "Cache-Control": "no-store"}
    if extra:
        h.update(extra)
    p = progress or {}
    if p.get("stage"):
        h["Haversack-Stage"] = str(p["stage"])
    if p.get("fraction") is not None:
        h["Haversack-Fraction"] = f"{float(p['fraction']):.3f}"
    return h


# The path surface's grid-variant menu: entity token -> the canonical options
# it keys and computes under. Naming is BIDS-inspired (key-value entities in
# the stem: labels_res-1mm.seg.nrrd), NOT BIDS compliance - the entity form
# namespaces the token grammar so future dimensions compose instead of
# colliding. Absolute tokens only (a menu entry means the same thing for
# every task, case, and weights version); grow it when a real user asks.
GRID_TOKENS = {"res-1mm": {"grid": 1.0}}

#: The forms ``GET /v1/jobs/{id}/result?format=`` serves a label map in (2026-09-26): none (or
#: ``seg.nrrd``) for the labels as computed, ``nii.gz`` and ``nii`` for the lossy conversion.
#: Anything else is a 422 naming these.
LABEL_FORMATS = (None, "seg.nrrd", "nii.gz", "nii")


def _task_stem(task: str) -> str:
    """The short task name for filenames - canonical names carry ':'."""
    return task.rpartition(":")[2]


def _prefer_wait(request, default: float, maximum: float) -> float:
    """RFC 7240: Prefer: wait=N / respond-async. Never in the query string -
    the URL stays the pure cache key, and 200s never Vary on Prefer."""
    for raw in request.headers.getlist("prefer"):
        for token in raw.split(","):
            token = token.strip().lower()
            if token == "respond-async":
                return 0.0
            if token.startswith("wait="):
                try:
                    w = float(token[5:])
                except ValueError:
                    continue
                if w != w:                 # NaN: min/max would pass it through
                    return 0.0             # (order-dependent); pin it explicitly
                return max(0.0, min(w, maximum))
    return default


def _prefer_wait_raw(request, maximum: float) -> float | None:
    """Like :func:`_prefer_wait`, but None when no Prefer token was sent -
    header PRESENCE expresses intent, the duration expresses patience:
    wait=0 means "materialize this, but do not hold my connection"
    (respond-async likewise)."""
    for raw in request.headers.getlist("prefer"):
        for token in raw.split(","):
            token = token.strip().lower()
            if token == "respond-async":
                return 0.0
            if token.startswith("wait="):
                try:
                    w = float(token[5:])
                except ValueError:
                    continue
                if w != w:                 # NaN: min/max would pass it through
                    return 0.0             # (order-dependent); pin it explicitly
                return max(0.0, min(w, maximum))
    return None


class CacheOnlyExecutor:
    """The executor protocol over a result cache and nothing else: no queue,
    no dispatcher, no compute path at all. ``create_app(..., read_only=True)``
    over one of these IS the public twin (review R4) - the same route code as
    the main app, so filenames, headers, grid variants, artifact routes and
    the listing cannot drift from it.

    ``key_fn(identity, task, opts)`` pins key derivation - the twin must key
    exactly as the writer did, including the weights-version component it has
    no segmenter to recompute. ``inflight_fn(key)`` optionally exposes an
    authorized flight's progress ({"progress": {...}} or None) so anonymous
    callers can watch it; the KEY doubles as the watch handle."""

    supports_push = False
    accepting = False

    class _TaskView:
        def __init__(self, tasks_fn, resolve_fn):
            self._tasks, self._resolve = tasks_fn, resolve_fn

        def tasks(self):
            return self._tasks()

        def resolve_task(self, t):
            if self._resolve is not None:
                return self._resolve(t)
            if t in self._tasks():
                return t
            raise LookupError(f"unknown task {t!r}")

    def __init__(self, cache_get, key_fn, tasks_fn, *, inflight_fn=None,
                 resolve_fn=None, list_fn=None, sources=None, versions_fn=None,
                 confirm_absent=None, weights_fn=None, artifact_state=None):
        self._get, self._key, self._inflight = cache_get, key_fn, inflight_fn
        if artifact_state is not None:     # optional: without it no render is ever
            self.artifact_state = artifact_state   # known to be pending (see below)
        if confirm_absent is not None:     # optional: without it a miss is taken as read
            self.confirm_absent = confirm_absent
        if weights_fn is not None:         # optional: the weights versions ``key_fn`` keys
            self.weights_versions = weights_fn     # on, so a listing reads them once a task
        self._versions = versions_fn
        self.segmenter = self._TaskView(tasks_fn, resolve_fn)
        self.sources = _source_registry(sources)
        if list_fn is not None:
            self.cache_list = list_fn

    def installed_versions(self, task: str):
        """What pin_status asks: the versions behind this twin's cache, from the operator's
        ``versions_fn`` - None without one, which refuses every pin (a twin has no
        describe() to read them from)."""
        return self._versions(task) if self._versions is not None else None

    def resource_key(self, identity: str, task: str, opts=None) -> str:
        return self._key(identity, task, opts or {})

    def cache_get(self, key: str):
        return self._get(key)

    def find_inflight(self, key: str):
        st = self._inflight(key) if self._inflight is not None else None
        return key if st else None

    def status_of(self, key: str) -> dict:
        if self._get(key) is not None:
            return {"state": "done"}
        st = self._inflight(key) if self._inflight is not None else None
        if st:
            return {"state": "running", "progress": st.get("progress")}
        if self._get(key) is not None:
            # completion window: the writer fills the cache BEFORE clearing
            # its marker, so miss-then-no-marker must recheck before
            # declaring failure
            return {"state": "done"}
        return {"state": "failed"}     # flight gone, nothing cached: stop watching

    def result_file(self, jid):
        return None, None


def _openapi_description() -> str:
    """The server guide's "What it is" and "Reads and computes" sections, verbatim, so the
    OpenAPI document states the rules in the guide's words (see SERVER.md, "Reference")."""
    try:
        from .cli import guide_sections, guide_text
        text = guide_text("server")
    except Exception:                                   # noqa: BLE001 - docs are optional
        return ""
    wanted = ("What it is", "Reads and computes")
    parts = [body for head, body in guide_sections(text) if head in wanted]
    return "\n".join(parts)


def create_app(executor: LocalExecutor, *, token: str | None = None,
               wait_default: float = 30.0, wait_max: float = 110.0,
               read_only: bool = False):
    """The FastAPI app over an executor. Import cost lives here, behind the
    ``serve`` extra.

    With ``token`` set, unauthenticated requests get the public subset only:
    health, tasks, and cache *hits* on the /v1/idc path surface - never a
    compute. That is the local single-server form of the tiering the Modal
    deployment expresses as two functions (proxy-auth'd api + read-only twin).
    """
    import asyncio

    from fastapi import FastAPI, File, Form, HTTPException, Request, UploadFile
    from fastapi.concurrency import run_in_threadpool
    from fastapi.responses import FileResponse, JSONResponse, StreamingResponse

    seg = executor.segmenter
    sources = getattr(executor, "sources", None) or _source_registry(None)
    _key_override = getattr(executor, "resource_key", None)

    def derive_key(identity: str, task: str, opts: dict) -> str:
        """One key derivation for every route. An executor may pin it
        (CacheOnlyExecutor must: the twin has no segmenter to read weights
        versions from); otherwise keys come from the segmenter's view."""
        if _key_override is not None:
            return _key_override(identity, task, opts)
        return result_key((identity,), task, opts,
                          weights_versions_of(seg, task))

    def canon_encoder(name) -> str | None:
        """The encoder ``name`` resolves to, or None: the encoder registry decides, never the
        task catalog (``ts.v2:total_fast`` is both, and the route decides which it means)."""
        from .encoders.serving import canonical
        return canonical(name)

    def embed_versions(encoder: str) -> list:
        """What an embedding of ``encoder`` is keyed on, from wherever this executor says keys
        come from: Modal's api and its twin read them stale-proof, and take the kind
        (``weights_versions(name, kind=)``); an executor that takes no kind - a local server,
        an operator's twin - is answered from the encoder registry, as ``_accept`` keys an
        embedding job. The same versions the job was keyed on, or the key is never found."""
        wv = getattr(executor, "weights_versions", None)
        if wv is not None:
            try:
                return wv(encoder, kind="embed")
            except TypeError:
                pass
        try:
            return versions_for(seg, encoder, "embed")
        except Exception:                  # an nnU-Net encoder on a twin with no describe()
            return ["unknown"]

    def embed_key(identities, encoder: str, opts: dict) -> str:
        """An embedding's key: ``result_key`` with the kind, over ``embed_versions``."""
        return result_key(tuple(identities), encoder, opts, embed_versions(encoder), kind="embed")

    def ranked_key(identities, task: str) -> str:
        """A ranked store's key (2026-09-24): ``result_key`` with the kind, no options, over the
        versions the job was keyed on (:func:`ranked_versions`)."""
        return result_key(tuple(identities), task, {}, ranked_versions(task), kind="rankfield")

    def ranked_versions(task: str) -> list:
        """The versions a ranked store of ``task`` is keyed on - from the executor that states
        them (Modal's api and its twin read them stale-proof and take the kind), else
        ``versions_for``, as ``_accept``. Split from :func:`ranked_key` (2026-09-25) so the
        listing reads them once a task a request, as the other listings do."""
        import inspect
        wv = getattr(executor, "weights_versions", None)
        if wv is not None:
            try:
                takes_kind = "kind" in inspect.signature(wv).parameters
            except (TypeError, ValueError):
                takes_kind = False
            # A one-argument versions function - an operator's twin, the object-store twin -
            # states a TASK's weights; a store keys on those plus its format tag, which is what
            # versions_for(kind="rankfield") is. The first version swallowed the TypeError and
            # fell back to a describe() the twin does not have: ["unknown"], a key no store
            # has, so the twin 404'd every store it held (review, 2026-09-25).
            if takes_kind:
                versions = wv(task, kind="rankfield")
            else:
                from .ranked_output import ranked_tag
                versions = list(wv(task)) + [ranked_tag()]
        else:
            try:
                versions = versions_for(seg, task, "rankfield")
            except Exception:              # no describe() and no versions function: no key
                versions = ["unknown"]
        return versions

    def norm_ident(prefix: str, ident: str) -> str:
        """An identifier as the path surface keys it: stripped, and an IDC series UUID in
        lower case. Shared by the surface and the listing's identity filter, which must
        derive the very key the surface would."""
        ident = ident.strip()
        return ident.lower() if prefix == "idc" else ident

    def _source_enabled(srcobj) -> bool:
        # _idc_enabled stays the patchable seam for the idc source
        return _idc_enabled() if srcobj.prefix == "idc" else srcobj.enabled()

    def source_tokens_of(request) -> dict | None:
        """Per-source credentials from the Haversack-Source-Token header
        (``prefix=token[,prefix=token]``). Headers, never query strings -
        query strings cache-bust and land in logs. The parsed dict lives only
        on the in-memory job record; the status whitelist cannot leak it."""
        raw = request.headers.get("haversack-source-token")
        if not raw:
            return None
        out = {}
        for part in raw.split(","):
            prefix, _, tok = part.strip().partition("=")
            if prefix and tok:
                out[prefix] = tok
        return out or None

    def canon_task(t: str, *, unverified_ok: bool = False):
        """Canonical task name for any accepted form (eco:name,
        eco:name@version) - None when unknown or bare. All forms converge to
        one canonical name and therefore one result-cache key.

        A pin is checked on the way (see ``pin_status``): a version this server
        provably does not run is a 409 on every route, and one it cannot verify
        is a 409 too unless the caller can act on it - ``unverified_ok`` is for
        submit and prepare, which carry the pin to the catalog.

        Path-bearing names are refused BEFORE resolution: the in-process
        API's freedom to run a model-folder path must not cross the wire,
        and a catalog without resolve() would pass the string through
        (Segmenter.resolve_task falls back to identity)."""
        if not re.fullmatch(r"[A-Za-z0-9][A-Za-z0-9_.:@-]*", t or ""):
            return None
        if hasattr(seg, "resolve_task"):
            try:
                canonical = seg.resolve_task(t)
            except LookupError:
                return None
        else:
            canonical = t if t in seg.tasks() else None
        if canonical is not None and "@" in t:
            pin_status(t, canonical, unverified_ok=unverified_ok)
        return canonical

    def pin_status(t: str, canonical: str, *, unverified_ok: bool = False) -> tuple:
        """``(version, verified)`` for a pinned name, by the rule every catalog's ``ensure``
        applies: the INSTALLED version decides, and an unknown one satisfies nothing.

        Raises 409 when the server provably runs another version, and when it cannot tell
        and ``unverified_ok`` is False - a read has no way to install anything, so
        answering it would be serving an unproven version under the caller's pin. Until
        2026-09-12 the wire dropped the pin entirely: `task@X` ran or served whatever was
        installed, the silent wrong version the grammar exists to prevent."""
        version = t.rpartition("@")[2]
        # the executor's own answer when it has one: Modal's reloads a weights volume that
        # is frozen at container start, and the public twin has no describe() at all
        versions_of = getattr(executor, "installed_versions", None)
        have = versions_of(canonical) if versions_of else installed_versions(seg, canonical)
        if have is None:
            if not unverified_ok:
                remedy = ("this server only serves cached results" if read_only else
                          "submit it as a job (POST /v1/jobs), which installs that "
                          "version or refuses it")
                raise HTTPException(409, (
                    f"{t}: this server cannot confirm which version of {canonical} it has "
                    f"installed, so it will not answer for a pin; {remedy}"))
            return version, False
        if any(v != version for v in have):
            runs = " / ".join(sorted(set(map(str, have))))
            raise HTTPException(409, f"{t}: this server runs {canonical} {runs}, not {version}")
        return version, True

    def unknown_task(t: str) -> str:
        """What a 404 for task ``t`` says: the resolver's own words when it has them - a bare
        name comes back naming the qualified form to use - else plain "unknown task". Only a
        catalog-shaped name reaches the resolver, as in canon_task."""
        if hasattr(seg, "resolve_task") and re.fullmatch(r"[A-Za-z0-9][A-Za-z0-9_.:@-]*", t or ""):
            try:
                seg.resolve_task(t)
            except LookupError as e:
                return str(e)
            except Exception:              # noqa: BLE001 - a 404 never echoes a resolver fault
                pass
        return f"unknown task {t!r}"

    # The OpenAPI document carries the guide's rules, so /docs and `haversack docs --server`
    # cannot say different things; the routes are grouped by the tags the guide names.
    app = FastAPI(title="haversack", version=_version(), description=_openapi_description(),
                  openapi_tags=[
                      {"name": "service", "description": "readiness, what is deployed, the sources"},
                      {"name": "tasks", "description": "the catalog: names, descriptions, weights"},
                      {"name": "jobs", "description": "submit, watch, fetch, cancel"},
                      {"name": "inputs", "description": "send content once, refer to it by digest"},
                      {"name": "results", "description": "results addressed by source, identifier and task"}])

    @app.exception_handler(ResultsNotVisible)
    async def _not_visible(request: Request, exc: ResultsNotVisible):
        return JSONResponse({"detail": {"code": "not_visible_yet", "message": str(exc)}},
                            status_code=503,
                            headers={"Retry-After": str(NOT_VISIBLE_RETRY_AFTER_S)})

    @app.exception_handler(405)
    async def _method_not_allowed(request: Request, exc):
        """``Allow`` names the methods of THIS url (RFC 9110 15.5.6), not of whichever
        route the router met first.

        Starlette answers a 405 from the first route whose PATH matches, with that one
        route's methods. Here the verbs of one URL are separate routes (HEAD, GET and
        DELETE of a labels file), and the bare-task ``DELETE /v1/<source>/<id>/<task>``
        is a greedy pattern that also matches every artifact URL - taking ``preview.png``
        for the task - and is registered before them. So until 2026-09-21 a HEAD of
        ``.../preview.png`` was refused with ``Allow: DELETE``: a method that URL has
        never had (the alias answers it 404, no such task), and not the GET it has.

        The methods are the union over the matching routes with the MOST SPECIFIC
        template - the most literal text, which is how the artifact's own route outranks
        the alias whose ``{task}`` swallowed its file name. It only describes: this runs
        when no route matched path and method both, so no dispatch depends on it, and it
        reads the router at request time, so the read-only twin (which drops routes
        after they are registered) answers for what it kept."""
        allow = ", ".join(sorted(_allowed_methods(request))) or (
            getattr(exc, "headers", None) or {}).get("Allow", "")
        return JSONResponse({"detail": "Method Not Allowed"}, status_code=405,
                            headers={"Allow": allow})

    def _allowed_methods(request) -> set:
        """The methods of the routes with the most literal template matching this URL: the
        ``Allow`` of a 405 (see ``_method_not_allowed``)."""
        from starlette.routing import Match
        best, allowed = -1, set()
        for r in app.router.routes:
            methods = getattr(r, "methods", None)
            if not methods or r.matches(request.scope)[0] == Match.NONE:
                continue
            literal = len(re.sub(r"\{[^}]*\}", "", getattr(r, "path", "")))
            if literal > best:
                best, allowed = literal, set(methods)
            elif literal == best:
                allowed |= set(methods)
        return allowed

    _confirm = getattr(executor, "confirm_absent", None)

    def confirm_absent(key: str, since: float):
        """``cache_get``'s miss for ``key``, re-asked of a view newer than ``since`` (a
        ``time.monotonic()`` taken before the lookup): the entry, or None only when its
        absence is verified. Raises ResultsNotVisible (503) when the executor cannot
        refresh its view; an executor without the method reads a current view already.
        Blocking and bounded (~2 s on Modal) - async routes call it off the loop."""
        return None if _confirm is None else _confirm(key, since)

    def authed(request) -> bool:
        if read_only:
            return False               # the twin can never compute
        if token is None:              # --no-token: open to anything that reaches the
            return True                # port. No heuristics: an open server is open.
        import secrets
        # The scheme is case-insensitive (RFC 9110 11.1: `bearer` and `BEARER` are Bearer,
        # refused until 2026-09-26); the credential after it is compared exactly, in constant
        # time, and one space or more may separate them.
        scheme, _, sent = request.headers.get("authorization", "").strip().partition(" ")
        return scheme.lower() == "bearer" and secrets.compare_digest(
            sent.strip().encode(), str(token).encode())

    def require_auth(request) -> None:
        if not authed(request):
            # RFC 9110 11.6.1: a 401 MUST say which scheme would do (2026-09-26)
            raise HTTPException(401, "this server requires a bearer token for "
                                     "anything beyond cached reads",
                                headers={"WWW-Authenticate": 'Bearer realm="haversack"'})

    import datetime as _dt
    _started_at = _dt.datetime.now(_dt.timezone.utc).isoformat(timespec="seconds")

    # -- the input store: send once, refer by digest ------------------------
    # Deliberately no route that hands input BYTES back. A client that referred
    # to a digest already has them, and serving them would turn "knows a hash"
    # into "can read what someone uploaded". Presence and storage only.

    def _store_or_404():
        store = getattr(executor, "content", None)
        if store is None:
            raise HTTPException(404, "this server has no input store")
        return store

    @app.get("/v1/inputs/{digest}", tags=["inputs"])
    def input_status(digest: str, request: Request):
        """Whether this server already holds that content - the call a client
        makes before deciding whether an upload is needed at all.

        Authenticated: a 200 here confirms that somebody uploaded exactly these
        bytes, which is a fact about another caller's data even though it hands
        none of it back. Anonymous has no legitimate use for it - it can neither
        compute nor store - so it does not get to ask.
        """
        require_auth(request)
        store = _store_or_404()
        digest = canonical_digest(digest)
        if not is_digest(digest):
            raise HTTPException(422, {
                "code": "bad_digest",
                "message": f"expected {content.BLOB}<hex> or {content.TREE}<hex>"})
        # Held while it is looked at, as a job holds its input (review, 2026-09-26): with the
        # input store a job's last unpin removed the view this route had just been handed (a
        # 500 from its stat), and an eviction between `has` and `resolve` raised out as a 500.
        store.pin(digest)
        try:
            return _input_status(store, digest)
        finally:
            store.unpin(digest)

    def _input_status(store, digest: str) -> dict:
        gone = HTTPException(404, {"code": "input_gone", "digest": digest,
                                   "message": "not held by this server"})
        if not store.has(digest):
            raise gone
        try:
            where = store.resolve(digest)
        except FileNotFoundError:                 # evicted since `has` (InputGone is one)
            raise gone from None
        kind = "tree" if digest.startswith(content.TREE) else "blob"
        from .input_copy import info, is_copy, stored_compression
        if is_copy(where):
            # the entry keeps its input copy INSTEAD of the uploaded bytes (docs/input-copy.md):
            # members and bytes still describe the content the digest names, recorded when it
            # was stored, and the stored form is said beside them
            h = info(where)
            return {"digest": digest, "kind": kind, "members": h.get("source_files"),
                    "bytes": h.get("source_bytes"), "stored_form": "input_copy",
                    "stored_compression": stored_compression(where),
                    "stored_bytes": where.stat().st_size}
        files = sorted(p for p in where.rglob("*") if p.is_file()) \
            if where.is_dir() else [where]
        return {"digest": digest, "kind": kind, "members": len(files),
                "bytes": sum(p.stat().st_size for p in files)}

    @app.put("/v1/inputs/{digest}", tags=["inputs"])
    async def put_input(digest: str, request: Request):
        """Store content under the digest of its own bytes - the preload call.

        The digest in the URL is what the caller CLAIMS. It is checked against
        the bytes as they land and never taken on trust: accepting it would let
        one caller store bytes Y under digest X and silently poison every later
        job - and every memoized result - that refers to X.
        """
        require_auth(request)              # anonymous never computes, and never stores
        store = _store_or_404()
        digest = canonical_digest(digest)
        if not is_digest(digest):
            raise HTTPException(422, {
                "code": "bad_digest",
                "message": f"expected {content.BLOB}<hex> or {content.TREE}<hex>"})
        # off the event loop: on a shared store a miss refreshes the backing volume
        if await asyncio.to_thread(store.has, digest):
            return {"digest": digest, "stored": False, "reason": "already held"}
        if digest.startswith(content.TREE):
            raise HTTPException(422, {
                "code": "unsupported",
                "message": "a tree is stored by POSTing its members (or a zip) "
                           "to /v1/inputs; this route takes single blobs, whose "
                           "digest a client can compute before sending"})
        import tempfile
        work = _local_scratch()
        try:
            fd, tmp = tempfile.mkstemp(dir=work)
            os.close(fd)
            tmp = Path(tmp)
            h = hashlib.sha256()
            with open(tmp, "wb") as f:
                async for chunk in request.stream():
                    h.update(chunk)
                    f.write(chunk)
            actual = f"sha256:{h.hexdigest()}"
            if actual != digest:
                raise HTTPException(422, {
                    "code": "digest_mismatch", "declared": digest, "actual": actual,
                    "message": "the bytes are not the ones you said they were; "
                               "nothing was stored"})
            # The store names entries from the CONTENT and refuses what it
            # cannot identify - no `?filename=` escape hatch, because a name the
            # caller asserts is not evidence, and a blob nothing can open is not
            # worth storing.
            try:
                # off the event loop (review, 2026-09-25): the adopt now decodes,
                # compresses and verifies the volume (the input copy)
                await asyncio.to_thread(store.put_file, tmp, computed=actual)
            except content.UnidentifiedContent as e:
                # named as the upload, not as the server's temporary file (2026-09-26)
                raise HTTPException(422, {"code": "unknown_format",
                                          "message": str(e).replace(tmp.name, "the upload",
                                                                    1)}) from e
            return {"digest": actual, "stored": True,
                    "stored_as": content.guess_name(tmp),
                    "bytes": tmp.stat().st_size}
        finally:
            _discard(work)

    @app.post("/v1/inputs", tags=["inputs"])
    async def post_input(request: Request, kind: str | None = None,
                         expect: str | None = None):
        """Store a multi-file input - a DICOM series - as one tree.

        Transport is the client's convenience: several multipart parts, or one
        zip. Identity is neither. The tree's digest is taken over the sorted
        digests of its MEMBERS, so it survives the order they arrived in, the
        names they were given, and the zip metadata of whatever carried them -
        the same series zipped twice differs in timestamps and member order, and
        keying on those bytes would make dedupe stop working while appearing to.

        Returns the digest, because a client cannot be expected to have computed
        our Merkle root before sending; one that HAS may pass ``expect`` and have
        it checked, or GET it first and skip the upload entirely.
        """
        require_auth(request)              # anonymous never computes, and never stores
        store = _store_or_404()
        try:
            form = await request.form()
        except HTTPException:
            raise
        except Exception as e:             # noqa: BLE001 - FastAPI's own rule for a body it parses
            # A body the multipart parser refuses - a part header past its limit, a delimiter
            # other than the declared boundary - escaped as a 500 and reset the connection
            # (2026-09-26); POST /v1/jobs, whose form FastAPI parses, answers 400 in these words.
            raise HTTPException(400, "There was an error parsing the body") from e
        from_job = form.get("from_job")
        if from_job:
            # One job's output becomes another's input, without the bytes taking
            # a round trip out through the client and back. The digest returned
            # is the one the producing job already published in `outputs` - same
            # bytes, same address - so a client can predict it.
            #
            # Copied in ON REQUEST rather than for every result: outputs are
            # re-derivable and inputs are not, so filling the input store with
            # results nobody chains would evict the irreplaceable to keep the
            # reproducible.
            #
            # What a downstream task DOES with a labelmap is a separate question:
            # `inputs[].kind` is "image" everywhere today, and a task that
            # consumes a mask would have to declare so before this composes into
            # anything meaningful.
            # the job's published entry first; off the loop, as its confirming reload
            # may wait (a 503 when it cannot see, never a 410 for what it cannot see)
            state, path, _ = await asyncio.to_thread(_job_result, str(from_job))
            if state is None:
                raise HTTPException(404, {"code": "no_job",
                                          "message": f"no job {from_job!r}"})
            if state == "done" and path is None:
                raise HTTPException(410, {
                    "code": "result_gone",
                    "message": f"job {from_job!r} finished but its result bytes are gone"})
            if state != "done":
                raise HTTPException(409, {
                    "code": "not_done",
                    "message": f"job {from_job!r} is {state}; nothing to promote"})
            digest = await asyncio.to_thread(store.put_file, path, expect=expect)
            return {"digest": digest, "kind": "blob", "members": 1, "stored": True,
                    "bytes": Path(path).stat().st_size, "from_job": str(from_job)}
        # multi_items(), not values(): a form is a MULTIdict, and several
        # parts sharing one name - which is how a client sends a series -
        # collapse to a single value through the dict-shaped accessor.
        uploads = [v for _, v in form.multi_items() if hasattr(v, "read")]
        if not uploads:
            raise HTTPException(422, {
                "code": "no_content",
                "message": "POST /v1/inputs takes one or more file parts, or a "
                           "single zip"})
        if kind not in (None, "tree", "blob"):
            raise HTTPException(422, {"code": "bad_kind",
                                      "message": "kind must be 'tree' or 'blob'"})
        work = Path(_local_scratch())
        try:
            staged = work / "in"
            staged.mkdir()
            for i, up in enumerate(uploads):
                name = Path(getattr(up, "filename", None) or f"part{i}").name
                with open(staged / f"{i}_{name}", "wb") as f:
                    while chunk := await up.read(1 << 20):
                        f.write(chunk)
            # Everything after the bytes land runs OFF the event loop (review, 2026-09-25):
            # hashing, unzipping, series detection and the store's adopt - which since the
            # input copy decodes, compresses and verifies the whole volume, tens of seconds
            # for a large series, while every other request to this container waited.
            return await asyncio.to_thread(_store_uploaded, work, staged, kind, expect)
        except content.DigestMismatch as e:
            raise HTTPException(422, {"code": "digest_mismatch",
                                      "declared": e.expected, "actual": e.actual,
                                      "message": str(e)}) from e
        except content.UnidentifiedContent as e:
            raise HTTPException(422, {"code": "unknown_format",
                                      "message": str(e)}) from e
        finally:
            _discard(work)

    def _store_uploaded(work: Path, staged: Path, kind, expect) -> dict:
        """``POST /v1/inputs``' work once its parts are on disk: one zip unpacked, the
        content identified and digested, stored. Blocking by nature; its route runs it in a
        thread."""
        store = _store_or_404()
        files = sorted(staged.iterdir())
        # One zip is an ARCHIVE of members, not a member itself - unpack it
        # unless the caller explicitly asked for a blob.
        def _is_zip(path):
            # four bytes, not the whole upload: this runs on every
            # single-part POST, against a file that may sit on a network volume
            with open(path, "rb") as f:
                return f.read(4) == b"PK\x03\x04"

        if len(files) == 1 and kind != "blob" and _is_zip(files[0]):
            unpacked = work / "unpacked"
            try:
                files = sorted(content.extract_zip(files[0], unpacked))
            except content.ArchiveError as e:
                raise HTTPException(422, {"code": "bad_archive",
                                          "message": str(e)}) from e
            staged = unpacked
        as_tree = kind == "tree" or (kind is None and len(files) > 1) or \
            staged.name == "unpacked"
        if not as_tree:
            digest = content.digest_file(files[0])
            already = store.has(digest)     # honest about a no-op adopt
            store.put_file(files[0], expect=expect, computed=digest)
            return {"digest": digest, "kind": "blob", "members": 1,
                    "stored": not already, "bytes": files[0].stat().st_size}
        # Refuse a mixed folder rather than pick a series out of it: reading
        # "the" series when there are two means choosing one, and choosing
        # silently is how a plausible, wrong segmentation gets produced.
        from haversack.io import dicom_series_ids
        series = dicom_series_ids(staged)
        if len(series) > 1:
            raise HTTPException(422, {
                "code": "multiple_series",
                "message": f"these {len(files)} files hold {len(series)} DICOM "
                           "series; submit one series per input",
                "series_instance_uids": sorted(series)})
        if len(files) > 1 and not series and not any(content.guess_name(p) for p in files):
            # Several files, none of them a DICOM instance or an image header (a .mhd/.nhdr
            # beside its data file): nothing a reader can open, stored until 2026-09-26 as a
            # "tree" whose every job was going to fail - what PUT refuses for one file.
            raise HTTPException(422, {
                "code": "unknown_format",
                "message": f"none of these {len(files)} files is a medical image this server "
                           "can read (a DICOM series, or NIfTI, NRRD or MetaImage with its data "
                           "files); nothing was stored"})
        # What it IS, not what the request called it: `put_dir` stores a
        # one-file directory as a blob, so that a one-member zip and the same
        # bytes sent loose are one identity. Ask for the digest first so the
        # `stored` flag is honest about a no-op adopt.
        digest = (content.digest_file(files[0]) if len(files) == 1
                  else content.digest_dir(staged))
        already = store.has(digest)
        store.put_dir(staged, expect=expect)
        return {"digest": digest,
                "kind": "blob" if len(files) == 1 else "tree", "members": len(files),
                "stored": not already,
                "bytes": sum(p.stat().st_size for p in files),
                "series_instance_uid": series[0] if series else None}

    @app.get("/v1/health", tags=["service"])
    def health():
        policy = getattr(seg, "policy", {})
        return {"name": "haversack", "version": _version(),
                "mode": "public-cache" if read_only else "serve",
                "device": str(policy.get("device", "?")),
                "n_tasks": len(seg.tasks()), "accepting": executor.accepting,
                "sources": ["upload"] + [k for k, v in sources.items()
                                         if _source_enabled(v)],
                # what a job here can be asked to render beside its labels - the
                # default of a request that names none, and the most one may name
                "deliverables": list(wanted_deliverables(
                    None, getattr(executor, "artifacts", ()) or ()))}

    @app.get("/v1/version", tags=["service"])
    def version():
        """Self-report - what this deployment is running. Anonymous, no external
        calls: the wire contract version, the haversack version, when this instance
        started, the installed package versions (with git commit for the engine
        packages, which is what pins their rev), and the weights identity per task.
        For clients (compat), operators (is it current?), and debugging (which rev
        produced this seg?)."""
        # haversack itself is reported by the top-level "version" (its __version__): it's
        # mounted/source-on-path in the deployed images and CI, so it has no dist
        # metadata to read here. `packages` reports the installed DEPENDENCIES.
        # Derived from the engine registry, never hand-listed: the list here used to
        # be five literals and had silently missed voxtell and monai since each was
        # added, so the endpoint that exists to say WHICH REV is running said nothing
        # about the one engine pinned to a git rev for exactly that reason. A package
        # absent from this environment is skipped, so naming every engine's is right.
        #
        # A package this process cannot see is reported as unknown rather than dropped.
        # Dropping it made an enabled engine's absence indistinguishable from an engine
        # nobody asked for - and on Modal that is the NORMAL case, not an edge one: the
        # API runs in `api_image` and each optional engine's dependencies are installed
        # only in that engine's own worker image, so their versions can never appear here
        # however the deployment is configured. Saying so is the honest answer; a per-worker
        # inventory is the complete one, and is not built yet.
        from .engines import registry as _engines
        pkgs = {}
        remote_only = {d: n for n, e in _engines.ENGINES.items() for d in e.dist}
        for name in sorted(remote_only):
            info = _pkg_info(name)
            if info is not None:
                pkgs[name] = info
            elif _engines.enabled(remote_only[name]):
                pkgs[name] = {"version": None,
                              "note": f"not installed in this process; the "
                                      f"{remote_only[name]} engine runs in its own "
                                      "environment and reports its own build there"}
        weights: dict = {}
        cat = getattr(seg, "catalog", None)
        if hasattr(cat, "info"):
            for t in seg.tasks():
                try:
                    wi = dict(cat.info(t)).get("weights_installed")
                    if wi:
                        weights[t] = wi
                except Exception:
                    pass
        engines = {n: {"enabled": _engines.enabled(n),
                       "description": _engines.ENGINES[n].description}
                   for n in _engines.ENGINES}
        return {"name": "haversack", "contract": CONTRACT_VERSION, "version": _version(),
                "started_at": _started_at, "engines": engines,
                "packages": pkgs, "weights": weights}

    @app.get("/v1/tasks", tags=["tasks"])
    def tasks():
        out = {"tasks": seg.tasks()}
        cat = getattr(seg, "catalog", None)
        if hasattr(cat, "info"):
            detail = {}
            for t in out["tasks"]:
                try:
                    i = dict(cat.info(t))
                    i.pop("structures", None)   # describe() carries the full list
                    i.pop("label_map", None)     # and the mapping, which is the same
                                                 # information again - this endpoint is
                                                 # one line per task and stays that way
                    i.pop("attribution", None)   # and the credit, per task at
                                                 # /v1/tasks/{task}: it was most of this
                                                 # listing's weight (2026-09-13)
                    detail[t] = i
                except Exception:
                    pass
            out["detail"] = detail
        return out

    @app.get("/v1/encoders", tags=["tasks"])
    def encoders():
        """What this server embeds with (``POST /v1/jobs`` with ``kind=embed``): each
        encoder's lattices, license, citation, and whether its weights are installed HERE -
        a downloaded checkpoint by its digest, an nnU-Net encoder by its task's install;
        None where this process cannot see the weights (an API that does not compute)."""
        from .encoders import ENCODERS
        from .encoders import weights as ew
        from .encoders.serving import describe as describe_encoder
        see = getattr(executor, "encoder_weights_visible", True)
        rows = []
        for spec in ENCODERS.values():
            installed = None
            if see:
                try:
                    installed = (ew.installed(spec) if spec.weights
                                 else bool((seg.describe(spec.uses_task) or {}).get("weights_installed")))
                except Exception:
                    installed = None
            rows.append(describe_encoder(spec, installed))
        # whether a `kind=embed` job runs HERE at all: a deployment with no encoder worker still
        # lists what the encoders are, and says so rather than letting a submit find out (501)
        return {"embeds": bool(getattr(executor, "embeds", False)), "encoders": rows}

    @app.post("/v1/tasks/{task}/prepare", status_code=202, tags=["tasks"])
    def prepare_task(request: Request, task: str):
        """Install a task's weights now (authorized): the deliberate form of
        what first use does implicitly. Returns a job to watch; its result is
        the task's full description once materialized."""
        require_auth(request)
        canonical = canon_task(task, unverified_ok=True)   # installing IS the answer
        if canonical is None:
            raise HTTPException(404, unknown_task(task))
        # canon_task drops @version by design (all wire forms converge to ONE
        # cache key). For prepare the version IS the request, so pass the
        # requested form through - dropping it silently installed the default
        # and answered 202, the "silent wrong version" bug this grammar exists
        # to prevent (found by the live integration pass).
        requested = task if "@" in task else canonical
        task = canonical
        if not executor.accepting:
            raise HTTPException(429, "queue is full, retry later",
                                headers={"Retry-After": "30"})
        jid, jdir = executor.new_job_dir()
        try:
            executor.submit_prepare(jid, jdir, requested)
        except QueueFull as e:
            import shutil
            shutil.rmtree(jdir, ignore_errors=True)
            raise HTTPException(429, str(e), headers={"Retry-After": "30"}) from e
        return {"id": jid, "kind": "prepare", "task": task,
                **({"version": requested.rpartition("@")[2]}
                   if requested != task else {})}

    from fastapi import Query

    @app.get("/v1/segments", tags=["tasks"], responses={
        422: {"description": "a query the search refuses: empty or over the length cap, "
                             "mode=regex, field=id with word search, a catalog with no tasks "
                             "here, limit outside 1-1000"},
        503: {"description": "the segments index, or this server's own task list, is "
                             "unavailable"}})
    def segments_search(
            q: str = Query(..., description="word prefixes in any order (mode=words), or a "
                                            "shell pattern over the whole id (mode=glob)"),
            mode: str = Query("words", description="words or glob; regex is refused here"),
            field: str = Query("key", description="key: ids folded for case, spaces and "
                                                  "hyphens; id: the model's own spelling "
                                                  "(glob only)"),
            catalog: str | None = Query(None, description="only this catalog (ts.v2, moose, ...)"),
            modality: str | None = Query(None, description="only tasks whose modality "
                                                          "contains this (CT, MR, ...)"),
            limit: int = Query(100, description="at most this many ids (result groups), "
                                                "1-1000"),
            offset: int = Query(0, description="the first id to return, for the next page: "
                                               "the previous answer's next_offset"),
            count_only: bool = Query(False, description="answer with the counts alone, to "
                                                        "size a search before fetching it")):
        """Which tasks produce a segment, and with what label value: a search over every
        task's segments as its model states them (``data/segments.json``), grouped by folded
        id. A read, open to anonymous callers like ``/v1/tasks``. Word prefixes in any order
        (the default) or a glob over the whole id; a regular expression is refused here,
        because a pattern from anyone can take unbounded time to evaluate. Only tasks this
        deployment serves come back. Not ``/v1/segmentations``, which lists cached results.

        The answer, in this order: ``index`` (a short version - it changes if the index is
        rebuilt between pages), ``key_count``, ``segment_count``, ``offset``, ``truncated``
        (more ids after this page) and ``next_offset`` (null on the last page); ``results``,
        one per folded id - ``key``, the ``ids`` as the models spell them, and ``segments``,
        each ``{task, value, id, modality, layer?}`` (no ``layer`` means layer 0) - absent
        under ``count_only``; ``notes`` (``{task: caveat}``), ``open_vocabulary`` (served tasks
        that segment whatever a prompt names); and last, ``end``, a receipt repeating the
        page and the next offset: an answer without it lost its tail in transit."""
        from . import segments as segments_index
        if not 1 <= limit <= 1000:
            raise HTTPException(422, "limit must be between 1 and 1000")
        if offset < 0:
            raise HTTPException(422, "offset must be 0 or more")
        try:
            idx = segments_index.index()
        except Exception as e:             # noqa: BLE001 - never echo a server path
            raise HTTPException(503, "the segments index is unavailable on this server") from e
        try:
            served = set(seg.tasks())
        except Exception as e:             # noqa: BLE001 - a fault, not "nothing produces it"
            raise HTTPException(503, "this server cannot list its tasks right now") from e
        try:
            return idx.search(q, mode=mode, field=field, catalog=catalog, modality=modality,
                              tasks=served, limit=limit, offset=offset, count_only=count_only,
                              allowed_modes=segments_index.WIRE_MODES)
        except InputError as e:
            raise HTTPException(422, str(e)) from e

    @app.get("/v1/sources", tags=["service"])
    def list_sources():
        return {"sources": [dict(v.describe(), enabled=_source_enabled(v))
                            for v in sources.values()]}

    def listed_identity(raw: str) -> str:
        """An ``identity=`` value as the identity a result key holds: a content digest as
        it stands, or ``<source>:<identifier>`` for a source this app mounts WITH a path
        surface, normalized and checked exactly as that surface does it - the listing's
        filter is the path surface's key derivation, asked for many tasks at once."""
        raw = canonical_digest(raw)
        if is_digest(raw):
            return raw
        prefix, sep, ident = raw.partition(":")
        srcobj = sources.get(prefix) if sep else None
        if srcobj is None or getattr(srcobj, "path_addressable", True) is False:
            mounted = ", ".join(f"{p}:" for p, s in sources.items()
                                if getattr(s, "path_addressable", True) is not False)
            raise HTTPException(422, (
                f"identity {raw!r}: expected <source>:<identifier> for a source this server "
                f"mounts ({mounted}), or a content digest ({content.BLOB}<hex>)"))
        ident = norm_ident(prefix, ident)
        if not re.fullmatch(srcobj.id_pattern, ident):
            raise HTTPException(422, f"{ident!r} is not a valid {prefix} identifier")
        return srcobj.identity(ident)

    def _cursor_scope(request) -> str:
        """Which listing, under which filters, a cursor belongs to: the route and every query
        parameter but the page's own (``cursor``, ``limit``), digested."""
        q = sorted((k, v) for k, v in request.query_params.multi_items()
                   if k not in ("cursor", "limit"))
        return hashlib.sha256(json.dumps([request.url.path, q]).encode()).hexdigest()[:16]

    def _listing_page(request, limit: int, cursor, identity):
        """What every listing checks before it looks at the cache - authorization (the twin
        lists anonymously, by its operator's opt-in), the page size, the cursor, the number
        of identities - and the position to resume after. One statement for both listings,
        so the segmentations' and the embeddings' rules cannot drift."""
        if not read_only:
            require_auth(request)
        if not 1 <= limit <= LIST_LIMIT_MAX:
            raise HTTPException(422, f"limit must be between 1 and {LIST_LIMIT_MAX}")
        after = None
        if cursor is not None:
            try:
                after = decode_cursor(cursor, _cursor_scope(request))
            except ValueError as e:
                what = ("issued for another listing or other filters"
                        if "another" in str(e) else "not one this server issued")
                raise HTTPException(422, f"cursor: {what}; start again without it") from None
        if identity and len(identity) > LIST_IDENTITIES_MAX:
            raise HTTPException(422, f"at most {LIST_IDENTITIES_MAX} identities a request")
        return after

    def _hosted_elsewhere(idents) -> bool:
        """An entry whose input came from a hosted source this app does not mount: its path
        would 404 here, so no listing offers it."""
        ident0 = str((idents or [""])[0])
        pfx = ident0.split(":", 1)[0] if ":" in ident0 else None
        return pfx in _ALL_SOURCE_PREFIXES and pfx not in sources

    @app.get("/v1/segmentations", tags=["results"], responses={
        422: {"description": "a filter or page the listing refuses: an identity that is "
                             "neither <source>:<identifier> for a mounted source nor a "
                             "content digest, more than 100 identities, an unknown task, a "
                             "limit outside 1-1000, a cursor this server did not issue"},
        503: {"description": "this server's view of the result cache could not be "
                             "refreshed (Modal: a volume reload was refused); retry"}})
    def list_segmentations(
            request: Request,
            identity: list[str] | None = Query(None, description=(
                "only results computed from this input: <source>:<identifier> "
                "(idc:<crdc_series_uuid>, ...) or a content digest. Repeat it for several "
                "inputs - the answer is the union. Computed, not searched: the results the "
                "path surface can address for that input, under this server's current "
                "weights")),
            task: str | None = Query(None, description="only results of this task"),
            limit: int = Query(LIST_LIMIT_DEFAULT, description=(
                f"rows on this page, 1-{LIST_LIMIT_MAX}")),
            cursor: str | None = Query(None, description=(
                "the previous page's next_cursor, as given"))):
        """Cached results this server can still resolve, newest published first, a page at
        a time: ``{"segmentations": [...], "next_cursor": ...}``, the cursor null on the
        last page. Each row: ``key``, ``task``, ``identity``, ``options``, ``computed``,
        ``published`` (what the order is by), ``bytes``, and ``links`` when the result has
        a path.

        Authorized only (review finding): the listing enumerates every
        cached result including sha256 identities of authenticated users'
        uploads - not part of the anonymous tier. The public twin's listing
        stays an explicit operator opt-in (list_fn): read_only serves it
        anonymously when a lister exists and drops the route otherwise.

        No index stands behind this (2026-09-20) - see ``ResultCache.list`` for the three
        mechanisms. ``identity`` derives the key of each served task under each
        path-addressable option set and looks those names up, so it finds what the path
        surface can serve for that input and nothing else: a result computed with other
        options, or from several inputs, is in the plain and the ``task`` listing only. A
        sync route on purpose: the lookup blocks (on Modal it can wait out a volume
        reload), and FastAPI runs a sync route on a worker thread, off the event loop."""
        after = _listing_page(request, limit, cursor, identity)
        want = None
        if task is not None:
            want = canon_task(task)
            if want is None:
                raise HTTPException(422, unknown_task(task))
        lister = getattr(executor, "cache_list", None)
        if lister is None:
            return {"segmentations": [], "next_cursor": None}
        _weights_of = getattr(executor, "weights_versions", None)
        wv_memo: dict = {}                 # weights per task, once per request
        canon_memo: dict = {}

        def key_of(identities, canonical: str, opts: dict) -> str:
            """The key an entry with these identities is published under NOW. All of them:
            a multi-input result is keyed on every role's identity, and asking only the
            first dropped each one from the listing as stale-keyed.

            A task's weights versions are read ONCE a request. They are the whole cost of a
            key - a ``describe()`` of the task, on Modal against the weights volume - and an
            identity filter derives tasks x option sets x identities of them: measured on
            Modal 2026-09-20, the lookup of 188 computed names took 0.05 s and deriving them
            2.1 s cold, twice over for the two option sets, and once more per identity. An
            executor that pins key derivation says how it reads versions
            (``weights_versions``); one that offers only ``resource_key`` (an operator's
            twin) is asked key by key."""
            ids = tuple(identities)
            if _key_override is not None and _weights_of is None:
                return _key_override(ids[0] if len(ids) == 1 else ids, canonical, opts)
            if canonical not in wv_memo:
                wv_memo[canonical] = (_weights_of(canonical) if _weights_of is not None
                                      else weights_versions_of(seg, canonical))
            return result_key(ids, canonical, opts, wv_memo[canonical])

        def canonical_of(t) -> str | None:
            if t not in canon_memo:
                try:
                    canon_memo[t] = canon_task(str(t))
                except HTTPException:      # one odd row must not refuse the listing
                    canon_memo[t] = None
            return canon_memo[t]

        def of_wanted_task(e: dict) -> bool:
            """The ``task`` filter. Asked twice, of one rule: of ``meta.json``'s fields
            before an entry's files are stat'ed (``match`` - what makes a scan for a rare
            task cheap), and of the finished row, so a lister that knows nothing of
            ``match`` still filters."""
            t = e.get("task")
            return want is None or (t is not None and canonical_of(t) == want)

        def accept(e: dict) -> bool:       # advertise only links that resolve
            if e.get("kind") not in (None, "segment"):
                # a field is not a segmentation: refused by what its meta SAYS, not by its key
                # failing to recompute as a segmentation's - that check sits in a `try` that
                # fails open, and a field came back as a segmentation row when it raised
                # (review, 2026-09-23)
                return False
            idents = e.get("identity") if isinstance(e.get("identity"), list) else []
            if _hosted_elsewhere(idents):  # on THIS app's mounted sources only
                return False
            t = e.get("task")
            canonical = canonical_of(t) if t is not None else None
            if t is not None and canonical is None:
                return False               # task this catalog cannot serve
            if not of_wanted_task(e):
                return False
            key = e.get("key")
            if canonical and idents and key:
                # key round-trip: a stale-keyed entry's link 404s WITH a
                # recompute hint - following the listing's own remedy would
                # duplicate GPU work for bytes already cached
                try:
                    if key_of(idents, canonical, e.get("options") or {}) != key:
                        return False
                except Exception:
                    pass
            return True

        keys = None
        if identity:
            wanted = list(dict.fromkeys(listed_identity(i) for i in identity))
            if want is not None:
                served = [want]
            else:
                try:
                    served = list(dict.fromkeys(filter(None, map(canonical_of, seg.tasks()))))
                except Exception as e:     # noqa: BLE001 - a fault, not "nothing computed"
                    raise HTTPException(503, "this server cannot list its tasks right "
                                             "now") from e
            # what the path surface keys: the default options and each grid token
            menu = [{}] + [dict(o) for o in GRID_TOKENS.values()]
            keys = [key_of((i,), t, o) for i in wanted for t in served for o in menu]
        rows, position = lister(keys=keys, limit=limit, after=after, accept=accept,
                                match=of_wanted_task if want is not None else None)
        return {"segmentations": rows,
                "next_cursor": (encode_cursor(position, _cursor_scope(request))
                                if position is not None else None)}

    @app.get("/v1/embeddings", tags=["results"], responses={
        422: {"description": "a filter or page the listing refuses: an identity that is "
                             "neither <source>:<identifier> for a mounted source nor a "
                             "content digest, more than 100 identities, an unknown encoder, "
                             "a limit outside 1-1000, a cursor this server did not issue"},
        503: {"description": "this server's view of the result cache could not be "
                             "refreshed (Modal: a volume reload was refused); retry"}})
    def list_embeddings(
            request: Request,
            identity: list[str] | None = Query(None, description=(
                "only embeddings of this input: <source>:<identifier> or a content digest. "
                "Repeat it for several inputs - the answer is the union. Computed, not "
                "searched, as for /v1/segmentations")),
            encoder: str | None = Query(None, description="only embeddings by this encoder"),
            limit: int = Query(LIST_LIMIT_DEFAULT, description=(
                f"rows on this page, 1-{LIST_LIMIT_MAX}")),
            cursor: str | None = Query(None, description=(
                "the previous page's next_cursor, as given"))):
        """Cached embedding fields this server can still resolve, newest published first, a
        page at a time: ``{"embeddings": [...], "next_cursor": ...}`` (2026-09-24). Each row:
        ``key``, ``encoder``, ``identity``, ``options``, ``computed``, ``published``,
        ``bytes``, and ``links.embedding`` - its path - when it has one: a single source
        identity, never an upload's digest, as for labels.

        The segmentations listing's machinery, asking for the other kind: the same cache
        scan, cursor and parallel reads, a row kept only when its ``meta.json`` says it is
        an embedding (the segmentations listing keeps only what says it is not), and a key
        round trip through the encoder's own versions (``embed_versions``), so an embedding
        keyed under weights this server no longer runs is not offered. The identity filter
        derives each encoder's key under each path option set - ``{}`` and int8 - and
        looks those up. Authorized, or the twin's operator opt-in, as the segmentations'."""
        after = _listing_page(request, limit, cursor, identity)
        want = None
        if encoder is not None:
            want = canon_encoder(encoder)
            if want is None:
                raise HTTPException(422, f"no encoder {encoder!r}; GET /v1/encoders lists them")
        lister = getattr(executor, "cache_list", None)
        if lister is None:
            return {"embeddings": [], "next_cursor": None}
        wv_memo: dict = {}                 # versions per encoder, once per request
        canon_memo: dict = {}

        def key_of(identities, name: str, opts: dict) -> str:
            if name not in wv_memo:
                wv_memo[name] = embed_versions(name)
            return result_key(tuple(identities), name, opts, wv_memo[name], kind="embed")

        def canonical_of(t) -> str | None:
            if t not in canon_memo:
                canon_memo[t] = canon_encoder(t)
            return canon_memo[t]

        def of_wanted_encoder(e: dict) -> bool:
            t = e.get("task")
            return want is None or (t is not None and canonical_of(t) == want)

        def accept(e: dict) -> bool:
            if e.get("kind") != "embed":
                return False               # a label map, or a kind this server does not know
            idents = e.get("identity") if isinstance(e.get("identity"), list) else []
            if _hosted_elsewhere(idents):
                return False
            t = e.get("task")
            canonical = canonical_of(t) if t is not None else None
            if canonical is None or not of_wanted_encoder(e):
                return False
            key = e.get("key")
            if idents and key:
                try:
                    if key_of(idents, canonical, e.get("options") or {}) != key:
                        return False       # keyed under versions this server no longer runs
                except Exception:
                    pass
            return True

        keys = None
        if identity:
            from .encoders.registry import ENCODERS
            wanted = list(dict.fromkeys(listed_identity(i) for i in identity))
            served = [want] if want is not None else sorted(ENCODERS)
            menu = [{}] + [dict(o) for o in EMBEDDING_TOKENS.values()]
            keys = [key_of((i,), n, o) for i in wanted for n in served for o in menu]
        rows, position = lister(keys=keys, limit=limit, after=after, accept=accept,
                                match=of_wanted_encoder if want is not None else None)
        out = []
        for r in rows:
            name = canonical_of(r.get("task")) or r.get("task")
            row = {"key": r.get("key"), "encoder": name, "identity": r.get("identity"),
                   "options": r.get("options"), "computed": r.get("computed"),
                   "published": r.get("published"), "bytes": r.get("bytes")}
            links = embedding_links(name, r.get("identity"), r.get("options"))
            if links:
                row["links"] = links
            out.append(row)
        return {"embeddings": out,
                "next_cursor": (encode_cursor(position, _cursor_scope(request))
                                if position is not None else None)}

    @app.get("/v1/rankfields", tags=["results"], responses={
        422: {"description": "a filter or page the listing refuses: an identity that is "
                             "neither <source>:<identifier> for a mounted source nor a "
                             "content digest, more than 100 identities, an unknown task, a "
                             "limit outside 1-1000, a cursor this server did not issue"},
        503: {"description": "this server's view of the result cache could not be "
                             "refreshed (Modal: a volume reload was refused); retry"}})
    def list_rankfields(
            request: Request,
            identity: list[str] | None = Query(None, description=(
                "only stores of this input: <source>:<identifier> or a content digest. "
                "Repeat it for several inputs - the answer is the union. Computed, not "
                "searched, as for /v1/segmentations")),
            task: str | None = Query(None, description="only stores of this task"),
            limit: int = Query(LIST_LIMIT_DEFAULT, description=(
                f"rows on this page, 1-{LIST_LIMIT_MAX}")),
            cursor: str | None = Query(None, description=(
                "the previous page's next_cursor, as given"))):
        """Cached ranked stores this server can still resolve, newest published first, a page
        at a time: ``{"rankfields": [...], "next_cursor": ...}`` (2026-09-25). Each row: ``key``,
        ``task``, ``identity``, ``computed``, ``published``, ``bytes``, and ``links.ranked`` -
        its path - when it has one: a single source identity, never an upload's digest.

        The third listing over one machinery: the same cache scan, cursor and parallel reads
        as ``/v1/segmentations`` and ``/v1/embeddings``, a row kept only when its ``meta.json``
        says it is a ranked store, and a key round trip through the task's store versions
        (:func:`ranked_versions` - the task's weights and the formats a store is written in),
        so a store keyed under weights or formats this server no longer writes is not offered.
        A store takes no options, so the identity filter derives one key a task. Authorized,
        or the twin's operator opt-in, as the other two."""
        after = _listing_page(request, limit, cursor, identity)
        want = None
        if task is not None:
            want = canon_task(task)
            if want is None:
                raise HTTPException(422, unknown_task(task))
        lister = getattr(executor, "cache_list", None)
        if lister is None:
            return {"rankfields": [], "next_cursor": None}
        wv_memo: dict = {}                 # store versions per task, once per request
        canon_memo: dict = {}

        def key_of(identities, canonical: str) -> str:
            if canonical not in wv_memo:
                wv_memo[canonical] = ranked_versions(canonical)
            return result_key(tuple(identities), canonical, {}, wv_memo[canonical], kind="rankfield")

        def canonical_of(t) -> str | None:
            if t not in canon_memo:
                try:
                    canon_memo[t] = canon_task(str(t))
                except HTTPException:      # one odd row must not refuse the listing
                    canon_memo[t] = None
            return canon_memo[t]

        def of_wanted_task(e: dict) -> bool:
            t = e.get("task")
            return want is None or (t is not None and canonical_of(t) == want)

        def accept(e: dict) -> bool:
            if e.get("kind") != "rankfield":
                return False               # labels, a field, or a kind this server does not know
            idents = e.get("identity") if isinstance(e.get("identity"), list) else []
            if _hosted_elsewhere(idents):
                return False
            t = e.get("task")
            canonical = canonical_of(t) if t is not None else None
            if canonical is None or not of_wanted_task(e):
                return False
            key = e.get("key")
            if idents and key:
                try:
                    if key_of(idents, canonical) != key:
                        return False       # keyed under versions this server no longer writes
                except Exception:
                    pass
            return True

        keys = None
        if identity:
            wanted = list(dict.fromkeys(listed_identity(i) for i in identity))
            if want is not None:
                served = [want]
            else:
                try:
                    served = list(dict.fromkeys(filter(None, map(canonical_of, seg.tasks()))))
                except Exception as e:     # noqa: BLE001 - a fault, not "nothing computed"
                    raise HTTPException(503, "this server cannot list its tasks right "
                                             "now") from e
            keys = [key_of((i,), t) for i in wanted for t in served]
        rows, position = lister(keys=keys, limit=limit, after=after, accept=accept,
                                match=of_wanted_task if want is not None else None)
        out = []
        for r in rows:
            name = canonical_of(r.get("task")) or r.get("task")
            row = {"key": r.get("key"), "task": name, "identity": r.get("identity"),
                   "computed": r.get("computed"), "published": r.get("published"),
                   "bytes": r.get("bytes")}
            links = ranked_links(name, r.get("identity"), r.get("options"))
            if links:
                row["links"] = links
            out.append(row)
        return {"rankfields": out,
                "next_cursor": (encode_cursor(position, _cursor_scope(request))
                                if position is not None else None)}

    @app.get("/v1/tasks/{task}", tags=["tasks"])
    def describe(task: str):
        # catalog names only, like every other route - and metadata, so a pin it cannot
        # check yet is described (a provably other version is still a 409)
        canonical = canon_task(task, unverified_ok=True)
        if canonical is None:
            raise HTTPException(404, unknown_task(task))
        try:
            return seg.describe(canonical)
        except Exception as e:             # noqa: BLE001 - never echo the resolver's path
            raise HTTPException(404, f"unknown task {task!r}") from e

    @app.post("/v1/jobs", status_code=202, tags=["jobs"])
    async def submit(request: Request, file: UploadFile | None = File(None),
                     task: str = Form(...), options: str = Form("{}"),
                     source: str = Form(None), deliverables: str = Form(None),
                     job_kind: str = Form("segment", alias="kind")):
        require_auth(request)
        if job_kind not in ("segment", "embed", "rankfield"):
            raise HTTPException(422, f"unknown job kind {job_kind!r}; a job is segment (the default), "
                                     "embed or rankfield")
        try:
            opts = json.loads(options)
            if not isinstance(opts, dict):
                raise ValueError("options must be a JSON object")
            if isinstance(opts.get("grid"), (int, float)) and not isinstance(opts["grid"], bool):
                opts["grid"] = float(opts["grid"])   # {"grid": 1} == {"grid": 1.0} == labels.1mm
            src = json.loads(source) if source else [{"kind": "upload"}]
            if not (isinstance(src, list) and all(isinstance(x, dict) for x in src)):
                raise ValueError("source must be a JSON list of objects")
            asked = json.loads(deliverables) if deliverables is not None else None
        except ValueError as e:
            raise HTTPException(422, f"bad request: {e}") from e
        # Which deliverables THIS request wants rendered beside its labels: a field of its
        # own, and refused inside `options` - every option is hashed into the result key,
        # and asking for a preview, or declining one, must never recompute or re-key a
        # segmentation (2026-09-20). Checked against what this deployment renders, which
        # is the default when the field is absent and the ceiling when it is not.
        from .errors import RequestError
        from .schemas import DELIVERABLES_FIELD, requested_deliverables
        if DELIVERABLES_FIELD in opts:
            raise HTTPException(422, {
                "code": "misplaced_deliverables",
                "message": f"`{DELIVERABLES_FIELD}` is a form field of its own, beside "
                           "`options`, not an option: options are part of a result's key "
                           "and what is rendered beside it is not"})
        try:
            wanted = requested_deliverables(asked, getattr(executor, "artifacts", ()))
        except RequestError as e:
            raise HTTPException(e.status, e.detail) from None
        # RFC 9111 semantics, deliberately: `no-cache` means "do not SERVE a stored
        # result", not "do not store one" - that is `no-store`, which we do not offer.
        # So this skips the lookup and still publishes (see the overwriting put in
        # ResultCache), which is what keeps the artifacts, `key` and `links` intact on
        # a forced recompute. Popped before keying: a cache directive is not part of
        # what identifies a result, or every forced run would land in its own entry.
        asked_no_cache = opts.pop("no_cache", False)
        if asked_no_cache is not None and not isinstance(asked_no_cache, bool):
            # a JSON boolean, strictly (2026-09-26): `bool("no")` is True, so any string -
            # "false" included - recomputed the result
            raise HTTPException(422, {"code": "invalid_parameter", "parameter": "no_cache",
                                      "message": "'no_cache' must be true or false, got "
                                                 f"{asked_no_cache!r}"})
        no_cache = bool(asked_no_cache) or wants_no_cache(request)
        # What the CALLER asked for, kept apart from the engine policy applied
        # below. An engine that declines result caching (VoxTell) forces
        # `no_cache` true for every job, and reading that as "re-fetch the input"
        # would re-download the series for each prompt and evict the copy the
        # others share - so the input refresh follows the caller alone.
        caller_asked_no_cache = no_cache
        for entry in src:                  # every source, not just the first
            kind = entry.get("kind", "upload")
            if kind == "input":
                continue                   # a digest, resolved against the store
            if kind == "url":
                raise HTTPException(422, "source kind 'url' is reserved for the "
                                         "authenticated tier")
            if kind == ResultSource.prefix and kind not in sources:
                raise HTTPException(422, "this server keeps no result cache, so a "
                                         f"{kind!r} source has nothing to name; send the "
                                         "bytes instead (kind 'upload' or 'input')")
            if kind != "upload" and kind not in sources:
                raise HTTPException(422, f"unknown source kind {kind!r}; this server "
                                         f"offers upload, {', '.join(sources)}")
            if kind != "upload" and not _source_enabled(sources[kind]):
                raise HTTPException(422, f"source kind {kind!r} is not enabled on this "
                                         "server (missing dependency)")
        if file is not None and source and not any(
                e.get("kind", "upload") == "upload" for e in src):
            # Two inputs named for one request, and one would be dropped in silence: a
            # `{"kind": "input"}` source ran and the `file` part was never read (2026-09-26)
            raise HTTPException(422, {"code": "ambiguous_input",
                                      "message": "this request sends a `file` part AND a `source` "
                                                 "that names no upload; send one of them"})
        kind = src[0].get("kind", "upload") if src else "upload"
        if job_kind == "embed":
            return await _submit_embed(request, task, opts, src, asked, file, no_cache,
                                        caller_asked_no_cache)
        written = task
        canonical = canon_task(task, unverified_ok=True)
        if canonical is None:              # catalog names only at the wire boundary
            why = unknown_task(task)
            # Keep the resolver's own words whenever they name a fix - "needs its catalog",
            # and a renamed catalog or task ("... is 'ts.v2' since 0.11.0: use ..."). Only a
            # plain "unknown task" is replaced by a sample of what this server offers. The
            # test used to be `"needs its catalog" not in why`, which swallowed the rename
            # hints at submit (seen on Modal: fastsurfer:brain, 2026-09-12; ts: since 0.11.0).
            if why.startswith("unknown task"):
                names = seg.tasks()
                why = (f"unknown task {task!r}; this server offers {len(names)} catalog "
                       "tasks, e.g. " + ", ".join(names[:4]))
            raise HTTPException(404, why)
        task = canonical
        if job_kind == "rankfield":
            # The task's ranked store (2026-09-24): its output distribution, not its labels. It
            # takes no options - depth and clip are the store's own rule (ranked_output), and an
            # option is a key; asks for no deliverables - a preview and statistics are of labels;
            # and exists only for a task whose engine hands over a distribution.
            from .ranked_output import supports_store_output
            if not getattr(executor, "ranked_stores", False):
                raise HTTPException(501, "this server writes no rank fields (duckn, zarr or rankfield is not "
                                         "installed where its jobs run); write one locally with "
                                         "`haversack segment ... -o <name>.duckn.zip`")
            if asked:
                raise HTTPException(422, {"code": "no_deliverables",
                                          "message": "a rankfield job renders no deliverables: a preview "
                                                     "and statistics are of labels"})
            if opts:
                raise HTTPException(422, {"code": "no_options",
                                          "message": "a rank field takes no options (its depth and "
                                                     f"clip are the store's own rule); got {sorted(opts)}"})
            if not supports_store_output(task):
                raise HTTPException(422, {"code": "no_distribution",
                                          "message": f"{task} has no rank field: its engine returns "
                                                     "labels, not the distribution a store holds"})
            wanted = None
        # The pin travels with the job so the worker's catalog installs that version or
        # refuses it. One this server cannot verify yet must not be answered from cache or
        # by joining a flight either: both are keyed on the version that IS installed,
        # which is unknown here - the worker re-keys on what it actually ran.
        # off the event loop: the check may reload the weights volume (ModalExecutor)
        version, verified = (await run_in_threadpool(pin_status, written, canonical,
                                                     unverified_ok=True)
                             if "@" in written else (None, True))
        if not verified:
            no_cache = True
        # ...and the engine may decline to be served from cache at all (see
        # engine_serves_from_cache): a per-engine default, overridable per request
        # only in the stricter direction - a caller cannot ask to be memoized.
        no_cache = no_cache or not engine_serves_from_cache(task)
        # Everything the task itself knows about the request: which images it
        # takes, and which options it accepts. Refused HERE, at submit, where the
        # answer is already in hand - not deep inside a worker minutes later, and
        # never in silence (an option we do not know is a typo or a stale client,
        # and accepting it leaves the caller believing a knob was turned).
        declared: dict = {}                # role -> what the task says it takes
        binding = _validate_request(seg, task, src, opts, declared=declared)
        if job_kind == "rankfield" and len(binding) > 1:
            # A store names its input (provenance.sources, source_file), and several inputs - a
            # CT and a result: mask - would be recorded as the first alone, in its role-tagged
            # form (review, 2026-09-25). Refused until a store can name each role.
            raise HTTPException(422, {"code": "multi_input",
                                      "message": f"{task} takes {len(binding)} inputs, and a ranked "
                                                 "store of a multi-input task is not built yet; "
                                                 "its labels are (kind=segment)"})
        if not executor.accepting:
            raise HTTPException(429, "queue is full, retry later",
                                headers={"Retry-After": "30"})
        jid, jdir = executor.new_job_dir()
        # From here the directory has an owner: this handler, until submit()
        # hands it to a JobRecord. Every refusal below - a missing part, a bad
        # digest, an evicted input, an invalid identifier - used to abandon it,
        # and a multi-input refusal abandoned up to N-1 already-streamed volumes
        # with it. Nothing reaps a directory that no record knows about, and on
        # Modal /scratch is a persistent Volume, so those were permanent.
        # `handed` is set once the hand-over thread holds it (see _accept).
        handed: list = []
        try:
            return await _accept(request, jid, jdir, binding, task, opts, src,
                                 file, no_cache, executor, seg,
                                 caller_asked_no_cache, version=version,
                                 handed=handed, role_specs=declared, wanted=wanted,
                                 job_kind=job_kind)
        except QueueFull as e:
            _discard(jdir)
            raise HTTPException(429, str(e), headers={"Retry-After": "30"}) from e
        except content.UnidentifiedContent as e:
            # Fail here, not thirty seconds later inside a worker: a volume
            # nothing can open is a job that was never going to succeed.
            _discard(jdir)
            raise HTTPException(422, {"code": "unknown_format",
                                      "message": str(e)}) from e
        except BaseException:
            # 422/410, a client disconnect, a bug - but not a cancellation that lands
            # while the hand-over thread runs on: the job may own the directory by
            # now, and that thread discards it itself if submit() refuses
            if not handed:
                _discard(jdir)
            raise

    async def _submit_embed(request, task, opts, src, asked, file, no_cache, caller_asked_no_cache):
        """``POST /v1/jobs`` with ``kind=embed`` (2026-09-23): an embedding field of ONE image.

        The name is an ENCODER, resolved by the encoder registry and never by the task catalog
        (``ts.v2:total_fast`` is both, and the kind decides). A pin (``@revision``) must be the
        revision this server runs - an encoder has one at a time - so it is checked here and
        not carried. Options are the encoder's (``int8``); a field has no deliverables. From
        there it is the segmentation's door: the same staging, identity, cache and links."""
        from .encoders.registry import resolve as resolve_encoder
        from .encoders.serving import validate_options as encode_options
        from .errors import InputError, RequestError
        from .schemas import bind_sources, declared_inputs
        try:
            spec = resolve_encoder(task)
        except InputError as e:
            raise HTTPException(404, str(e)) from None
        if not getattr(executor, "embeds", False):
            raise HTTPException(501, "this server runs no embedding jobs (no encoder worker is deployed); "
                                     "embed locally with `haversack embed`")
        if asked:
            raise HTTPException(422, {"code": "no_deliverables",
                                      "message": "an embedding job renders no deliverables: a preview "
                                                 "and statistics are of labels"})
        try:
            opts = encode_options(opts)
            binding = bind_sources(src, declared_inputs({}), multi_input=False, task=spec.name)
        except RequestError as e:
            raise HTTPException(e.status, e.detail) from None
        if not executor.accepting:
            raise HTTPException(429, "queue is full, retry later", headers={"Retry-After": "30"})
        jid, jdir = executor.new_job_dir()
        handed: list = []
        try:
            return await _accept(request, jid, jdir, binding, spec.name, opts, src, file,
                                 no_cache, executor, seg, caller_asked_no_cache,
                                 handed=handed, role_specs={}, wanted=None, job_kind="embed")
        except QueueFull as e:
            _discard(jdir)
            raise HTTPException(429, str(e), headers={"Retry-After": "30"}) from e
        except content.UnidentifiedContent as e:
            _discard(jdir)
            raise HTTPException(422, {"code": "unknown_format", "message": str(e)}) from e
        except BaseException:
            if not handed:
                _discard(jdir)
            raise

    async def _accept(request, jid, jdir, binding, task, opts, src, file,
                      no_cache, executor, seg, caller_asked_no_cache=False,
                      version=None, handed=None, role_specs=None, wanted=None, job_kind="segment"):
        # `wanted`: the request's deliverables, already checked (None: it named none).
        # It rides beside `opts` to the executor and never into them - `opts` is keyed.
        # `role_specs`: role -> what the task declares it takes (_validate_request's
        # `declared`). NOT named `declared` here: the upload branch below has a local of
        # that name, and an upload bound before a reference - upload a CT, refer to its
        # segmentation, the commonest request there is - turned it into None, so the mask
        # role read as an image and every such job was refused (found on Modal, 2026-09-20).
        multi = len(binding) > 1
        # Only a multi-input job needs to look past the declared `file` part;
        # re-parsing the form for the single case would change nothing and
        # re-read the body.
        form = await request.form() if multi else None

        async def _save(upload, role: str) -> tuple:
            """Stream one upload to the job dir, hashing as it goes."""
            import contextlib
            import hashlib
            h = hashlib.sha256()
            name = Path(getattr(upload, "filename", None) or "input.nii.gz").name
            dest = jdir / (upload_name(role, name) if multi else f"input_{name}")
            # Executors backed by a snapshot-consistent volume expose a guard: a
            # concurrent reload elsewhere would discard this uncommitted write. The
            # guard is a threading.Lock, so it is taken in a worker thread and never
            # held across an await: until 2026-09-19 the loop awaited upload.read()
            # under it, Starlette ran reads over 1 MB in a thread, and a second
            # upload's acquire() then blocked the event loop the first needed to
            # resume - two concurrent uploads deadlocked the api container. The
            # multipart parser has spooled the part by now, so `upload.file` is a
            # local read.
            def _write():
                upload.file.seek(0)
                with _write_guard(executor), open(dest, "wb") as f:
                    while chunk := upload.file.read(1 << 20):
                        h.update(chunk)
                        f.write(chunk)
            await asyncio.to_thread(_write)
            digest = f"sha256:{h.hexdigest()}"
            store = getattr(executor, "content", None)
            if store is not None:
                # Addressable from now on: the same bytes submitted again - for
                # another task, or as another channel - can be referred to by
                # this digest instead of re-sent. `computed`, not `expect`: the
                # digest was taken here, from these bytes, as they streamed.
                # off the loop too: on Modal this commits the inputs volume, a blocking
                # RPC that Modal's AsyncUsageWarning flagged on every upload (2026-09-19)
                await asyncio.to_thread(store.put_file, dest, computed=digest)
            return dest, digest

        def _refuse_wrong_kind(role, digest, held):
            """The refusal a ``result:`` reference of the same bytes gets (``sources.pin``),
            for bytes sent or named by digest (2026-09-26)."""
            from .schemas import input_kind
            takes = input_kind((role_specs or {}).get(role))
            if held is not None and held != takes:
                raise HTTPException(422, {
                    "code": "wrong_input_kind",
                    "message": f"{digest[:19]}... is a {held} input, and the role it is bound "
                               f"to takes {takes!r}: bind it to a role that takes {held!r} "
                               "(see the task's `inputs`)",
                    "digest": digest, "input_kind": held, "role_kind": takes})

        staged, idents = [], []
        for role, entry in binding:
            sent_as = str(entry.get("role") or "")   # the client's own spelling
            # the CANONICAL role - the model's own spelling, whatever the client
            # sent - so dispatch and the cache key agree on one name
            if multi:
                entry["role"] = role
            kind = entry.get("kind", "upload")
            if kind == "upload":
                # The client named its PART in its own vocabulary. Binding
                # accepts an alias (t1ce for T1c), so looking the part up under
                # the canonical name alone would let a request bind and then fail
                # to find its own upload - the alias table would work for
                # matching and break the transport it exists to enable.
                declared = entry.get("part")
                names = ([declared] if declared
                         else ["file"] if not multi
                         else [n for n in (sent_as, role) if n])
                upload = None
                for cand in names:
                    upload = file if (cand == "file" and file is not None) else (
                        form.get(cand) if form is not None else None)
                    if upload is not None and hasattr(upload, "read"):
                        part = cand
                        break
                    upload = None
                if upload is None:
                    raise HTTPException(422, {
                        "code": "missing_part",
                        "message": "source kind 'upload' needs a multipart part "
                                   f"named {' or '.join(repr(n) for n in names)}",
                        "part": names[0], "accepted": names})
                dest, digest = await _save(upload, role)
                _refuse_wrong_kind(role, digest, await asyncio.to_thread(
                    stored_input_kind, _FileAt(dest), digest))
                staged.append((role, dest))
                idents.append(digest)
                continue
            if kind == "input":
                # A reference to content this server already holds. Its identity
                # IS the digest, which is exactly what an upload of the same
                # bytes produces - so referring and re-sending land on the same
                # result-cache key, as they must.
                digest = canonical_digest(entry.get("sha256") or entry.get("digest")
                                          or entry.get("id") or "")
                if not is_digest(digest):
                    raise HTTPException(422, {
                        "code": "bad_digest",
                        "message": f"{digest!r} is not a content digest; expected "
                                   f"{content.BLOB}<hex> or {content.TREE}<hex>"})
                store = getattr(executor, "content", None)
                # off the loop: `has` may adopt a legacy upload into the input store (a copy
                # and a hash of the whole entry), or refresh a shared volume (review, 2026-09-26)
                if store is None or not await asyncio.to_thread(store.has, digest):
                    raise HTTPException(410, {
                        "code": "input_gone",
                        "message": f"{digest} is not held by this server (never "
                                   "stored, or evicted); send the bytes again",
                        "digest": digest})
                _refuse_wrong_kind(role, digest, await asyncio.to_thread(
                    stored_input_kind, store, digest))
                entry["id"] = digest
                staged.append((role, None))
                idents.append(digest)
                continue
            if file is not None and not any(
                    e.get("kind", "upload") == "upload" for _, e in binding):
                raise HTTPException(422, f"unexpected file upload with a {kind!r} source")
            src_entry = entry
            if kind == "idc":
                # Explicit identifier fields, no format sniffing: the two IDC
                # identifiers MEAN different things. crdc_series_uuid is the storage
                # identity - version-pinned, immutable, cache-key-grade. A DICOM
                # SeriesInstanceUID names the series in DICOM space and can resolve to
                # different crdc uuids across IDC data releases; accepting it is a
                # resolution step, which is /v1/resolve's job when it lands.
                if "series_instance_uid" in src_entry:
                    raise HTTPException(422, "series_instance_uid (+ optional idc_version) is "
                                             "not accepted yet: pass crdc_series_uuid, IDC's "
                                             "version-pinned series id")
                if "series" in src_entry:
                    raise HTTPException(422, "ambiguous field 'series': pass "
                                             "crdc_series_uuid (IDC's storage id, "
                                             "8-4-4-4-12 hex)")
                if "idc_version" in src_entry:
                    raise HTTPException(422, "idc_version goes with series_instance_uid; "
                                             "a crdc_series_uuid is already pinned to one "
                                             "IDC data release")
            ident = str(src_entry.get("id") or src_entry.get("crdc_series_uuid") or "").strip()
            ident = ident.lower() if kind == "idc" else ident
            if not ident:
                need = "crdc_series_uuid" if kind == "idc" else "id"
                raise HTTPException(422, f"a {kind!r} source needs {need}")
            # Everything the source can refuse WITHOUT I/O, refused here: the
            # grammar, an allowlist, a credential it does not accept. Deferring
            # any of it to the worker turns a bad request into an accepted job
            # that fails minutes later - and on Modal, into a GPU container
            # started for a request that was never going to run.
            try:
                _check_identifier(sources[kind], ident,
                                  (source_tokens_of(request) or {}).get(kind))
            except InputError as e:
                hint = (" (expected IDC's crdc_series_uuid, 8-4-4-4-12 hex; a dotted value is "
                        "a DICOM SeriesInstanceUID, which is not accepted)") if kind == "idc" else ""
                raise HTTPException(422, str(e) + hint) from None
            if getattr(sources[kind], "pins_at_submit", False) is True:
                # A source whose identifier names its bytes only through a lookup (a
                # `result:` reference) is asked ONCE, here, and the answer replaces what
                # the caller sent: the identity below, the series-cache key and the
                # worker's fetch are all read out of the pinned string, so none of them
                # can be answered differently from the others. A reference that does not
                # resolve is REFUSED here, with what to compute first - never a queued job
                # that fails minutes later in a worker. Off the loop: on Modal the lookup
                # may wait out a volume reload, and a miss is confirmed against a view
                # newer than this request (503, not a refusal, when none can be had).
                from .errors import RequestError
                from .schemas import input_kind
                try:
                    ident = await asyncio.to_thread(
                        sources[kind].pin, ident, input_kind((role_specs or {}).get(role)))
                except RequestError as e:
                    raise HTTPException(e.status, e.detail) from None
                except InputError as e:
                    raise HTTPException(422, str(e)) from None
            src_entry["id"] = ident
            staged.append((role, None))
            idents.append(sources[kind].identity(ident))
        # Canonical identity. For one input it stays the bare identity it has
        # always been, so every cached result keeps its key. For several, each is
        # tagged with its role and the pairs are SORTED, which makes the key a
        # pure function of the request: permuting the source list cannot split a
        # key, and rebinding the same files to different roles must not merge
        # two - the output bytes differ.
        identity = (tuple(sorted(f"{role}={i}" for (role, _), i in zip(staged, idents)))
                    if multi else (idents[0],))
        tokens = source_tokens_of(request)

        def _hand_over():
            try:
                rec = executor.submit(jid, jdir, staged[0][1], task, opts,
                                # in the model's declared channel order, not the
                                # order the client happened to list them: both
                                # executors take "the first source" as the reference
                                # image, and that must mean channel 0 either way
                                source=[e for _, e in binding],
                                identity=identity, no_cache=no_cache,
                                # passed only when set, so an executor that predates
                                # pins keeps its signature
                                **({"version": version} if version else {}),
                                # likewise: a request that named no list is the
                                # executor's own default
                                **({"deliverables": wanted} if wanted is not None else {}),
                                # and the kind only when it is not a segmentation
                                **({"kind": job_kind} if job_kind != "segment" else {}),
                                refresh_input=caller_asked_no_cache,
                                source_tokens=tokens,
                                inputs=tuple(staged) if multi else ())
            except BaseException:
                _discard(jdir)             # refused: no record ever owned it
                raise
            # the executor may have joined this ask to an identical flight already
            # running: the status it answers with is that job's, under its id
            rid = (rec.get("id") if isinstance(rec, dict) else getattr(rec, "id", None)) or jid
            # the record in hand when the executor can read a status off it (Modal: the
            # read back was a Dict round trip per submit, 2026-09-25)
            of_record = getattr(executor, "status_of_record", None)
            if of_record is not None and isinstance(rec, dict) and rec.get("id") == rid:
                return of_record(rec)
            return executor.status_of(rid)

        # In a worker thread, never on the event loop: ModalExecutor's submit is a
        # dozen blocking RPCs (Dict writes, a spawn, a volume reload), and run inline
        # they serialized every concurrent submit in the container behind one another
        # - 1.48 s each, 0.67 submits/s from 8 clients however many there were
        # (measured on Modal, 2026-09-19). Sync routes already run in this pool, so
        # both executors were already called from threads.
        if handed is not None:
            handed.append(True)
        return await run_in_threadpool(_hand_over)

    @app.get("/v1/jobs", tags=["jobs"])
    def jobs(request: Request):
        require_auth(request)
        return {"jobs": executor.statuses()}

    def _status_or_404(jid: str) -> dict:
        s = executor.status_of(jid)
        if s is None:
            raise HTTPException(404, f"no job {jid!r}")
        return s

    def _with_links(d: dict) -> dict:
        """Add the job's key and the URLs for everything it produced.

        Built here rather than in either executor: both LocalExecutor and
        ModalExecutor assemble their own status dict, and a thing written twice
        drifts (this codebase has paid for that already). Clients follow these
        instead of reconstructing paths - the URL grammar is the server's.
        """
        if not isinstance(d, dict):
            return d
        out = dict(d)
        key = out.pop("cache_key", None) or out.get("key")
        if key:
            out["key"] = key
        jid = out.get("id")
        links = {"self": f"/v1/jobs/{jid}", "events": f"/v1/jobs/{jid}/events"}
        if out.get("state") == "done":
            if out.get("result_available", True):   # an evicted record says when it is gone
                links["result"] = f"/v1/jobs/{jid}/result"
            # What THIS job was asked to deliver, less what it said it could not - so a
            # link is there only for what is, or will be, there (2026-09-20). The
            # artifact overlap runs after done, so this reads the job's own list rather
            # than probing the cache per request; a record from before the list (none on
            # it) advertises what this deployment renders, as every job then did.
            asked = out.get("deliverables")
            kinds = set(getattr(executor, "artifacts", ()) or ()) if asked is None else set(asked)
            kinds -= set(out.get("deliverables_unavailable") or ())
            # A field has no path form yet (its URL grammar is its own; phase 2's path
            # surface), and `resource_links` would mint the LABELS' urls for a task-named
            # encoder such as ts.v2:total_fast - so an embedding job is reached through itself.
            by_path = ({} if out.get("kind") == "embed" else
                       ranked_links(out.get("task"), out.get("input_identity"), out.get("options"))
                       if out.get("kind") == "rankfield" else resource_links(
                           out.get("task"), out.get("input_identity"), out.get("options"),
                           preview="preview" in kinds, statistics="statistics" in kinds))
            if not by_path and "result" in links:
                # A result with NO PATH - an upload, a `result:` reference, a
                # multi-input job, options off the grid menu - reaches its artifacts
                # through its job, under the names a path-addressable one uses, so a
                # client follows `links.preview` without asking which kind it has.
                # Until 2026-09-21 such a job rendered its deliverables into the cache
                # and advertised nothing: no route served them. Only beside `result`:
                # these resolve through the same bytes, and are gone when they are.
                by_path = {"meta": f"/v1/jobs/{jid}/meta.json"}
                if "preview" in kinds:
                    by_path["preview"] = f"/v1/jobs/{jid}/preview.png"
                if "statistics" in kinds:
                    by_path["statistics"] = f"/v1/jobs/{jid}/statistics.tsv"
            links.update(by_path)
        out["links"] = links
        return out

    @app.get("/v1/jobs/{jid}", tags=["jobs"])
    def status(request: Request, jid: str):
        require_auth(request)
        return _with_links(_status_or_404(jid))

    # HEAD beside GET on the service routes and a job's status (RFC 9110 9.3.2: a server
    # SHOULD answer HEAD wherever it answers GET; these were 405 until 2026-09-26). Separate
    # routes, kept out of the schema: one route under both verbs publishes two operations with
    # one id (see ARTIFACT_VIEWS). The server sends the GET's headers and no body.
    for _path, _fn in (("/v1/health", health), ("/v1/tasks", tasks),
                       ("/v1/sources", list_sources), ("/v1/jobs/{jid}", status)):
        app.add_api_route(_path, _fn, methods=["HEAD"], include_in_schema=False)

    @app.get("/v1/jobs/{jid}/events", tags=["jobs"])
    async def events(request: Request, jid: str):
        require_auth(request)
        first = _status_or_404(jid)
        push = bool(getattr(executor, "supports_push", False))
        loop = q = None
        if push:
            loop = asyncio.get_running_loop()
            q = asyncio.Queue()
            executor.subscribe(jid, loop, q)
            # a transition between the first fetch and the subscribe was never
            # pushed; re-fetch so the stream can't idle on a stale snapshot
            first = await asyncio.to_thread(executor.status_of, jid) or first

        def sse(payload: dict) -> str:
            # the status GET /v1/jobs/{id} answers, key and links included: SERVER.md says each
            # event IS that snapshot, and a client's wait() returns the last one - a raw record
            # without them left `RemoteClient.embed`'s final status keyless (Modal smoke, 2026-09-23)
            return f"event: status\ndata: {json.dumps(_with_links(payload))}\n\n"

        async def stream():
            snap = first
            quiet = time.time()
            try:
                yield sse(snap)
                while snap["state"] not in TERMINAL:
                    if push:
                        try:
                            snap = await asyncio.wait_for(q.get(), timeout=15.0)
                            yield sse(snap)
                        except asyncio.TimeoutError:
                            yield ": keepalive\n\n"
                    else:                       # poll branch: Modal, or any pushless executor
                        await asyncio.sleep(0.7)
                        nxt = await asyncio.to_thread(executor.status_of, jid)
                        if nxt is None:
                            break
                        if nxt != snap:
                            snap = nxt
                            quiet = time.time()
                            yield sse(snap)
                        elif time.time() - quiet > 15:
                            quiet = time.time()
                            yield ": keepalive\n\n"
            finally:
                if push:
                    executor.unsubscribe(jid, loop, q)

        return StreamingResponse(stream(), media_type="text/event-stream",
                                 headers={"Cache-Control": "no-cache",
                                          "X-Accel-Buffering": "no"})

    def _job_result(jid: str):
        """``(state, labels path or None, result)`` for a job; state None for an unknown one.

        A job with a cache key is read from its PUBLISHED entry, through the same leased
        ``cache_get`` the path surface uses; the job's own copy is the fallback, for
        results with no entry (uploads without an identity, a server with no cache) and
        for an entry since republished with different bytes - the job's result is what
        that job produced, and its ETag says so. Reading the job's copy first was a 500
        on Modal (2026-09-19, ts.v2:total on 440 IDC series: 162 failed, intermittently
        per job) where the api container did not see the worker's scratch file, while the
        entry answered by path for every one.

        A done job with neither copy in view is gone (410) only once a view newer than
        its completion says so: 0.12.3 answered 410 from whatever the container last saw,
        and on Modal that was 191 of 300 finished jobs whose entries had been committed
        (2026-09-19). The miss is re-asked through ``confirm_absent``, which raises
        ResultsNotVisible (503) when no current view can be had; so may ``result_file``.
        """
        since = time.monotonic()               # before the record: done precedes this
        status = executor.status_of(jid)
        if status is None:
            return None, None, None
        state = status.get("state")
        if state != "done":
            return state, None, None
        own = status.get("result")
        key = status.get("cache_key") or status.get("key")
        unseen = None
        if key:
            hit = executor.cache_get(key)
            if hit is None:
                try:
                    hit = confirm_absent(key, since)
                except ResultsNotVisible as e:  # the job's own copy may still answer
                    unseen = e
            if hit is not None and same_output(own, hit[1]):
                return state, Path(hit[0]), hit[1]
        state, path = executor.result_file(jid)
        if path is None and unseen is not None:
            raise unseen
        return state, path, own


    def result(request: Request, jid: str, format: str = None):
        """A job's labels, under GET and HEAD. HEAD (2026-09-21: the one file route the
        artifact work left without it, and invisible to the tripwire that reads the
        router for names with a dot) answers what GET would - status, ETag, the file's
        Content-Length, a 304 for a matching ``If-None-Match`` - and converts nothing:
        with ``?format=`` it says 200 and no length, since the NIfTI's size is only
        known by writing it."""
        require_auth(request)
        state, path, res = _job_result(jid)
        if state is None:
            raise HTTPException(404, f"no job {jid!r}")
        if state != "done":
            raise HTTPException(409, f"job is {state}, not done")
        gone = "result no longer on the server; recompute it"
        if path is None:                       # done, but the bytes were purged
            raise HTTPException(410, gone)
        task_name = (executor.status_of(jid) or {}).get("task", "labels")
        stem = _task_stem(task_name)           # canonical eco:name is not filename-safe
        head = request.method == "HEAD"
        # What the bytes ARE, from the file the lookup handed back (either executor, entry or
        # the job's own copy): an embedding job's field is a zip, named and typed as one, and has
        # no NIfTI form - refused, where converting it used to be SimpleITK's 500 (2026-09-23).
        is_field = Path(path).name == EMBEDDING_NAME
        is_store = Path(path).name == RANKED_NAME     # a ranked job's store (2026-09-24): likewise
        if is_field:                           # radar:pretrain -> radar_pretrain: the family says which model
            stem = re.sub(r"[^A-Za-z0-9._-]+", "_", str(task_name))
        suffix, media = ((".zarr.zip", "application/zip") if is_field else
                         (".duckn.zip", "application/zip") if is_store else
                         (".seg.nrrd", "application/octet-stream"))
        if is_field and format is not None:
            raise HTTPException(422, f"format={format!r}: an embedding field is served only as itself "
                                     "(a .zarr.zip); `feldglas` reads it")
        if is_store and format is not None:
            raise HTTPException(422, f"format={format!r}: a ranked store is served only as itself (a "
                                     ".duckn.zip); its labels are the task's segmentation job")
        if not (is_field or is_store) and format not in LABEL_FORMATS:
            # Refused, never served as seg.nrrd (2026-09-26): `?format=bogus` answered 200 with
            # the labels, so a client asking for a form this server does not make could not
            # tell it got another
            raise HTTPException(422, {
                "code": "unknown_format",
                "message": f"format={format!r} is not a form of a label map this server "
                           f"serves; use one of {', '.join(repr(f) for f in LABEL_FORMATS if f)}, "
                           "or none for the .seg.nrrd"})
        if format == "seg.nrrd":
            format = None                      # the labels as they are, said explicitly
        if format in ("nii.gz", "nii"):        # the LOSSY conversion, by request only
            # The validator is the result's digest and the form, not the converted file's
            # (2026-09-26): a temporary file's stat gave a new tag each request, so no client
            # ever got a 304. Weak, because the conversion is a function of the labels, not a
            # promise about every byte of the NIfTI writer's output.
            conv_tag = f'W/"{etag_of(jid, res).strip(chr(34))}.{format}"'
            media = "application/gzip" if format == "nii.gz" else "application/octet-stream"
            name = f"{stem}_{jid}.{format}"
            conv_headers = {"ETag": conv_tag,
                            "Content-Disposition": f'attachment; filename="{name}"'}
            fresh = not_modified(request, conv_tag)
            if fresh is not None:
                return fresh
            if head:
                from fastapi import Response
                probe = Response(status_code=200, media_type=media, headers=conv_headers)
                del probe.headers["content-length"]    # Starlette's 0: not this body's length
                return probe
            import shutil
            import tempfile

            import SimpleITK as sitk
            from starlette.background import BackgroundTask
            from starlette.responses import StreamingResponse
            tmpd = tempfile.mkdtemp(prefix="haversack-conv-")
            out = Path(tmpd) / name
            try:
                sitk.WriteImage(sitk.ReadImage(str(path)), str(out), format == "nii.gz")
            except RuntimeError:
                shutil.rmtree(tmpd, ignore_errors=True)
                if Path(path).exists():
                    raise
                raise HTTPException(410, gone) from None   # left between check and read
            conv = open(out, "rb")
            size = os.fstat(conv.fileno()).st_size

            async def converted():
                try:
                    while block := await asyncio.to_thread(conv.read, 1 << 20):
                        yield block
                finally:
                    conv.close()

            def _cleanup():
                conv.close()
                shutil.rmtree(tmpd, ignore_errors=True)
            # streamed from an open handle, not a FileResponse: that stamps the temporary
            # file's own ETag and Last-Modified, which say nothing about the result
            return StreamingResponse(converted(), media_type=media,
                                     headers={**conv_headers, "Content-Length": str(size)},
                                     background=BackgroundTask(_cleanup))
        # The route a client uses for results that are NOT path-addressable -
        # uploads, and every multi-input job - so this is where revalidation
        # actually saves a download. The validator is the content digest of the
        # bytes served, published in `outputs`; no re-hashing per request.
        etag = etag_of(jid, res)
        fresh = not_modified(request, etag)
        if fresh is not None:
            return fresh
        # Opened HERE, not by FileResponse at send time: a job's own copy can leave
        # between the existence check and the send (a purge, a Modal scratch reload),
        # and FileResponse then raised mid-response - a 500 where SERVER.md says 410.
        # An open handle keeps the bytes readable however the path changes after.
        try:
            fh = open(path, "rb")
        except FileNotFoundError:
            raise HTTPException(410, gone) from None
        if head:
            from fastapi import Response
            with fh:
                size = os.fstat(fh.fileno()).st_size
            return Response(status_code=200, media_type=media,
                            headers={"ETag": etag, "Content-Length": str(size),
                                     "Content-Disposition":
                                         f'attachment; filename="{stem}_{jid}{suffix}"'})
        from starlette.background import BackgroundTask
        from starlette.responses import StreamingResponse

        async def chunks():
            # An async generator, closed with its response: a sync one parked in
            # Starlette's threadpool iterator kept its handle open after a client
            # disconnect until a gc pass (review round 2), and on Windows an open
            # handle blocks the purge that unlinks it.
            try:
                while block := await asyncio.to_thread(fh.read, 1 << 20):
                    yield block
            finally:
                fh.close()

        name = f"{stem}_{jid}{suffix}"
        return StreamingResponse(
            chunks(), media_type=media,
            headers={"ETag": etag, "Content-Length": str(os.fstat(fh.fileno()).st_size),
                     "Content-Disposition": f'attachment; filename="{name}"'},
            background=BackgroundTask(fh.close))

    # -- the artifacts beside a result: one body, two doors, both verbs ---------
    def _prefer_echo(request, h: dict) -> dict:
        """``h`` plus the RFC 7240 echo of the token the client SENT (respond-async is
        echoed as itself, never rewritten to wait=0)."""
        for raw in request.headers.getlist("prefer"):
            for token in raw.split(","):
                token = token.strip().lower()
                if token == "respond-async":
                    h["Preference-Applied"] = "respond-async"
                    return h
                if token.startswith("wait="):
                    w = _prefer_wait_raw(request, wait_max)
                    if w is not None:
                        h["Preference-Applied"] = f"wait={int(w)}"
                    return h
        return h

    def _artifact_headers(request, resp, *, shared: bool) -> dict:
        """The caching fields of an artifact's 200: its validator is the digest of the
        body in hand (``body_etag``). ``shared`` is the path surface - anonymous reads
        of public data, cacheable by anyone for the hour the labels are. A job's
        artifacts are neither: they sit behind the token and can show an upload, so
        ``private``; and ``no-cache``, store but revalidate, because what a job's URL
        serves can still change (absent, then rendered; an entry republished with the
        same labels) and the ETag makes asking cheap. HEAD never waits, so it never
        echoes a ``Prefer`` - as the labels' probe does not."""
        h = {"Cache-Control": "public, max-age=3600" if shared else "private, no-cache",
             "ETag": body_etag(resp.body), "Vary": "Prefer"}
        return h if request.method == "HEAD" else _prefer_echo(request, h)

    async def _await_artifact(key, labels, filename: str, what: str, *, deadline,
                              look_again, confirmed=None, why: str | None = None):
        """The artifact file beside ``labels``, waiting out a pending overlap thread.
        202 + Retry-After while pending (or Prefer: wait exhausted); 404 only when its
        absence is definitive. ``deadline`` is the REQUEST's one Prefer budget, shared
        with the materialize leg - two legs must not each spend wait_max - and None
        never waits, which is every HEAD.

        The door supplies the two re-asks, each answering a labels path or None:
        ``look_again()`` of the entry as it stands - on Modal the path in hand is a
        local copy taken at lookup, which an artifact placed since does not reach
        (2026-09-19) - and ``confirmed(since)`` of a view newer than ``since``, for an
        executor whose view can be stale. By path both are the key's entry; through a
        job both hold the entry to the job's own digest (``_job_result``). ``why`` is
        the job's own reason it could not deliver this one, said in the 404."""
        since = time.monotonic()
        state = {"path": Path(labels).parent / filename}

        async def look():
            if state["path"].exists():
                return state["path"]
            again = await asyncio.to_thread(look_again)
            if again is not None:
                state["path"] = Path(again).parent / filename
            return state["path"] if state["path"].exists() else None

        if (found := await look()) is not None:
            return found
        _state = getattr(executor, "artifact_state", None)

        async def state_fn() -> str:
            # asked about THIS deliverable: a render that was not asked for it
            # will never place it, so its absence is definitive at once. Off the
            # loop: on Modal it is a Dict read, and since 2026-09-21 the twin asks too
            return await asyncio.to_thread(_state, key, what)
        pending = _state is not None and bool(key) and await state_fn() == "pending"
        if pending:
            if deadline is None:
                deadline = time.time()
            while time.time() < deadline:
                await asyncio.sleep(0.2)
                if (found := await look()) is not None:
                    return found
                if await state_fn() != "pending":
                    break
            if (found := await look()) is not None:
                return found
            if await state_fn() == "pending":
                raise HTTPException(202,
                                    headers=_progress_headers(
                                        None, {"Retry-After": "2"}),
                                    detail=f"{what} still materializing")
        if (found := await look()) is not None:   # placed between our probe and
            return found                          # the pending flag clearing
        if confirmed is not None:
            # a stale view is not an absence: ask one newer than this request, and
            # answer 503 if none can be had (adversarial review, 2026-09-19)
            again = await asyncio.to_thread(confirmed, since)
            p = Path(again).parent / filename if again is not None else None
            if p is not None and p.exists():
                return p
        if why:
            raise HTTPException(404, f"no {what} for this job's result: {why}")
        # A read never renders (decided 2026-09-20): a deliverable is asked for where
        # the input is named and can be held - POST /v1/jobs - and this URL serves
        # what exists, to anyone. Anonymous never computes; an authorized GET of a
        # stored result's missing artifact does not either, Prefer or not: it has no
        # job to stage an input under. So the answer is a definitive 404 that names
        # the door which does.
        # The door that renders it, as THIS server has it (review, 2026-09-25): a local
        # server renders what a cache hit lacks; Modal renders only where a result is
        # computed, so there the lever is a recompute - the old advice was refused there.
        lever = (f'with deliverables ["{what}"] renders it'
                 if getattr(executor, "renders_on_hit", False) else
                 f'with deliverables ["{what}"] and Cache-Control: no-cache recomputes the '
                 "result with it (this server renders only where a result is computed)")
        raise HTTPException(404, f"no {what} for this result: it was not asked for when "
                                 "the result was computed, or could not be rendered; an "
                                 "authorized POST /v1/jobs of the same input and task "
                                 + lever)

    def _absence_is_never_stored(route):
        """A result route whose 404s say ``Cache-Control: no-store`` - as its 202s
        always have (``_progress_headers``). On the labels' routes (HEAD probe and GET)
        as on the artifacts': "not materialized" is the answer until somebody computes
        the result, which is the very next thing an authorized caller does with it, and
        the 200 that follows says ``public, max-age=3600`` - so a shared cache that had
        kept the 404 on a heuristic would go on hiding a result for as long as it
        pleased. Every 404 of these routes, the unknown task's included: a task unknown
        today is served after the deploy that adds its catalog, and an uncached error
        costs a request.

        An artifact arrives LATE: rendered after `done`, on a cache hit that asks for it,
        and - with a result store several hosts share - by another host into the same
        generation, with no republication to announce it. So "not here" is only ever
        "not here yet, as far as this request could see", and a 404 followed moments
        later by a 200 is a legitimate sequence. RFC 9111 4.2.2 lets a cache give a 404
        with no explicit freshness a heuristic one, and the 200 beside it invites shared
        caches (``public``): without this a proxy may keep answering 404 for a preview
        that landed a second later. Nothing here remembers an absence either - every
        request looks again (2026-09-21, with the object-store session)."""
        import functools
        import inspect                  # asyncio's is deprecated, gone in 3.16

        def unstored(e):
            # 410 with it (adversarial pass, 2026-09-21): "the bytes are gone" turns back
            # into a 200 when the key is recomputed with the same output, and RFC 9111
            # 4.2.2 lists 410 among the statuses a cache may keep on a heuristic. A 409
            # is not on that list and is left alone.
            if e.status_code in (404, 410):
                e.headers = {**(e.headers or {}), "Cache-Control": "no-store"}
            return e

        if inspect.iscoroutinefunction(route):
            @functools.wraps(route)
            async def guarded(*args, **kwargs):
                try:
                    return await route(*args, **kwargs)
                except HTTPException as e:
                    raise unstored(e)
        else:                                  # a plain route stays one: FastAPI runs it
            @functools.wraps(route)            # in its threadpool, off the event loop
            def guarded(*args, **kwargs):
                try:
                    return route(*args, **kwargs)
                except HTTPException as e:
                    raise unstored(e)
        return guarded

    # the labels' own job route, registered here because its 404 and 410 are absences
    # too; two routes, one function, as the artifacts' are (one operation id per verb)
    _job_labels = _absence_is_never_stored(result)
    app.head("/v1/jobs/{jid}/result", tags=["jobs"])(_job_labels)
    app.get("/v1/jobs/{jid}/result", tags=["jobs"])(_job_labels)

    async def _artifact_answer(request, view: str, *, shared: bool, result=None, path=None):
        """The response for one view whose entry (``result``) or file (``path``) is in
        hand: GET's 200, HEAD's 200, or the 304 of either."""
        try:
            resp = await asyncio.to_thread(artifact_response, view, result=result, path=path)
        except OSError:                        # left between the look and the read
            raise HTTPException(404, "not materialized") from None
        return answer_body(request, resp, _artifact_headers(request, resp, shared=shared))

    def _register_job_artifact(view: str):
        file, what = ARTIFACT_VIEWS[view]

        @_absence_is_never_stored
        async def job_artifact(request: Request, jid: str):
            """One artifact of a job's result - the door for results with NO PATH (an
            upload, a ``result:`` reference, a multi-input job), and open to every job.

            Authorized like ``/result``, never anonymous: a job's artifacts show what was
            uploaded. Resolved like ``/result`` too - through the job's key to its
            published entry, leased, and only while that entry holds the bytes THIS job
            reported (``same_output``), else beside the job's own copy - and answered by
            its rules: 404 no such job, 409 not done, 410 the bytes are gone, 503 not
            visible yet. Then the artifact's own: 202 + Retry-After while a render that
            will place it is pending, 404 when none will - with the job's own reason
            where it gave one. HEAD is the same answer with no body, and never waits:
            ``Prefer: wait=N`` on a GET waits out a render, as it does by path."""
            require_auth(request)
            state, labels, res = await asyncio.to_thread(_job_result, jid)
            if state is None:
                raise HTTPException(404, f"no job {jid!r}")
            if state != "done":
                raise HTTPException(409, f"job is {state}, not done")
            if labels is None:                 # done, but the bytes were purged
                raise HTTPException(410, "result no longer on the server; recompute it")
            if what is None:
                return await _artifact_answer(request, view, shared=False, result=res)
            # off the loop: on Modal a record is a Dict round trip (~60-80 ms)
            status = await asyncio.to_thread(executor.status_of, jid) or {}
            key = status.get("cache_key") or status.get("key")
            w = None if request.method == "HEAD" else _prefer_wait_raw(request, wait_max)

            def confirmed(since: float):
                again = confirm_absent(key, since)
                return again[0] if again is not None and \
                    same_output(status.get("result"), again[1]) else None

            found = await _await_artifact(
                key, labels, file, what, deadline=None if w is None else time.time() + w,
                look_again=lambda: _job_result(jid)[1],
                confirmed=confirmed if _confirm is not None and key else None,
                why=(f"a {status.get('kind')} job has no {what}: only a segmentation "
                     "renders deliverables" if status.get("kind") in NOT_LABELS else
                     (status.get("deliverables_unavailable") or {}).get(what)))
            return await _artifact_answer(request, view, shared=False, path=found)

        # two routes, one function: FastAPI names an operation after its first method,
        # so one route under both verbs would publish two operations with one id
        app.head(f"/v1/jobs/{{jid}}/{view}", tags=["jobs"])(job_artifact)
        app.get(f"/v1/jobs/{{jid}}/{view}", tags=["jobs"])(job_artifact)

    for _view in ARTIFACT_VIEWS:
        _register_job_artifact(_view)

    @app.delete("/v1/jobs/{jid}", tags=["jobs"])
    def cancel(request: Request, jid: str):
        require_auth(request)
        state, deleted = executor.cancel(jid)
        if state is None:
            raise HTTPException(404, f"no job {jid!r}")
        if deleted:
            return {"id": jid, "deleted": True, "state": state}
        if state == "released":
            # this caller had joined a flight others are still waiting on: it leaves,
            # the computation goes on
            now = (executor.status_of(jid) or {}).get("state")
            return {"id": jid, "cancelling": False, "released": True, "state": now}
        return {"id": jid, "cancelling": state not in TERMINAL, "state": state}


    # -- the IDC path surface: results addressed like the source data ---------
    def _resource_headers(key: str, result=None) -> dict:
        # Vary: the 200s differ (Preference-Applied) by the Prefer header,
        # and these are the public-cacheable responses
        return {"Cache-Control": "public, max-age=3600",
                "ETag": etag_of(key, result), "Vary": "Prefer"}

    def _pref_headers(request, key: str, result=None) -> dict:
        """Resource headers + the RFC 7240 echo of the token the client
        SENT (respond-async is echoed as itself, never rewritten to
        wait=0); applied uniformly - labels and artifacts, waits and
        cache hits alike (a hit trivially satisfies wait=N)."""
        return _prefer_echo(request, _resource_headers(key, result))

    # The explicit HEAD registration is the compute-free probe, and the one
    # place status codes distinguish in-flight: 200 materialized / 202
    # computing / 404 absent. (FastAPI's APIRoute does NOT auto-add HEAD to
    # GETs - registering probes first is belt-and-braces, not load-bearing.)
    def _mount_source(prefix: str, srcobj) -> None:
        """The path surface for one data source: probe / blocking GET / evict /
        meta / preview, all parameterized by the source's prefix, identifier
        pattern, and identity. Routes are greedy catch-alls parsed
        RIGHT-TO-LEFT: the artifact name is fixed and the task is exactly one
        segment, so everything between the prefix and them is the identifier -
        which is what lets multi-segment identifiers (hf repo@sha paths,
        openneuro file paths, zenodo recid/file!member) live in ordinary URLs
        with no percent-encoded slashes for proxies to mangle. The source's
        id_pattern remains the validation boundary either way."""
        pat = srcobj.id_pattern
        base = f"/v1/{prefix}/{{ident:path}}/{{task}}"

        def norm(ident: str) -> str:
            return norm_ident(prefix, ident)

        def keyed(ident: str, task: str, opts: dict | None = None):
            canonical = canon_task(task)
            if not re.fullmatch(pat, ident) or canonical is None:
                return None
            return derive_key(srcobj.identity(ident), canonical, opts or {})

        def _grid_routes(register):
            """Register an artifact route for the default grid and each token:
            labels.seg.nrrd plus labels.1mm.seg.nrrd and friends - the token
            keys (and computes) under its canonical options."""
            register("", {})
            for tok, opts in GRID_TOKENS.items():
                register("_" + tok, dict(opts))

        def _register_probe(tok: str, gopts: dict):
            @app.head(base + f"/labels{tok}.seg.nrrd", tags=["results"])
            @_absence_is_never_stored
            def probe(request: Request, ident: str, task: str):
                """200 materialized / 202 computing / 404 absent, never a compute.

                The 200 describes the representation GET would send (RFC 9110 9.3.2):
                the same validator - the content digest, from the entry's result, which
                both lookups hand back - and the same Content-Length. Until 2026-09-21
                it built its headers without the result, so its ETag was the key-derived
                fallback GET never issues, and Starlette filled in ``Content-Length: 0``
                from the empty body, which RFC 9110 8.6 forbids unless GET's content
                would be empty too. A client asking "has this changed?" compared a tag
                no GET had given it, and a shared cache that forwards a HEAD marks its
                stored GET stale when either field differs (RFC 9111 4.3.5) - on
                responses sent ``Cache-Control: public``.

                ``If-None-Match`` is honored, deliberately: RFC 9110 13.1.2 names GET
                and HEAD together for the 304, GET answers it here, and a HEAD that
                said 200 to the request GET says 304 to would be the same disagreement
                one header over. Only the 200 is conditional, as on GET: a flight or an
                absence selects no representation for a tag to match. GET's other
                fields (Content-Type, Content-Disposition, Last-Modified) are left to
                GET - nothing acts on them here, and each would be a second copy of a
                fact ``FileResponse`` owns."""
                from fastapi import Response
                key = keyed(norm(ident), task, gopts)
                if key is None:
                    raise HTTPException(404, "unknown resource")

                def found(hit):
                    headers = _resource_headers(key, hit[1])
                    # WITH the headers, as GET's two sites hand them: a HEAD's 304 repeats its
                    # 200's Cache-Control and Vary too (RFC 9110 15.4.5). The seam between two
                    # branches of 2026-09-21 - the conditional HEAD and the 304's headers -
                    # that `test_whatever_a_conditional_head_answers_says_what_its_200_says`
                    # was written to catch when they met.
                    fresh = not_modified(request, headers["ETag"], headers)
                    if fresh is not None:
                        return fresh
                    resp = Response(status_code=200, headers=headers)
                    try:                       # the file GET's FileResponse would stat
                        resp.headers["content-length"] = str(os.stat(hit[0]).st_size)
                    except OSError:            # left since the lookup: no length beats
                        del resp.headers["content-length"]     # a wrong one; 200 stands
                    return resp

                since = time.monotonic()
                hit = executor.cache_get(key)
                if hit is not None:
                    return found(hit)
                jid = executor.find_inflight(key)
                if jid is not None:
                    # anonymous callers see this too (user decision): watching a
                    # flight for public data is harmless - check back later
                    snap = executor.status_of(jid) or {}
                    return Response(status_code=202,
                                    headers=_progress_headers(snap.get("progress")))
                # a miss from a stale view is not "not materialized" (503 if unverifiable)
                hit = confirm_absent(key, since)
                if hit is not None:
                    return found(hit)
                raise HTTPException(404, "not materialized")

        _grid_routes(_register_probe)

        def _register_resource(tok: str, gopts: dict):
            @app.get(base + f"/labels{tok}.seg.nrrd", tags=["results"])
            @_absence_is_never_stored
            async def resource(request: Request, ident: str, task: str):
                ident = norm(ident)
                if not re.fullmatch(pat, ident):
                    raise HTTPException(422, f"{ident!r} is not a valid {prefix} identifier")
                canonical = canon_task(task)
                if canonical is None:
                    raise HTTPException(404, unknown_task(task))
                task = canonical
                key = derive_key(srcobj.identity(ident), task, gopts)
                fname = f"{_task_stem(task)}_{ident[:8]}{tok}.seg.nrrd"
                # Cache-Control: no-cache from an authorized caller skips the
                # lookup; everything below is the ordinary miss path, so the
                # anonymous rule and "a plain GET is a read" still hold - forcing
                # a recompute from this URL also needs Prefer: wait.
                skip = (wants_no_cache(request) and authed(request)) or \
                    not engine_serves_from_cache(task)

                def serve_hit(hit):
                    headers = _pref_headers(request, key, hit[1])
                    # the client may already hold these exact bytes
                    fresh = not_modified(request, headers["ETag"], headers)
                    if fresh is not None:
                        return fresh
                    return FileResponse(hit[0], media_type="application/octet-stream",
                                        filename=fname, headers=headers)

                since = time.monotonic()
                # off the loop: on Modal a lookup waits out any reload in progress
                hit = None if skip else await asyncio.to_thread(executor.cache_get, key)
                if hit is not None:
                    return serve_hit(hit)
                jid = executor.find_inflight(key)  # single flight: ride an existing run
                if jid is None and not skip:
                    # Nothing running and nothing in view: before calling that "not
                    # materialized" - or computing it again - ask a view newer than this
                    # request (on Modal a refused reload leaves an old one; 2026-09-19).
                    # Unverifiable is a 503: a duplicate compute is no answer to it.
                    hit = await asyncio.to_thread(confirm_absent, key, since)
                    if hit is not None:
                        return serve_hit(hit)
                is_authed = authed(request)
                if not is_authed and jid is None:
                    raise HTTPException(404, "not materialized; authenticated access can "
                                             "compute it")
                initiated = False
                if jid is None:                # authed, nothing running
                    # Labels follow the same rule as every derived artifact
                    # (user decision 2026-08-25, closing review F8): the
                    # Prefer header expresses the intent to compute, its
                    # duration the patience. A plain GET is a read.
                    if _prefer_wait_raw(request, wait_max) is None:
                        raise HTTPException(404, "not materialized; send Prefer: wait to "
                                                 "compute it from this URL (wait=0 fires "
                                                 "the job and returns 202 immediately)")
                    if not _source_enabled(srcobj):
                        raise HTTPException(404, "not materialized, and this server cannot "
                                                 f"fetch {prefix} data (missing dependency)")
                    initiated = True
                    srcdict = {"kind": prefix, "id": ident}
                    if prefix == "idc":
                        srcdict["crdc_series_uuid"] = ident
                    # The same door check submit does. This surface initiates a
                    # compute too, so validating on only one of them lets the two
                    # disagree about what is acceptable - a task refused at
                    # POST /v1/jobs would still run from here. Before
                    # new_job_dir(), so a refusal allocates nothing.
                    _validate_request(seg, task, [srcdict], dict(gopts))
                    # ...and the source's own door check: the allowlist a bucket
                    # must be on, and a credential the source does not take. Both
                    # are decidable with no I/O, and leaving them to the worker
                    # costs a queue slot here and a GPU container on Modal.
                    try:
                        _check_identifier(srcobj, ident,
                                          (source_tokens_of(request) or {}).get(prefix))
                    except InputError as e:
                        raise HTTPException(422, str(e)) from None
                    jid, jdir = executor.new_job_dir()
                    try:
                        # off the loop: on Modal a submit's cache lookup can wait out a
                        # reload (adversarial review, 2026-09-19)
                        await asyncio.to_thread(
                            executor.submit, jid, jdir, None, task, dict(gopts),
                                        no_cache=skip,      # the same skip the lookup used
                                        # ...but the INPUT refresh follows the CALLER only:
                                        # `skip` also carries the engine's cache policy, and
                                        # a VoxTell-class task would then re-download its
                                        # series on every request
                                        refresh_input=(wants_no_cache(request)
                                                       and authed(request)),
                                        source=[srcdict],
                                        identity=(srcobj.identity(ident),),
                                        source_tokens=source_tokens_of(request))
                    except QueueFull as e:
                        import shutil
                        shutil.rmtree(jdir, ignore_errors=True)
                        raise HTTPException(429, str(e),
                                            headers={"Retry-After": "30"}) from e
                wait = _prefer_wait(request, wait_default, wait_max)
                deadline = time.time() + wait
                snap = await asyncio.to_thread(executor.status_of, jid) or {}
                while snap.get("state") not in TERMINAL and time.time() < deadline:
                    await asyncio.sleep(0.5)
                    nxt = await asyncio.to_thread(executor.status_of, jid)
                    if nxt is None:        # record purged mid-watch: the cache
                        if await asyncio.to_thread(executor.cache_get, key) is not None:
                            nxt = {"state": "done"}
                        else:              # job gone, bytes gone - the honest
                                           # answer is absence, NOT a
                                           # synthesized failure (the job may
                                           # have succeeded under no cache)
                            raise HTTPException(404, "not materialized")
                    snap = nxt
                since = time.monotonic()
                hit = await asyncio.to_thread(executor.cache_get, key)
                if snap.get("state") == "done" or hit is not None:
                    # a hit wins even against a failed/cancelled marker:
                    # under duplicate flights the sibling may have published
                    unseen = None
                    if hit is None:            # done, but is it in view?
                        try:
                            hit = await asyncio.to_thread(confirm_absent, key, since)
                        except ResultsNotVisible as e:   # the job's own copy may answer,
                            unseen = e                   # as _job_result lets it
                    headers = _pref_headers(request, key, hit[1] if hit else None)
                    src_path = hit[0] if hit else \
                        (await asyncio.to_thread(executor.result_file, jid))[1]
                    if src_path is None and unseen is not None:
                        raise unseen
                    if src_path is None:       # evicted between done and read
                        raise HTTPException(404, "not materialized")
                    fresh = not_modified(request, headers["ETag"], headers)
                    if fresh is not None:
                        return fresh
                    return FileResponse(src_path, media_type="application/octet-stream",
                                        filename=fname, headers=headers)
                if snap.get("state") == "failed":
                    if not is_authed:          # for anonymous the resource just is not there
                        raise HTTPException(404, "not materialized")
                    raise HTTPException(502, f"segmentation failed: {snap.get('error')}")
                if not is_authed:              # watcher's view: no job vocabulary
                    p = snap.get("progress") or {}
                    return JSONResponse({"state": "materializing",
                                         "progress": {"stage": p.get("stage"),
                                                      "fraction": p.get("fraction")}},
                                        status_code=202,
                                        headers=_progress_headers(snap.get("progress")))
                return JSONResponse({"state": snap.get("state", "queued"), "job": jid,
                                     "initiated": initiated,  # did THIS request start it?
                                     "progress": snap.get("progress")},
                                    status_code=202,
                                    headers=_progress_headers(snap.get("progress")))

        _grid_routes(_register_resource)

        def _register_embedding(tok: str, eopts: dict):
            @app.head(base + f"/embedding{tok}.zarr.zip", tags=["results"])
            @app.get(base + f"/embedding{tok}.zarr.zip", tags=["results"])
            @_absence_is_never_stored
            async def embedding(request: Request, ident: str, task: str):
                """An embedding field by path (2026-09-24): the READ door beside the labels',
                ``task`` being the ENCODER. 200 with the field (304 on a matching
                If-None-Match), 202 while an embedding job for it runs, 404 when there is
                none. It computes nothing, whatever Prefer says: an embedding is computed by
                ``POST /v1/jobs`` with ``kind=embed`` (``haversack remote embed``), whose
                cache hit costs what this does - a second way to start a GPU job would be a
                second set of door checks to keep equal. Anonymous, as a cached label map is."""
                ident = norm(ident)
                if not re.fullmatch(pat, ident):
                    raise HTTPException(422, f"{ident!r} is not a valid {prefix} identifier")
                encoder = canon_encoder(task)
                if encoder is None:
                    raise HTTPException(404, f"no encoder {task!r}; GET /v1/encoders lists them")
                key = await asyncio.to_thread(embed_key, (srcobj.identity(ident),), encoder,
                                              dict(eopts))
                since = time.monotonic()
                # off the loop: on Modal a lookup waits out any reload in progress
                hit = await asyncio.to_thread(executor.cache_get, key)
                if hit is None and executor.find_inflight(key) is None:
                    # a miss is believed only from a view newer than this request: on Modal a
                    # refused reload leaves an old one, and that is a 503, never a 404
                    hit = await asyncio.to_thread(confirm_absent, key, since)
                if hit is None:
                    if executor.find_inflight(key) is not None:
                        return JSONResponse({"state": "materializing"}, status_code=202,
                                            headers=_progress_headers(None))
                    raise HTTPException(404, "not materialized; compute it with POST /v1/jobs "
                                             "kind=embed (haversack remote embed "
                                             f"{prefix}:{ident} --encoder {encoder})")
                headers = _resource_headers(key, hit[1])
                fresh = not_modified(request, headers["ETag"], headers)
                if fresh is not None:
                    return fresh
                stem = re.sub(r"[^A-Za-z0-9._-]+", "_", encoder)
                return FileResponse(hit[0], media_type="application/zip", headers=headers,
                                    filename=f"{stem}_{ident[:8]}{tok}.zarr.zip")

        _register_embedding("", {})
        for etok, eopts in EMBEDDING_TOKENS.items():
            _register_embedding("_" + etok, dict(eopts))

        @app.head(base + f"/{RANKED_NAME}", tags=["results"])
        @app.get(base + f"/{RANKED_NAME}", tags=["results"])
        @_absence_is_never_stored
        async def ranked_store(request: Request, ident: str, task: str):
            """A task's ranked store by path (2026-09-24): the READ door beside its labels, as the
            embedding's is. 200 with the store (304 on a matching If-None-Match), 202 while a
            ranked job for it runs, 404 when there is none. It computes nothing, whatever Prefer
            says: a store is computed by ``POST /v1/jobs`` with ``kind=rankfield``. Anonymous, as a
            cached label map is."""
            ident = norm(ident)
            if not re.fullmatch(pat, ident):
                raise HTTPException(422, f"{ident!r} is not a valid {prefix} identifier")
            canonical = canon_task(task)
            if canonical is None:
                raise HTTPException(404, unknown_task(task))
            key = await asyncio.to_thread(ranked_key, (srcobj.identity(ident),), canonical)
            since = time.monotonic()
            hit = await asyncio.to_thread(executor.cache_get, key)
            if hit is None and executor.find_inflight(key) is None:
                hit = await asyncio.to_thread(confirm_absent, key, since)
            if hit is None:
                if executor.find_inflight(key) is not None:
                    return JSONResponse({"state": "materializing"}, status_code=202,
                                        headers=_progress_headers(None))
                raise HTTPException(404, "not materialized; compute it with POST /v1/jobs "
                                         f"kind=rankfield (haversack remote submit {prefix}:{ident} "
                                         f"--task {canonical} -o <name>.duckn.zip)")
            headers = _resource_headers(key, hit[1])
            fresh = not_modified(request, headers["ETag"], headers)
            if fresh is not None:
                return fresh
            return FileResponse(hit[0], media_type="application/zip", headers=headers,
                                filename=f"{_task_stem(canonical)}_{ident[:8]}.duckn.zip")

        def _register_evict(tok: str, gopts: dict):
            paths = [base + f"/labels{tok}.seg.nrrd"]

            def evict(request: Request, ident: str, task: str):
                """Evict the cached entry (authorized only). Also cancels any
                in-flight single-flight compute for the same key - otherwise
                the entry would repopulate moments after being cleared.
                DELETE + GET = recompute with whatever is installed now; the
                jobs API's no_cache is the per-job form."""
                require_auth(request)
                key = keyed(norm(ident), task, gopts)
                if key is None:
                    raise HTTPException(404, "unknown resource")
                # the delete FIRST: it can refuse (an entry a newer haversack wrote),
                # and cancelling a running compute for a delete that then does not
                # happen is work thrown away for nothing (review, 2026-09-20)
                try:
                    deleted = executor.cache_delete(key)
                except InputError as e:        # an entry a newer haversack wrote:
                    # refusing is the honest answer, and 409 says what to do about it
                    raise HTTPException(409, str(e)) from None
                jid = executor.find_inflight(key)
                if jid is not None:
                    executor.cancel(jid)
                if not deleted and jid is None:
                    raise HTTPException(404, "not materialized")
                out = {"deleted": deleted}
                if jid is not None:
                    out["cancelled_job"] = jid
                return out

            for pth in paths:
                app.delete(pth, tags=["results"])(evict)

        _grid_routes(_register_evict)

        # The bare-task DELETE alias registers LAST: its greedy ident would
        # otherwise swallow the variant URLs, capturing labels.1mm.seg.nrrd
        # as the task segment.
        @app.delete(base, tags=["results"])
        def evict_bare(request: Request, ident: str, task: str):
            allow = _allowed_methods(request)
            if "DELETE" not in allow:
                # the greedy `{ident:path}` took an artifact's file name for the task: that URL
                # has GET and HEAD, not DELETE, which is a 405 saying so - not the 404 "unknown
                # resource" it was until 2026-09-26. A result is deleted at its task's URL.
                return JSONResponse({"detail": "Method Not Allowed"}, status_code=405,
                                    headers={"Allow": ", ".join(sorted(allow))})
            require_auth(request)
            key = keyed(norm(ident), task, {})
            if key is None:
                raise HTTPException(404, "unknown resource")
            # the delete FIRST: it can refuse (an entry a newer haversack wrote),
            # and cancelling a running compute for a delete that then does not
            # happen is work thrown away for nothing (review, 2026-09-20)
            try:
                deleted = executor.cache_delete(key)
            except InputError as e:        # an entry a newer haversack wrote:
                # refusing is the honest answer, and 409 says what to do about it
                raise HTTPException(409, str(e)) from None
            jid = executor.find_inflight(key)
            if jid is not None:
                executor.cancel(jid)
            if not deleted and jid is None:
                raise HTTPException(404, "not materialized")
            out = {"deleted": deleted}
            if jid is not None:
                out["cancelled_job"] = jid
            return out

        def _skip_cache(request: Request) -> bool:
            # `Cache-Control: no-cache` from an authorized caller means "not the stored
            # one" on every path-addressed artifact, not only the labels
            return wants_no_cache(request) and authed(request)

        async def _materialize_entry(request, ident: str, task: str, opts: dict,
                                     key: str, deadline: float, since: float | None = None):
            """Initiate the segmentation chain from an artifact GET - the
            refined rule (user decision): authorized callers with explicit
            intent (Prefer: wait) may materialize the whole dependency chain
            from any derived resource; implicit reads (no Prefer - e.g. bulk
            <img> preview embeds) never compute, and anonymous never computes
            anywhere. WATCHING an already-running flight is read-only and
            open to anyone, as on the labels URL - the gates guard initiation
            only. (Deliberate asymmetry: without Prefer this returns
            immediately - implicit reads never hold a connection - while the
            labels URL holds wait_default for watchers.) Returns the cache
            hit, or raises 202/404/429 - or 503 when ``since`` (the lookup's
            monotonic time; None when the lookup was skipped) cannot be confirmed
            against a current view."""
            jid = executor.find_inflight(key)
            if jid is None and since is not None:
                hit = await asyncio.to_thread(confirm_absent, key, since)
                if hit is not None:
                    return hit
            if jid is None:
                if not authed(request):
                    raise HTTPException(404, "not materialized; authenticated "
                                             "access can compute it")
                if deadline is None:
                    raise HTTPException(404, "not materialized; send Prefer: wait "
                                             "to compute it from this URL (wait=0 "
                                             "fires the job and returns 202 "
                                             "immediately)")
                if not _source_enabled(srcobj):
                    raise HTTPException(404, "not materialized, and this server "
                                             f"cannot fetch {prefix} data")
                srcdict = {"kind": prefix, "id": ident}
                if prefix == "idc":
                    srcdict["crdc_series_uuid"] = ident
                # the same door check submit does - this surface initiates a
                # compute too, and validating on only one door lets them disagree
                _validate_request(seg, task, [srcdict], dict(opts))
                try:
                    _check_identifier(srcobj, ident,
                                      (source_tokens_of(request) or {}).get(prefix))
                except InputError as e:
                    raise HTTPException(422, str(e)) from None
                jid, jdir = executor.new_job_dir()
                try:
                    await asyncio.to_thread(       # off the loop, as on the labels URL
                        executor.submit, jid, jdir, None, task, dict(opts),
                                    no_cache=((wants_no_cache(request) and authed(request))
                                              or not engine_serves_from_cache(task)),
                                    # the CALLER's directive alone - an engine that
                                    # declines result caching must not re-download
                                    # every input as a side effect
                                    refresh_input=(wants_no_cache(request) and authed(request)),
                                    source=[srcdict],
                                    identity=(srcobj.identity(ident),),
                                    source_tokens=source_tokens_of(request))
                except QueueFull as e:
                    import shutil
                    shutil.rmtree(jdir, ignore_errors=True)
                    raise HTTPException(429, str(e),
                                        headers={"Retry-After": "30"}) from e
            snap = await asyncio.to_thread(executor.status_of, jid) or {}
            wait_until = time.time() if deadline is None else deadline
            while snap.get("state") not in TERMINAL and time.time() < wait_until:
                await asyncio.sleep(0.5)
                nxt = await asyncio.to_thread(executor.status_of, jid)
                if nxt is None:            # record purged mid-watch
                    if await asyncio.to_thread(executor.cache_get, key) is not None:
                        nxt = {"state": "done"}
                    else:                  # job gone, bytes gone: absence,
                                           # never a synthesized failure
                        raise HTTPException(404, "not materialized")
                snap = nxt
            hit = await asyncio.to_thread(executor.cache_get, key)
            if hit is not None:            # a hit wins even against a failed/
                return hit                 # cancelled marker (duplicate flights)
            st = snap.get("state")
            if st == "cancelled":          # terminal without a result: absence
                raise HTTPException(404, "not materialized")   # (202 here looped
            if st == "failed":                                 # a poller forever)
                if not authed(request):    # watcher's view: it just is not there
                    raise HTTPException(404, "not materialized")
                raise HTTPException(502, f"segmentation failed: {snap.get('error')}")
            raise HTTPException(202, detail="materializing",
                                headers=_progress_headers(snap.get("progress"),
                                                          {"Retry-After": "5"}))

        def _register_artifact(view: str, tok: str, gopts: dict):
            file, what = ARTIFACT_VIEWS[view]
            stem, _, ext = view.partition(".")

            @_absence_is_never_stored
            async def artifact(request: Request, ident: str, task: str):
                """One artifact of a path-addressed result, under GET and HEAD.

                Both verbs describe ONE representation: the validator is the digest of
                the body (``body_etag``), a HEAD carries the GET's ETag, Content-Length,
                Cache-Control and Vary, and either answers a matching ``If-None-Match``
                with a 304 that repeats the caching fields - what the labels do. Until
                2026-09-21 there was no HEAD here at all (405, ``Allow: DELETE``), the
                tag was the key's, and nothing evaluated ``If-None-Match``; ``meta.json``
                said so in as many words, which was true only while its tag could not
                be trusted. Artifacts land late, so "has the preview rendered?" is a
                question worth a probe that does not download the answer.

                HEAD is a read of what exists: it never computes, never renders, never
                waits, and ignores ``Prefer`` and ``Cache-Control: no-cache``. 200 (or
                304) when the artifact is there; 202 + Retry-After while the labels are
                still computing, or a render that will place THIS deliverable is
                pending; 404 otherwise - a deliverable nobody asked for is a definitive
                404, not a 202, since no render is coming. ``meta.json`` is every
                entry's and waits on nothing, under either verb: 404 until the labels
                are published, as its GET has always answered."""
                from fastapi import Response
                key = keyed(norm(ident), task, gopts)
                if key is None:
                    raise HTTPException(404, "unknown resource")
                head = request.method == "HEAD"
                if head or what is None:
                    since = time.monotonic()
                    # `no-cache` from an authorized caller means "not the stored one";
                    # a HEAD starts nothing, so there it has nothing to mean
                    skip = not head and _skip_cache(request)
                    hit = None if skip else await asyncio.to_thread(executor.cache_get, key)
                    if hit is None and not skip:
                        # both off the loop: on Modal they are Dict reads and a
                        # FunctionCall probe, and this branch is every anonymous HEAD
                        jid = await asyncio.to_thread(executor.find_inflight, key) \
                            if what is not None else None
                        if jid is not None:    # computing: what a GET of it answers too
                            snap = await asyncio.to_thread(executor.status_of, jid) or {}
                            return Response(status_code=202, headers=_progress_headers(
                                snap.get("progress"), {"Retry-After": "5"}))
                        hit = await asyncio.to_thread(confirm_absent, key, since)  # 503 when
                    if hit is None:                        # a stale view cannot tell
                        raise HTTPException(404, "not materialized")
                    deadline = None
                else:
                    w = _prefer_wait_raw(request, wait_max)
                    deadline = None if w is None else time.time() + w
                    since = None if _skip_cache(request) else time.monotonic()
                    hit = None if since is None else \
                        await asyncio.to_thread(executor.cache_get, key)
                    if hit is None:
                        hit = await _materialize_entry(request, norm(ident),
                                                       canon_task(task), gopts, key,
                                                       deadline, since)
                if what is None:
                    return await _artifact_answer(request, view, shared=True, result=hit[1])

                def entry_labels(again):
                    return again[0] if again is not None else None

                found = await _await_artifact(
                    key, hit[0], file, what, deadline=deadline,
                    look_again=lambda: entry_labels(executor.cache_get(key)),
                    confirmed=None if _confirm is None else
                    (lambda since: entry_labels(confirm_absent(key, since))))
                return await _artifact_answer(request, view, shared=True, path=found)

            # two routes, one function (see the job-scoped registration)
            url = base + f"/{stem}{tok}.{ext}"
            app.head(url, tags=["results"])(artifact)
            app.get(url, tags=["results"])(artifact)

        def _register_artifacts(tok: str, gopts: dict):
            # every view under every grid token, from the one table: a view added
            # there is served here and through a job, under both verbs
            for view in ARTIFACT_VIEWS:
                _register_artifact(view, tok, gopts)

        _grid_routes(_register_artifacts)

        if not read_only:                      # the twin can never authenticate: no route
            _register_input_tags_for(prefix, srcobj)

    def _register_input_tags_for(prefix: str, srcobj) -> None:
        """``/v1/<prefix>/<identifier>/dicom.json``: the input's own DICOM tags as JSON
        (2026-09-27). Its own function, not in ``_mount_source``'s closure, so its names
        cannot shadow the path surface's."""
        pat = srcobj.id_pattern

        @_absence_is_never_stored
        async def input_tags(request: Request, ident: str,
                             select: list[str] | None = Query(None),
                             slices: bool = True):
            """The DICOM tags of the input this path names, as its input copy carries them
            (duckn's dicom encoding): ``{"series": {...}, "slices": [{...}, ...],
            "stored_values": ..., "tags_version": ...}``.

            ``select`` (repeatable) keeps what it names - dicom-spec §5's groups (``ct``,
            ``series``, ``patient`` ...) or PS3.6 keywords (``KVP``); ``slices=false`` leaves
            the per-slice tags out. What this server's policy withholds is ``null``, with
            ``"anonymized": true`` - never silently left out.

            Needs the token, and fetches the input if this server does not hold it yet (a GET
            is the request for it; HEAD never fetches, and says 404 until it is held). Hosted
            sources only: an upload's tags are never handed back, as its bytes are not."""
            require_auth(request)
            fn = getattr(executor, "input_tags", None)
            if not callable(fn):
                raise HTTPException(501, "this deployment does not serve input tags; read them "
                                         "with `haversack tags SPEC` where the input is")
            ident = norm_ident(prefix, ident)
            if not re.fullmatch(pat, ident):
                raise HTTPException(422, {"code": "bad_identifier",
                                          "message": f"not a {prefix} identifier: {ident}"})
            try:
                tags = await asyncio.to_thread(fn, prefix, ident,
                                               fetch=request.method != "HEAD",
                                               select=select, per_slice=slices)
            except ValueError as e:            # a group or keyword that is neither
                raise HTTPException(422, {"code": "bad_name", "message": str(e)}) from None
            except TagsWithheld as e:
                raise HTTPException(403, {"code": "input_withheld", "message": str(e)}) from None
            except InputError as e:
                raise HTTPException(422, {"code": "fetch_failed", "message": str(e)}) from None
            if tags is None:
                raise HTTPException(404, {"code": "not_held", "message": (
                    f"this server does not hold {prefix}:{ident}; a GET fetches it")})
            if not tags:
                raise HTTPException(404, {"code": "no_dicom_tags", "message": (
                    f"{prefix}:{ident} carries no DICOM tags (it is not DICOM)")})
            from fastapi.responses import Response
            body = json.dumps(tags, ensure_ascii=False, separators=(",", ":")).encode("utf-8")
            # private: a token's answer; no-cache: a policy change or a refetch changes it
            return answer_body(request, Response(body, media_type="application/json"),
                               {"Cache-Control": "private, no-cache", "ETag": body_etag(body)})

        # two routes, one function, as the artifacts (FastAPI names an operation per route)
        url = f"/v1/{prefix}/{{ident:path}}/dicom.json"
        app.head(url, tags=["inputs"])(input_tags)
        app.get(url, tags=["inputs"])(input_tags)

    for _prefix, _srcobj in sources.items():
        # a source that says it has no path surface gets none (`result`: its identity
        # needs a lookup, and a path is keyed without one - see resource_links, which
        # mints no link for it either). `is False`: a duck-typed stand-in that says
        # nothing is mounted, as every source always was.
        if getattr(_srcobj, "path_addressable", True) is False:
            continue
        _mount_source(_prefix, _srcobj)

    if read_only:
        # The read-only surface is the SAME routes minus everything that
        # writes: jobs, prepare, describe (needs a real segmenter), every
        # DELETE (path-surface evicts + job cancel), and the listing when
        # no lister was provided. Removing them from the router is exactly
        # never-registering them - a POST /v1/jobs 404s, it does not 401.
        def _keep(r):
            path = getattr(r, "path", "")
            if path.startswith("/v1/jobs") or path in ("/v1/tasks/{task}",
                                                       "/v1/tasks/{task}/prepare"):
                return False
            if "DELETE" in (getattr(r, "methods", None) or ()):
                return False
            if path == "/v1/segmentations" and getattr(executor, "cache_list",
                                                       None) is None:
                return False
            return True

        app.router.routes = [r for r in app.router.routes if _keep(r)]

    return app


def create_public_app(key_fn, cache_get, tasks_fn, inflight=None, sources=None,
                      list_fn=None, resolve_fn=None, versions_fn=None, confirm_absent=None,
                      weights_fn=None, artifact_state=None):
    """The anonymous read-only twin: cache hits and nothing else.

    Since review R4 this is create_app itself over a CacheOnlyExecutor with
    ``read_only=True`` - the same route code as the main app, so filenames,
    headers, grid variants, meta/preview/statistics routes and the listing
    hold parity by construction instead of by copy. Read-only means: authed()
    is constant-False (nothing can initiate) and every mutating route (jobs,
    prepare, DELETEs) is absent from the router - it cannot spend a GPU cent
    by construction, the right worst case for a public face. Misses are 404;
    ``inflight(key)`` (optional) lets anonymous callers watch an authorized
    flight with 202 + progress and long-poll it with Prefer: wait - watching
    is read-only, only starting needs auth.

    ``key_fn(identity, task, opts)`` maps a source identity string
    ("idc:<uuid>") and grid options to the result-cache key - the twin must
    key exactly as the writer did. ``list_fn`` (optional) backs
    /v1/segmentations; omit it to keep the twin listing-free. It is called as
    ``list_fn(keys=, limit=, after=, accept=, match=)`` and answers ``(rows, position)`` -
    ``ResultCache.list``'s own signature, so a bound ``cache.list`` is one (2026-09-20;
    it used to take nothing and return every row, capped at 500). ``confirm_absent(key,
    since)`` (optional) re-asks a miss of a current view - see ResultsNotVisible.
    ``weights_fn(task)`` (optional) is the weights-versions list ``key_fn`` keys ``task``
    on - ``result_key``'s fourth argument: with it the listing reads a task's versions once
    a request instead of once a key, and MUST then derive exactly what ``key_fn`` would.
    Optional for labels only: a rank field's or an embedding's key is derived from it (a
    rank field's from ``weights_fn(task)`` plus its format tag; either kind's from
    ``weights_fn(name, kind=...)`` when it takes the kind), so a twin without it finds none
    of either (review, 2026-09-25).
    ``artifact_state(key, name)`` (optional) is the writer's pending-render signal -
    "pending" while a render that will place deliverable ``name`` into ``key``'s entry is
    still running, else "absent" - read-only like ``inflight``. With it an artifact that is
    seconds from landing answers 202 + Retry-After here as it does on the api; without it
    (before 2026-09-21 there was no way to give it) the twin cannot tell and says 404.
    """
    ex = CacheOnlyExecutor(cache_get, key_fn, tasks_fn, inflight_fn=inflight,
                           resolve_fn=resolve_fn, list_fn=list_fn,
                           sources=sources, versions_fn=versions_fn,
                           confirm_absent=confirm_absent, weights_fn=weights_fn,
                           artifact_state=artifact_state)
    return create_app(ex, read_only=True)


def _truthy_env(name: str) -> bool:
    """Case-insensitive, so `HAVERSACK_ALLOW_TRANSPOSE=False` means what it says."""
    return (os.environ.get(name) or "").strip().lower() not in ("0", "false", "no", "off", "")


def main_serve(args) -> int:
    """`haversack serve` - build a Segmenter from the CLI arguments and run uvicorn."""
    try:
        import uvicorn
    except ImportError as e:
        raise InputError("the server needs the serve extra: uv sync --extra serve "
                         "(or uv pip install 'haversack[serve] @ git+https://github.com/mhalle/haversack')") from e
    import tempfile

    from .segmenter import Segmenter

    seg = Segmenter(device=args.device, dtype=args.dtype, weights=args.model_root,
                    cache_models=args.cache_models,
                    allow_transpose=bool(getattr(args, "allow_transpose", False)
                                         or _truthy_env("HAVERSACK_ALLOW_TRANSPOSE")))
    from .cache_admin import check_cache_root
    check_cache_root()                     # the token file lives under it whatever else does
    workdir = args.workdir or Path(tempfile.gettempdir()) / "haversack-serve"
    cache_dir = None
    if not getattr(args, "no_result_cache", False):
        from .cache_admin import results_dir
        cache_dir = getattr(args, "cache_dir", None) or results_dir()
    for flag, d in (("--workdir", workdir), ("--cache-dir", cache_dir)):
        if d is None:
            continue
        try:
            Path(d).mkdir(parents=True, exist_ok=True)
        except OSError as e:
            raise InputError(f"{flag} {d}: {e.strerror or e}") from None
    ex = LocalExecutor(seg, workdir=workdir, max_pending=args.max_pending,
                       input_cache_bytes=int(float(getattr(args, "input_cache_gb", 8.0)) * (1 << 30)),
                       keep_finished=args.keep_finished, cache_dir=cache_dir,
                       jobs_ttl_h=getattr(args, "jobs_ttl_hours", 24.0),
                       result_store=getattr(args, "result_store", None) or None,
                       sweep_interval_h=getattr(args, "sweep_interval_hours", 24.0),
                       dicom_withhold=[n.strip() for n in
                                       str(getattr(args, "dicom_withhold", None) or "").split(",")
                                       if n.strip()])
    # The token: given (--token, then HAVERSACK_SERVER_TOKEN), generated, or - only when
    # asked for in so many words - none. A generated token goes to a file only this user can
    # read, and the bundled client on this machine reads it back, so personal use needs no
    # ceremony while a proxy or tunnel in front of the server exposes something that still
    # demands a token.
    from .cache_admin import (TOKEN_FLAG_NOTE, _alive, _is_loopback,  # noqa: PLC2701
                              serve_token_path, server_token, write_serve_token)
    token, token_source = server_token(getattr(args, "token", None))
    generated = False
    if getattr(args, "no_token", False):
        token, token_source = None, None
        print(f"warning: serving on {args.host}:{args.port} WITHOUT a token - this server is "
              "open to anything that can reach the port, a proxy or tunnel included",
              file=sys.stderr, flush=True)
    elif not token:
        import secrets
        token, generated = secrets.token_urlsafe(24), True
    app = create_app(ex, token=token)
    # Bind BEFORE touching the token file: a second server on a busy port must fail
    # here, without overwriting the running server's file and then deleting it on exit.
    config = uvicorn.Config(app, host=args.host, port=args.port, log_level="warning")
    server = uvicorn.Server(config)
    try:
        sock = config.bind_socket()
    except OSError as e:
        raise InputError(f"cannot listen on {args.host}:{args.port}: {e}") from e
    token_file = serve_token_path(args.port)
    # A successful bind does not prove the port is ours alone (a wildcard bind beside a
    # loopback one, or v4 beside v6, both succeed): a file whose server is still alive
    # belongs to that server, and its clients - refuse rather than take its file away.
    try:
        import json as _json
        owner = _json.loads(token_file.read_text(encoding="utf-8")).get("pid")
    except (OSError, ValueError, AttributeError):
        owner = None
    if owner and owner != os.getpid() and _alive(owner):
        sock.close()
        raise InputError(f"another haversack server (pid {owner}) already serves port "
                         f"{args.port} on this machine; stop it, or pick another port")
    try:                                   # what is left is stale whatever we do
        token_file.unlink(missing_ok=True)
    except OSError:
        pass
    # The file is for the bundled client on THIS machine, which only ever reads it for a
    # loopback address; a server bound to one interface's address is not reachable there
    wildcard = args.host in ("0.0.0.0", "::", "")
    if generated and (wildcard or _is_loopback(str(args.host).lower())):
        try:
            write_serve_token(token_file, token, host=args.host, port=args.port)
        except OSError as e:
            sock.close()
            raise InputError(f"cannot write the token file {token_file}: {e}") from None
    print(f"haversack {_version()} serving on http://{args.host}:{args.port} "
          f"(device={args.device}, workdir={workdir})", flush=True)
    if getattr(args, "result_store", None):
        # which store a writer publishes into is the first thing to know about a shared cache,
        # and the startup lines did not say it (2026-09-26); any credentials in the URL are cut
        from urllib.parse import urlsplit, urlunsplit
        u = urlsplit(str(args.result_store))
        shown = (urlunsplit(u._replace(netloc=u.netloc.rsplit("@", 1)[1])) if "@" in u.netloc
                 else str(args.result_store))
        print(f"result store: {shown} (local copy {cache_dir})", flush=True)
    if generated:
        print(f"token: {token}\n  written to {token_file} (this user only); `haversack remote` "
              "on this machine uses it by itself, other machines pass --token", flush=True)
    elif token_source:
        print(f"token: from {token_source}", flush=True)
        if token_source == "--token":
            print(TOKEN_FLAG_NOTE, file=sys.stderr, flush=True)
    try:
        server.run(sockets=[sock])
    except KeyboardInterrupt:
        # uvicorn has already shut down gracefully on the Ctrl-C; asyncio's runner re-raises
        # it after, and it reached the interpreter as a traceback (2026-09-26). A server is
        # stopped this way on purpose: say so, and exit 130 (128 + SIGINT, the status a shell
        # reports for it) with the exit handlers run - the token file is removed by one.
        print("haversack: stopped", file=sys.stderr, flush=True)
        return 130
    return 0
