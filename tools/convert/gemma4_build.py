"""One-command Gemma 4 31B `.ninfer` builder: presets, step plan, resumable runner.

`python -m tools.convert.gemma4_build --preset best-small --model <BF16 dir> --assistant <dir> --out-dir <dir>`
chains the steps of the conversion guide (calibration text, GPTQ or llama.cpp statistics, `gemma4_q4 convert`)
and writes the artifact, its receipts, a Windows launcher and BUILD-SUMMARY.md. The converter, the GPTQ scripts
and llama.cpp keep doing the work; this module only builds their command lines, runs them with logs, and records
which step finished. Source weights are only read.

Calibration text. Without `--calibration-text` the builder downloads the pinned public English corpus the measured
quality numbers used (eaddario/imatrix-calibration, combined_en_large.parquet) and exports it byte for byte as the
author's text file: a UTF-8 BOM, CRLF line ends, and the CP437 round trip that Windows PowerShell applied to the
export (it affects the 18,228 non-ASCII characters of the 20 MB). The result is checked against its sha256.
"""

from __future__ import annotations

from collections.abc import Callable
from dataclasses import dataclass, field
import hashlib
import json
import os
from pathlib import Path
import re
import shlex
import shutil
import subprocess
import sys
import time
import urllib.request

from . import gemma4_build_launcher as launcher_tools

FORK_ROOT = Path(__file__).resolve().parents[2]
STATE_SCHEMA = "ninfer.gemma4-build-state/v1"
BUILD_SCHEMA = "ninfer.gemma4-build/v1"
CHAT_PREFIX_IDS = "2,105,2364,107,34230,506,2354,236761,106,107,105,4368,107,100,45518,107,101"
CALIBRATION_CHUNKS = 400
CALIBRATION_CONTEXT = 512
CALIBRATION_REPO = "eaddario/imatrix-calibration"
CALIBRATION_REVISION = "e87ed55dcba9d9c3a3e41539f3e728e981b1daa4"
CALIBRATION_FILE = "combined_en_large.parquet"
CALIBRATION_URL = (
    f"https://huggingface.co/datasets/{CALIBRATION_REPO}/resolve/{CALIBRATION_REVISION}/{CALIBRATION_FILE}"
)
CALIBRATION_PARQUET_SHA256 = "8a804421c074713aaa537a35da8bdb12e93b94b44344c09a9942d047c25d6e03"
CALIBRATION_TEXT_SHA256 = "82b7e7804f2486a34c23feef43c5356e542724102321cd53c52e2c4d0c316c8a"
SAFE_NAME = re.compile(r"[^A-Za-z0-9._-]+")


@dataclass(frozen=True, slots=True)
class Preset:
    """A measured conversion recipe. Quality figures are the author's (one model, text only, W4A8, FP8 MTP)."""

    id: str
    method: str  # "gptq", "rtn" (calibrated round-to-nearest) or "plain"
    summary: str
    meaning: str
    size_class: str
    file_gb: float  # text + MTP
    kl: float  # mean KL from the near-lossless FP8-row reference, English instrument
    wait: str
    group_size: int
    native_groups: bool
    scale_bits: int | None
    format_name: str  # tensor format the serving binary must know
    work_hard_gb: float  # free space the work drive needs at the peak
    work_soft_gb: float  # comfortable free space (adds estimated scratch)
    residual_gb: float  # what stays in the work dir once big intermediates are pruned
    minutes: dict[str, float]  # per step, typical RTX 5090 + NVMe


PRESETS: dict[str, Preset] = {
    "best-small": Preset(
        "best-small", "gptq", "GPTQ, group 256", "Best quality per byte: the recommended default for most people.",
        "small", 16.9, 0.1213, "about 30 min", 256, True, None, "q4_g256_fp16", 75, 103, 17,
        {"calibration-source": 1, "calibration-render": 1, "calibration-tokens": 1, "text-tree": 2, "gptq": 18,
         "gptq-check": 1, "convert": 6, "receipt-check": 0.5, "finalize": 0.5},
    ),
    "best-medium": Preset(
        "best-medium", "gptq", "GPTQ, group 32", "Highest quality of the five; about 1.6 GB larger than best-small.",
        "medium", 18.4, 0.0845, "about 30 min", 32, False, None, "q4_g32_fp16", 75, 103, 17,
        {"calibration-source": 1, "calibration-render": 1, "calibration-tokens": 1, "text-tree": 2, "gptq": 18,
         "gptq-check": 1, "convert": 6, "receipt-check": 0.5, "finalize": 0.5},
    ),
    "fast-medium": Preset(
        "fast-medium", "rtn", "calibrated RTN, g32 with 6-bit two-level scales",
        "Best choice when you will not wait for GPTQ: needs llama.cpp for statistics, no GPTQ environment.",
        "medium", 17.5, 0.1543, "about 40 min", 32, True, 6, "q4_g32_s6_fp16", 36, 54, 1,
        {"calibration-source": 1, "calibration-render": 1, "gguf": 7, "imatrix": 12, "convert": 15,
         "receipt-check": 0.5, "finalize": 0.5},
    ),
    "fast-small": Preset(
        "fast-small", "rtn", "calibrated RTN, group 256",
        "Small and quick, but quality-compromised (KL 0.2376, about twice best-small); prefer best-small.",
        "small", 16.8, 0.2376, "about 40 min", 256, True, None, "q4_g256_fp16", 36, 54, 1,
        {"calibration-source": 1, "calibration-render": 1, "gguf": 7, "imatrix": 12, "convert": 15,
         "receipt-check": 0.5, "finalize": 0.5},
    ),
    "draft": Preset(
        "draft", "plain", "uncalibrated absmax, group 32 (the old default)",
        "A quick test build only: nothing to install, but the lowest quality of the five.",
        "medium", 18.4, 0.2654, "about 15 min", 32, False, None, "q4_g32_fp16", 0, 0, 0,
        {"convert": 15, "receipt-check": 0.5, "finalize": 0.5},
    ),
}
SCORE_MINUTES = {
    "score-corpus": 8, "score-reference": 41, "score-reference-write": 5, "score-candidate": 8,
    "score-run": 2, "score-report": 0.5,
}
SCORE_EXTRA_GB = 62  # reference artifact 31 + corpus cache 14 + candidate 17


@dataclass(frozen=True)
class BuildConfig:
    """Everything that decides the artifact; launcher settings live in `ServeSettings`."""

    preset: Preset
    model: Path
    assistant: Path | None
    with_vision: bool
    out_dir: Path
    work_dir: Path
    name: str
    python: str = sys.executable
    gptq_python: Path | None = None
    llama_cpp_dir: Path | None = None
    llama_imatrix: Path | None = None
    llama_python: str = sys.executable
    imatrix_gpu_layers: str = "auto"
    calibration_text: Path | None = None
    score: bool = False
    perplexity_exe: Path | None = None
    keep_work: bool = False

    @property
    def artifact(self) -> Path:
        return self.out_dir / f"{self.name}.ninfer"

    @property
    def receipts(self) -> tuple[Path, ...]:
        base = str(self.artifact)
        return (self.artifact, Path(base + ".build.json"), Path(base + ".conversion.json"))

    def work(self, *parts: str) -> Path:
        return self.work_dir.joinpath(*parts)


@dataclass(frozen=True, slots=True)
class ServeSettings:
    host: str = launcher_tools.DEFAULT_HOST
    port: int = launcher_tools.DEFAULT_PORT
    alias: str | None = None
    context: int = launcher_tools.DEFAULT_CONTEXT
    kv_dtype: str = "fp8"
    model_match: str = launcher_tools.DEFAULT_MODEL_MATCH
    server_exe: Path | None = None
    cuda_bin: Path | None = None
    launcher: bool = True


@dataclass
class Step:
    id: str
    title: str
    minutes: float
    argv: list[str] | None = None
    call: Callable[["Builder"], None] | None = None
    note: str = ""
    env: dict[str, str] = field(default_factory=dict)
    outputs: tuple[Path, ...] = ()
    external: bool = False  # outputs live outside the work dir (only ever written, never overwritten)
    prune_always: tuple[Path, ...] = ()
    prune_if_short: tuple[Path, ...] = ()


def safe_name(text: str) -> str:
    return SAFE_NAME.sub("-", text).strip("-.") or "gemma4-31b"


def default_name(model: Path, preset: str) -> str:
    return safe_name(f"{model.resolve().name}-{preset}")


def format_command(argv: list[str]) -> str:
    return subprocess.list2cmdline(argv) if os.name == "nt" else shlex.join(argv)


def sha256_file(path: Path) -> str:
    digest = hashlib.sha256()
    with path.open("rb") as stream:
        while chunk := stream.read(8 * 1024 * 1024):
            digest.update(chunk)
    return digest.hexdigest()


def gb(value: float) -> str:
    return f"{value:g} GB"


# ---------------------------------------------------------------- plan


def q4_convert_flags(cfg: BuildConfig, checkpoint: Path | None, imatrix: Path | None) -> list[str]:
    """Recipe flags of `gemma4_q4 convert` for the preset (always the W4A8 route `q4_g32`)."""
    preset = cfg.preset
    flags = ["--weights", "q4_g32"]
    if preset.method == "gptq":
        flags += ["--gptq-source", str(checkpoint)]
        if preset.native_groups:
            flags.append("--native-groups")
    elif preset.method == "rtn":
        flags += ["--scale-search", "weighted", "--imatrix", str(imatrix)]
        if preset.scale_bits:
            flags += ["--scale-bits", str(preset.scale_bits)]
        elif preset.group_size != 32:
            flags += ["--group-size", str(preset.group_size)]
        if preset.native_groups:
            flags.append("--native-groups")
    return flags


def convert_argv(
    cfg: BuildConfig, out: Path, *, scoring: bool, checkpoint: Path | None, imatrix: Path | None
) -> list[str]:
    """`gemma4_q4 convert` command; the scoring twin is always text-only and without MTP."""
    argv = [cfg.python, "-m", "tools.convert.gemma4_q4", "convert", "--model", str(cfg.model)]
    argv += q4_convert_flags(cfg, checkpoint, imatrix)
    if scoring or not cfg.with_vision:
        argv.append("--text-only")
    if not scoring and cfg.assistant is not None:
        argv += ["--mtp-assistant", str(cfg.assistant)]
    else:
        argv.append("--no-mtp")
    argv += ["--name", cfg.name, "--out", str(out)]
    return argv


def build_plan(cfg: BuildConfig) -> list[Step]:
    """The ordered steps with their exact commands. Pure: touches no file."""
    preset = cfg.preset
    minutes = preset.minutes
    templated = cfg.work("calibration", "templated.txt")
    source = cfg.calibration_text or cfg.work("calibration", "source.txt")
    tokenizer = cfg.model / "tokenizer.json"
    checkpoint = cfg.work("gptq")
    tree = cfg.work("text60")
    gguf = cfg.work("model-q8_0.gguf")
    imatrix = cfg.work("model.imatrix.gguf")
    steps: list[Step] = []

    if preset.method != "plain":
        if cfg.calibration_text is None:
            steps.append(Step(
                "calibration-source", f"Download the pinned public English calibration text ({CALIBRATION_REPO})",
                minutes["calibration-source"], call=fetch_calibration, outputs=(source,),
                note=f"{CALIBRATION_URL} (sha256 {CALIBRATION_PARQUET_SHA256[:12]}...) exported to {source}",
            ))
        steps.append(Step(
            "calibration-render", f"Render {CALIBRATION_CHUNKS} chat-prefixed chunks of {CALIBRATION_CONTEXT} tokens",
            minutes["calibration-render"],
            [cfg.python, "-m", "tools.convert.gemma4_q4", "calibration-text", "--tokenizer", str(tokenizer),
             "--source", str(source), "--prefix-ids", CHAT_PREFIX_IDS, "--chunks", str(CALIBRATION_CHUNKS),
             "--ctx-size", str(CALIBRATION_CONTEXT), "--out", str(templated)],
            outputs=(templated, templated.with_suffix(".json")),
        ))
    if preset.method == "gptq":
        gpy = str(cfg.gptq_python)
        gptq_dir = FORK_ROOT / "tools" / "gptq"
        calib = cfg.work("calib.pt")
        offload = cfg.work("offload")
        steps += [
            Step("calibration-tokens", "Tokenize the calibration text for GPTQ", minutes["calibration-tokens"],
                 [gpy, str(gptq_dir / "make_calib.py"), "--text", str(templated), "--tokenizer", str(tokenizer),
                  "--out", str(calib)], outputs=(calib,)),
            Step("text-tree", "Write the text-only 60-layer tree GPTQ loads (about 58 GB)", minutes["text-tree"],
                 [gpy, str(gptq_dir / "make_text_tree.py"), "--model", str(cfg.model), "--out", str(tree)],
                 outputs=(tree,)),
            Step("gptq", f"GPTQ, group {preset.group_size}, imatrix_mse observer (the long step)", minutes["gptq"],
                 [gpy, str(gptq_dir / "run_gptq.py"), "--tree", str(tree), "--calib", str(calib), "--out",
                  str(checkpoint), "--observer", "imatrix_mse", "--group-size", str(preset.group_size),
                  "--max-cpu-gb", "32", "--offload-dir", str(offload), "--peak-log",
                  str(cfg.work("gptq.peak.jsonl"))],
                 outputs=(checkpoint, offload, cfg.work("gptq.peak.jsonl")), prune_always=(offload,)),
            Step("gptq-check", "Check the GPTQ checkpoint is importable (4-bit codes, exact binary16 scales)",
                 minutes["gptq-check"],
                 [gpy, str(gptq_dir / "check_checkpoint.py"), "--gptq", str(checkpoint), "--tree", str(tree)],
                 prune_if_short=(tree,)),
        ]
    elif preset.method == "rtn":
        convert_hf = cfg.llama_cpp_dir / "convert_hf_to_gguf.py"
        steps += [
            Step("gguf", "Q8_0 GGUF of your model for statistics (llama.cpp, about 35 GB)", minutes["gguf"],
                 [cfg.llama_python, str(convert_hf), str(cfg.model), "--outtype", "q8_0", "--outfile", str(gguf)],
                 outputs=(gguf,)),
            Step("imatrix", "Collect importance statistics (llama-imatrix)", minutes["imatrix"],
                 [str(cfg.llama_imatrix), "-m", str(gguf), "-f", str(templated), "--parse-special", "--ctx-size",
                  str(CALIBRATION_CONTEXT), "--chunks", str(CALIBRATION_CHUNKS), "--gpu-layers", cfg.imatrix_gpu_layers,
                  "-o", str(imatrix)],
                 outputs=(imatrix,), prune_if_short=(gguf,)),
        ]
    steps.append(Step(
        "convert", f"Convert to .ninfer ({preset.id}: {preset.summary}; the converter verifies storage itself)",
        minutes["convert"],
        convert_argv(cfg, cfg.artifact, scoring=False, checkpoint=checkpoint, imatrix=imatrix),
        outputs=cfg.receipts, external=True,
    ))
    steps.append(Step("receipt-check", "Check the converter's receipt (status, size, sha256)", minutes["receipt-check"],
                      call=check_receipt))
    steps.append(Step("finalize", "Write the launcher, BUILD-SUMMARY.md and the build receipt", minutes["finalize"],
                      call=finalize, outputs=finalize_outputs(cfg), external=True))
    if cfg.score:
        steps += score_steps(cfg, checkpoint, imatrix)
    return steps


def finalize_outputs(cfg: BuildConfig) -> tuple[Path, ...]:
    return (
        cfg.out_dir / "BUILD-SUMMARY.md",
        cfg.out_dir / f"{cfg.name}.gemma4-build.json",
        cfg.out_dir / f"serve-{cfg.name}.cmd",
    )


def score_steps(cfg: BuildConfig, checkpoint: Path, imatrix: Path) -> list[Step]:
    """Section 6 of docs/gemma4-31b-conversion-technical.md: FP8-row reference, English corpus, then W4A8 exact
    scoring of a no-MTP text-only twin."""
    root = cfg.work("score")
    corpus, reference, nklref = root / "corpus", root / "ref-fp8row.ninfer", root / "ref.nklref"
    candidate, run = root / "candidate.ninfer", root / "run"
    manifest = corpus / "manifest.json"
    exe = str(cfg.perplexity_exe)
    common = ["--corpus", str(manifest), "--context", "512", "--stride", "256", "--prefill-chunk", "128",
              "--prefix-ids", CHAT_PREFIX_IDS]
    minutes = SCORE_MINUTES
    twin = candidate
    return [
        Step("score-corpus", "Build the English KL corpus from the bundled corpus (about 14 GB of cache)",
             minutes["score-corpus"],
             [cfg.python, "-m", "tools.bench.kv_eval.kl_corpus", "--source",
              str(FORK_ROOT / "eval" / "corpora" / "perplexity-1m" / "manifest.json"), "--out", str(corpus),
              "--chars", "chinese_reference=0"], outputs=(corpus,)),
        Step("score-reference", "Convert the near-lossless FP8-row reference (31 GB; the slow scoring step)",
             minutes["score-reference"],
             [cfg.python, "-m", "tools.convert.gemma4_q4", "convert", "--model", str(cfg.model), "--text-only",
              "--no-mtp", "--weights", "fp8_row", "--out", str(reference)],
             outputs=(reference, Path(str(reference) + ".build.json"), Path(str(reference) + ".conversion.json"))),
        Step("score-reference-write", "Score the reference once and keep its logits for pairing", minutes["score-reference-write"],
             [exe, str(reference)] + common + ["--headroom-mib", "128", "--kl-reference-write", str(nklref)],
             outputs=(nklref,), prune_if_short=(reference,)),
        Step("score-candidate", "Convert a no-MTP text-only twin of your recipe for scoring", minutes["score-candidate"],
             convert_argv(cfg, twin, scoring=True, checkpoint=checkpoint, imatrix=imatrix),
             outputs=(candidate, Path(str(candidate) + ".build.json"), Path(str(candidate) + ".conversion.json"))),
        Step("score-run", "Paired KL against the reference (W4A8 exact, NINFER_Q4_EXACT=1)", minutes["score-run"],
             [exe, str(candidate)] + common + ["--kl-reference", str(nklref), "--output", str(run)],
             env={"NINFER_Q4_EXACT": "1"}, outputs=(run,)),
        Step("score-report", "Record the score in the build receipt and BUILD-SUMMARY.md", minutes["score-report"],
             call=score_report),
    ]


def plan_minutes(steps: list[Step]) -> float:
    return sum(step.minutes for step in steps)


def describe_plan(cfg: BuildConfig, steps: list[Step]) -> list[str]:
    """Human-readable plan: one block per step with its time estimate and exact command."""
    preset = cfg.preset
    lines = [
        f"Preset      {preset.id}: {preset.summary} ({preset.size_class}; {gb(preset.file_gb)} with MTP; "
        f"KL {preset.kl:.4f}, lower is better)",
        f"            {preset.meaning}",
        f"Model       {cfg.model}",
        f"MTP         {cfg.assistant if cfg.assistant else 'none (--no-mtp)'}",
        f"Vision      {'kept (--with-vision)' if cfg.with_vision else 'left out (text only)'}",
        f"Output      {cfg.artifact}",
        f"Work dir    {cfg.work_dir}",
        f"Estimate    about {plan_minutes(steps):.0f} min in total (typical RTX 5090 + NVMe; your times vary)",
        "",
    ]
    for index, step in enumerate(steps, 1):
        lines.append(f"{index:>2}. {step.id:<22} ~{step.minutes:g} min  {step.title}")
        if step.argv:
            lines.append(("    " + (" ".join(f"{k}={v}" for k, v in step.env.items()) + " " if step.env else ""))
                         + format_command(step.argv))
        elif step.note:
            lines.append(f"    {step.note}")
    return lines


# ---------------------------------------------------------------- calibration text


def export_author_text(parquet: Path, out: Path, *, expected_sha256: str | None = CALIBRATION_TEXT_SHA256) -> str:
    """Parquet `content` column -> the author's calibration text file; returns its sha256."""
    try:
        import pyarrow.parquet as parquet_reader
    except ImportError as error:
        raise RuntimeError(
            f"{sys.executable} needs pyarrow to read the calibration corpus: {sys.executable} -m pip install pyarrow "
            "(or pass --calibration-text FILE)"
        ) from error
    rows = parquet_reader.read_table(parquet, columns=["content"]).column("content").to_pylist()
    text = "\n".join(rows).encode("utf-8").decode("cp437")
    data = ("\ufeff" + text.replace("\r\n", "\n").replace("\n", "\r\n") + "\r\n").encode("utf-8")
    digest = hashlib.sha256(data).hexdigest()
    if expected_sha256 is not None and digest != expected_sha256:
        raise RuntimeError(
            f"exported calibration text has sha256 {digest}, expected {expected_sha256}; pass --calibration-text FILE "
            "to use your own text"
        )
    part = out.with_name(out.name + ".part")
    part.write_bytes(data)
    os.replace(part, out)
    return digest


def download_pinned(url: str, out: Path, sha256: str, log: Callable[[str], None]) -> None:
    """Download `url` to `out`, refusing any size or hash surprise."""
    part = out.with_name(out.name + ".part")
    digest = hashlib.sha256()
    try:
        request = urllib.request.Request(url, headers={"User-Agent": "ninfer-spo-gemma4-build"})
        with urllib.request.urlopen(request, timeout=60) as response, part.open("wb") as stream:
            while chunk := response.read(1 << 20):
                digest.update(chunk)
                stream.write(chunk)
    except OSError as error:
        part.unlink(missing_ok=True)
        raise RuntimeError(
            f"download of {url} failed: {error}. Fix the connection and rerun (the build resumes), or pass "
            "--calibration-text FILE with public English text"
        ) from error
    if digest.hexdigest() != sha256:
        part.unlink(missing_ok=True)
        raise RuntimeError(f"{url} has sha256 {digest.hexdigest()}, expected {sha256}; refusing the download")
    os.replace(part, out)
    log(f"downloaded {out.name}: {out.stat().st_size} bytes, sha256 {sha256}")


def fetch_calibration(builder: "Builder") -> None:
    cfg = builder.cfg
    folder = cfg.work("calibration")
    folder.mkdir(parents=True, exist_ok=True)
    parquet = folder / CALIBRATION_FILE
    if not parquet.exists():
        builder.log(f"downloading {CALIBRATION_URL}")
        download_pinned(CALIBRATION_URL, parquet, CALIBRATION_PARQUET_SHA256, builder.log)
    digest = export_author_text(parquet, folder / "source.txt")
    builder.log(f"exported calibration text, sha256 {digest}")
    parquet.unlink(missing_ok=True)


# ---------------------------------------------------------------- receipts


def read_json(path: Path) -> dict:
    return json.loads(path.read_text(encoding="utf-8"))


def write_json(path: Path, data: dict) -> None:
    part = path.with_name(path.name + ".part")
    part.write_text(json.dumps(data, indent=2, ensure_ascii=False) + "\n", encoding="utf-8")
    os.replace(part, path)


def check_receipt(builder: "Builder") -> None:
    """The converter verifies storage before it returns; confirm its receipt says so for the file on disk."""
    cfg = builder.cfg
    receipt_path = Path(str(cfg.artifact) + ".build.json")
    if not receipt_path.is_file():
        raise RuntimeError(f"converter receipt missing: {receipt_path}")
    receipt = read_json(receipt_path)
    status = str(receipt.get("status", ""))
    if not status.startswith("storage-verified"):
        raise RuntimeError(f"converter receipt status is {status!r}: {receipt.get('error', 'no error recorded')}")
    size = cfg.artifact.stat().st_size
    if receipt["artifact"]["file_bytes"] != size:
        raise RuntimeError(f"{cfg.artifact} is {size} bytes, its receipt says {receipt['artifact']['file_bytes']}")
    if not receipt["artifact"].get("file_sha256", {}).get(cfg.artifact.name):
        raise RuntimeError("converter receipt has no sha256 for the artifact")
    builder.log(f"receipt ok: {status}; {size} bytes; revision {receipt.get('revision')}")


def render_summary(info: dict) -> str:
    """BUILD-SUMMARY.md text from the facts `build_info` collected."""
    p = info["preset"]
    steps = "\n".join(f"| {s['id']} | {s['status']} | {s['seconds']:.0f} |" for s in info["steps"])
    parts = [
        f"# {info['name']}",
        "",
        f"Built by `python -m tools.convert.gemma4_build` (preset `{p['id']}`).",
        "",
        "## What you built",
        "",
        f"- Preset: **{p['id']}**: {p['summary']} ({p['size_class']} file).",
        f"- In plain words: {p['meaning']}",
        f"- Weights: W4A8 (4-bit weights, FP8 activations while reading the prompt); "
        f"{'with the MTP draft assistant (speculative decoding)' if info['mtp'] else 'no MTP assistant'}; "
        f"{'with the vision tower' if info['vision'] else 'text only'}.",
        f"- Measured on the author's model (one fine-tune, English, text only, RTX 5090): mean KL {p['kl']:.4f} from "
        "the near-lossless reference (lower is better). A different model can move this number.",
        "",
        "## Files",
        "",
        f"- Artifact: `{info['artifact']}`",
        f"- Size: {info['file_bytes']:,} bytes ({info['file_bytes'] / 1e9:.2f} GB)",
        f"- sha256: `{info['sha256']}`",
        f"- Converter receipt: `{info['artifact']}.build.json`",
        f"- Launcher: `{info['launcher']}`" if info["launcher"] else "- Launcher: not generated (--no-launcher)",
        "",
        "## Serve it",
        "",
        "```bat",
        info["serve_command"] if info["serve_command"] else "REM no launcher; see docs/serving.md",
        "```",
        "",
        "Check the real KV capacity in the server's startup log: the model list can overstate an auto-sized pool. "
        f"`/v1/models` reports `{info['alias']}`; "
        + (
            "OpenAI-style requests may send any model name (`--model-match any`). "
            if "--model-match any" in (info["serve_command"] or "")
            else "OpenAI-style requests must send that exact model name. "
        )
        + "No API key is required.",
        "",
        "## Versions",
        "",
        f"- ninfer.spo revision: `{info['revision']}`",
        f"- Python: {info['python']}",
    ]
    parts += [f"- {k}: {v}" for k, v in info["tools"].items()]
    parts += ["", "## Steps", "", "| step | status | seconds |", "|---|---|---|", steps]
    if info.get("score"):
        s = info["score"]
        parts += [
            "", "## Quality check (--score)", "",
            f"- Mean KL vs FP8-row reference: {s['mean_kl']:.4f}; delta NLL {s['mean_delta_nll']:+.3f}; "
            f"top-1 disagreement {s['top1_disagreement']:.4f}; perplexity {s['perplexity']:.3f}",
            "- Instrument: 47 windows of 512 tokens (English subset), W4A8 exact, no MTP, text only.",
        ]
    return "\n".join(parts) + "\n"


def build_info(builder: "Builder") -> dict:
    cfg, settings = builder.cfg, builder.serve
    receipt = read_json(Path(str(cfg.artifact) + ".build.json"))
    launcher_path = cfg.out_dir / f"serve-{cfg.name}.cmd"
    alias = settings.alias or launcher_tools.default_alias(settings.context)
    info_artifact = builder.read_artifact_info()
    steps = [
        {"id": step_id, "status": rec["status"], "seconds": rec.get("seconds", 0.0)}
        for step_id, rec in builder.state["steps"].items()
        if rec["status"] == "done"
    ]
    server = builder.server_exe
    serve = None
    if settings.launcher and server is not None:
        serve = format_command(
            launcher_tools.serve_argv(
                server, cfg.artifact, host=settings.host, port=settings.port, alias=alias, context=settings.context,
                kv_dtype=settings.kv_dtype, mtp=info_artifact.mtp, vision=info_artifact.vision,
                model_match=settings.model_match,
            )
        )
    return {
        "name": cfg.name,
        "preset": {k: getattr(cfg.preset, k) for k in ("id", "summary", "meaning", "size_class", "kl", "method")},
        "mtp": info_artifact.mtp,
        "vision": info_artifact.vision,
        "artifact": str(cfg.artifact),
        "file_bytes": receipt["artifact"]["file_bytes"],
        "sha256": receipt["artifact"]["file_sha256"][cfg.artifact.name],
        "launcher": str(launcher_path) if settings.launcher and server is not None else None,
        "serve_command": serve,
        "alias": alias,
        "revision": receipt.get("revision"),
        "python": sys.version.split()[0],
        "tools": builder.tool_versions,
        "steps": steps,
        "recipe": receipt.get("recipe"),
        "converter_seconds": receipt.get("seconds"),
        "score": builder.score,
    }


def finalize(builder: "Builder") -> None:
    cfg, settings = builder.cfg, builder.serve
    cfg.out_dir.mkdir(parents=True, exist_ok=True)
    if settings.launcher and builder.server_exe is not None:
        launcher_tools.write_launcher(
            cfg.out_dir / f"serve-{cfg.name}.cmd", cfg.artifact, builder.server_exe, host=settings.host,
            port=settings.port, alias=settings.alias, context=settings.context, kv_dtype=settings.kv_dtype,
            model_match=settings.model_match,
            cuda_bin=settings.cuda_bin, info=builder.read_artifact_info(), overwrite=True,
        )
    write_summary(builder)


def write_summary(builder: "Builder") -> None:
    info = build_info(builder)
    cfg = builder.cfg
    (cfg.out_dir / "BUILD-SUMMARY.md").write_text(render_summary(info), encoding="utf-8")
    write_json(cfg.out_dir / f"{cfg.name}.gemma4-build.json", {"schema": BUILD_SCHEMA, **info})
    builder.log("wrote BUILD-SUMMARY.md and the build receipt")


def score_report(builder: "Builder") -> None:
    report = read_json(builder.cfg.work("score", "run", "report.json"))
    overall = report["kl"]["statistics"]["overall"]
    builder.score = {
        "mean_kl": overall["mean_kl"],
        "mean_delta_nll": overall["mean_delta_nll"],
        "top1_disagreement": overall["top1_disagreement"],
        "perplexity": report["overall"]["perplexity"],
    }
    write_summary(builder)


# ---------------------------------------------------------------- state and runner


def popen_argv(argv: list[str]) -> list[str]:
    """Batch files need cmd /c on Windows; executables are started directly."""
    if os.name == "nt" and Path(argv[0]).suffix.lower() in (".cmd", ".bat"):
        return ["cmd", "/c", *argv]
    return list(argv)


def tail_line(path: Path) -> str:
    try:
        with path.open("rb") as stream:
            stream.seek(0, os.SEEK_END)
            stream.seek(max(0, stream.tell() - 4096))
            text = stream.read().decode("utf-8", errors="replace")
    except OSError:
        return ""
    lines = [line.strip() for line in re.split(r"[\r\n]+", text) if line.strip()]
    return lines[-1] if lines else ""


def run_child(argv: list[str], log_path: Path, env: dict[str, str], cwd: Path, status: Callable[[str], None]) -> int:
    """Run `argv` with stdout+stderr in `log_path`; call `status(last log line)` every few seconds."""
    child_env = {**os.environ, "PYTHONUTF8": "1", "PYTHONIOENCODING": "utf-8", "PYTHONUNBUFFERED": "1", **env}
    with log_path.open("ab") as log:
        log.write(f"$ {format_command(argv)}\n".encode("utf-8"))
        log.flush()
        process = subprocess.Popen(popen_argv(argv), cwd=cwd, env=child_env, stdout=log, stderr=subprocess.STDOUT,
                                   stdin=subprocess.DEVNULL)
        try:
            while True:
                try:
                    return process.wait(timeout=3)
                except subprocess.TimeoutExpired:
                    status(tail_line(log_path))
        except BaseException:
            process.terminate()
            try:
                process.wait(timeout=30)
            except subprocess.TimeoutExpired:
                process.kill()
            raise


def remove_path(path: Path) -> None:
    if path.is_dir() and not path.is_symlink():
        shutil.rmtree(path, ignore_errors=False)
    elif path.exists() or path.is_symlink():
        path.unlink()


def device_of(path: Path) -> int:
    probe = path
    while not probe.exists() and probe.parent != probe:
        probe = probe.parent
    return os.stat(probe).st_dev


class BuildError(RuntimeError):
    pass


def fingerprint_of(identity: dict) -> str:
    return hashlib.sha256(json.dumps(identity, sort_keys=True).encode()).hexdigest()


def _hash_or_none(path: Path) -> str | None:
    return sha256_file(path) if path.is_file() else None


def build_identity(cfg: BuildConfig) -> dict:
    """Facts that decide the artifact; a work dir only resumes under the same identity. Reads inputs, writes nothing."""
    model, files = cfg.model, {}
    index = model / "model.safetensors.index.json"
    shards = sorted(set(read_json(index)["weight_map"].values())) if index.is_file() else ["model.safetensors"]
    for name in ("config.json", "model.safetensors.index.json", "tokenizer.json"):
        files[name] = _hash_or_none(model / name)
    files["shards"] = [[name, (model / name).stat().st_size if (model / name).is_file() else None] for name in shards]
    assistant = None
    if cfg.assistant is not None:
        assistant = {name: _hash_or_none(cfg.assistant / name) for name in ("config.json", "model.safetensors.index.json")}
        assistant["weights"] = sorted(
            [path.name, path.stat().st_size] for path in cfg.assistant.glob("*.safetensors")
        )
    if cfg.preset.method == "plain":
        calibration = None
    elif cfg.calibration_text is not None:
        calibration = {"file": str(cfg.calibration_text.resolve()), "sha256": _hash_or_none(cfg.calibration_text)}
    else:
        calibration = {"source": f"{CALIBRATION_REPO}@{CALIBRATION_REVISION}", "text_sha256": CALIBRATION_TEXT_SHA256}
    return {
        "preset": cfg.preset.id,
        "model": str(model.resolve()),
        "model_files": files,
        "assistant": str(cfg.assistant.resolve()) if cfg.assistant is not None else None,
        "assistant_files": assistant,
        "with_vision": cfg.with_vision,
        "name": cfg.name,
        "out_dir": str(cfg.out_dir.resolve()),
        "calibration": calibration,
    }


def load_state(work: Path, fingerprint: str, identity: dict) -> dict | None:
    """The saved state of a work dir that matches, None for a missing or empty dir; refuses anything else."""
    if not work.exists() or not any(work.iterdir()):
        return None
    path = work / "build-state.json"
    if not path.is_file():
        raise BuildError(
            f"{work} is not empty and has no build-state.json, so it is not a gemma4_build work dir. "
            "Choose another --work-dir or empty this one yourself."
        )
    state = read_json(path)
    if state.get("fingerprint") != fingerprint:
        saved = state.get("identity", {})
        changed = sorted(key for key in set(identity) | set(saved) if identity.get(key) != saved.get(key))
        raise BuildError(
            f"{work} was created with different arguments ({', '.join(changed) or 'identity'}). Rerun with the "
            "original arguments to resume, pick a new --work-dir, or delete this one."
        )
    return state


class Builder:
    """Runs a plan in order, skipping steps whose done-marker matches, and records every step in the work dir."""

    def __init__(
        self,
        cfg: BuildConfig,
        steps: list[Step],
        identity: dict,
        serve: ServeSettings,
        *,
        server_exe: Path | None = None,
        tool_versions: dict[str, str] | None = None,
        disk_free: Callable[[Path], int] | None = None,
        runner: Callable[..., int] = run_child,
        out: Callable[[str], None] = print,
        artifact_info: launcher_tools.ArtifactInfo | None = None,
    ):
        self.cfg, self.steps, self.identity, self.serve = cfg, steps, identity, serve
        self.server_exe = server_exe
        self.tool_versions = tool_versions or {}
        self.disk_free = disk_free or (lambda path: shutil.disk_usage(path).free)
        self.runner, self.out = runner, out
        self.artifact_info = artifact_info
        self.fingerprint = fingerprint_of(identity)
        self.state: dict = {}
        self.score: dict | None = None
        self._log_path: Path | None = None
        self._last_status = 0.0

    # -- state
    @property
    def state_path(self) -> Path:
        return self.cfg.work("build-state.json")

    def save(self) -> None:
        write_json(self.state_path, self.state)

    def read_artifact_info(self) -> launcher_tools.ArtifactInfo:
        if self.artifact_info is None:
            self.artifact_info = launcher_tools.artifact_info(self.cfg.artifact)
        return self.artifact_info

    def open_work_dir(self) -> None:
        """Create or resume the work dir; refuse one that is foreign or was made with other arguments."""
        state = load_state(self.cfg.work_dir, self.fingerprint, self.identity)
        if state is not None:
            self.state = state
            return
        work = self.cfg.work_dir
        work.mkdir(parents=True, exist_ok=True)
        (work / "logs").mkdir(exist_ok=True)
        self.state = {"schema": STATE_SCHEMA, "fingerprint": self.fingerprint, "identity": self.identity,
                      "created": time.strftime("%Y-%m-%dT%H:%M:%S"), "steps": {}}
        self.save()

    def check_outputs_free(self) -> None:
        """Never overwrite: an external output may pre-exist only if this work dir already started its step."""
        for step in self.steps:
            if not step.external or step.id in self.state["steps"]:
                continue
            for path in step.outputs:
                if path.exists():
                    raise BuildError(
                        f"Output already exists: {path}. This build never overwrites; choose another --name or "
                        "--out-dir, or move the file away."
                    )

    def step_key(self, step: Step) -> str:
        args = step.argv[1:] if step.argv else [step.id]
        return hashlib.sha256(json.dumps([self.fingerprint, step.id, args, step.env]).encode()).hexdigest()

    # -- output
    def log(self, message: str) -> None:
        if self._log_path is not None:
            with self._log_path.open("a", encoding="utf-8") as stream:
                stream.write(message + "\n")

    def status(self, index: int, step: Step, started: float, last: str) -> None:
        now = time.time()
        if sys.stdout.isatty():
            line = f"[{index}/{len(self.steps)}] {step.id} {int(now - started) // 60}:{int(now - started) % 60:02d} {last}"
            sys.stdout.write("\r" + line[:110].ljust(110))
            sys.stdout.flush()
        elif now - self._last_status >= 60:
            self._last_status = now
            self.out(f"[{index}/{len(self.steps)}] {step.id} running {int(now - started) // 60} min: {last[:100]}")

    # -- pruning
    def disk_short(self) -> bool:
        cfg = self.cfg
        need = 10.0 * 2**30
        if device_of(cfg.out_dir) == device_of(cfg.work_dir):
            need += cfg.preset.file_gb * 1e9
        if cfg.score:
            need += SCORE_EXTRA_GB * 1e9
        return self.disk_free(cfg.work_dir) < need

    def prune(self, step: Step) -> None:
        targets = list(step.prune_always)
        if step.prune_if_short and self.disk_short():
            targets += step.prune_if_short
        for path in targets:
            if path.exists():
                remove_path(path)
                self.out(f"    removed {path} (no longer needed{'; disk is short' if path in step.prune_if_short else ''})")
                self.state["steps"][step.id].setdefault("pruned", []).append(str(path))

    # -- run
    def finished(self, step: Step) -> bool:
        record = self.state["steps"].get(step.id)
        if not record or record.get("status") != "done" or record.get("key") != self.step_key(step):
            return False
        pruned = set(record.get("pruned", []))
        return all(path.exists() or str(path) in pruned or self.pruned_later(path) for path in step.outputs)

    def pruned_later(self, path: Path) -> bool:
        return any(str(path) in rec.get("pruned", []) for rec in self.state["steps"].values())

    def run_step(self, index: int, step: Step) -> None:
        total = len(self.steps)
        if self.finished(step):
            self.out(f"[{index}/{total}] {step.id}: already done, skipped")
            return
        for path in step.outputs:
            if path.exists() and (not step.external or step.id in self.state["steps"]):
                remove_path(path)
        self._log_path = self.cfg.work("logs", f"{index:02d}-{step.id}.log")
        started = time.time()
        self.out(f"[{index}/{total}] {step.id}: {step.title} (about {step.minutes:g} min); log {self._log_path}")
        self.state["steps"][step.id] = {"status": "running", "key": self.step_key(step), "log": str(self._log_path),
                                         "started": time.strftime("%Y-%m-%dT%H:%M:%S")}
        self.save()
        try:
            if step.call is not None:
                step.call(self)
                code = 0
            else:
                code = self.runner(step.argv, self._log_path, step.env, FORK_ROOT,
                                   lambda last: self.status(index, step, started, last))
        except BaseException as error:
            self.finish_failed(step, started, str(error))
            raise
        if code != 0:
            self.finish_failed(step, started, f"exit code {code}")
            raise BuildError(
                f"step {step.id} failed (exit code {code}). Log: {self._log_path}\n    last line: {tail_line(self._log_path)}\n"
                "    Fix the cause and rerun the same command: finished steps are skipped."
            )
        record = self.state["steps"][step.id]
        record.update(status="done", seconds=time.time() - started, finished=time.strftime("%Y-%m-%dT%H:%M:%S"))
        self.save()
        if sys.stdout.isatty():
            sys.stdout.write("\r" + " " * 110 + "\r")
        self.out(f"[{index}/{total}] {step.id}: done in {record['seconds'] / 60:.1f} min")
        self.prune(step)
        self.save()

    def finish_failed(self, step: Step, started: float, reason: str) -> None:
        self.state["steps"][step.id].update(status="failed", seconds=time.time() - started, error=reason)
        self.save()

    def run(self) -> None:
        self.open_work_dir()
        self.check_outputs_free()
        self.cfg.out_dir.mkdir(parents=True, exist_ok=True)
        for index, step in enumerate(self.steps, 1):
            try:
                self.run_step(index, step)
            except Exception as error:
                message = str(error) if isinstance(error, BuildError) else (
                    f"step {step.id} failed: {error}\n    Log: {self._log_path}"
                )
                if step.id.startswith("score-"):
                    message = (
                        f"The build itself is complete and usable ({self.cfg.artifact}); only the quality check "
                        f"failed.\n    {message}"
                    )
                raise BuildError(message) from error

    def cleanup(self) -> bool:
        """Delete this build's own work dir after success; returns whether it did."""
        work = self.cfg.work_dir.resolve()
        protected = [self.cfg.out_dir.resolve(), self.cfg.model.resolve(), FORK_ROOT.resolve()]
        if self.cfg.assistant:
            protected.append(self.cfg.assistant.resolve())
        if any(work == item or work in item.parents for item in protected):
            raise BuildError(f"refusing to delete {work}: it contains the output, a source or the checkout")
        if self.cfg.keep_work or not self.state_path.is_file():
            return False
        shutil.rmtree(work)
        return True


if __name__ == "__main__":
    from .gemma4_build_cli import main

    raise SystemExit(main())
