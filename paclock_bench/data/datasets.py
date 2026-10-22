"""Datasets over shared preprocessed arrays.

Stored normalization is preserved by default. Rebuild configurations may request
physical microvolts/100 using explicitly stored q95 denominators; transformations,
sampling rate, and manifest identity are recorded in the input contract.
"""

from __future__ import annotations

import json
import os

from ..paths import expand
from .contracts import verify_arrays, describe_contract, labram_divisor, resolve_signal_transform
import numpy as np
import torch
from torch.utils.data import DataLoader, Dataset, Subset


# Read the whole split into RAM when it is at most this large; above it, fall
# back to mmap. 24 GB covers every corpus in the matrix except TUAB/TUSZ/CHB-MIT
# (38-42 GB), and the compute nodes have far more than that -- a four-process
# benchmark reported 8.6% memory use on a 128-core node.
PRELOAD_LIMIT_GB = 24.0


class WindowDataset(Dataset):
    """(signals, labels) npy pair produced by `preprocessing/`, in RAM if it fits.

    The original comment here read "mmap rather than a full load: TUAB is ~300k
    windows x 16 x 2000 float32, which is far past comfortable RAM". That is true
    of TUAB and false of the machine: TUEV's training split is 4.4 GB.

    mmap plus ``shuffle=True`` turns an epoch into one random 64 KB read per
    sample -- 68,445 of them for TUEV -- against a shared Lustre filesystem, and
    Lustre is at its worst on small random reads. A four-arm benchmark measured
    the consequence: batch 32, 128 and 256 with and without bf16 all landed
    within 2% of each other at ~31 samples/s, while GPU memory use rose 4.5% ->
    18.3% (so the larger batches really were being used) and GPU power stayed
    flat at 75-80 W on a 300 W part with the host at 3.5% CPU. Neither the device
    nor the host was busy; both were waiting on I/O.

    So the split is read into RAM when it fits, and mmap remains for the corpora
    that genuinely do not. Reading is sequential and happens once.
    """

    def __init__(self, root: str, split: str, *, flatten_sequences: bool = False,
                 preload: bool | None = None, normalization_scales=None, input_multiplier: float = 1.0):
        sig_path = os.path.join(root, f"{split}_signals.npy")
        lab_path = os.path.join(root, f"{split}_labels.npy")
        for p in (sig_path, lab_path):
            if not os.path.exists(p):
                raise FileNotFoundError(
                    f"{p} not found -- run the preprocessing script for this dataset"
                )
        size_gb = os.path.getsize(sig_path) / 1024 ** 3
        if preload is None:
            preload = size_gb <= PRELOAD_LIMIT_GB
        if preload:
            self.signals = np.load(sig_path)
            print(f"  [{split}] {size_gb:.1f} GB read into RAM", flush=True)
        else:
            self.signals = np.load(sig_path, mmap_mode="r")
            print(f"  [{split}] {size_gb:.1f} GB left on disk (mmap), over the "
                  f"{PRELOAD_LIMIT_GB:.0f} GB preload limit", flush=True)
        self.labels = np.load(lab_path)
        verify_arrays(self.signals, self.labels, sig_path, lab_path)
        self.split = split
        self.normalization_scales = normalization_scales
        self.input_multiplier = input_multiplier
        if normalization_scales is not None and len(normalization_scales)!=len(self.labels):
            raise ValueError("normalizer/label count mismatch")

        # ISRUC is stored as (n_seq, 20, C, T) sequences. Models that consume one
        # epoch at a time set flatten_sequences and see (n_seq*20, C, T).
        self.flatten = flatten_sequences and self.signals.ndim == 4
        if self.flatten:
            n, s = self.signals.shape[0], self.signals.shape[1]
            self.signals = self.signals.reshape(n * s, *self.signals.shape[2:])
            self.labels = self.labels.reshape(-1)

    def __len__(self) -> int:
        return len(self.labels)

    def __getitem__(self, i: int):
        # np.array (a copy) rather than asarray: the mmap is read-only, and
        # torch.from_numpy on a non-writable buffer warns on every call and
        # hands back a tensor that is unsafe to write in place.
        x = np.array(self.signals[i], dtype=np.float32)
        if self.normalization_scales is not None:
            x = x * self.normalization_scales[i]
        x = torch.from_numpy((x * self.input_multiplier).astype(np.float32))
        y = self.labels[i]
        y = torch.from_numpy(np.array(y, dtype=np.int64)) if np.ndim(y) else int(y)
        return x, y

    @property
    def shape(self) -> tuple[int, ...]:
        return tuple(self.signals.shape[1:])

    def class_counts(self) -> np.ndarray:
        return np.bincount(np.asarray(self.labels).ravel())


def load_manifest(root: str) -> dict:
    path = os.path.join(root, "manifest.json")
    if not os.path.exists(path):
        raise FileNotFoundError(
            f"{path} missing -- the protocol requires every run to reference the "
            f"manifest its data was built from"
        )
    with open(path) as f:
        return json.load(f)


def _counts(d):
    """Class counts for a WindowDataset or a Subset view of one."""
    if isinstance(d, Subset):
        return np.bincount(np.asarray(d.dataset.labels).ravel()[d.indices]).tolist()
    return d.class_counts().tolist()


def stratified_subset(dataset, cap: int, seed: int):
    """A class-stratified random subset of `cap` windows, as a Subset view.

    Stratified rather than plain random because the corpora this exists for are
    imbalanced -- TUEV's rarest class is under 2% of its training split -- and a
    uniform draw at cap=2160 could drop a class entirely, which would change the
    task rather than its sample size and confound the very comparison the
    subsample is built to make.

    `seed` is deliberately independent of the run's model seed, so every model
    and every seed at a given cap trains on the IDENTICAL subset: the curve then
    varies in sample size only.
    """
    labels = np.asarray(dataset.labels).ravel()
    rng = np.random.default_rng(seed)
    classes, counts = np.unique(labels, return_counts=True)
    # proportional allocation, at least one window per class, largest-remainder
    # rounding so the parts sum to exactly `cap`
    exact = counts / counts.sum() * cap
    take = np.maximum(np.floor(exact).astype(int), 1)
    short = cap - take.sum()
    if short > 0:
        order = np.argsort(-(exact - np.floor(exact)))
        for k in range(short):
            take[order[k % len(order)]] += 1
    elif short < 0:
        order = np.argsort(exact - np.floor(exact))
        i = 0
        while take.sum() > cap:
            j = order[i % len(order)]
            if take[j] > 1:
                take[j] -= 1
            i += 1
    take = np.minimum(take, counts)
    idx = np.concatenate([
        rng.choice(np.where(labels == c)[0], n, replace=False)
        for c, n in zip(classes, take)
    ])
    return Subset(dataset, np.sort(idx).tolist())


def build_dataloaders(cfg: dict) -> tuple[DataLoader, DataLoader, DataLoader, dict]:
    """train/val/test loaders plus the manifest the data came from."""
    root = expand(cfg["data_root"])
    manifest = load_manifest(root)
    contract = describe_contract(cfg, manifest, root, "shared")
    flatten = bool(cfg.get("flatten_sequences", False))
    # None lets each split decide from its own size; set explicitly to force
    preload = cfg.get("preload")

    transforms = {s: resolve_signal_transform(root,s,cfg,manifest) for s in ("train","val","test")}
    contract["loader_signal_mode"] = cfg.get("loader_signal_mode","stored")
    sets = {
        s: WindowDataset(root, s, flatten_sequences=flatten, preload=preload,
            normalization_scales=transforms[s][0], input_multiplier=transforms[s][1])
        for s in ("train", "val", "test")
    }

    # Sample-size ablation (docs/FINDINGS.md): the tier boundary in this
    # benchmark coincides with training-set size -- every corpus we lead has
    # >=68k training windows and every corpus we lose has <=6.7k, with nothing in
    # between -- so the explanation has to be tested by moving that variable on a
    # corpus we win, holding everything else fixed.
    cap = int(cfg.get("train_subsample", 0))
    if cap and cap < len(sets["train"]):
        full = len(sets["train"])
        sets["train"] = stratified_subset(
            sets["train"], cap, int(cfg.get("train_subsample_seed", 0))
        )
        print(f"  [train] subsampled {cap} / {full} windows (stratified, "
              f"seed {int(cfg.get('train_subsample_seed', 0))})", flush=True)

    bs = cfg.get("batch_size", 32)
    nw = cfg.get("num_workers", 8)
    common = dict(num_workers=nw, pin_memory=True,
                  persistent_workers=nw > 0)

    loaders = (
        DataLoader(sets["train"], batch_size=bs, shuffle=True,
                   drop_last=bool(cfg.get("train_drop_last", False)), **common),
        DataLoader(sets["val"], batch_size=bs, shuffle=False, drop_last=False, **common),
        DataLoader(sets["test"], batch_size=bs, shuffle=False, drop_last=False, **common),
    )
    info = {
        "manifest": manifest,
        "input_contract": contract,
        "input_shape": (sets["train"].dataset.shape
                        if isinstance(sets["train"], Subset)
                        else sets["train"].shape),
        "class_counts": {s: _counts(d) for s, d in sets.items()},
        "n_samples": {s: len(d) for s, d in sets.items()},
    }
    return (*loaders, info)
