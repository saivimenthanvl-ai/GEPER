"""
Loader for the official SpliceBERT checkpoint.

Distinct from `pipeline.models.cache.WeightCache` (the generic
on-disk-weight-file cache every plugin shares) the same way
`pipeline/models/spliceformer/loader.py` is distinct from it: this
module is about *fetching the official archive and getting one
checkpoint's files onto disk in a `transformers`-loadable layout*;
`cache.py` (reused here, not reimplemented) is about *where the
downloaded files live on disk*.
"""

import shutil
import tarfile
from pathlib import Path

from utils.logger import get_logger

logger = get_logger(__name__)

# SpliceBERT's official weights are published ONLY on Zenodo (DOI
# 10.5281/zenodo.7995778) -- there is no GitHub release asset the way
# SpliceFormer's checkpoints are (see pipeline/models/spliceformer/
# loader.py); the repo's own `download.sh` fetches this exact URL.
# Pinned to a specific Zenodo record id (not "latest") for the same
# reason SpliceFormer pins a specific GitHub release tag: the exact
# weights GEPER downloads must never silently change underneath a
# running deployment. Zenodo records are immutable once published (a
# new version gets a new record id), so pinning the id is sufficient
# -- no separate ref/tag concept applies here.
DEFAULT_ZENODO_RECORD = "7995778"
_ARCHIVE_URL_TEMPLATE = "https://zenodo.org/record/{record}/files/models.tar.gz?download=1"

# Three checkpoints ship inside the same archive (confirmed by listing
# the archive's own contents): `SpliceBERT.510nt`,
# `SpliceBERT-human.510nt` (human-only pretraining, fixed 510nt input),
# and `SpliceBERT.1024nt` (all 72 vertebrates, variable length up to
# 1024nt). `SpliceBERT.1024nt` is the flagship/most general checkpoint
# (matches the paper's own headline "72 vertebrates" pretraining set
# and supports the longest, variable-length input) -- the same
# "most general, officially flagship checkpoint" rationale
# EnformerPlugin/BorzoiPlugin/SpliceFormerPlugin's own default
# checkpoint choices already follow.
DEFAULT_CHECKPOINT = "SpliceBERT.1024nt"

# From the downloaded checkpoint's own config.json: max_position_embeddings
# is 1026 (1,024 content positions + [CLS] + [SEP]), vocab_size 10
# ([PAD],[UNK],[CLS],[SEP],[MASK],N,A,C,G,T -- single-nucleotide
# tokens, one per position, no k-mer/BPE merging). Not a free
# parameter here -- the pretrained weights below were trained with
# exactly this position-embedding table size.
MAX_POSITION_EMBEDDINGS = 1026
NUM_SPECIAL_TOKENS = 2  # [CLS] + [SEP], added by the tokenizer around the sequence
MAX_CONTENT_LENGTH = MAX_POSITION_EMBEDDINGS - NUM_SPECIAL_TOKENS  # 1,024


def archive_url(record: str = DEFAULT_ZENODO_RECORD) -> str:
    return _ARCHIVE_URL_TEMPLATE.format(record=record)


def checkpoint_dir_for(cache_dir: Path, checkpoint: str = DEFAULT_CHECKPOINT) -> Path:
    return cache_dir / checkpoint


def is_checkpoint_cached(cache_dir: Path, checkpoint: str = DEFAULT_CHECKPOINT) -> bool:
    """A cached checkpoint is considered complete once its config.json
    and weight file both exist -- config.json is written last by
    `download_and_extract_checkpoint` below, so its presence alone is
    already a reasonable "extraction finished" signal, and checking
    the weight file too guards against a hand-edited/partial cache
    directory."""
    directory = checkpoint_dir_for(cache_dir, checkpoint)
    return (directory / "config.json").is_file() and (directory / "pytorch_model.bin").is_file()


def download_and_extract_checkpoint(
    cache_dir: Path, checkpoint: str = DEFAULT_CHECKPOINT, record: str = DEFAULT_ZENODO_RECORD
) -> Path:
    """
    Downloads the official `models.tar.gz` archive (~208 MiB, all
    three checkpoints bundled together -- Zenodo does not support
    fetching a single subfolder of a tar.gz by itself) to a temporary
    location, extracts ONLY the `checkpoint` subfolder's files (not
    the other two checkpoints, to avoid keeping ~140 MiB of unused
    weights on disk), moves them into `cache_dir/{checkpoint}/`, and
    deletes the downloaded archive afterwards. Uses `requests`,
    already an unconditional GEPER dependency, exactly like
    `pipeline/models/spliceformer/loader.py::download_checkpoint`.

    Writes the archive to a `.part` sibling first and only extracts
    after a full, successful download, so an interrupted download
    never leaves a corrupt/partial checkpoint directory that
    `is_checkpoint_cached` would mistake for a good one.
    """
    import requests

    cache_dir.mkdir(parents=True, exist_ok=True)
    archive_path = cache_dir / "models.tar.gz"
    tmp_archive_path = archive_path.with_name(archive_path.name + ".part")

    url = archive_url(record)
    logger.info(f"Downloading SpliceBERT model archive from {url} ...")
    with requests.get(url, stream=True, timeout=60) as response:
        response.raise_for_status()
        with open(tmp_archive_path, "wb") as fh:
            for chunk in response.iter_content(chunk_size=1024 * 1024):
                if chunk:
                    fh.write(chunk)
    tmp_archive_path.replace(archive_path)
    logger.info(f"SpliceBERT archive saved to {archive_path}; extracting '{checkpoint}' ...")

    member_prefix = f"models/{checkpoint}/"
    extract_root = cache_dir / "_extract_tmp"
    if extract_root.exists():
        shutil.rmtree(extract_root)
    try:
        with tarfile.open(archive_path, "r:gz") as tar:
            members = [m for m in tar.getmembers() if m.name.startswith(member_prefix) and m.isfile()]
            if not members:
                raise RuntimeError(
                    f"'{member_prefix}' not found in the downloaded SpliceBERT archive "
                    f"-- checkpoint name may be wrong, or upstream changed the archive layout."
                )
            tar.extractall(extract_root, members=members)

        destination = checkpoint_dir_for(cache_dir, checkpoint)
        if destination.exists():
            shutil.rmtree(destination)
        shutil.move(str(extract_root / "models" / checkpoint), str(destination))
    finally:
        shutil.rmtree(extract_root, ignore_errors=True)
        archive_path.unlink(missing_ok=True)

    logger.info(f"SpliceBERT checkpoint '{checkpoint}' extracted to {destination}.")
    return destination


def build_model_and_tokenizer(checkpoint_dir: Path):
    """
    Loads the tokenizer and `BertForMaskedLM` weights from an already
    downloaded/extracted checkpoint directory via `transformers`'
    standard `AutoTokenizer`/`AutoModelForMaskedLM.from_pretrained`,
    exactly the way the official repo's own README documents loading
    it (`AutoTokenizer.from_pretrained(SPLICEBERT_PATH)` /
    `AutoModel.from_pretrained(SPLICEBERT_PATH)` -- `AutoModelForMaskedLM`
    here instead of the README's plain `AutoModel` because
    SpliceBERTPlugin needs the MLM head's per-token logits for
    zero-shot variant scoring, not just the encoder's hidden states;
    both share the same `BertForMaskedLM` checkpoint, `AutoModel`
    would simply discard the head). No custom model code -- the
    checkpoint's own `config.json` (`architectures:
    ["BertForMaskedLM"]`) is standard `transformers` BERT, imported
    here (not at this module's top level) so importing
    `splicebert_plugin.py` never itself requires `transformers` to be
    importable, mirroring `pipeline/models/spliceformer/loader.py
    ::build_model`'s deferred-import rationale.

    HISTORY (round 18 correction -- the story below is what this
    docstring used to assert, and is now known to be false; recorded
    so a future reader doesn't reintroduce it): earlier rounds
    attributed the SpliceBERT load timeout to `transformers`
    internally detecting/caching a TensorFlow backend, and shipped two
    fixes for it (`USE_TF=0`, then a direct override of
    `transformers.utils.import_utils._tf_available`). Confirmed live
    on Colab under this repo's own committed pin
    (`transformers>=5.12.1,<6.0.0`, installed `5.13.1`): neither
    `transformers.utils.import_utils._tf_available` nor
    `transformers.TFAutoModel` exist under this version at all --
    `transformers` v5 dropped TensorFlow support entirely, so there
    was no TensorFlow-backend code path left for either fix to steer
    away from. Both fixes were confirmed no-ops and have been removed.

    WHAT IS ACTUALLY KNOWN about the timeout this function still
    guards against (see `_load_with_timeout` below, kept -- it is
    doing real work: SpliceBERT genuinely still stalls at exactly the
    configured timeout inside the full orchestrator process): loading
    this checkpoint in isolation succeeds quickly (13s cold, 0.2s
    warm, all 108/108 weights present) -- the stall is specific to
    running inside the full pipeline process, where `pipeline/models/
    mmsplice/` has already loaded real TensorFlow onto the GPU (MMSplice
    genuinely requires it -- this project keeps TensorFlow installed,
    the fixes removed above only ever touched an env var and an
    internal flag, never the TensorFlow install itself) and
    `pipeline/models/esm2.py` has already used `transformers`'
    `AutoModel` machinery. The stall correlates with `transformers`
    emitting `You are using a model of type 'bert' to instantiate a
    model of type ''` immediately before it. The specific import or
    call that actually triggers the stall has not been isolated --
    nothing beyond the above is established.
    """
    from transformers import AutoModelForMaskedLM, AutoTokenizer

    return _load_with_timeout(checkpoint_dir, AutoModelForMaskedLM, AutoTokenizer)


def _load_with_timeout(checkpoint_dir: Path, model_cls, tokenizer_cls):
    """
    Runs the actual `from_pretrained` calls in a worker thread and
    waits up to `CONFIG.splicing.SPLICEBERT_LOAD_TIMEOUT_SECS` for them
    to finish, raising `TimeoutError` (caught by
    `SpliceBERTPlugin._load_impl`, which demotes this model to
    unavailable for the rest of the run -- the same graceful-
    degradation path every other model already uses) instead of
    hanging the whole pipeline silently if they don't.

    Known, disclosed limitation: CPython cannot forcibly kill a thread
    that is itself stuck (e.g. in a C extension or blocked on I/O with
    no timeout of its own), so a worker that truly never returns keeps
    running in the background, using memory/CPU, until it either
    finishes on its own or the process exits. What this DOES guarantee
    is that the *caller* stops waiting and reports a clear, actionable
    error at a bounded time -- turning a silent multi-hour hang into an
    immediate, diagnosable failure, which is the actual goal.
    """
    import concurrent.futures

    from config import CONFIG

    def _load():
        tokenizer = tokenizer_cls.from_pretrained(str(checkpoint_dir))
        model = model_cls.from_pretrained(str(checkpoint_dir))
        return model, tokenizer

    timeout = CONFIG.splicing.SPLICEBERT_LOAD_TIMEOUT_SECS
    executor = concurrent.futures.ThreadPoolExecutor(max_workers=1, thread_name_prefix="splicebert-load")
    future = executor.submit(_load)
    try:
        return future.result(timeout=timeout)
    except concurrent.futures.TimeoutError as exc:
        raise TimeoutError(
            f"Loading SpliceBERT checkpoint from '{checkpoint_dir}' did not complete within "
            f"{timeout:.0f}s (GEPER_SPLICEBERT_LOAD_TIMEOUT_SECS) -- treating this as a load "
            f"failure rather than waiting indefinitely. This load succeeds quickly in isolation "
            f"(confirmed: 13s cold, 0.2s warm) but has repeatedly stalled at exactly this timeout "
            f"inside the full orchestrator process, where MMSplice has already loaded real "
            f"TensorFlow onto the GPU and ESM2 has already used transformers' AutoModel machinery; "
            f'the stall correlates with transformers emitting "You are using a model of type '
            f"'bert' to instantiate a model of type ''\" immediately beforehand. The triggering "
            f"import/call has not been isolated -- see build_model_and_tokenizer's docstring."
        ) from exc
    finally:
        # Don't block process shutdown on a worker that may never
        # return (see docstring) -- `wait=False` lets the interpreter
        # exit without joining it.
        executor.shutdown(wait=False)
