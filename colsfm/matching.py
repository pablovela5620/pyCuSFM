"""LightGlue matching plus geometric verification — the replacement for `feature_matcher_main`.

COLMAP 4.2 ships `FeatureMatcherType.ALIKED_LIGHTGLUE` and downloads the ONNX
graph itself into `~/.cache/colmap/`, so the whole stage is a
`pycolmap.match_image_pairs` call over a pair list, with verification running
inside COLMAP. Its graph is not the blob's — see `MatchingOptions.model_path`.

The blob's own pipeline is LightGlue -> score gate -> spatial NMS -> essential
matrix RANSAC (feature_matcher_main.md §5). Three of those four map straight
across; the fourth does not:

| blob | here |
|---|---|
| `mscores0 > match_threshold` (0.3) | `LightGlueONNXMatchingOptions.min_score` |
| SSC NMS down to `match_top_k: 500` | `match_limit` — a score-free grid subsample, see below |
| `cv::findEssentialMat`, threshold `0.5*(err/f0 + err/f1)` on bearings | `TwoViewGeometryOptions.ransac.max_error = 4.0` px on a real camera model |
| `n_inliers < 10` empties the pair | `TwoViewGeometryOptions.min_num_inliers = 10` |

**The SSC divergence.** The blob thins each pair's matches to a spatially uniform
top-500 using the LightGlue score as the keypoint response, which is what turns
its ~931 raw matches per Galileo pair into ~430. pycolmap exposes no per-match
score: `Database.read_matches` and `FeatureMatcher.match` both return bare
`uint32[m, 2]` index pairs, so neither the sort key nor SSC's "strongest per
cell" rule exists on this side. What the blob is *buying* with SSC — spatial
uniformity and a bounded track density — is reachable without a score, so
`subsample_matches_by_coverage` lays a fixed grid of about `match_top_k` cells
over image 0 and keeps one match per occupied cell, ties broken by keypoint
index. It runs **after** verification, so every survivor is an inlier of the same
RANSAC; only the count changes.

What binds is the number of *occupied* cells, not the cap: ALIKED keypoints
cluster on texture, so a 1920x1200 Galileo pair fills about 160 of its 476 cells
and the survivors come out well under 500. Measured over the 331 Galileo pairs:

| | mean matches per pair | mean reprojection | ATE vs ground truth |
|---|---|---|---|
| uncapped | 1300 | 1.80 px | 5.39 mm |
| `match_limit` fixed at 500 | 156 | 1.33 px | 4.32 mm |
| blob (SSC, `match_top_k: 500`) | 430 | 1.55 px | 5.00 mm |

So the cap costs nothing in accuracy — it *buys* it, by refusing to pile a
thousand near-collinear observations from one image region onto one track — and
it takes Galileo's bundle adjustment from 27.7 s to 2.8 s.

**Two phases, not one.** `match_image_pairs` can verify inline, but when a pair
fails verification COLMAP stores neither the geometry *nor the raw matches* —
measured: a pair with 400 LightGlue matches and `min_num_inliers = 1e6` leaves an
empty `matches` row. Reporting "raw matches and inliers per pair", which is what
tells a stale threshold apart from a genuinely textureless pair, therefore needs
matching and verification split: `match_image_pairs` with
`skip_geometric_verification`, then COLMAP's own batch `verify_matches` over the
same pair file. That is also the blob's order. One wrinkle in between: the
skipped-verification pass still writes an `UNDEFINED` two-view geometry row per
pair, and `verify_matches` silently skips any pair that already has one, so the
placeholders are deleted first.

**The score threshold.** The blob's 0.3 is calibrated for its own LightGlue
engine. COLMAP's graph scores differently, and at 0.3 the low-texture
`left_stereo_*` pairs collapse: 22 of 331 Galileo pairs come back empty (6.6 %)
against the blob's 8 (2.4 %). The default here is COLMAP's own 0.1, measured at
13 empty pairs (3.9 %) with a 10th-percentile match count of 116 against the
blob's 118. `BLOB_MATCH_THRESHOLD` is kept for parity runs.

**The other backend.** `MatchingOptions.backend = "tensorrt"` runs the blob's own
`lightglue_aliked.onnx` through the blob's own engine instead
(`colsfm.matching_trt`). That path *does* see the per-match score, so it runs the
real SSC (`select_by_square_covering`) before verification, at the blob's own 0.3
threshold, and skips the grid subsample below entirely. It is not the default
because it needs `tensorrt`, `cuda-python` and an engine built for this machine's
GPU. Both paths leave the same two database tables filled, so the choice is
invisible to every later stage.
"""

from __future__ import annotations

import math
import tempfile
import time
from collections.abc import Sequence
from dataclasses import dataclass, field
from pathlib import Path
from statistics import median
from typing import Final, Literal, TypeAlias

import numpy as np
import pycolmap
from jaxtyping import Float32, Int64
from numpy import ndarray

from colsfm.database import (
    ImagePair,
    Keypoints,
    KeypointsXY,
    MatchIndices,
    delete_two_view_geometries,
    pair_inlier_counts,
    raw_match_counts,
    read_keypoints_batch,
)
from colsfm.features import DeviceChoice, ResolvedDevice, resolve_device
from colsfm.pairs import write_pair_list

MatcherVariant: TypeAlias = Literal["ALIKED_LIGHTGLUE", "ALIKED_BRUTEFORCE"]
"""The ALIKED matchers COLMAP 4.2 offers; the pipeline uses LightGlue."""

MatchingBackend: TypeAlias = Literal["pycolmap", "tensorrt", "raco"]
"""Which LightGlue runs: COLMAP's own ONNX one, or one of two TensorRT engines.

`tensorrt` is `colsfm.matching_trt`, the blob's own LightGlue graph; `raco` is
`colsfm.matching_raco`, the LightGlue+ that fabio-sim trained against
RaCo-ALIKED. Both have the per-match score COLMAP's bindings hide and therefore
run the blob's real SSC spatial NMS rather than
`subsample_matches_by_coverage`'s score-free stand-in; they differ only in the
graph and in the normalised frame its keypoints arrive in."""

MatchCapMode: TypeAlias = Literal["fixed", "image_area", "off"]
"""`--match-cap-mode`, the command line's spelling; `MatchLimitPolicy.of` resolves it."""

MatchLimitKind: TypeAlias = Literal["unlimited", "fixed", "image_area"]
"""A resolved match limit. `off` and a `None` count both become `unlimited` exactly once."""

MatchScores: TypeAlias = Float32[ndarray, " num_matches"]
"""LightGlue's confidence per match, which only the TensorRT backend can see."""

DEFAULT_MIN_SCORE: Final[float] = 0.1
"""COLMAP's own `LightGlueONNXMatchingOptions.min_score`, measured best on Galileo."""

BLOB_MATCH_THRESHOLD: Final[float] = 0.3
"""`lightglue_params.match_threshold` in `matching_task_worker_config.pb.txt`.

Applied by the blob with a strict `>`. Calibrated for the blob's own engine; on
COLMAP's graph it empties 6.6 % of Galileo's pairs, so it is not the default.
"""

BLOB_MIN_NUM_INLIERS: Final[int] = 10
"""`SelectMatchesByEpipolarGeometry` empties a pair below this, rather than trimming it."""

BLOB_MAX_PIXEL_ERROR: Final[float] = 4.0
"""`verification_config.max_pixel_error`; COLMAP takes it in pixels directly."""

BLOB_RANSAC_CONFIDENCE: Final[float] = 0.98
"""`verification_config.min_ransac_confidence`; COLMAP's own default is 0.999."""

BLOB_MATCH_TOP_K: Final[int] = 500
"""`lightglue_params.match_top_k`; the match budget the blob's SSC NMS aims at."""

BLOB_NUM_POINTS_TOLERANCE_FRACTION: Final[float] = 0.3
"""`lightglue_params.num_points_tolerance_fraction`; SSC's acceptance band around `match_top_k`."""

CAP_REFERENCE_IMAGE_AREA_PX: Final[int] = 1920 * 1200
"""The image area `BLOB_MATCH_TOP_K` was calibrated on, i.e. one Galileo camera.

`match_cap_mode = "image_area"` keeps the *match density* of that calibration
rather than its count: one kept match per `1920*1200 / 500 = 4608` pixels of
image. Galileo therefore reproduces 500 exactly and KITTI's 1241x376 frames get
101. See `MatchLimitPolicy` and the KITTI follow-up in `docs/kitti-06-results.md`
for what that measured."""


@dataclass(frozen=True, slots=True)
class MatchLimitPolicy:
    """How many verified matches one pair may keep — one answer, not two knobs.

    `match_cap_mode` and `max_matches_per_pair` used to be separate fields, and two
    different spellings disabled the limit: `mode="off"`, and a `None` count. A
    caller reading either one alone could therefore be wrong, and both the grid
    subsample and the TensorRT matcher had to test both. Here "no limit" has
    exactly one representation, and `limit_for` is the only place the arithmetic
    lives.

    Three policies, because 500 was calibrated on one image size and one dataset
    and is not obviously the right number anywhere else:

    * **`unlimited`** — every verified inlier survives.
    * **`fixed`** — `matches_per_pair` verbatim. What every run before the KITTI
      follow-up used.
    * **`image_area`** — the same *density*, one kept match per
      `CAP_REFERENCE_IMAGE_AREA_PX / matches_per_pair` pixels, so a 1920x1200 frame
      keeps 500 and a 1241x376 KITTI frame keeps 101.
    """

    kind: MatchLimitKind
    """Which of the three policies applies."""
    matches_per_pair: int | None
    """The budget the policy is parameterised by; None exactly when `kind` is `unlimited`."""

    @staticmethod
    def of(mode: MatchCapMode, max_matches_per_pair: int | None) -> MatchLimitPolicy:
        """Fold the command line's two knobs into one policy.

        Args:
            mode: `--match-cap-mode`.
            max_matches_per_pair: `--max-matches-per-pair`; None means no limit
                whatever the mode says.

        Returns:
            The policy those two spell, with "no limit" normalised to one form.
        """
        if mode == "off" or max_matches_per_pair is None:
            return MatchLimitPolicy(kind="unlimited", matches_per_pair=None)
        return MatchLimitPolicy(kind=mode, matches_per_pair=max_matches_per_pair)

    @property
    def limits(self) -> bool:
        """Whether anything is capped at all.

        Returns:
            False for `unlimited`, True otherwise.
        """
        return self.kind != "unlimited"

    def limit_for(self, image_width: int, image_height: int) -> int | None:
        """The number of matches one pair may keep, given its first image's size.

        Args:
            image_width: Width of the pair's first image in pixels.
            image_height: Height of the pair's first image in pixels.

        Returns:
            The per-pair cap, or None when nothing is capped.
        """
        if self.matches_per_pair is None:
            return None
        if self.kind == "fixed":
            return self.matches_per_pair
        area: int = max(image_width * image_height, 1)
        return max(round(self.matches_per_pair * area / CAP_REFERENCE_IMAGE_AREA_PX), 1)


DEFAULT_MATCH_LIMIT: Final[MatchLimitPolicy] = MatchLimitPolicy(kind="fixed", matches_per_pair=BLOB_MATCH_TOP_K)
"""The blob's own budget: 500 verified matches per pair, whatever the image size."""


@dataclass(frozen=True, slots=True)
class MatchingOptions:
    """How LightGlue and the two-view verifier run over a pair list."""

    backend: MatchingBackend = "pycolmap"
    """Which LightGlue implementation runs; see `MatchingBackend`.

    On `tensorrt` the `variant`, `model_path`, `min_score`, `max_num_matches`,
    `skip_image_pairs_in_same_frame`, `device` and `gpu_index` fields are not
    read: the engine is the blob's own graph, its score gate is
    `tensorrt_min_score`, its thinning is `select_by_square_covering`, and it
    runs on CUDA device 0 or not at all. Verification is the same
    `pycolmap.verify_matches` call on both paths, so `min_num_inliers`,
    `max_error_px`, `confidence` and `num_threads` still apply."""
    variant: MatcherVariant = "ALIKED_LIGHTGLUE"
    """Matcher COLMAP runs; LightGlue is what the blob uses."""
    min_score: float = DEFAULT_MIN_SCORE
    """LightGlue score gate; see the module docstring for why this is not the blob's 0.3."""
    model_path: Path | None = None
    """Explicit LightGlue ONNX file; None lets COLMAP download and cache its own.

    Not a slot for the blob's `pycusfm/models/aliked_lightglue/lightglue_aliked.onnx`:
    that graph takes four inputs (`kpts0/1`, `desc0/1`) and returns `matches0` as
    an int32 `[num_matches, 2]` index matrix, while COLMAP's own
    `aliked-lightglue.onnx` takes six (adding `image_size0/1`, so normalisation
    happens inside the graph) and returns an int64 `[num_keypoints0]` assignment
    vector. `CreateLightGlueONNXFeatureMatcher` rejects the mismatch by throwing
    inside a worker thread, which aborts the process.
    """
    max_num_matches: int = 32768
    """COLMAP's cap on matches per pair; never binds at 2048 keypoints per image."""
    min_num_inliers: int = BLOB_MIN_NUM_INLIERS
    """Inlier count below which the pair is emptied, matching the blob's rule."""
    max_error_px: float = BLOB_MAX_PIXEL_ERROR
    """RANSAC inlier threshold in pixels."""
    confidence: float = BLOB_RANSAC_CONFIDENCE
    """RANSAC success probability driving the trial count."""
    skip_image_pairs_in_same_frame: bool = False
    """Must stay False: the stereo pairs of one rig frame are exactly what cuSFM matches."""
    device: DeviceChoice = "auto"
    """Compute device; `auto` falls back to the CPU provider when cuDNN is missing."""
    gpu_index: str = "-1"
    """CUDA device index as COLMAP's comma-separated string."""
    num_threads: int = -1
    """COLMAP matching threads; -1 lets COLMAP choose."""
    match_limit: MatchLimitPolicy = DEFAULT_MATCH_LIMIT
    """How many verified matches one pair may keep, as one resolved policy.

    The score-free stand-in for the blob's SSC spatial NMS — see
    `subsample_matches_by_coverage` and the module docstring. On the `tensorrt`
    backend the number is the SSC *target* instead, applied before verification
    with the real LightGlue scores, and the post-verification grid subsample does
    not run at all. `MatchLimitPolicy.of` is what turns `--match-cap-mode` and
    `--max-matches-per-pair` into it."""
    tensorrt_min_score: float = BLOB_MATCH_THRESHOLD
    """LightGlue score gate on the `tensorrt` backend, applied with `>` as the blob does.

    A second field rather than a second default for `min_score`, because the two
    graphs are not the same graph: 0.3 is calibrated for the blob's engine, which
    this backend runs, while `min_score` is calibrated for COLMAP's, which the
    default backend runs (see the module docstring's "score threshold" note)."""
    num_points_tolerance_fraction: float = BLOB_NUM_POINTS_TOLERANCE_FRACTION
    """SSC's acceptance band around the target, as a fraction of it; `tensorrt` only."""


DEFAULT_MATCHING_OPTIONS: Final[MatchingOptions] = MatchingOptions()
"""Shared immutable default, so the signatures below hold no constructor call."""


@dataclass(frozen=True, slots=True)
class PairMatchStats:
    """What one image pair produced."""

    raw_matches: int
    """Matches LightGlue kept before verification.

    On the `pycolmap` backend that is after the score gate only, because the grid
    subsample runs later; on `tensorrt` it is after the score gate *and* SSC,
    because that is where the blob puts its spatial NMS too. `retention` is
    therefore comparable to the blob's published 0.985 on the TensorRT path and
    is a different quantity on the pycolmap one."""
    inlier_matches: int
    """Matches surviving two-view verification; 0 when the pair was emptied."""

    @property
    def retention(self) -> float:
        """Inliers as a fraction of raw matches.

        Returns:
            The ratio, or 0.0 when the pair had no raw matches. The blob's median
            on Galileo is 0.985 — verification is a light filter, not a gate.
        """
        return 0.0 if self.raw_matches == 0 else self.inlier_matches / self.raw_matches


@dataclass(frozen=True, slots=True)
class MatchReport:
    """What one matching run produced, per pair and in aggregate."""

    pair_stats: dict[ImagePair, PairMatchStats] = field(default_factory=dict)
    """Raw and inlier counts keyed by the pair as given."""
    device: ResolvedDevice = "cpu"
    """The device the run actually used."""
    elapsed_seconds: float = 0.0
    """Wall time of both phases: LightGlue matching and two-view verification."""

    @property
    def empty_pairs(self) -> int:
        """How many pairs came back with no verified match.

        Returns:
            The count of pairs whose inlier list is empty.
        """
        return sum(1 for stats in self.pair_stats.values() if stats.inlier_matches == 0)

    @property
    def median_inliers(self) -> float:
        """Median verified match count over all pairs.

        Returns:
            The median, or 0.0 when nothing was matched.
        """
        if not self.pair_stats:
            return 0.0
        return float(median(stats.inlier_matches for stats in self.pair_stats.values()))

    @property
    def median_retention(self) -> float:
        """Median inlier fraction over the pairs that produced any raw match.

        Returns:
            The median retention, or 0.0 when no pair produced a raw match.
        """
        retentions: list[float] = [stats.retention for stats in self.pair_stats.values() if stats.raw_matches > 0]
        return float(median(retentions)) if retentions else 0.0

    def summary(self) -> str:
        """One line naming the pair count, the inlier median and the wall time.

        Returns:
            A printable summary; `"no pairs"` when nothing was matched.
        """
        if not self.pair_stats:
            return f"matched no pairs on {self.device} in {self.elapsed_seconds:.2f}s"
        empty_fraction: float = 100.0 * self.empty_pairs / len(self.pair_stats)
        return (
            f"matched {len(self.pair_stats)} pairs on {self.device} in {self.elapsed_seconds:.2f}s, "
            f"median inliers {self.median_inliers:.0f}, retention {self.median_retention:.3f}, "
            f"{self.empty_pairs} empty ({empty_fraction:.1f}%)"
        )


def _matching_options(options: MatchingOptions, device: ResolvedDevice) -> pycolmap.FeatureMatchingOptions:
    """Build the pycolmap matcher options.

    Args:
        options: The typed settings.
        device: The already-resolved device.

    Returns:
        `FeatureMatchingOptions` with the ALIKED LightGlue sub-options filled in.
    """
    matching_options: pycolmap.FeatureMatchingOptions = pycolmap.FeatureMatchingOptions()
    matching_options.type = getattr(pycolmap.FeatureMatcherType, options.variant)
    matching_options.use_gpu = device == "cuda"
    matching_options.gpu_index = options.gpu_index
    matching_options.num_threads = options.num_threads
    matching_options.max_num_matches = options.max_num_matches
    matching_options.skip_image_pairs_in_same_frame = options.skip_image_pairs_in_same_frame
    matching_options.aliked.lightglue.min_score = options.min_score
    if options.model_path is not None:
        matching_options.aliked.lightglue.model_path = str(options.model_path)
    return matching_options


def verification_options(options: MatchingOptions) -> pycolmap.TwoViewGeometryOptions:
    """Build the two-view geometry options that mirror cuSFM's verifier.

    COLMAP works in pixels against the real camera model, so the blob's
    `MapErrorToNormalizedPlane` conversion (`0.5*(err/f0 + err/f1)` on bearing
    vectors) is not needed: `max_error` takes the 4.0 px straight from the
    config.

    Args:
        options: The typed settings.

    Returns:
        `TwoViewGeometryOptions` carrying the blob's thresholds.
    """
    geometry_options: pycolmap.TwoViewGeometryOptions = pycolmap.TwoViewGeometryOptions()
    geometry_options.min_num_inliers = options.min_num_inliers
    geometry_options.ransac.max_error = options.max_error_px
    geometry_options.ransac.confidence = options.confidence
    return geometry_options


def subsample_matches_by_coverage(
    keypoints_xy: KeypointsXY,
    matches: MatchIndices,
    image_width: int,
    image_height: int,
    max_matches: int,
) -> MatchIndices:
    """Thin a pair's matches to one per grid cell, so the survivors cover the image.

    The score-free replacement for the blob's SSC non-maximum suppression
    (feature_matcher_main.md §5.3). SSC sorts the matched keypoints by their
    LightGlue score and binary-searches a suppression radius until roughly
    `match_top_k` survive; pycolmap exposes no per-match score, so neither the
    sort key nor the "strongest per cell" rule is reachable *on this backend*.
    What *is* reachable is the property the blob is buying with it — spatial
    uniformity — so this lays a fixed grid over image 0 and keeps one match per
    occupied cell. The TensorRT backend does see the score and runs the real
    thing instead; that is `select_by_square_covering`.

    The grid is `num_columns = floor(sqrt(max_matches * width / height))` by
    `num_rows = floor(max_matches / num_columns)`, i.e. cells of roughly
    `sqrt(width * height / max_matches)` on a side, rounded so the cell count
    never exceeds `max_matches`. That makes the cap a real maximum rather than
    the blob's plus-or-minus 30 % target band.

    Ties inside a cell are broken by the image-0 keypoint index, which makes the
    result a pure function of the inputs; nothing here depends on match order or
    on a random seed.

    Args:
        keypoints_xy: Float32 `[num_keypoints, 2]` xy pixel coordinates of the
            pair's **first** image, as `colsfm.database.read_keypoints` returns them.
        matches: Int64 `[num_matches, 2]` keypoint index pairs, first image first.
        image_width: Width of the first image in pixels.
        image_height: Height of the first image in pixels.
        max_matches: Target match count, i.e. roughly the cell count.

    Returns:
        Int64 `[num_kept, 2]` subset of `matches`, in ascending image-0 keypoint
        index order. `matches` is returned unchanged when it already holds
        `max_matches` rows or fewer, when the cap is not positive, or when the
        image has no area.
    """
    if len(matches) <= max_matches or max_matches <= 0 or image_width <= 0 or image_height <= 0:
        return np.asarray(matches, dtype=np.int64)

    order: Int64[ndarray, "num_matches"] = np.lexsort((matches[:, 1], matches[:, 0]))
    ordered: MatchIndices = np.asarray(matches, dtype=np.int64)[order]
    positions_xy: KeypointsXY = keypoints_xy[ordered[:, 0]]
    num_columns: int = max(int(math.sqrt(max_matches * image_width / image_height)), 1)
    num_rows: int = max(max_matches // num_columns, 1)
    columns: Int64[ndarray, "num_matches"] = np.clip(
        (positions_xy[:, 0] * num_columns / image_width).astype(np.int64), 0, num_columns - 1
    )
    rows: Int64[ndarray, "num_matches"] = np.clip(
        (positions_xy[:, 1] * num_rows / image_height).astype(np.int64), 0, num_rows - 1
    )
    cells: Int64[ndarray, "num_matches"] = rows * num_columns + columns
    # `np.unique` returns the first index of each value because `cells` is scanned in
    # the sorted keypoint order above, so the winner per cell is the lowest index.
    _, first_in_cell = np.unique(cells, return_index=True)
    return ordered[np.sort(first_in_cell)]


def select_by_square_covering(
    keypoints_xy: KeypointsXY,
    scores: MatchScores,
    image_width: int,
    image_height: int,
    target: int,
    tolerance: float = BLOB_NUM_POINTS_TOLERANCE_FRACTION,
) -> Int64[ndarray, " num_kept"]:
    """The blob's spatial non-maximum suppression: SSC over scored points.

    `GlobalNonMaximumSuppressionViaSquareCovering` (feature_matcher_main.md §5.3)
    is the SSC algorithm of Bailo et al. 2018: sort the points by strength, then
    binary-search a suppression square width `w`; for each candidate width, lay a
    grid of cells `w/2` on a side, walk the points strongest first, keep a point
    whose cell is not yet covered and mark the 5x5 block of cells around it.
    Stop as soon as the surviving count lands inside
    `[target - target*tolerance, target + target*tolerance]`.

    This is the real thing, not `subsample_matches_by_coverage`'s score-free
    stand-in: it is only reachable on the TensorRT matching backend, which has
    the LightGlue score the blob uses as each point's response
    (`colsfm.matching_trt`). Unlike the stand-in it targets a *band* around
    `target` rather than a hard ceiling, so a result slightly above `target` is
    the algorithm working, not a bug.

    The search bounds are the blob's: `low = floor(sqrt(n / target))` and
    `high = (exp1 + exp3) / (2*target - 2)` with `exp1 = width + height + 2*target`
    and `exp3 = sqrt(exp2)`, `exp2` the discriminant of the same quadratic.

    Args:
        keypoints_xy: Float32 `[num_points, 2]` xy pixel coordinates, one per
            scored point — for a match list, the coordinates in the *first* image.
        scores: Float32 `[num_points]` strength per point; the LightGlue score.
        image_width: Image width in pixels.
        image_height: Image height in pixels.
        target: Points to aim for, i.e. the blob's `match_top_k`.
        tolerance: Half-width of the acceptable band as a fraction of `target`.

    Returns:
        Int64 indices into `keypoints_xy`, ascending. Every point is kept —
        `arange(num_points)` — when `target` is not positive, when there are
        already no more than `target` points, or when the image has no area,
        which is the blob's own `matches.size() < match_top_k` early return. A
        `target` of one short-circuits to the single strongest point.
    """
    num_points: int = len(scores)
    if target <= 0 or num_points <= target or image_width <= 0 or image_height <= 0:
        return np.arange(num_points, dtype=np.int64)

    order: Int64[ndarray, " num_points"] = np.argsort(-np.asarray(scores, dtype=np.float64), kind="stable")
    if target < 2:
        # The search bound below divides by `2 * target - 2`. A target of one is not a
        # suppression problem anyway: it is "keep the strongest point".
        return np.sort(order[:target])
    ordered_xy: KeypointsXY = np.asarray(keypoints_xy, dtype=np.float32)[order]
    ordered_indices: list[int] = order.tolist()

    exp1: float = float(image_width + image_height + 2 * target)
    exp2: float = float(
        4 * image_width
        + 4 * target
        + 4 * image_height * target
        + image_height * image_height
        + image_width * image_width
        - 2 * image_height * image_width
        + 4 * image_height * image_width * target
    )
    low: float = float(math.floor(math.sqrt(num_points / target)))
    high: float = (exp1 + math.sqrt(max(exp2, 0.0))) / (2 * target - 2)
    lowest_acceptable: int = round(target - target * tolerance)
    highest_acceptable: int = round(target + target * tolerance)

    previous_width: float = -1.0
    kept: list[int] = ordered_indices[:target]
    while low <= high:
        width: float = low + (high - low) / 2.0
        if width == previous_width:
            break
        previous_width = width
        kept = _cover_squares(ordered_xy, ordered_indices, width, image_width, image_height)
        if lowest_acceptable <= len(kept) <= highest_acceptable:
            break
        if len(kept) < lowest_acceptable:
            high = width - 1.0
        else:
            low = width + 1.0
    return np.sort(np.asarray(kept, dtype=np.int64))


def _cover_squares(
    ordered_xy: KeypointsXY, ordered_indices: Sequence[int], width: float, image_width: int, image_height: int
) -> list[int]:
    """One SSC pass at one suppression width.

    The covered set is a Python `set` of flat cell ids rather than a boolean
    grid: only the kept points write, and each writes 25 cells, so the whole pass
    is a few thousand hash operations instead of a NumPy slice assignment per
    point. That is what keeps the binary search inside the per-pair budget.

    Args:
        ordered_xy: Float32 `[num_points, 2]` coordinates, already sorted strongest first.
        ordered_indices: The original index of each row of `ordered_xy`.
        width: Suppression square width in pixels; cells are `width / 2` on a side.
        image_width: Image width in pixels.
        image_height: Image height in pixels.

    Returns:
        The original indices of the kept points, strongest first.
    """
    cell_size: float = max(width / 2.0, 1e-6)
    num_cell_columns: int = int(image_width / cell_size)
    num_cell_rows: int = int(image_height / cell_size)
    stride: int = num_cell_columns + 1
    span: int = int(width / cell_size)
    columns: list[int] = np.clip((ordered_xy[:, 0] / cell_size).astype(np.int64), 0, num_cell_columns).tolist()
    rows: list[int] = np.clip((ordered_xy[:, 1] / cell_size).astype(np.int64), 0, num_cell_rows).tolist()

    covered: set[int] = set()
    kept: list[int] = []
    for index, row, column in zip(ordered_indices, rows, columns, strict=True):
        if row * stride + column in covered:
            continue
        kept.append(index)
        column_low: int = max(0, column - span)
        column_high: int = min(num_cell_columns, column + span)
        for covered_row in range(max(0, row - span), min(num_cell_rows, row + span) + 1):
            covered.update(range(covered_row * stride + column_low, covered_row * stride + column_high + 1))
    return kept


def _image_sizes(database: pycolmap.Database, image_ids: Sequence[int]) -> dict[int, tuple[int, int]]:
    """Look up the pixel size of each image through its camera.

    Args:
        database: An open database.
        image_ids: Images to size.

    Returns:
        `(width, height)` per `image_id`.
    """
    cameras: dict[int, pycolmap.Camera] = {camera.camera_id: camera for camera in database.read_all_cameras()}
    images: dict[int, pycolmap.Image] = {image.image_id: image for image in database.read_all_images()}
    sizes: dict[int, tuple[int, int]] = {}
    for image_id in image_ids:
        camera: pycolmap.Camera = cameras[images[image_id].camera_id]
        sizes[image_id] = (int(camera.width), int(camera.height))
    return sizes


def cap_verified_matches(
    database_path: Path, pairs: Sequence[ImagePair], options: MatchingOptions = DEFAULT_MATCHING_OPTIONS
) -> int:
    """Rewrite every over-full two-view geometry with a spatially spread subset.

    Runs **after** verification, so the survivors are inliers of the same
    essential-matrix RANSAC the blob verifies with; only the count changes. The
    geometry's `E`/`F`/`H`, its configuration and its triangulation angle are kept
    as verification estimated them.

    The cap is per pair, because `MatchLimitPolicy`'s `image_area` kind derives
    it from the first image's size; in `fixed` mode every pair gets the same one.

    Args:
        database_path: An existing COLMAP database holding verified geometries.
        pairs: Pairs to cap, as `(min(image_id), max(image_id))`.
        options: The matching settings, for `match_limit`.

    Returns:
        Total inlier matches removed across every pair; 0 when nothing is capped.
    """
    removed: int = 0
    first_image_ids: list[int] = sorted({pair[0] for pair in pairs})
    # `read_keypoints_batch` owns the "leading xy columns" rule; spelling it a second time
    # here is how the two readers drifted to different dtypes in the first place.
    keypoints_by_image_id: dict[int, Keypoints] = read_keypoints_batch(database_path, first_image_ids)
    with pycolmap.Database.open(database_path) as database:
        sizes: dict[int, tuple[int, int]] = _image_sizes(database, first_image_ids)
        for image_id1, image_id2 in pairs:
            width, height = sizes[image_id1]
            cap: int | None = options.match_limit.limit_for(width, height)
            if cap is None:
                continue
            geometry: pycolmap.TwoViewGeometry = database.read_two_view_geometry(image_id1, image_id2)
            inliers: MatchIndices = np.asarray(geometry.inlier_matches, dtype=np.int64)
            if len(inliers) <= cap:
                continue
            kept: MatchIndices = subsample_matches_by_coverage(
                keypoints_by_image_id[image_id1], inliers, width, height, cap
            )
            removed += len(inliers) - len(kept)
            geometry.inlier_matches = kept.astype(np.uint32)
            database.update_two_view_geometry(image_id1, image_id2, geometry)
    return removed


def match_pairs(
    database_path: Path,
    pairs: Sequence[ImagePair],
    options: MatchingOptions = DEFAULT_MATCHING_OPTIONS,
) -> MatchReport:
    """Match and verify a list of image pairs, writing the results into the database.

    Both images of every pair must already carry keypoints and descriptors (see
    `colsfm.features.extract_features`). Matching and verification both run
    inside COLMAP, in two phases so that the raw match count survives a pair that
    fails verification; the database ends up with both tables filled.

    Args:
        database_path: An existing COLMAP database.
        pairs: Image-id pairs, normalised and deduplicated by `colsfm.pairs`.
        options: Matching and verification settings.

    Returns:
        Per-pair raw and inlier counts, the device used and the wall time.

    Raises:
        FileNotFoundError: When the database is missing.
        KeyError: When a pair names an image the database does not hold.
        RuntimeError: When `options.device` is `cuda` and CUDA is unusable.
        ImportError: When `options.backend` is `tensorrt` and TensorRT or
            `cuda-python` is not importable.
    """
    if options.backend == "raco":
        # Imported here, not at module scope, for the same reason as `tensorrt`.
        from colsfm.matching_raco import match_pairs_raco

        return match_pairs_raco(database_path, list(pairs), options)
    if options.backend == "tensorrt":
        # Imported here, not at module scope: TensorRT and `cuda-python` are only
        # needed by this branch, and a machine without a usable engine must still
        # be able to run the default backend.
        from colsfm.matching_trt import match_pairs_tensorrt

        return match_pairs_tensorrt(database_path, list(pairs), options)
    if not database_path.is_file():
        raise FileNotFoundError(f"No COLMAP database at {database_path}")
    if not pairs:
        return MatchReport(device=resolve_device(options.device))

    device: ResolvedDevice = resolve_device(options.device)
    with tempfile.TemporaryDirectory(prefix="colsfm-pairs-") as scratch:
        pair_list_path: Path = Path(scratch) / "pairs.txt"
        write_pair_list(pair_list_path, pairs, database_path)
        pairing_options: pycolmap.ImportedPairingOptions = pycolmap.ImportedPairingOptions()
        pairing_options.match_list_path = pair_list_path
        matching_options: pycolmap.FeatureMatchingOptions = _matching_options(options, device)
        matching_options.skip_geometric_verification = True
        geometry_options: pycolmap.TwoViewGeometryOptions = verification_options(options)
        started: float = time.perf_counter()
        pycolmap.match_image_pairs(
            database_path,
            matching_options=matching_options,
            pairing_options=pairing_options,
            verification_options=geometry_options,
            device=pycolmap.Device.cuda if device == "cuda" else pycolmap.Device.cpu,
        )
        raw: dict[ImagePair, int] = raw_match_counts(database_path, pairs)
        delete_two_view_geometries(database_path, pairs)
        pycolmap.verify_matches(database_path, pair_list_path, geometry_options)
        dropped: int = cap_verified_matches(database_path, pairs, options)
        print(
            f"colsfm.matching: spatial cap ({options.match_limit.kind}, "
            f"{options.match_limit.matches_per_pair}/pair) dropped {dropped} inlier matches"
        )
        elapsed_seconds: float = time.perf_counter() - started

    inliers: dict[ImagePair, int] = pair_inlier_counts(database_path, pairs)
    report: MatchReport = MatchReport(
        pair_stats={pair: PairMatchStats(raw_matches=raw[pair], inlier_matches=inliers[pair]) for pair in pairs},
        device=device,
        elapsed_seconds=elapsed_seconds,
    )
    print(f"colsfm.matching: {report.summary()}")
    return report
