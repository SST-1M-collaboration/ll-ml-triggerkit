from __future__ import annotations

import os
import warnings
import numpy as np
from dataclasses import dataclass
from typing import Any, Callable, Dict, Iterator, List, Optional, Sequence, Tuple, Union

import tensorflow as tf

# FileType / FileOpenerCTAO / AsyncFileOpenerProcess live in their own,
# TensorFlow-free module -- see AsyncFileOpener.py's docstring for why (short
# version: AsyncFileOpenerProcess must spawn, not fork, its worker processes
# to avoid a fork-after-CUDA-init hang, and spawning from a module that
# imports tensorflow at top level would re-pay a full TF+CUDA init in every
# spawned worker). Re-exported here since most of the codebase imports them
# from this module.
from triggerkit.FileIO.paths import normalize_files
from triggerkit.FileIO.AsyncFileOpener import (  # noqa: F401
    FileType,
    FileOpenerCTAO,
    AsyncFileOpenerProcess,
    FileReadError,
)


def iterate_batches(dataset):
    """Iterate a tf.data stream, turning a worker's read failure into ``FileReadError``.

    tf.data wraps any exception raised inside a Python generator into a generic
    ``tf.errors.UnknownError`` whose text merely contains the original one. This
    wrapper re-raises it as :class:`FileReadError` (original text kept, cause
    chained) so callers can ``except FileReadError`` instead of string-matching.
    Other errors pass through untouched.
    """
    iterator = iter(dataset)
    while True:
        try:
            item = next(iterator)
        except StopIteration:
            return
        except tf.errors.OpError as exc:
            if "FileReadError" in str(exc):
                raise FileReadError(str(exc)) from exc
            raise
        yield item


@dataclass
class SimTelTFDatasetConfig:
    batch_size: int = 32
    # Global caps across all files (None = no cap)
    max_gamma_samples_total: Optional[int] = None
    max_nsb_samples_total: Optional[int] = None

    # Shuffling
    shuffle_files: bool = True
    shuffle_samples: bool = True
    sample_shuffle_buffer: int = 10_000
    seed: int = 1337

    load_ram: bool = False  # If True, load all data into RAM at start (may use lots of memory) but faster training.

    # If True, read from all files in a round-robin/random fashion instead of
    # consuming one file completely before moving to the next. Keep true
    # to have a better mixing of gamma/nsb samples within each batch.
    interleave_files: bool = True

    # Cap on how many files (each an AsyncFileOpenerProcess subprocess + Queue)
    # are open at once when interleave_files=True. Previously every file in
    # the gamma+nsb list was opened up front and round-robined forever, so
    # e.g. 40 gamma files + 1 nsb file meant 41 concurrent subprocesses/queues
    # for the whole dataset build. A small rolling window gives essentially
    # the same gamma/nsb mixing (as long as it's >= 2) at a fraction of the
    # concurrent resource footprint; exhausted files are replaced from the
    # backlog as they finish.
    interleave_max_concurrent_files: int = 8

    # Which waveform to use: "r0" or "r1"
    waveform_level: str = "r0"  # "r0" or "r1"

    # If set, keep only this tel_id for gamma files (label=1)
    gamma_tel_id_only: Optional[int] = 2

    # -------- NEW: gamma filter by n_pe --------
    # Keep gamma only if (n_pe_min < n_pe < n_pe_max), when bounds are set.
    gamma_n_pe_max: Optional[float] = None  # e.g. 350.0
    gamma_n_pe_min: Optional[float] = None
    gamma_skip_if_missing_n_pe: bool = True

    # If True, yield extra scalar features from stat_event dict
    # Emit the simulated Cherenkov image, (P,) photo-electrons per pixel, as a
    # feature alongside the waveform. Off by default: it costs an extra array
    # per event on the queue, and only an auxiliary-target trainer wants it.
    # NSB events carry an all-zero map, which is a valid target rather than a
    # missing one.
    emit_true_image: bool = False
    # Emit the DL1 peak_time, (P,) samples per pixel. Note it is a DL1
    # RECONSTRUCTION, not simulation truth, and it is meaningful only on
    # sufficiently bright pixels: measured on SST-1M gammas, its dispersion
    # inside an event is 0.5-3 samples on pixels above 5 pe but 13 (i.e. uniform
    # noise) if 1-pe pixels are included. Mask it against true_image downstream.
    emit_peak_time: bool = False
    include_event_features: bool = True

    # Which scalar keys to include (must exist in your stat_event dict)
    event_feature_keys: Tuple[str, ...] = (
        "n_pe", "ev_time", "energy", "azimuth", "altitude",
        "h_first_int", "xmax", "xcore", "ycore"
    )

    # -------- NEW: NSB augmentation via rolling --------
    # For each NSB sample, yield N additional rolled copies (in addition to the original).
    nsb_skip_original_events: bool = False  # If True, skip the original NSB sample, keep only the rolled copies.
    nsb_roll_copies: int = 0  # N additional samples per NSB telescope-sample
    nsb_roll_axis: int = 1    # axis=1 corresponds to P in [C, P, S]

    # -------- NEW: NSB augmentation via a random per-sample circular pixel roll --------
    # Independent of nsb_roll_copies above (which duplicates samples with a
    # fixed +1,+2,+3... shift -- the same "watermark" rotation sequence for
    # every NSB event in the dataset). This instead gives every NSB row in a
    # batch its own random circular pixel shift, redrawn each time a batch is
    # produced (waveform and pedestal are shifted together so pixel identity
    # stays consistent). No duplication: one NSB event in, one rotated NSB
    # event out. Gamma rows are untouched. Give train/val/test configs
    # different nsb_roll_seed values so their rotations aren't correlated.
    nsb_roll_augment: bool = False
    nsb_roll_seed: int = 1337

    # If you want to repeat forever (useful with steps_per_epoch)
    repeat: bool = True

    # If True, skip samples that error (corrupt event, unexpected shapes, etc.)
    ignore_errors: bool = True


class SimTelTFDataset:
    """
    Streams simtel-derived waveforms into a tf.data.Dataset using:
      - gamma_files => label 1
      - nsb_file(s) => label 0

    Pattern 1: one telescope = one training sample.
    """

    def __init__(
        self,
        gamma_files: Sequence[str],
        nsb_files: Union[str, os.PathLike, Sequence[str]],  # can be a single file path
        opener_cls: Callable[..., Any],  # e.g. AsyncFileOpenerProcess
        config: Optional[SimTelTFDatasetConfig] = None,
    ):
        # a path, a list/tuple of paths, or None -- always stored as a list of str
        self.gamma_files = normalize_files(gamma_files, name="gamma_files")
        self.nsb_files = normalize_files(nsb_files, name="nsb_files")

        self.opener_cls = opener_cls
        self.cfg = config or SimTelTFDatasetConfig()
        # global quota trackers (set/reset in dataset())
        self._remaining_gamma: Optional[int] = None
        self._remaining_nsb: Optional[int] = None

        if self.cfg.waveform_level not in ("r0", "r1"):
            raise ValueError("config.waveform_level must be 'r0' or 'r1'")

        # Used when load_ram=True to cache all samples in memory.
        self._ram_cache: Optional[Tuple[Dict[str, np.ndarray], np.ndarray]] = None

    # ---------- Public API ----------

    def _reset_quotas(self):
        """Refill the per-label sample quotas.

        Called both when the pipeline is built AND at the start of every pass
        through the streaming generator. The second one matters: tf.data assumes
        a dataset can be iterated more than once (a second epoch, a counting
        pass, a callback taking a sample), but the quotas used to be filled only
        at build time, so any second pass started already exhausted and silently
        yielded nothing -- surfacing much later as "input ran out of data" and a
        zero-step progress bar. Only the load_ram path was immune, because it
        caches everything in RAM.
        """
        self._remaining_gamma = (
            None if self.cfg.max_gamma_samples_total is None
            else int(self.cfg.max_gamma_samples_total)
        )
        self._remaining_nsb = (
            None if self.cfg.max_nsb_samples_total is None
            else int(self.cfg.max_nsb_samples_total)
        )

    def dataset(self) -> tf.data.Dataset:
        self._reset_quotas()

        rng = np.random.default_rng(self.cfg.seed)

        file_label_pairs: List[Tuple[str, int]] = (
            [(f, 1) for f in self.gamma_files] +
            [(f, 0) for f in self.nsb_files]
        )

        if self.cfg.load_ram:
            ds = self._dataset_from_ram(file_label_pairs, rng)
            ds = ds.padded_batch(
                self.cfg.batch_size,
                padded_shapes=self._padded_shapes(),
                padding_values=self._padding_values(),
                drop_remainder=False
            )
            ds = self._maybe_apply_nsb_roll(ds)
            return ds.prefetch(tf.data.AUTOTUNE)

        def infinite_generator() -> Iterator[Tuple[Dict[str, np.ndarray], np.ndarray]]:
            # every pass starts from full quotas, so the stream is re-iterable
            self._reset_quotas()
            while True:
                if self._quotas_exhausted():
                    break
                pairs = list(file_label_pairs)
                if self.cfg.shuffle_files:
                    rng.shuffle(pairs)

                if self.cfg.interleave_files:
                    yield from self._interleaved_files(pairs, rng)
                else:
                    for filepath, label in pairs:
                        yield from self._iter_one_file(filepath, label, rng)

                if not self.cfg.repeat:
                    break
                if self._quotas_exhausted():
                    break

        ds = tf.data.Dataset.from_generator(
            infinite_generator,
            output_signature=self._output_signature()
        )

        if self.cfg.ignore_errors:
            # WARNING:tensorflow:From /home/tanguy/Desktop/tm-ctao/Code/Stat/triggerkit/FileIO/FileOpenerCTAO.py:704: ignore_errors (from tensorflow.python.data.experimental.ops.error_ops) is deprecated and will be removed in a future version.
            # ds = ds.apply(tf.data.experimental.ignore_errors())
            ds = ds.ignore_errors()

        if self.cfg.shuffle_samples:
            ds = ds.shuffle(
                self.cfg.sample_shuffle_buffer,
                seed=self.cfg.seed,
                reshuffle_each_iteration=True
            )

        ds = ds.padded_batch(
            self.cfg.batch_size,
            padded_shapes=self._padded_shapes(),
            padding_values=self._padding_values(),
            drop_remainder=False
        )
        ds = self._maybe_apply_nsb_roll(ds)

        return ds.prefetch(tf.data.AUTOTUNE)

    def _maybe_apply_nsb_roll(self, ds: tf.data.Dataset) -> tf.data.Dataset:
        """Give each NSB row a fresh, independent random pixel-index rotation.

        Runs after padded_batch so the shift is drawn per batch (not once for
        the whole dataset like nsb_roll_copies' fixed +1,+2,+3... sequence),
        and per row within the batch, so two NSB events in the same batch get
        different rotations. tf.random.Generator.from_seed makes the sequence
        of draws reproducible for a given nsb_roll_seed across runs, while
        still varying batch to batch within one run.
        """
        if not self.cfg.nsb_roll_augment:
            return ds
        rng = tf.random.Generator.from_seed(self.cfg.nsb_roll_seed)

        def _roll_batch(features, label):
            wf = features["waveform"]   # (B, C, P, S)
            ped = features["pedestal"]  # (B, P)
            P = tf.shape(wf)[2]
            B = tf.shape(wf)[0]

            # One random shift per row; same shift applied to waveform and
            # pedestal so a pixel's ADC trace and its pedestal move together.
            shifts = rng.uniform((B,), minval=0, maxval=P, dtype=tf.int32)
            roll_idx = tf.math.floormod(tf.range(P)[None, :] - shifts[:, None], P)  # (B, P)

            wf_rolled = tf.gather(wf, roll_idx, axis=2, batch_dims=1)
            ped_rolled = tf.gather(ped, roll_idx, batch_dims=1)

            is_nsb = tf.equal(label, 0)
            wf_out = tf.where(is_nsb[:, None, None, None], wf_rolled, wf)
            ped_out = tf.where(is_nsb[:, None], ped_rolled, ped)

            features = dict(features)
            features["waveform"] = wf_out
            features["pedestal"] = ped_out

            # Any per-pixel truth map must follow the same permutation, or it
            # desynchronises from the waveform. NSB carries an all-zero map so
            # this is numerically a no-op today, but it keeps the maps correct
            # if the roll is ever applied to gammas too.
            for key in ("true_image", "peak_time"):
                if key in features:
                    m = features[key]
                    m_rolled = tf.gather(m, roll_idx, batch_dims=1)
                    features[key] = tf.where(is_nsb[:, None], m_rolled, m)
            return features, label

        # Sequential on purpose: the seeded Generator is stateful, so parallel
        # calls would draw in a nondeterministic order and break the
        # "reproducible for a given nsb_roll_seed" guarantee above.
        return ds.map(_roll_batch, num_parallel_calls=1)

    # ---------- Internals ----------

    @staticmethod
    def _to_float_or_nan(v: Any) -> float:
        try:
            a = np.asarray(v)
            if a.size == 0:
                return float("nan")
            return float(a.reshape(-1)[0])
        except Exception:
            return float("nan")

    def _passes_gamma_n_pe_filter(self, sd: Dict[str, Any]) -> bool:
        # If no bounds set, always pass.
        if self.cfg.gamma_n_pe_max is None and self.cfg.gamma_n_pe_min is None:
            return True

        n_pe = self._to_float_or_nan(sd.get("n_pe", float("nan")))
        if np.isnan(n_pe):
            return not self.cfg.gamma_skip_if_missing_n_pe

        if self.cfg.gamma_n_pe_max is not None and not (n_pe < float(self.cfg.gamma_n_pe_max)):
            return False
        if self.cfg.gamma_n_pe_min is not None and not (n_pe > float(self.cfg.gamma_n_pe_min)):
            return False
        return True

    def _interleaved_files(
        self,
        pairs: List[Tuple[str, int]],
        rng: np.random.Generator,
    ) -> Iterator[Tuple[Dict[str, np.ndarray], np.ndarray]]:
        """
        Pull samples from multiple files in a random round-robin fashion to avoid
        long stretches of a single label, while keeping at most
        interleave_max_concurrent_files open (each open file is a live
        AsyncFileOpenerProcess subprocess + Queue) instead of opening every
        file in `pairs` at once. Exhausted files are replaced from the backlog
        as they finish, so the active window stays roughly constant.
        """
        max_active = max(1, int(self.cfg.interleave_max_concurrent_files))
        backlog = list(pairs)
        active_streams: List[Iterator] = []

        def _refill():
            while backlog and len(active_streams) < max_active:
                fp, lbl = backlog.pop(0)
                active_streams.append(self._iter_one_file(fp, lbl, rng))

        _refill()
        try:
            while active_streams:
                if self._quotas_exhausted():
                    break
                idx = int(rng.integers(len(active_streams))) if len(active_streams) > 1 else 0
                try:
                    yield next(active_streams[idx])
                except StopIteration:
                    active_streams.pop(idx)
                    _refill()
        finally:
            # Deterministically close any streams left open (quota exhausted,
            # or this generator itself abandoned early) instead of leaving
            # their subprocess+Queue cleanup to whenever the GC gets to them.
            # close() throws GeneratorExit at the suspended yield inside each
            # stream's `with self.opener_cls(...) as fo:`, which runs its
            # __exit__ right away.
            for stream in active_streams:
                stream.close()

    def _one_pass_stream(
        self,
        pairs: List[Tuple[str, int]],
        rng: np.random.Generator,
    ) -> Iterator[Tuple[Dict[str, np.ndarray], np.ndarray]]:
        if self.cfg.interleave_files:
            return iter(self._interleaved_files(pairs, rng))

        def sequential():
            for filepath, label in pairs:
                if self._quota_exhausted_label(label) and self._quotas_exhausted():
                    break
                yield from self._iter_one_file(filepath, label, rng)

        return iter(sequential())

    def _load_all_into_memory(
        self,
        pairs: List[Tuple[str, int]],
        rng: np.random.Generator,
    ) -> Tuple[Dict[str, np.ndarray], np.ndarray]:
        feat_lists: Dict[str, List[np.ndarray]] = {}
        labels: List[np.ndarray] = []

        stream = self._one_pass_stream(pairs, rng)
        while True:
            try:
                features, label = next(stream)
            except StopIteration:
                break
            except Exception:
                if self.cfg.ignore_errors:
                    continue
                raise

            for k, v in features.items():
                feat_lists.setdefault(k, []).append(np.array(v))
            labels.append(np.array(label, dtype=np.int32))

        if not labels:
            return {}, np.array([], dtype=np.int32)

        feat_arrays: Dict[str, np.ndarray] = {}
        for k, vals in feat_lists.items():
            try:
                feat_arrays[k] = np.stack(vals, axis=0)
            except ValueError as exc:
                raise ValueError(
                    f"Inconsistent shapes for feature '{k}' while using load_ram; "
                    "disable load_ram or ensure fixed shapes."
                ) from exc

        labels_arr = np.array(labels, dtype=np.int32)
        return feat_arrays, labels_arr

    def _dataset_from_ram(
        self,
        file_label_pairs: List[Tuple[str, int]],
        rng: np.random.Generator,
    ) -> tf.data.Dataset:
        # ensure quotas exist when dataset() was bypassed (defensive)
        if self._remaining_gamma is None and self.cfg.max_gamma_samples_total is not None:
            self._remaining_gamma = int(self.cfg.max_gamma_samples_total)
        if self._remaining_nsb is None and self.cfg.max_nsb_samples_total is not None:
            self._remaining_nsb = int(self.cfg.max_nsb_samples_total)

        pairs = list(file_label_pairs)
        if self.cfg.shuffle_files:
            rng.shuffle(pairs)

        if self._ram_cache is None:
            feat_arrays, labels_arr = self._load_all_into_memory(pairs, rng)
            if labels_arr.size == 0:
                raise ValueError(
                    "No samples loaded into RAM; check input files, filters, or disable load_ram."
                )
            self._ram_cache = (feat_arrays, labels_arr)

        feat_arrays, labels_arr = self._ram_cache
        # host memory on purpose: with a GPU visible, the default placement copies the whole
        # cached split to the device as one constant and runs out of GPU memory on large splits
        with tf.device("/CPU:0"):
            ds = tf.data.Dataset.from_tensor_slices((feat_arrays, labels_arr))

        if self.cfg.repeat:
            ds = ds.repeat()

        if self.cfg.shuffle_samples:
            ds = ds.shuffle(
                self.cfg.sample_shuffle_buffer,
                seed=self.cfg.seed,
                reshuffle_each_iteration=True
            )

        return ds

    def _iter_one_file(
        self,
        simtel_file: str,
        label: int,
        rng: np.random.Generator,
    ) -> Iterator[Tuple[Dict[str, np.ndarray], np.ndarray]]:
        """Stream one file; a file that cannot be read costs only itself.

        A generator that raises is dead, and tf.data (or the RAM loader) would
        then end the WHOLE dataset. So a FileReadError is confined here: with
        ignore_errors the rest of that file is skipped (the opener already
        warned loudly) and the other files keep streaming; otherwise it raises.
        """
        try:
            yield from self._iter_one_file_unguarded(simtel_file, label, rng)
        except FileReadError as exc:
            if not self.cfg.ignore_errors:
                raise
            warnings.warn(
                f"ignore_errors=True: skipping the unread rest of {simtel_file!r} "
                f"and continuing with the other files ({str(exc).splitlines()[0]})",
                RuntimeWarning, stacklevel=2)

    def _iter_one_file_unguarded(
        self,
        simtel_file: str,
        label: int,
        rng: np.random.Generator,
    ) -> Iterator[Tuple[Dict[str, np.ndarray], np.ndarray]]:
        # bail out early if this label quota is already exhausted
        if self._quota_exhausted_label(label):
            return

        # This is the only opener_cls call site that knows upfront exactly what
        # it needs (one waveform level, never dl0/dl1/true_image -- see below),
        # so it's the only one that opts into AsyncFileOpenerProcess's payload
        # trimming; the other TriggerChain call sites keep the untrimmed default.
        with self.opener_cls(
            simtel_file,
            waveform_level=self.cfg.waveform_level,
            keep_dl0=False,
            keep_dl1=False,
            keep_true_image=bool(self.cfg.emit_true_image),
            keep_peak_time=bool(self.cfg.emit_peak_time),
        ) as fo:
            for (
                tel_ids_list, wf_r0_list, wf_r1_list, dl0_list, dl1_list, true_image_list,
                peak_time_list, pedestal_per_sample_list, event_stat_list, i_event
            ) in fo:
                if self._quota_exhausted_label(label):
                    break

                if not event_stat_list:
                    continue

                stats_by_tel: Dict[int, Dict[str, Any]] = {}
                for d in event_stat_list:
                    if isinstance(d, dict) and "telescope" in d:
                        try:
                            stats_by_tel[int(d["telescope"])] = d
                        except Exception:
                            pass

                ev0 = event_stat_list[0] if isinstance(event_stat_list[0], dict) else {}
                event_id = np.int64(ev0.get("event_id", -1))

                wf_list = wf_r0_list if self.cfg.waveform_level == "r0" else wf_r1_list
                ped_list = pedestal_per_sample_list

                ti_list = true_image_list if self.cfg.emit_true_image else None
                pt_list = peak_time_list if self.cfg.emit_peak_time else None
                for i_tel, (tel_id, wf, ped) in enumerate(
                        zip(tel_ids_list, wf_list, ped_list)):
                    tel_id_i = int(tel_id)

                    # Gamma-only tel_id filter
                    if label == 1 and self.cfg.gamma_tel_id_only is not None:
                        if tel_id_i != int(self.cfg.gamma_tel_id_only):
                            continue

                    sd = stats_by_tel.get(tel_id_i, ev0)

                    # -------- NEW: gamma filter by n_pe --------
                    if label == 1 and not self._passes_gamma_n_pe_filter(sd):
                        continue

                    x = np.asarray(wf, dtype=np.uint16)

                    # Normalize waveform shape to [C, P, S]
                    # C = channels, P = pixels, S = samples
                    if x.ndim == 2:
                        x = x[None, ...]
                    elif x.ndim != 3:
                        raise ValueError(f"Unexpected waveform ndim={x.ndim}, shape={x.shape}")

                    if ped is None:
                        ped = np.zeros(x.shape[1], dtype=np.float32)  # assume shape [C, P, S] -> ped per pixel
                    ped_arr = np.array(ped, dtype=np.int32)

                    ti_arr = None
                    if self.cfg.emit_true_image:
                        # NSB has no shower: an all-zero map is the right target,
                        # not a missing one.
                        n_pix = x.shape[1]
                        if ti_list is not None and i_tel < len(ti_list) \
                                and ti_list[i_tel] is not None:
                            ti_arr = np.asarray(ti_list[i_tel], dtype=np.float32)
                        if ti_arr is None or ti_arr.shape != (n_pix,):
                            ti_arr = np.zeros(n_pix, dtype=np.float32)
                        # ctapipe writes a NEGATIVE sentinel (-3 in the SST-1M
                        # bias-curve files) when there is no simulated image, and
                        # it has the right shape so it flows straight through.
                        # Clamping to zero is the physical truth for NSB -- no
                        # Cherenkov photons -- and stops the auxiliary task from
                        # being trained to predict the sentinel on a whole class.
                        np.maximum(ti_arr, 0.0, out=ti_arr)

                    pt_arr = None
                    if self.cfg.emit_peak_time:
                        n_pix = x.shape[1]
                        if pt_list is not None and i_tel < len(pt_list) \
                                and pt_list[i_tel] is not None:
                            pt_arr = np.asarray(pt_list[i_tel], dtype=np.float32)
                        if pt_arr is None or pt_arr.shape != (n_pix,):
                            pt_arr = np.zeros(n_pix, dtype=np.float32)

                    def make_features(wf_arr: np.ndarray, ped_vec: np.ndarray,
                                      ti_vec: np.ndarray = None,
                                      pt_vec: np.ndarray = None) -> Dict[str, np.ndarray]:
                        features: Dict[str, np.ndarray] = {
                            "waveform": wf_arr,
                            "pedestal": ped_vec,
                            "event_id": np.array(event_id, dtype=np.int64),
                            "n_pe": np.array(sd.get("n_pe", -1), dtype=np.float32),
                            "tel_id": np.array(tel_id_i, dtype=np.int32),
                        }
                        if self.cfg.emit_true_image:
                            features["true_image"] = (
                                ti_arr if ti_vec is None else ti_vec)
                        if self.cfg.emit_peak_time:
                            features["peak_time"] = (
                                pt_arr if pt_vec is None else pt_vec)
                        if self.cfg.include_event_features:
                            for k in self.cfg.event_feature_keys:
                                v = sd.get(k, -1.0)
                                features[k] = np.array(v, dtype=np.float32)
                        return features

                    y = np.array(label, dtype=np.int32)
                
                    # Yield original
                    if label == 1:  # gamma
                        if self._consume_quota(label):
                            yield make_features(x, ped_arr), y
                    else:
                        if not self.cfg.nsb_skip_original_events and self._consume_quota(label):
                            yield make_features(x, ped_arr), y

                    if label == 0 and self.cfg.nsb_roll_copies > 0:
                        n = int(self.cfg.nsb_roll_copies)
                        wf_aug = x
                        ped_aug = ped_arr
                        # print(ped_aug.shape) # (1296,)
                        # print(wf_aug.shape)  # (1,1296,50) -> (batch, pixels, samples)
                        ti_aug, pt_aug = ti_arr, pt_arr
                        for i in range(n):
                            wf_aug = np.roll(wf_aug, shift=1, axis=int(self.cfg.nsb_roll_axis)).copy()
                            ped_aug = np.roll(ped_aug, shift=1, axis=0).copy()
                            # the truth map must follow the pixels, otherwise it
                            # desynchronises from the waveform as soon as the
                            # augmentation is on
                            if ti_aug is not None:
                                ti_aug = np.roll(ti_aug, shift=1, axis=0).copy()
                            if pt_aug is not None:
                                pt_aug = np.roll(pt_aug, shift=1, axis=0).copy()
                            if self._consume_quota(label):
                                yield make_features(wf_aug, ped_aug, ti_aug, pt_aug), y
                            else:
                                break

                if self._quota_exhausted_label(label):
                    break

    def _output_signature(self):
        feat = {
            "waveform": tf.TensorSpec(shape=(None, None, None), dtype=tf.uint16),
            "pedestal": tf.TensorSpec(shape=(None,), dtype=tf.int32),
            "n_pe": tf.TensorSpec(shape=(), dtype=tf.float32),
            "event_id": tf.TensorSpec(shape=(), dtype=tf.int64),
            "tel_id": tf.TensorSpec(shape=(), dtype=tf.int32),
        }
        if self.cfg.emit_true_image:
            feat["true_image"] = tf.TensorSpec(shape=(None,), dtype=tf.float32)
        if self.cfg.emit_peak_time:
            feat["peak_time"] = tf.TensorSpec(shape=(None,), dtype=tf.float32)
        if self.cfg.include_event_features:
            for k in self.cfg.event_feature_keys:
                feat[k] = tf.TensorSpec(shape=(), dtype=tf.float32)

        return (feat, tf.TensorSpec(shape=(), dtype=tf.int32))

    def _padded_shapes(self):
        feat_shapes = {
            "waveform": [None, None, None],
            "pedestal": [None],
            "n_pe": [],
            "event_id": [],
            "tel_id": [],
        }
        if self.cfg.emit_true_image:
            feat_shapes["true_image"] = [None]
        if self.cfg.emit_peak_time:
            feat_shapes["peak_time"] = [None]
        if self.cfg.include_event_features:
            for k in self.cfg.event_feature_keys:
                feat_shapes[k] = []
        return (feat_shapes, [])

    def _padding_values(self):
        feat_vals = {
            "waveform": tf.constant(0, tf.uint16),
            "pedestal": tf.constant(0, tf.int32),
            "n_pe": tf.constant(-1.0, tf.float32),
            "event_id": tf.constant(-1, tf.int64),
            "tel_id": tf.constant(-1, tf.int32),
        }
        if self.cfg.emit_true_image:
            feat_vals["true_image"] = tf.constant(0.0, tf.float32)
        if self.cfg.emit_peak_time:
            feat_vals["peak_time"] = tf.constant(0.0, tf.float32)
        if self.cfg.include_event_features:
            for k in self.cfg.event_feature_keys:
                feat_vals[k] = tf.constant(0.0, tf.float32)
        return (feat_vals, tf.constant(0, tf.int32))

    # ---------- Global quota helpers ----------
    def _consume_quota(self, label: int) -> bool:
        if label == 1:
            if self._remaining_gamma is None:
                return True
            if self._remaining_gamma <= 0:
                return False
            self._remaining_gamma -= 1
            return True
        else:
            if self._remaining_nsb is None:
                return True
            if self._remaining_nsb <= 0:
                return False
            self._remaining_nsb -= 1
            return True

    def _quota_exhausted_label(self, label: int) -> bool:
        if label == 1:
            return self._remaining_gamma is not None and self._remaining_gamma <= 0
        return self._remaining_nsb is not None and self._remaining_nsb <= 0

    def _quotas_exhausted(self) -> bool:
        gamma_done = self._remaining_gamma is not None and self._remaining_gamma <= 0
        nsb_done = self._remaining_nsb is not None and self._remaining_nsb <= 0
        return gamma_done and nsb_done
