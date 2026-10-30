"""
Shared plumbing for the three benchmark CLIs: data loading with held-out splits, the tokenizer
suite, duplicate-vocabulary detection and run provenance.

Every CLI trains tokenizers on the prepared dataset's TRAIN split only and evaluates on a held-out
split (tokka and intrinsic: TEST; proxy LM: VAL). ``assert_disjoint`` checks that at runtime.
"""

from __future__ import annotations

import argparse
import hashlib
import json
import os
import platform
import subprocess
import sys
import tempfile
import time
import warnings
from pathlib import Path
from typing import Any, Callable, Dict, Iterable, List, Optional, Sequence, Tuple

from tokenisers.data.pipeline import (
    DEFAULT_TRAIN_BYTES,
    DataPipeline,
    PreparedDataset,
    SigmorphonLoader,
)

REPO_ROOT = Path(__file__).resolve().parents[3]

DEFAULT_VOCAB_SIZE = 16_384
# 16k is the default; 32k and 64k are the other sizes the suite is meant to be run at.
STANDARD_VOCAB_SIZES = (16_384, 32_768, 65_536)

# SIGMORPHON 2022 languages that also occur in the prepared corpus.
DEFAULT_MORPH_LANGS = ("eng", "fra", "hun", "rus", "spa")

MORPHEME_LAMBDA = 2.0

VARIANTS: Tuple[str, ...] = (
    "bpe_frequency",
    "wordpiece_pmi",
    "wp_bpe_base",
    "wp_bpe_ft",
    "wp_bpe_pig",
    "wp_bpe_scp",
    "wp_bpe_npmi",
    "wp_bpe_ppig",
    "mdl_bits",
    "length_penalized",
    "super_bpe",
    "morpheme_bpe",
    "unigram_lm",
)

# Scorer name and explicit parameters of every BpeTokenizer.train variant; None = scorer default.
_BPE_SCORERS: Dict[str, Tuple[str, Dict[str, Any]]] = {
    "bpe_frequency": ("frequency", {}),
    "wordpiece_pmi": ("wordpiece", {}),
    "wp_bpe_base": ("wp-bpe-base", {}),
    "wp_bpe_ft": ("wp-bpe-ft", {}),
    "wp_bpe_pig": ("wp-bpe-pig", {}),
    "wp_bpe_scp": ("wp-bpe-scp", {}),
    "wp_bpe_npmi": ("wp-bpe-npmi", {}),
    "wp_bpe_ppig": ("wp-bpe-ppig", {}),
    "mdl_bits": ("mdl", {}),
    "length_penalized": ("length_penalized", {"beta": 0.5}),
}


# ----------------------------------------------------------------------------
# CLI arguments and data
# ----------------------------------------------------------------------------

def add_common_args(parser: argparse.ArgumentParser, output_dir: str) -> None:
    parser.add_argument("--vocab-size", type=int, default=DEFAULT_VOCAB_SIZE,
                        help=f"Total vocabulary size (default {DEFAULT_VOCAB_SIZE}; also run at 32768 / 65536)")
    parser.add_argument("--train-bytes", type=int, default=DEFAULT_TRAIN_BYTES,
                        help="Train-split size of the prepared dataset (python -m tokenisers.data)")
    parser.add_argument("--data-seed", type=int, default=0, help="Dataset split seed")
    parser.add_argument("--cache-dir", default=None, help="Dataset cache dir (default: the data pipeline's)")
    parser.add_argument("--offline", action="store_true",
                        help="Use the synthetic offline corpus and the 12-word morpheme fixture (results are labelled synthetic)")
    parser.add_argument("--variants", nargs="+", default=list(VARIANTS), choices=VARIANTS, metavar="VARIANT",
                        help="Tokenizer variants to train (default: all)")
    parser.add_argument("--output-dir", default=output_dir, help="Directory for result JSON/Markdown")
    parser.add_argument("--skip-memory-check", action="store_true",
                        help="Train even if the estimated peak memory exceeds what is available")


def load_dataset(args: argparse.Namespace) -> PreparedDataset:
    pipeline = DataPipeline(cache_dir=args.cache_dir, force_offline=args.offline)
    return pipeline.prepare(train_bytes=args.train_bytes, seed=args.data_seed)


# Peak resident memory of training one variant, in bytes per byte of training text: the largest
# value measured on 4 MB of the real corpus at V=16384 and V=65536 (unigram_lm 139, super_bpe 100,
# BPE variants <= 45), plus ~25% margin. It grows linearly with the text and, for the merge-based
# variants, with V (super_bpe 78 -> 100 B/B from 16k to 64k). Variants train one after another, so
# the run's peak is the largest variant's.
TRAIN_MEMORY_PER_BYTE: Dict[str, int] = {"unigram_lm": 175, "super_bpe": 125}
DEFAULT_TRAIN_MEMORY_PER_BYTE = 60
BASE_MEMORY = 600 * 2**20  # interpreter, torch, corpus copies, SIGMORPHON gold


def usable_system_memory(meminfo: str) -> Optional[int]:
    """MemAvailable minus a reserve for the rest of the machine (desktop session, other jobs):
    max(2 GiB, 15% of MemTotal). A benchmark may not take all free memory of a shared machine."""
    kb = {}
    for line in meminfo.splitlines():
        key, _, rest = line.partition(":")
        if key in ("MemTotal", "MemAvailable"):
            kb[key] = int(rest.split()[0]) * 1024
    if "MemAvailable" not in kb:
        return None
    reserve = max(2 * 2**30, int(0.15 * kb.get("MemTotal", 0)))
    return max(0, kb["MemAvailable"] - reserve)


def available_memory() -> Optional[int]:
    """Bytes this process may allocate: min(usable_system_memory, the free part of every cgroup v2
    memory.max above it). A cgroup limit (e.g. systemd-run -p MemoryMax=) is used in full."""
    avail: Optional[int] = None
    try:
        avail = usable_system_memory(Path("/proc/meminfo").read_text())
        rel = next(l[3:] for l in Path("/proc/self/cgroup").read_text().splitlines() if l.startswith("0::"))
        cg = Path("/sys/fs/cgroup") / rel.strip().lstrip("/")
        for d in [cg, *cg.parents]:
            limit = d / "memory.max"
            if limit.is_file() and limit.read_text().strip() != "max":
                free = int(limit.read_text()) - int((d / "memory.current").read_text())
                avail = free if avail is None else min(avail, free)
            if d == Path("/sys/fs/cgroup"):
                break
    except (OSError, StopIteration, ValueError):
        pass
    return avail


def estimate_train_memory(variants: Sequence[str], train_bytes: int) -> int:
    per_byte = max(TRAIN_MEMORY_PER_BYTE.get(v, DEFAULT_TRAIN_MEMORY_PER_BYTE) for v in variants)
    return BASE_MEMORY + per_byte * train_bytes


def check_memory(variants: Sequence[str], train_bytes: int) -> None:
    """Exit before training if the estimated peak exceeds the memory this process may use, instead
    of letting the kernel OOM-kill it (or the desktop session) halfway through."""
    need = estimate_train_memory(variants, train_bytes)
    avail = available_memory()
    if avail is not None and need > avail:
        worst = max(variants, key=lambda v: TRAIN_MEMORY_PER_BYTE.get(v, DEFAULT_TRAIN_MEMORY_PER_BYTE))
        raise SystemExit(
            f"Training {worst} on {train_bytes / 1e6:.0f} MB needs ~{need / 2**30:.1f} GiB but only "
            f"{avail / 2**30:.1f} GiB is available. Use a smaller --train-bytes, drop {worst} from "
            "--variants, or pass --skip-memory-check."
        )


def assert_disjoint(train_texts: Iterable[str], eval_texts: Iterable[str], what: str = "evaluation") -> None:
    """Raise if any evaluation document is also a training document."""
    overlap = set(train_texts) & set(eval_texts)
    if overlap:
        raise RuntimeError(f"{len(overlap)} {what} documents also occur in the training split")


def load_morphology(
    args: argparse.Namespace, train_texts: Sequence[str], langs: Sequence[str]
) -> Tuple[Dict[str, List[str]], List[Dict[str, Any]], Dict[str, Any]]:
    """(lexicon for morpheme_bpe, gold annotations, provenance).

    Gold = SIGMORPHON TEST split (surface entries). Lexicon = SIGMORPHON TRAIN split surface entries
    whose word occurs (whitespace-delimited) in the training text, minus every gold word, so the
    evaluated words never reach the tokenizer through the lexicon. Offline runs use the 12-word
    fixture as gold and an empty lexicon.
    """
    loader = SigmorphonLoader(cache_dir=args.cache_dir, offline=args.offline)
    if args.offline:
        gold = loader.load_offline_fixture()
        for g in gold:
            g["lang"] = "fixture"
        src = "offline test fixture (12 hand-written words, NOT SIGMORPHON)"
        return {}, gold, {"gold_source": src, "gold_entries": len(gold), "lexicon": None}

    gold: List[Dict[str, Any]] = []
    lexicon: Dict[str, List[str]] = {}
    prov: Dict[str, Any] = {"gold_source": f"SIGMORPHON 2022 test split, surface entries ({', '.join(langs)})",
                            "gold": [], "lexicon": []}
    words = {w for text in train_texts for w in text.split()}
    for lang in langs:
        gold.extend(loader.load(lang, "test"))
        prov["gold"].append(loader.provenance(lang, "test"))
        # Streamed: the train files hold up to ~750k words per language, only corpus words are kept.
        with open(loader.path(lang, "train"), encoding="utf-8") as f:
            for line in f:
                parts = line.rstrip("\r\n").split("\t")
                if len(parts) < 2 or parts[0] not in words:
                    continue
                segments = [s for s in parts[1].split(" @@") if s]
                if "".join(segments) == parts[0]:  # surface segmentations only, as in SigmorphonLoader
                    lexicon.setdefault(parts[0], segments)
        prov["lexicon"].append(loader.provenance(lang, "train"))
    gold_words = {g["word"] for g in gold}
    dropped = sorted(gold_words & set(lexicon))
    for w in dropped:
        del lexicon[w]
    prov["gold_entries"] = len(gold)
    prov["lexicon_entries"] = len(lexicon)
    prov["lexicon_words_dropped_as_gold"] = len(dropped)
    return lexicon, gold, prov


# ----------------------------------------------------------------------------
# Tokenizer suite
# ----------------------------------------------------------------------------

def variant_config(name: str, vocab_size: int) -> Dict[str, Any]:
    """Class and training parameters of a suite variant (recorded in every result file)."""
    if name in _BPE_SCORERS:
        scorer, params = _BPE_SCORERS[name]
        return {"class": "BpeTokenizer", "scorer": scorer, **params}
    if name == "super_bpe":
        return {"class": "SuperBpeTokenizer", "v_switch": 256 + (max(vocab_size, 256) - 256) * 9 // 10}
    if name == "morpheme_bpe":
        return {"class": "MorphemeBpeTokenizer", "scorer": "frequency", "lambda_weight": MORPHEME_LAMBDA}
    if name == "unigram_lm":
        return {"class": "UnigramTokenizer"}
    raise ValueError(f"unknown variant {name!r}")


def train_variant(name: str, corpus: List[str], vocab_size: int, lexicon: Dict[str, List[str]]) -> Any:
    from tokenisers.models import BpeTokenizer, MorphemeBpeTokenizer, SuperBpeTokenizer, UnigramTokenizer

    if name in _BPE_SCORERS:
        scorer, params = _BPE_SCORERS[name]
        return BpeTokenizer.train(corpus=corpus, vocab_size=vocab_size, scorer=scorer, **params)
    if name == "super_bpe":
        return SuperBpeTokenizer.train(corpus=corpus, vocab_size=vocab_size)
    if name == "morpheme_bpe":
        return MorphemeBpeTokenizer.train(
            corpus=corpus, vocab_size=vocab_size, morpheme_lexicon=lexicon, lambda_weight=MORPHEME_LAMBDA
        )
    if name == "unigram_lm":
        return UnigramTokenizer.train(corpus=corpus, vocab_size=vocab_size)
    raise ValueError(f"unknown variant {name!r}")


def train_suite(
    variants: Sequence[str],
    corpus: List[str],
    vocab_size: int,
    lexicon: Dict[str, List[str]],
    log: Callable[[str], None] = print,
) -> Tuple[Dict[str, Any], Dict[str, Dict[str, Any]]]:
    """Train each variant sequentially. Returns (tokenizers, per-variant training record)."""
    models: Dict[str, Any] = {}
    records: Dict[str, Dict[str, Any]] = {}
    for name in variants:
        t0 = time.perf_counter()
        with warnings.catch_warnings(record=True) as caught:
            warnings.simplefilter("always")
            tok = train_variant(name, corpus, vocab_size, lexicon)
        secs = time.perf_counter() - t0
        models[name] = tok
        records[name] = {
            **variant_config(name, vocab_size),
            "requested_vocab_size": vocab_size,
            "vocab_size": tok.vocab_size,
            "train_seconds": round(secs, 2),
            "warnings": [str(w.message) for w in caught],
        }
        log(f"  trained {name}: |V|={tok.vocab_size} in {secs:.1f}s")
    return models, records


def tokenizer_fingerprint(tok: Any) -> str:
    """sha256 of the serialized tokenizer (vocab, merges/scores, pre-tokenizer): equal iff it encodes identically."""
    if hasattr(tok, "export_hf_json"):
        with tempfile.TemporaryDirectory() as d:
            path = Path(d) / "tokenizer.json"
            tok.export_hf_json(str(path))
            return hashlib.sha256(path.read_bytes()).hexdigest()
    vocab = sorted(tok.get_vocab().items())
    return hashlib.sha256(json.dumps(vocab).encode("utf-8")).hexdigest()


def find_duplicates(models: Dict[str, Any]) -> Dict[str, str]:
    """{duplicate_name: first_name_with_the_same_tokenizer}, in ``models`` order."""
    first: Dict[str, str] = {}
    dups: Dict[str, str] = {}
    for name, tok in models.items():
        fp = tokenizer_fingerprint(tok)
        if fp in first:
            dups[name] = first[fp]
        else:
            first[fp] = name
    return dups


# ----------------------------------------------------------------------------
# Provenance
# ----------------------------------------------------------------------------

def _git(*args: str) -> Optional[str]:
    try:
        out = subprocess.run(["git", *args], cwd=REPO_ROOT, capture_output=True, text=True, timeout=10)
    except (OSError, subprocess.SubprocessError):
        return None
    return out.stdout.strip() if out.returncode == 0 else None


def _cpu_model() -> str:
    try:
        for line in Path("/proc/cpuinfo").read_text().splitlines():
            if line.startswith("model name"):
                return line.split(":", 1)[1].strip()
    except OSError:
        pass
    return platform.processor() or platform.machine()


def run_metadata(
    args: argparse.Namespace,
    dataset: PreparedDataset,
    benchmark: str,
    eval_split: str,
    train_records: Dict[str, Dict[str, Any]],
    duplicates: Dict[str, str],
    **extra: Any,
) -> Dict[str, Any]:
    status = _git("status", "--porcelain", "--untracked-files=no")
    manifest = dataset.manifest
    return {
        "benchmark": benchmark,
        "created_utc": time.strftime("%Y-%m-%dT%H:%M:%SZ", time.gmtime()),
        "command": [Path(sys.argv[0]).name, *sys.argv[1:]],
        "git_commit": _git("rev-parse", "HEAD"),
        "git_dirty": None if status is None else bool(status),
        "host": {
            "platform": platform.platform(),
            "cpu": _cpu_model(),
            "cpu_count": os.cpu_count(),
            "python": platform.python_version(),
        },
        "requested_vocab_size": args.vocab_size,
        "synthetic_data": dataset.synthetic,
        "train_split": "train",
        "eval_split": eval_split,
        "train_bytes": manifest["splits"]["train"]["text_bytes"],
        "train_docs": manifest["splits"]["train"]["docs"],
        "eval_bytes": manifest["splits"][eval_split]["text_bytes"],
        "eval_docs": manifest["splits"][eval_split]["docs"],
        "dataset": {"root": dataset.root.name, **manifest},
        "variants": train_records,
        "duplicates": duplicates,
        **extra,
    }


def write_json(path: Path, payload: Dict[str, Any]) -> None:
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text(json.dumps(payload, indent=2, ensure_ascii=False) + "\n", encoding="utf-8")


__all__ = [
    "DEFAULT_VOCAB_SIZE",
    "STANDARD_VOCAB_SIZES",
    "VARIANTS",
    "add_common_args",
    "assert_disjoint",
    "available_memory",
    "usable_system_memory",
    "check_memory",
    "estimate_train_memory",
    "find_duplicates",
    "load_dataset",
    "load_morphology",
    "run_metadata",
    "tokenizer_fingerprint",
    "train_suite",
    "train_variant",
    "variant_config",
    "write_json",
]
