"""RaCo-ALIKED feature extraction through a batched, dynamic-shape TensorRT engine.

The `raco` half of `colsfm.features`, and the third backend after `pycolmap`
(COLMAP's own ONNX ALIKED) and `tensorrt` (the blob's static batch-1 engine).

**What the model is.** RaCo-ALIKED is fabio-sim's rotation-and-scale-consistent
retraining of ALIKED, published with LightGlue-ONNX and the subject of the
"Discovering TensorRT Optimizations for RaCo-ALIKED-LightGlue+" write-up. The
graph this module runs is `data/cusfm_models/raco-aliked-b1-16.onnx`, exported
from that package by `tools/export_cusfm_raco.py --batched-extractor-path` in
the repo's `raco` Pixi environment (`lightglue-onnx` at `d12b4ba`). Nothing here
imports `onnx` or `torch`: the `colsfm` environment only parses the graph with
TensorRT's own `OnnxParser`, which is the same split `colsfm.tensorrt_runtime`
documents.

**What is different from `colsfm.features_trt`.** One thing, and it is the whole
point: the graph has a real batch axis, `image [batch, 3, 1200, 1920]` with
`batch` in 1..16, so the engine is built with an optimisation profile rather than
at the shipped static shape and `DEFAULT_BATCH_SIZE` images cross the PCIe bus
and the detector pyramid together. Everything either side of the engine is
unchanged and runs through `colsfm.features_native`, the same module the blob's
backend runs through: the same OpenCV preprocessing, the same bounded
decode-ahead thread pool, the same `(k + 1) * 0.5 * (size - 1)` mapping back onto
the original image, the same two database columns written for image rows
somebody else created. What this module still owns is what is RaCo's alone —
which of two graphs serves a size, what its optimisation profiles are, how wide
a batch each admits, and that its `scores` output is a rank rather than a
detector response.

**Native resolution is the default, and it is a deliberate deviation.** The
blob's feature extractor resizes every input to its network size
(`docs/spec/feature_extractor_main.md` §8), and the fixed-shape graph above does
the same: a 1226x370 KITTI frame is inferred over 1920x1200, five times the
pixels it has, for 19.6 ms against pycolmap's 7.8 ms at the native size
(`docs/kitti-06-results.md` §9). `native_resolution=True` instead runs each image at its own size rounded up to
`INPUT_DIM_DIVISOR` — so KITTI at 1248x384 and Galileo at 1920x1216. Images are
grouped by that rounded size so a batch is still one shape, and the mapping back
to pixels needs nothing new: `normalized_to_pixels` already targets the
*original* size, and rounding up (a rescale) rather than padding (a translation)
keeps it exact. `native_resolution=False` restores the stretch, on the old graph
and the old engine, so the two are measurable against each other.

**Native resolution does not mean the shape-dynamic engine.** Two engines can
serve a size, and the shape-dynamic one
(`data/cusfm_models/raco-aliked-dyn.onnx`, spatial axes symbolic) is only faster
below the top of its profile. Galileo *is* the top — 1920x1200, the profile
maximum — and there the dynamic engine costs 4.96 s against the fixed engine's
2.70 s over 226 images: one profile's tactics have to cover 256x256 to 1216x1920,
and the host pays a `cv2.resize` from 1200 to 1216 the fixed path skips. So
`select_raco_engine` decides per size group, `raco_engine="auto"`: a group the
fixed engine already accepts goes to the fixed engine, everything else to the
dynamic one, and KITTI keeps its 11.86 to 4.87 ms an image. `raco_engine="fixed"`
and `"dynamic"` force one, which is how the two are measured against each other.

**Scores are a selection order, not a detector response.** Upstream's boundary
ranker returns its top 2048 points already ordered but never materialises a
dense score map, so `tools/export_cusfm_raco.py` writes a strictly decreasing
`arange(2048, 0, -1) / 2048` in the `scores` output and stamps
`cusfm_scores=monotonic_upstream_selection_priority` into the ONNX metadata. The
smallest of those is `1/2048 = 0.00049`, which is *below* the blob's
`detector_threshold` of 0.005, so applying that gate here would throw away ten
points per image for no reason and for no meaning. `min_score` is therefore read
but compared against a rank, and `DEFAULT_MIN_SCORE` is 0: the honest reading is
that this graph has no score gate, and the matcher's SSC (which runs on
*LightGlue* scores, `colsfm.matching_raco`) is where selection actually happens.
"""

from __future__ import annotations

import time
from collections.abc import Sequence
from dataclasses import dataclass
from pathlib import Path
from typing import Final, Literal, TypeAlias

from colsfm import REPO_ROOT
from colsfm.database import keypoint_counts
from colsfm.features import RacoEngineChoice, TensorRTExtraction
from colsfm.features_native import (
    ALIKED_IMAGE_BINDING,
    DEFAULT_GPU_PREPROCESSING,
    DEFAULT_PREPROCESSING_WORKERS,
    DESCRIPTOR_TYPE,
    ExtractionGroup,
    ImageTask,
    NativeModel,
    image_tasks,
    run_native_extraction,
)
from colsfm.features_trt import NETWORK_HEIGHT, NETWORK_WIDTH
from colsfm.tensorrt_runtime import ShapeProfile, resolve_engine

RACO_ONNX_PATH: Final[Path] = REPO_ROOT / "data" / "cusfm_models" / "raco-aliked-b1-16.onnx"
"""The batch-dynamic RaCo-ALIKED graph; its engine is cached beside it.

Not committed — `data/cusfm_models` is gitignored and the graph is 8.9 MB of
weights. Produce it with
`pixi run -e raco raco-export --batched-extractor-path data/cusfm_models/raco-aliked-b1-16.onnx`."""

RACO_DYNAMIC_ONNX_PATH: Final[Path] = REPO_ROOT / "data" / "cusfm_models" / "raco-aliked-dyn.onnx"
"""The batch- **and** shape-dynamic RaCo-ALIKED graph; its engine is cached beside it.

Also not committed. Produce it with
`pixi run -e raco raco-export --dynamic-shape --batched-extractor-path data/cusfm_models/raco-aliked-dyn.onnx`."""

MINIMUM_BATCH_SIZE: Final[int] = 1
"""The optimisation profile's `min`, so a one-image run still executes."""

DEFAULT_BATCH_SIZE: Final[int] = 8
"""Images per execution, and the profile's `opt`; `tools/raco_extract.py`'s own default."""

MAXIMUM_BATCH_SIZE: Final[int] = 16
"""The fixed-shape profile's `max`, and the ceiling the ONNX graph itself was exported with."""

DYNAMIC_MAXIMUM_BATCH_SIZE: Final[int] = 8
"""The shape-dynamic profile's `max` batch.

16 is inside the fixed-shape graph's export bounds but its execution already
failed on a 32 GB 5090 (NOTES.md "RaCo backend"), and with the spatial axes
dynamic the builder has to size its tactic workspace for the *maximum* shape as
well, which pushes the build itself over. 8 is `DEFAULT_BATCH_SIZE`, so nothing
in the extraction path wants more."""

INPUT_DIM_DIVISOR: Final[int] = 32
"""RaCo's four-level pyramid pools by 32, so both network sides must be multiples of it.

`tools/export_cusfm_raco.INPUT_DIM_DIVISOR` is the same constant read off
upstream's `Extractor.raco_aliked.input_dim_divisor`; the dynamic graph's input
is literally declared as `32 * height_factor` by `32 * width_factor`."""

MINIMUM_NETWORK_SIDE: Final[int] = 256
"""The profile's `min` height and width.

Below this the detector's top-2048 head starts competing with the number of
candidates the boundary ranker can find, and no camera this pipeline sees is
smaller."""

OPTIMAL_NETWORK_HEIGHT: Final[int] = 768
"""The profile's `opt` height; a midpoint between KITTI's 384 and Galileo's 1216."""

OPTIMAL_NETWORK_WIDTH: Final[int] = 1024
"""The profile's `opt` width; the same midpoint between KITTI's 1248 and Galileo's 1920."""

MAXIMUM_NETWORK_HEIGHT: Final[int] = 1216
"""The profile's `max` height: Galileo's 1200 rounded up to `INPUT_DIM_DIVISOR`.

1216 is also the height the *fixed*-shape graph resamples to internally, so a
Galileo frame reaches the same convolutions either way."""

MAXIMUM_NETWORK_WIDTH: Final[int] = 1920
"""The profile's `max` width, which Galileo already is."""

RACO_MODEL: Final[NativeModel] = NativeModel(
    name="raco",
    image_binding=ALIKED_IMAGE_BINDING,
    descriptor_type=DESCRIPTOR_TYPE,
    score_meaning="selection_rank",
)
"""RaCo's graphs as `colsfm.features_native` sees them.

`selection_rank` is the load-bearing half, and the module docstring above is its
justification: this graph's `scores` never touched a score map, so the blob's
`detector_threshold` means nothing against it and `colsfm.features` passes
`RACO_MIN_SCORE` instead. Both graphs bind their image as `image` and store
`ALIKED_N16ROT` descriptors, which is why one runner drives both."""


def raco_profile(network_height: int = NETWORK_HEIGHT, network_width: int = NETWORK_WIDTH) -> dict[str, ShapeProfile]:
    """The optimisation profile the batch-dynamic, fixed-shape graph is built with.

    Args:
        network_height: The graph's input height.
        network_width: The graph's input width.

    Returns:
        One `(minimum, optimal, maximum)` shape for the `image` binding.
    """
    return {
        ALIKED_IMAGE_BINDING: (
            (MINIMUM_BATCH_SIZE, 3, network_height, network_width),
            (DEFAULT_BATCH_SIZE, 3, network_height, network_width),
            (MAXIMUM_BATCH_SIZE, 3, network_height, network_width),
        )
    }


def raco_dynamic_profile() -> dict[str, ShapeProfile]:
    """The optimisation profile the shape-dynamic graph is built with.

    One profile, not two: TensorRT picks tactics for `opt` and tolerates the rest
    of the range, and a second profile would double the build (already the
    expensive part) to serve a bimodal size distribution this repo does not have.

    Returns:
        One `(minimum, optimal, maximum)` shape for the `image` binding, spanning
        256x256 to 1216x1920 at batch 1 to `DYNAMIC_MAXIMUM_BATCH_SIZE`.
    """
    return {
        ALIKED_IMAGE_BINDING: (
            (MINIMUM_BATCH_SIZE, 3, MINIMUM_NETWORK_SIDE, MINIMUM_NETWORK_SIDE),
            (DEFAULT_BATCH_SIZE, 3, OPTIMAL_NETWORK_HEIGHT, OPTIMAL_NETWORK_WIDTH),
            (DYNAMIC_MAXIMUM_BATCH_SIZE, 3, MAXIMUM_NETWORK_HEIGHT, MAXIMUM_NETWORK_WIDTH),
        )
    }


def raco_dynamic_engine_tag() -> str:
    """The engine cache name's profile tag, so a re-tuned profile is a different file.

    Returns:
        `b<min>-<max>_<min side>x<min side>_<max height>x<max width>`.
    """
    return (
        f"b{MINIMUM_BATCH_SIZE}-{DYNAMIC_MAXIMUM_BATCH_SIZE}"
        f"_{MINIMUM_NETWORK_SIDE}x{MINIMUM_NETWORK_SIDE}"
        f"_{MAXIMUM_NETWORK_HEIGHT}x{MAXIMUM_NETWORK_WIDTH}"
    )


def network_size_for(image_height: int, image_width: int) -> tuple[int, int]:
    """The network size one image runs at when the engine is shape-dynamic.

    The image's own size, rounded **up** to `INPUT_DIM_DIVISOR` and clamped into
    the profile. Rounding up rather than padding keeps the mapping back to pixels
    a plain linear rescale, which is exactly what `normalized_to_pixels` already
    is — a padded border would put keypoints in a frame that mapping does not
    describe.

    Args:
        image_height: The image's own height in pixels.
        image_width: The image's own width in pixels.

    Returns:
        `(network_height, network_width)`, both multiples of `INPUT_DIM_DIVISOR`
        and inside the profile's bounds.
    """

    def rounded(side: int, ceiling: int) -> int:
        grid: int = -(-max(side, MINIMUM_NETWORK_SIDE) // INPUT_DIM_DIVISOR) * INPUT_DIM_DIVISOR
        return min(grid, ceiling)

    return rounded(image_height, MAXIMUM_NETWORK_HEIGHT), rounded(image_width, MAXIMUM_NETWORK_WIDTH)


RacoEngineKind: TypeAlias = Literal["fixed", "dynamic"]
"""Which of the two RaCo graphs an engine was built from."""


@dataclass(frozen=True, slots=True)
class RacoEngine:
    """The engine one size group runs through, and the input size it is handed."""

    kind: RacoEngineKind
    """`fixed` is the batch-dynamic graph at its declared size, `dynamic` the shape-dynamic one."""
    onnx_path: Path
    """The graph the engine is built from, and the cache name it is stored under."""
    network_height: int
    """The height the engine takes, which is what preprocessing resizes to."""
    network_width: int
    """The width the engine takes."""
    maximum_batch_size: int
    """The images its optimisation profile admits in one execution."""


def fixed_engine_size_group() -> tuple[int, int]:
    """The `network_size_for` group whose images the fixed-shape engine also serves.

    The two graphs do not take the same numbers for the same picture: the fixed
    one is declared at 1200x1920 and interpolates to 1216x1920 *inside* itself,
    while the dynamic export rounds 1200 up to 1216 on the host. So the group is
    the fixed engine's own input put through the same rounding — 1216x1920 —
    and not the input itself.

    Returns:
        `(network_height, network_width)` of the group the fixed engine covers.
    """
    return network_size_for(NETWORK_HEIGHT, NETWORK_WIDTH)


def select_raco_engine(network_size: tuple[int, int], choice: RacoEngineChoice = "auto") -> RacoEngine:
    """Pick the engine one size group runs on.

    `auto` exists because the dynamic engine is not free at the top of its
    profile: Galileo, which *is* the profile maximum, extracts in 4.96 s against
    the fixed engine's 2.70 s (`docs/gpu-preprocessing.md`), part single-profile
    tactic selection and part a host `cv2.resize` from 1200 to 1216 that the
    fixed path skips. Below the maximum the dynamic engine is the whole win —
    KITTI goes 11.86 to 4.87 ms an image — so the rule is size-directed, not
    global.

    Args:
        network_size: `(network_height, network_width)` from `network_size_for`.
        choice: `auto` decides by size; `fixed` and `dynamic` force one engine.

    Returns:
        The graph, the input size to preprocess to, and the batch ceiling.
    """
    fixed: bool = choice == "fixed" or (choice == "auto" and network_size == fixed_engine_size_group())
    if fixed:
        return RacoEngine(
            kind="fixed",
            onnx_path=RACO_ONNX_PATH,
            network_height=NETWORK_HEIGHT,
            network_width=NETWORK_WIDTH,
            maximum_batch_size=MAXIMUM_BATCH_SIZE,
        )
    return RacoEngine(
        kind="dynamic",
        onnx_path=RACO_DYNAMIC_ONNX_PATH,
        network_height=network_size[0],
        network_width=network_size[1],
        maximum_batch_size=DYNAMIC_MAXIMUM_BATCH_SIZE,
    )


def engine_file(engine: RacoEngine) -> Path:
    """Build or find the cached engine file for one selection.

    Args:
        engine: What `select_raco_engine` returned.

    Returns:
        The serialised engine, built on first use.
    """
    if engine.kind == "fixed":
        return resolve_engine(engine.onnx_path, raco_profile())
    return resolve_engine(engine.onnx_path, raco_dynamic_profile(), profile_tag=raco_dynamic_engine_tag())


def _size_groups(tasks: Sequence[ImageTask]) -> dict[tuple[int, int], list[ImageTask]]:
    """Group images by the network size they will run at, keeping their order.

    A batch is one TensorRT execution at one input shape, so images of different
    sizes cannot share one. Grouping first means a mixed-camera set still fills
    its batches instead of flushing a short one at every size change.

    Args:
        tasks: The images, in the order their results are wanted.

    Returns:
        Tasks per `(network_height, network_width)`, first-seen size first.
    """
    groups: dict[tuple[int, int], list[ImageTask]] = {}
    for task in tasks:
        groups.setdefault(network_size_for(task.image_height, task.image_width), []).append(task)
    return groups


def extraction_groups(tasks: Sequence[ImageTask], *, native_resolution: bool, choice: RacoEngineChoice) -> list[ExtractionGroup]:
    """Decide which engine runs which images, and at what size.

    The whole of RaCo's engine policy, and the only part of extraction this
    backend still owns: group by the size each image will run at, pick an engine
    per group, and resolve — building on first use — the engine file. Resolving
    every group before any of them executes means a build that fails leaves no
    half-extracted database behind.

    Args:
        tasks: The images, in the order their results are wanted.
        native_resolution: Run each image at its own size rounded up to
            `INPUT_DIM_DIVISOR`. `False` puts every image in one group at the
            fixed graph's declared 1920x1200.
        choice: Which engine serves a group; see `select_raco_engine`.

    Returns:
        One group per network size, first-seen size first; empty when there is
        nothing to extract.
    """
    sizes: dict[tuple[int, int], list[ImageTask]] = (
        _size_groups(tasks) if native_resolution else {fixed_engine_size_group(): list(tasks)}
    )
    groups: list[ExtractionGroup] = []
    for network_size, group in sizes.items():
        if not group:
            continue
        engine: RacoEngine = select_raco_engine(network_size, choice)
        groups.append(
            ExtractionGroup(
                engine_path=engine_file(engine),
                tasks=group,
                network_height=engine.network_height,
                network_width=engine.network_width,
            )
        )
    return groups


def extract_raco(
    database_path: Path,
    image_root: Path,
    image_names: Sequence[str],
    *,
    min_score: float,
    max_num_features: int,
    batch_size: int = DEFAULT_BATCH_SIZE,
    preprocessing_workers: int = DEFAULT_PREPROCESSING_WORKERS,
    gpu_preprocessing: bool = DEFAULT_GPU_PREPROCESSING,
    native_resolution: bool = True,
    raco_engine: RacoEngineChoice = "auto",
) -> TensorRTExtraction:
    """Run the batched RaCo-ALIKED engine over the named images and store the features.

    Args:
        database_path: An existing COLMAP database whose image rows are written.
        image_root: Directory the `image_names` are relative to.
        image_names: Images to extract, as stored in the database.
        min_score: Gate on the graph's `scores` output. See the module docstring:
            that output is a selection rank, so anything above 0 truncates by
            rank rather than by detector response.
        max_num_features: Keypoint ceiling per image; the graph's own top-2048
            head normally binds first, so this only ever truncates.
        batch_size: Images executed together, 1 to the graph's batch ceiling.
            `native_resolution` bounds it at `DYNAMIC_MAXIMUM_BATCH_SIZE` unless
            `raco_engine` forces the fixed engine, because `auto` may reach the
            dynamic one for any size group.
        preprocessing_workers: Decode-and-resize threads.
        gpu_preprocessing: Stage the decoded uint8 frames in one page-locked
            batch buffer and let a TensorRT preprocessing engine transpose, widen
            and scale them. `False` restores the host conversion plus the
            `np.concatenate` that used to build every batch.
        native_resolution: Run each image at its own size, rounded up to
            `INPUT_DIM_DIVISOR`, on whichever engine `raco_engine` picks for that
            size. `False` is the legacy behaviour: the fixed-shape graph, and
            every frame stretched to 1920x1200 whatever it was.
        raco_engine: Which engine serves a size group; see `select_raco_engine`.
            Read only when `native_resolution` is on — the stretch is the fixed
            engine by definition.

    Returns:
        Keypoints stored per `image_id`, and the wall time of the whole pass
        including the engine load.

    Raises:
        FileNotFoundError: When the database, the image root, an image or the
            ONNX graph is missing.
        ValueError: When `batch_size` is outside the graph's profile.
    """
    if not database_path.is_file():
        raise FileNotFoundError(f"No COLMAP database at {database_path}")
    if not image_root.is_dir():
        raise FileNotFoundError(f"No image directory at {image_root}")
    engine_choice: RacoEngineChoice = raco_engine if native_resolution else "fixed"
    maximum_batch_size: int = MAXIMUM_BATCH_SIZE if engine_choice == "fixed" else DYNAMIC_MAXIMUM_BATCH_SIZE
    if not MINIMUM_BATCH_SIZE <= batch_size <= maximum_batch_size:
        raise ValueError(f"batch_size must be in [{MINIMUM_BATCH_SIZE}, {maximum_batch_size}], got {batch_size}")

    started: float = time.perf_counter()
    tasks: list[ImageTask] = image_tasks(database_path, image_root, image_names)
    run_native_extraction(
        database_path,
        extraction_groups(tasks, native_resolution=native_resolution, choice=engine_choice),
        RACO_MODEL,
        min_score=min_score,
        max_num_features=max_num_features,
        batch_size=batch_size,
        preprocessing_workers=preprocessing_workers,
        gpu_preprocessing=gpu_preprocessing,
    )
    elapsed_seconds: float = time.perf_counter() - started
    return keypoint_counts(database_path, [task.image_id for task in tasks]), elapsed_seconds
