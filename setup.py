#!/usr/bin/env python3
# SPDX-FileCopyrightText: 2026 Peasant Smith and the Project Maya contributors
# SPDX-FileCopyrightText: 2026 Niko1221 and the Strata contributors
# SPDX-FileCopyrightText: 2026 MistVVK and the XeStrata contributors
# SPDX-License-Identifier: LGPL-3.0-or-later AND MIT
"""Strata setup and start (Linux; Intel GPUs, RDNA2 or later AMD GPUs, NVIDIA GPUs).

    ./setup.sh installs Python if needed and runs this file

The first time it asks four questions - which model (the original Qwen3.8-Flash-Next or the Swift 1.5 fine-tune),
which size, how much context, and whether the model should also read images - then installs everything and starts
the model on http://127.0.0.1:8095 (OpenAI- and Anthropic-compatible API; a small page there shows that it runs).
Every later start skips straight to running the model: nothing that is already downloaded, installed or prepared is
done again.

What the first run does (each step is skipped when it is already done):

  1. checks your PC: the GPU (Intel, AMD; NVIDIA in the contrib build, the default) and its driver, RAM, CPU, free
     disk space
  2. asks the questions
  3. installs the Python packages it needs into .venv (numpy, jinja2, ...)
  4. compiles the Strata engine for the GPU with a SYCL compiler (see docs/XE.md) with its image generator, and the
     image encoder when images are wanted (on the CPU, and on the GPU through Vulkan)
  5. downloads the model from Hugging Face (resumable), and the vision encoder if you want images
  6. prepares the model for Strata and fetches the MTP draft layer (~5 GB, from the original Qwen checkpoint)
  7. writes run-<model>.sh and starts the model

Options: --family qwen|swift, --model Q2_0|IQ2_XS|IQ3_XXS|IQ3_S, --context 32768, --rope-scaling none|linear|yarn
(--rope-scale F; past the trained 262144 setup adds yarn and the factor final context / 262144),
--vision yes|no|gpu|cpu, --port 8095, --yes (recommended
answers, no questions), --setup (install another model / change settings instead of starting), --no-start,
--host 0.0.0.0 --api-key KEY (reach it from other devices on your network), --experimental-speed-projection on|off
(EXPERIMENTAL, off by default),
--models-dir DIR, --gguf-dir DIR (use GGUF files you already have), --check (only check this PC), --check-update
(whether a newer XeStrata release is out), --images qwen-image-turbo|qwen-image-base|...-uncensored|no (image
generation on XeStrata's image engine, POST /v1/images/generations: Qwen-Image-2.1-Turbo in 8 steps, or its base
model Qwen-Image-2.1 in 40; mage-flow-turbo|mage-flow|mage-flow-base[-uncensored]: Mage-Flow in 4, 20 or 30;
-uncensored: the text encoder with the refusal direction removed; --image-quant Q4_K_M|Q6_K|Q8_0 (Qwen-Image),
--image-dit-q8 auto|on|off and --image-dit-keep on|off (Mage-Flow), --image-ssd-offload on|off, --image-gpu-policy
auto|keep|shrink|unload).

Setup recommends, it never forces: the recommended answers are the defaults (--yes, or Enter), and a bigger choice
than it recommends - a longer context, a size it thinks will not fit - is kept, with what it risks.  With --yes, an
explicit flag (--model, --context) is the consent to a risk setup would otherwise stop at; --yes alone is not.
"""
from __future__ import annotations

import argparse
import calendar
import hashlib
import http.client
import importlib
import json
import math
import os
import platform
import re
import shutil
import site
import struct
import subprocess
import sys
import tempfile
import textwrap
import threading
import time
import urllib.error
import urllib.parse
import urllib.request
import zipfile
from pathlib import Path
from typing import Any, NoReturn

from serve import places, release_check

ROOT = Path(__file__).resolve().parent
WIN = places.WIN


# A deb or rpm package installs this folder read-only (/usr/share/xestrata) with a PACKAGED record (where the engine
# package puts the engine), and so does the Windows 7z.  Then nothing is compiled, the Python packages are the
# distribution's (or the 7z's), and what setup writes for a model (its config, the logs) goes to the user's folders
# (serve/places.py) instead of next to this file.
PACKAGED: dict[str, Any] | None = None
if (ROOT / "PACKAGED").is_file():
    PACKAGED = json.loads((ROOT / "PACKAGED").read_text(encoding="utf-8"))
CONF = places.user_dir("config") if PACKAGED else ROOT   # the model configs, xestrata-<model>.json
STATE = places.user_dir("state") if PACKAGED else ROOT    # the logs, and the engine's working folder
SETUP_CMD = ("xestrata-cli" if WIN else "xestrata") if PACKAGED else "./setup.sh"
# Every Hugging Face file comes from a fixed commit of its repository (the `sha` of
# https://huggingface.co/api/models/<repo> when it was pinned, upstream #214), so a checkout installs the same files
# on any day.  Every file has a fixed size and SHA-256 too (REPO_PINS); a revision the repository no longer has stops
# the download (download()), unless a tester sets STRATA_ALLOW_UNPINNED=1.
HF_REVISIONS = {
    "unsloth/DeepSeek-V4.1-Flash-1017-GGUF": "f924b94f19c1fea02c06a65c8475b0a45e2b88b1",
    "ISTA-DASLab/DeepSeek-V4.1-Flash-1017-GSQ-RCO-GGUF": "cb02422c900df489cea5833e8a92171224059b3c",
    "ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF": "ed59f92082b1e93c0e96d60a8b11aab089b52f09",        # 2026-09-29
    # 2026-10-07: the commit that adds Swift's IQ3_S (upstream e193161de)
    "ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF": "99bb8f7f95c7aa7b24a36a7786a4f657b30f5d3d",
    "ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-Coder-GGUF": "5348543e0147355ac9cbcb031184a3546350988e",  # 2026-09-29
    "unsloth/Qwen3.8-Flash-Next-GGUF": "38bb39ee97821de2c9009abb7e93950eec396e66",                   # 2026-09-30
    "ornith-ai/Ornith-1.5-35B-A3B-GGUF": "12393612fd4f730ff5aadc23e9b8f9648aa49ceb",                 # 2026-10-11
    "pfeifferj/Ornith-1.5-35B-A3B-GSQ-RCO-GGUF": "0bfdfe7f6c424de60481c26379c9d821469f75f1",         # 2026-10-11
    "llm-jp/llm-jp-4.1-32b-a3b-thinking-gguf": "044a4447c2da94b489484927355665b819eb3d4b",           # 2026-10-11
    "unsloth/Qwen3.6-35B-A3B-MTP-GGUF": "5bc3e238d916f48a861bac2f8a1990a0e9b7e98d",                  # 2026-10-12
    "unsloth/GLM-5.3-Flash-GGUF": "a38483c8cd5df544f53d70fb281afe97369d5ab6",                        # 2026-10-09
    "agentionai/Qwen3.8-Flash-Next-Gyro-GGUF": "1ada08422e404aca51ab9df665f089f34c419c6b",          # 2026-10-13
    "huihui-ai/Huihui-Qwen3.8-Flash-Next-abliterated-GGUF": "06a318de4011598a142ee54bcfec47c6921c958e",  # 2026-10-22
}


HF_DEFAULT = "https://huggingface.co"


def hf_endpoint() -> str:
    """#495: the Hugging Face host - HF_ENDPOINT as huggingface_hub reads it (a mirror, e.g. https://hf-mirror.com),
    else huggingface.co.  The pinned revisions and the SHA-256 checks are the same whichever host serves the files."""
    return (os.environ.get("HF_ENDPOINT") or "").strip().rstrip("/") or HF_DEFAULT


def hf(repo: str) -> str:
    """The download folder of a Hugging Face repository at its pinned revision."""
    return f"{hf_endpoint()}/{repo}/resolve/{HF_REVISIONS[repo]}/"


def hf_unpinned(url: str) -> str:
    """The same file at the repository's current revision (main)."""
    return re.sub(r"^(https?://[^/]+/.+?/resolve/)[0-9a-f]{40}/", r"\1main/", url, count=1)


_unpinned_said: list[int] = []


def allow_unpinned() -> bool:
    """STRATA_ALLOW_UNPINNED=1: a tester's opt-out (upstream e193161de).  A file whose pinned version is gone from
    Hugging Face is then taken from the repository's current files, without the SHA-256 check (nothing pins them).
    Off by default, announced when set."""
    on = (os.environ.get("STRATA_ALLOW_UNPINNED") or "").strip() == "1"
    if on and not _unpinned_said:
        _unpinned_said.append(1)
        warn("STRATA_ALLOW_UNPINNED=1: a model file whose pinned version is gone from Hugging Face is taken from its "
             "current files instead, and is NOT checked against a SHA-256. Unset it to get the checked files only")
    return on


def file_pin(url: str):
    """(bytes, sha256) pinned for the Hugging Face file `url` names (REPO_PINS), else None."""
    m = HF_FILE.match(url)
    if m is None:
        return None
    return REPO_PINS.get(m.group("repo"), {}).get(m.group("path").rsplit("/", 1)[-1])


# ModelScope (www.modelscope.cn) hosts every repository above under the same name, with the same file paths and
# sizes, and is reachable from mainland China where huggingface.co often is not.  It serves a repository's current
# files (no pinned revision), so a file from it is checked against the SHA-256 ModelScope publishes for it, and the
# MTP tensors against the pinned checkpoint's own hashes (tools/mtp_fetch.py).
# --source / STRATA_SOURCE: huggingface (what auto means), or modelscope: only when asked for (a different host
# serving current files, not our pinned revision: setup never switches to it by itself, it recommends it, #908).
MS_DEFAULT = "https://www.modelscope.cn"
SOURCES = ("auto", "modelscope", "huggingface")
HF_FILE = re.compile(r"^https?://[^/]+/(?P<repo>[^/]+/[^/]+)/resolve/[^/]+/(?P<path>.+)$")
_sources = {}                                      # model_source()'s answer per (STRATA_SOURCE, HF_ENDPOINT, host)
_ms_files = {}


def ms_endpoint() -> str:
    return (os.environ.get("MODELSCOPE_ENDPOINT") or "").strip().rstrip("/") or MS_DEFAULT


def reachable(url: str, timeout: float = 5.0) -> bool:
    """Whether `url` answers a HEAD request with success (2xx, after redirects) within `timeout` seconds."""
    try:
        urllib.request.urlopen(urllib.request.Request(url, method="HEAD", headers={"User-Agent": "strata-setup"}),
                               timeout=timeout).close()
        return True
    except OSError:                                    # HTTPError too: an error page is not the file
        return False


def model_source() -> str:
    """"modelscope" or "huggingface".  ModelScope only when --source modelscope / STRATA_SOURCE=modelscope asks for it;
    everything else (auto, a HF_ENDPOINT mirror chosen on purpose, #495) is Hugging Face.  Setup does not switch hosts
    by itself (#908): ModelScope serves a repository's current files, not our pinned revision."""
    want = (os.environ.get("STRATA_SOURCE") or "auto").strip().lower()
    key = (want, os.environ.get("HF_ENDPOINT") or "", ms_endpoint())
    if key not in _sources:
        _sources[key] = "modelscope" if want in ("ms", "modelscope") else "huggingface"
    return _sources[key]


def source_hint(url: str) -> str:
    """The recommendation that goes with a failed download from Hugging Face: ModelScope, by an explicit choice."""
    if "huggingface" in url or "hf-mirror" in url:
        return ("; if huggingface.co does not reach you (mainland China), the same files are on ModelScope: run setup "
                "with --source modelscope (docs/DETAILS.md)")
    return ""


def ms_file(url: str):
    """(repo, path) when `url` is a Hugging Face file of a repository setup knows (HF_REVISIONS), else None."""
    m = HF_FILE.match(url)
    if m is None or m.group("repo") not in HF_REVISIONS:
        return None
    return m.group("repo"), m.group("path")


def ms_url(repo: str, path: str) -> str:
    return f"{ms_endpoint()}/models/{repo}/resolve/master/{path}"


def ms_meta(repo: str, path: str):
    """(size, sha256) ModelScope publishes for a file, or None when it cannot be asked."""
    if repo not in _ms_files:
        try:
            api = f"{ms_endpoint()}/api/v1/models/{repo}/repo/files?Recursive=true"
            with urllib.request.urlopen(urllib.request.Request(api, headers={"User-Agent": "strata-setup"}),
                                        timeout=60) as r:
                files = json.loads(r.read())["Data"]["Files"]
            _ms_files[repo] = {f["Path"]: (int(f.get("Size") or 0), (f.get("Sha256") or "").lower()) for f in files}
        except (OSError, ValueError, KeyError, TypeError):
            return None
    return _ms_files[repo].get(path)


HF = hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF")
LLAMA_CPP_COMMIT = "3cf03257f219afbe7334045ff7c6a06ac68c627d"
LLAMA_CPP_ZIP = f"https://github.com/ggml-org/llama.cpp/archive/{LLAMA_CPP_COMMIT}.zip"
# #32: what the zip holds at that commit (tree_sha256: every file's path and SHA-256, in path order), checked before the
# source is used and compiled.  The zip's own bytes are not pinned: GitHub makes archives on request and does not
# promise the same compression; the files in it are the commit's.  A new LLAMA_CPP_COMMIT takes its own value:
# tree_sha256() of the zip unpacked with zipfile.
LLAMA_CPP_TREE_SHA256 = "87b1443f593e9b9159a61fa933e0fd4a2bc29e95f5ad6da422789d1c7cc515ae"

# KV bytes per context token and attention layer: 8-bit 1056, rotated 4-bit 576, hybrid K8V4 (8-bit K, 4-bit V) 816
KV_CELL_BYTES = {"q4_0": 576, "k8v4": 816}
PY_PACKAGES = ["numpy", "jinja2", "regex", "pyyaml", "tqdm", "requests", "pillow", "psutil"]
REQUIREMENTS = ROOT / "requirements.txt"   # the same packages and their dependencies, pinned (upstream #214)
# the build helpers, installed into .venv only when an engine or image-encoder build finds none (upstream a24253783)
BUILD_PACKAGES = ["cmake", "ninja"]
BUILD_REQUIREMENTS = ROOT / "requirements-build.txt"

# agentionai's Gyro files (Qwen3.8-Flash-Next with trellis-coded, Hadamard-rotated experts, TQ2_T / TQK6 / TQK7;
# upstream ba64156fd): one GGUF per size, the n-gram table inside it (hence the 58 / 92 GB downloads for 27.6 / 35 GB of
# memory).  The pack is xs2 (Hadamard-folded experts, hadamard.txt).  The sizes and SHA-256 are the Hub's LFS pointers
# of the revision pinned in HF_REVISIONS.  The model's license is Qwen's.
GYRO_FILES = {
    "Qwen3.8-Flash-Next-Gyro-S-TQ1_0.gguf":
        (58487015808, "c6ea1b08ca312f99095b27588ba35976b53f948268e7f91e7761926aa01d9c87"),
    "Qwen3.8-Flash-Next-Gyro-M-TQ2_0.gguf":
        (91965774272, "7aa36d15131d255179ab6c87fa9c9f81a0b541fc9e81e959d4c3e29eb20feb5f"),
}

MODELS: dict[str, dict[str, Any]] = {
    "Q2_0": {"about": "2-bit, the fastest", "download_gb": 66.4, "ram_gb": 48, "arena_gb": 34.0},
    "IQ2_XS": {"about": "2-bit i-quant, a little better quality, close in speed", "download_gb": 68.0, "ram_gb": 48,
               "arena_gb": 35.5, "families": ("qwen", "swift", "huihui-swift")},
    "IQ3_XXS": {"about": "3-bit i-quant, better quality, slower (more CPU work per token)", "download_gb": 75.8,
                "ram_gb": 60, "arena_gb": 42.9, "families": ("qwen", "swift", "huihui-swift")},
    # matches the full BF16 model on the published benchmarks; Swift 1.5 got an IQ3_S tier of its own (#1651)
    "IQ3_S": {"about": "3.5-bit i-quant, the best quality (matches the full model), the slowest; needs a 64 GB PC "
                       "with little else running", "download_gb": 83.6, "ram_gb": 62, "arena_gb": 50.3},
    # the Coder release: 256 of the 512 experts kept (the ones code, tools and vision use), IQ2_S-IQ4_XS like IQ3_S
    "IQ1_M": {"about": "the Coder's only size: half the experts, stored like IQ3_S (3.5 bits)", "download_gb": 58.4,
              "ram_gb": 32, "arena_gb": 23.4, "families": ("coder",)},
    # upstream #621: Unsloth's UD-IQ4_XS - IQ3_S gate/up experts with IQ4_NL (43 layers) or Q8_0 (5) downs, the dense
    # side as UD-Q4_K_XL's; three shards.  Its 59.5 GB of experts: a RAM budget of them, like UD-Q4_K_XL, but far
    # fewer read from the SSD on a 64 GB PC and none from ~80 GB of RAM.  Images: the same base model and encoder
    "UD-IQ4_XS": {"about": "~4-bit i-quant (Unsloth Dynamic), between IQ3_S and UD-Q4_K_XL in quality; on a PC with "
                           "less than ~80 GB of RAM part of its experts are read from the SSD",
                  "download_gb": 93.7, "ram_gb": 48, "arena_gb": 59.5, "families": ("unsloth", "huihui-unsloth"),
                  "budget": True, "shards": 3, "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00003.gguf", "vision": True},
    # EXPERIMENTAL (upstream's UD-Q4_K_XL support, 3889344 / 872af82): Unsloth's 4-bit file; its 77 GB of experts do not
    # fit a 64 GB PC, so the engine keeps a RAM budget of them (--resident-budget-gib, chosen below) and reads the rest
    # from the GGUF files in place
    "UD-Q4_K_XL": {"about": "4-bit (Unsloth Dynamic), EXPERIMENTAL: the best quality, but on a 64 GB PC part of its "
                            "experts come from the SSD while it answers, so it is slower than the 2-3-bit "
                            "models", "download_gb": 111.3, "ram_gb": 48, "arena_gb": 77.0,
                   "families": ("unsloth", "huihui-unsloth"), "budget": True, "experimental": True,
                   # upstream #967: images are allowed (the same base model and image encoder as UD-IQ4_XS), with a
                   # warning: reported working by hand upstream (#967, #971), not run with this file
                   "vision": True, "vision_untested": True},
    # upstream 0.1.44 (23250b5d): Unsloth's 5-, 6- and 8-bit files, six shards each; their experts are Q5_K, Q6_K and
    # Q8_0 gate/up with Q8_0 downs, which the expert kernels read.  Not run here (the user's decision of 2026-10-14:
    # offered as they are); on a PC with less RAM than "ram_gb" a RAM budget of the experts, the rest read from the SSD.
    "UD-Q5_K_XL": {"about": "5-bit (Unsloth Dynamic): Q5_K experts with Q8_0 downs, close to Q8_0 in quality; not "
                            "tested in XeStrata", "download_gb": 158.3, "ram_gb": 108, "arena_gb": 98.4,
                   "families": ("unsloth",), "budget": True, "experimental": True, "shards": 6,
                   "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00006.gguf", "vision": True, "vision_untested": True},
    "UD-Q6_K_XL": {"about": "6-bit (Unsloth Dynamic): Q6_K experts with Q8_0 downs; not tested in XeStrata",
                   "download_gb": 169.2, "ram_gb": 118, "arena_gb": 109.2, "families": ("unsloth",), "budget": True,
                   "experimental": True, "shards": 6, "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00006.gguf",
                   "vision": True, "vision_untested": True},
    "Q8_0": {"about": "8-bit, the reference quality (every expert Q8_0), for a 192 GB PC; not tested in XeStrata",
             "download_gb": 188.2, "ram_gb": 136, "arena_gb": 128.3, "families": ("unsloth", "huihui-unsloth"),
             "budget": True, "experimental": True, "shards": 6, "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00006.gguf",
             "vision": True, "vision_untested": True},
    # Gyro (agentionai): "ram_gb" is the memory the weights need in total, VRAM and RAM together ("mem_total"): Gyro-S
    # 27.6 GB, Gyro-M 35 GB (the rest of the download is the n-gram table, read from the SSD).  Neither is anyone's
    # default.  Images: the same mmproj as every Flash-Next model; strata-vision reads only the vocabulary and header of
    # the Gyro GGUF (tools/vision/gguf_meta.h), whose TQK6 / TQK7 tensors llama.cpp does not know.
    "Gyro-S": {"about": "the smallest option, for PCs with little memory (27.6 GB of VRAM + RAM together); lower "
                        "quality than the 2-3-bit sizes, and the 2-bit Q2_0 decodes faster",
               "download_gb": 58.5, "ram_gb": 27.6, "arena_gb": 25.8, "families": ("gyro",), "mem_total": True,
               "file": "Qwen3.8-Flash-Next-Gyro-S-TQ1_0.gguf", "shards": 1, "vision": True},
    "Gyro-M": {"about": "about IQ3_XXS quality with about 20% less GPU memory (35 GB of VRAM + RAM together)",
               "download_gb": 92.0, "ram_gb": 35.0, "arena_gb": 32.1, "families": ("gyro",), "mem_total": True,
               "file": "Qwen3.8-Flash-Next-Gyro-M-TQ2_0.gguf", "shards": 1, "vision": True},
}
# The experimental Unsloth file's four shards at the pinned revision: name -> (bytes, sha256), checked after the
# download (check_shards reads the other model files' directories; these are also hashed once).
UNSLOTH_SHARDS = {
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00001-of-00004.gguf":
        (10946624, "4448186216b3af4cc558bbce2c3213f01608f8f8b2e5267a9767971dd3ec8082"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00002-of-00004.gguf":
        (49859583136, "3f342f1c1580473f1ee94ddd5b28206e8c07a70fa1a366f59d1d6c922919a6c9"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00003-of-00004.gguf":
        (49376141504, "56758f40269cad5cd9b0d3d6fbae0f40f6d5be6de49e4ab392dbe83157d9cbd3"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00004-of-00004.gguf":
        (12087983520, "753bda48b98ba4f1636134a90a967de1b2d3908a236c026e464777342e53510a"),
}
# UD-IQ4_XS's three shards at the same revision (sizes and SHA-256: the Hub's LFS pointers; upstream #621)
UNSLOTH_IQ4_XS_SHARDS = {
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00001-of-00003.gguf":
        (10946624, "5ce89370720f8bf90890f439361282104c1aa1482d4013bb9a50923e758e71a4"),
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00002-of-00003.gguf":
        (49835229856, "577a38a2392b40ca2193cea502e1d92f60b8cd370675d308e0ec21885d9daaa7"),
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00003-of-00003.gguf":
        (43836407744, "d4634e6d84f0ebb0940be15c90d3790bf6464e3dea3a1cddc567dc0e83ad8833"),
}
# Unsloth's bigger files (upstream 0.1.44), offered without a run here (the user's decision of 2026-10-14)
UNSLOTH_BIG_SHARDS = {
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00001-of-00006.gguf":
        (10946618, "610922cdb1afe1094e95d7a3e86b12ee33317ebbf7320ac9344e21b6ae4bb69f"),
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00002-of-00006.gguf":
        (682434912, "494ca4ed3dbf97bc28da88af3890b8877b9032f909812d00c0526a9ca5e91d2e"),
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00003-of-00006.gguf":
        (54400261312, "34efd79a80a1ce540a517a5d56171924b66ce1c38b04c904f17ad6d8ef17cf20"),
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00004-of-00006.gguf":
        (49990245824, "9ee6bbe462e6830864382d629101490625b1c95afa15492b7ad550c7bed2dd13"),
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00005-of-00006.gguf":
        (49882416192, "0b2437f661f584030cb5aeb8fb1bb70f6422518a6746bfcc0304167c7b6b8beb"),
    "Qwen3.8-Flash-Next-UD-Q5_K_XL-00006-of-00006.gguf":
        (3320101792, "55dd96c5ad0863b06b6393151b9ad0ac727b8d58a62e02a296ca5d5ddbfee4a3"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00001-of-00006.gguf":
        (10946624, "8bdc6bad55b6699f46f60708829932ff4018d7ac9bd309c388534fa31753bdb7"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00002-of-00006.gguf":
        (682434912, "494ca4ed3dbf97bc28da88af3890b8877b9032f909812d00c0526a9ca5e91d2e"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00003-of-00006.gguf":
        (54400261312, "34efd79a80a1ce540a517a5d56171924b66ce1c38b04c904f17ad6d8ef17cf20"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00004-of-00006.gguf":
        (49814108512, "0ea4b599880a5a52fcd9c188ba1443f646c69c96571904ddbd6a79246a01a997"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00005-of-00006.gguf":
        (49419317344, "9948e81ae8368144b135a7403d8c0f2cf9a6c2f9f692313865855b2832e696c9"),
    "Qwen3.8-Flash-Next-UD-Q6_K_XL-00006-of-00006.gguf":
        (14838313984, "e4ae255234f42b18012f6d6eec5bf615b57479b7e0a0233c47436a321ffeec3f"),
    "Qwen3.8-Flash-Next-Q8_0-00001-of-00006.gguf":
        (10946624, "2dabcbb53ca537a7947bc7d20414fd464eeaf4d66d43021b5b2556cc87544ad2"),
    "Qwen3.8-Flash-Next-Q8_0-00002-of-00006.gguf":
        (682434912, "494ca4ed3dbf97bc28da88af3890b8877b9032f909812d00c0526a9ca5e91d2e"),
    "Qwen3.8-Flash-Next-Q8_0-00003-of-00006.gguf":
        (54400261312, "34efd79a80a1ce540a517a5d56171924b66ce1c38b04c904f17ad6d8ef17cf20"),
    "Qwen3.8-Flash-Next-Q8_0-00004-of-00006.gguf":
        (49446841216, "bfa634025fabbd2658bf7694bc80b90e571699c768723f844c934c7ef06c691a"),
    "Qwen3.8-Flash-Next-Q8_0-00005-of-00006.gguf":
        (49668930400, "232a8f14cc0fa4262e7efe8593774b136fe40909e39c7a020342ddaa27259a97"),
    "Qwen3.8-Flash-Next-Q8_0-00006-of-00006.gguf":
        (34015618784, "538a93bca918064983409a41187ad4c68640f9aced6f29564da8f551bf86d7a5"),
}
# ISTA-DASLab's Qwen3.8-Flash-Next shards (Q2_0, IQ2_XS, IQ3_XXS, IQ3_S) and the picture reader at the revision pinned
# in HF_REVISIONS: name -> (bytes, sha256), the Hub's LFS pointers (tools/hf_pin_fetch.py).  The n-gram table
# (shard 2) is the same file for all four sizes.
ISTA_FILES = {
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00001-of-00002.gguf":
        (39225954592, "92cee27ae5bbadcd732416a0f7a7f0acc092399dbbe8f5a5efa707c2ec0a49d7"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00002-of-00002.gguf":
        (28800138432, "316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ3_S-00001-of-00002.gguf":
        (54817524224, "4c1eb2ceb4915e1192f4f386021897bde56a97f40a0bb78bb86465e0f7d2aca3"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ3_S-00002-of-00002.gguf":
        (28800138432, "316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00001-of-00002.gguf":
        (47039860096, "219ea929900dfa9ef091f3aa473fdba6874b65fcb36526d7d851ac9e95856d15"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00002-of-00002.gguf":
        (28800138432, "316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113"),
    "Qwen3.8-Flash-Next-GSQ-RCO-Q2_0-00001-of-00002.gguf":
        (37623740192, "69820c02ec7d0b45ef2ebb19d6620299db749fe2aded7f39f93c6b88b199b720"),
    "Qwen3.8-Flash-Next-GSQ-RCO-Q2_0-00002-of-00002.gguf":
        (28800138432, "316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113"),
    "mmproj-Qwen3.8-Flash-Next-BF16.gguf":
        (907543008, "b1a82259702816a5330d7bd7607cd9676b11780e79ff7348c21103ff3ce49bd0"),
}
# Swift 1.5's shards (Q2_0, IQ2_XS, IQ3_XXS, IQ3_S) and its picture reader, same source and form.
SWIFT_FILES = {
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00001-of-00002.gguf":
        (39788473344, "ca3b302d3d1eb6eddce3ea4acc79854e6cc5fdc0583e374a6a8b6bb67327743b"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00002-of-00002.gguf":
        (28363693824, "e4996a6de18fd49c58d9a0040fcfd73787db6407c51973f29884bee7b14c9dbb"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_S-00001-of-00002.gguf":
        (44900816736, "46cb3996cd1a17fe8bc5ae1f9bb16869480de5a03f17f868d6047a20a46edd3b"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_S-00002-of-00002.gguf":
        (38842920384, "70ce6fb48a94fe34bd7e9a53a526be68066c64b5a5077cdc82fb31350b66b608"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00001-of-00002.gguf":
        (39785790560, "3bddaa667c750f63baca766df9433e1afd35a139f401c5ca5e7ff560ceff3d23"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00002-of-00002.gguf":
        (36180282560, "b0b15f782af71eb471909d2f3313b2927c324962f86c084325c247cd411a0160"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-Q2_0-00001-of-00002.gguf":
        (39799117984, "79e2a3873f1b05df835a1a191b20f2e74b9e12df949cd89861d17d98b6ef9678"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-Q2_0-00002-of-00002.gguf":
        (26750834816, "ef3bb04fb4e14f04624abd8acf25faf1603594a034050b048df85ec152ad5ae0"),
    "mmproj-Swift-Qwen3.8-Flash-Next-BF16.gguf":
        (907543520, "cd1140f4abba943ce8d9fa92fed8407e389954d26907efde7b72153c75bd8a60"),
}
# huihui-ai's abliterated copies (uncensored) of Swift 1.5's IQ2_XS and IQ3_XXS and of Unsloth's UD-IQ4_XS,
# UD-Q4_K_XL and Q8_0: the same file names, shards and sizes as those (Q8_0: 32 bytes more in shards 2 to 6), other
# weights.  The picture readers are the originals' files.  name -> (bytes, sha256) at the pinned revision.
HUIHUI_FILES = {
    "Qwen3.8-Flash-Next-Q8_0-00001-of-00006.gguf":
        (10946624, "2dabcbb53ca537a7947bc7d20414fd464eeaf4d66d43021b5b2556cc87544ad2"),
    "Qwen3.8-Flash-Next-Q8_0-00002-of-00006.gguf":
        (682434944, "df11d036f89c9f04865b8f1785db1a705ad401088517a6000d24483b7799626f"),
    "Qwen3.8-Flash-Next-Q8_0-00003-of-00006.gguf":
        (54400261344, "2af1a1f000ab162ea77795348a3df054404915815a19ab04eba51cfe2d79c439"),
    "Qwen3.8-Flash-Next-Q8_0-00004-of-00006.gguf":
        (49446841248, "680cfda198b36a61801fd0a38895690aa6af9346d36b32c0eed3f0b096ae8f7c"),
    "Qwen3.8-Flash-Next-Q8_0-00005-of-00006.gguf":
        (49668930432, "d16e9b874de3aa2dd4a879a749747a1642c046313875ec2cbfff22a801a839aa"),
    "Qwen3.8-Flash-Next-Q8_0-00006-of-00006.gguf":
        (34015618848, "2581ef059bc50ed4653b81223bae778202e62421854a9db3661382de763497e6"),
    "mmproj-Qwen3.8-Flash-Next-BF16.gguf":
        (907543008, "b1a82259702816a5330d7bd7607cd9676b11780e79ff7348c21103ff3ce49bd0"),
    "mmproj-Swift-Qwen3.8-Flash-Next-BF16.gguf":
        (907543520, "cd1140f4abba943ce8d9fa92fed8407e389954d26907efde7b72153c75bd8a60"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00001-of-00002.gguf":
        (39788473344, "234b93685cb484386016e387ae0a3ded3e1f7867ea94b58fcb8c95f6b13c138f"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ2_XS-00002-of-00002.gguf":
        (28363693824, "34ae43e481e1df2c77c7d8b733ae6355123c39982975978d405810f20105cd06"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00001-of-00002.gguf":
        (39785790560, "d815c962f3436e5571f81f874989b89cd25443a15c6b39f9336982b8d1e42d36"),
    "Swift-Qwen3.8-Flash-Next-GSQ-RCO-IQ3_XXS-00002-of-00002.gguf":
        (36180282560, "953b8b1ad56dd6885ac724a770e3b6e914e9e65287f61ee853da285914503cd5"),
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00001-of-00003.gguf":
        (10946624, "5ce89370720f8bf90890f439361282104c1aa1482d4013bb9a50923e758e71a4"),
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00002-of-00003.gguf":
        (49835229856, "c67b468b3b83bc12a987e455ec4a0c2c3937250da1c234ae1638d9505180c161"),
    "Qwen3.8-Flash-Next-UD-IQ4_XS-00003-of-00003.gguf":
        (43836407744, "130560b6a447e0febf61de9b03476f52143160bc4bcbacc9bfa07d9538718e2c"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00001-of-00004.gguf":
        (10946624, "4448186216b3af4cc558bbce2c3213f01608f8f8b2e5267a9767971dd3ec8082"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00002-of-00004.gguf":
        (49859583136, "b6b52d0c156217efc06bcf06c6906e93b552eb24327abb076a90e02397820432"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00003-of-00004.gguf":
        (49376141504, "ab7d9af2f3b824218fe460de0703b6b349ea83fe51f480f48e0107beb986b0a7"),
    "Qwen3.8-Flash-Next-UD-Q4_K_XL-00004-of-00004.gguf":
        (12087983520, "b8cc1e386c6dc8e92b3e420f839239c2a595598518b179b7a88a4c430b3fc973"),
}
# The Coder's IQ1_M shards and its picture reader (the original's file), same source and form.
CODER_FILES = {
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ1_M-00001-of-00002.gguf":
        (29608446496, "e11083ba855e7666b48ea3f2db6a9c3a20c18751a012cc24f948de91b7087fad"),
    "Qwen3.8-Flash-Next-GSQ-RCO-IQ1_M-00002-of-00002.gguf":
        (28800138432, "316b46f3a2dbd68c900f43136ab9449f9dcc3725dfd8c794847c204bc161e113"),
    "mmproj-Qwen3.8-Flash-Next-BF16.gguf":
        (907543008, "b1a82259702816a5330d7bd7607cd9676b11780e79ff7348c21103ff3ce49bd0"),
}
UNSLOTH_RAM_LEFT_GB = 24        # RAM beside the budget: the OS, the engine, and the file cache the rest is read through
# Contexts past 262144 (the model's trained length) extend it by rope scaling (upstream #84): for the context it will
# serve the setup takes yarn (or asks, when interactive) and the factor final / 262144 (at least 1), keeps an explicit
# --rope-scaling / --rope-scale, and refuses an explicit --rope-scaling none there.
# 204800 (200K) sits between 128K and 256K: it is inside the trained 262144, so it needs no rope scaling and
# costs ~2.8 GB of 8-bit KV with IQ3_S (vs ~3.6 GB at 256K) - a middle step for PCs that cannot hold 256K.
CONTEXTS = [8192, 32768, 65536, 131072, 204800, 262144, 393216, 524288]
# The model families: the same architecture, weights in the same three GSQ-RCO sizes, different files.
HUIHUI = "huihui-ai/Huihui-Qwen3.8-Flash-Next-abliterated-GGUF"
HUIHUI_URL = "https://huggingface.co/" + HUIHUI
FAMILIES: dict[str, dict[str, Any]] = {
    "qwen": {"title": "Qwen3.8-Flash-Next", "by": "Qwen; GSQ-RCO quants by ISTA-DASLab",
             "about": "the original model",
             "hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF") + "{q}/",
             "file": "Qwen3.8-Flash-Next-GSQ-RCO-{q}-0000{i}-of-00002.gguf", "tag": "",
             "mmproj_hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF"),
             "mmproj": "mmproj-Qwen3.8-Flash-Next-BF16.gguf", "name": "qwen3.8-flash-next"},
    "swift": {"title": "Swift 1.5", "by": "UkisAI's fine-tune of Qwen3.8-Flash-Next",
              "about": "thinks much shorter (-63% thinking tokens, 1.8x sooner answers by its authors' numbers)",
              "hf": hf("ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF"),
              "file": "Swift-Qwen3.8-Flash-Next-GSQ-RCO-{q}-0000{i}-of-00002.gguf", "tag": "swift-",
              "mmproj_hf": hf("ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF"),
              "mmproj": "mmproj-Swift-Qwen3.8-Flash-Next-BF16.gguf", "name": "swift-1.5",
              "license": "Swift Open License 1.0: "
                         "https://huggingface.co/ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF"},
    # ISTA-DASLab's expert-pruned release: half of each layer's experts removed, chosen for code, agentic tool use and
    # vision; its shard 2 (the n-gram table) and vision encoder are the original's files, shared with it
    "coder": {"title": "Qwen3.8-Flash-Next Coder", "by": "ISTA-DASLab's coding version",
              "about": "half the experts (code, tools, images kept): needs ~32 GB of RAM, faster; weaker outside "
                       "coding",
              "hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-Coder-GGUF") + "{q}/",
              "file": "Qwen3.8-Flash-Next-GSQ-RCO-{q}-0000{i}-of-00002.gguf", "tag": "coder-",
              "mmproj_hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-Coder-GGUF"),
              "mmproj": "mmproj-Qwen3.8-Flash-Next-BF16.gguf", "name": "qwen3.8-flash-next-coder",
              "profile": "expert-profile-coder.bin"},
    # Unsloth's UD-IQ4_XS (three shards, upstream #621) and the EXPERIMENTAL UD-Q4_K_XL (four) of the original model;
    # "experimental" and "vision" are per model (MODELS)
    "unsloth": {"title": "Qwen3.8-Flash-Next (Unsloth)", "by": "Unsloth's ~4-bit quantizations",
                "about": "UD-IQ4_XS: a 94 GB download; with less than ~80 GB of RAM part of its experts are read from "
                         "the SSD (UD-Q4_K_XL, 111 GB: experimental)",
                "hf": hf("unsloth/Qwen3.8-Flash-Next-GGUF") + "{q}/",
                "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00004.gguf", "shards": 4, "tag": "unsloth-",
                "mmproj_hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF"),
                "mmproj": "mmproj-Qwen3.8-Flash-Next-BF16.gguf", "name": "qwen3.8-flash-next-unsloth",
                "vision": False, "pack_args": ["--compat-bf16"],
                "sha256": {**UNSLOTH_SHARDS, **UNSLOTH_IQ4_XS_SHARDS, **UNSLOTH_BIG_SHARDS}},
    # agentionai's Gyro quantizations (see GYRO_FILES): after the regular families, never the default
    "gyro": {"title": "Qwen3.8-Flash-Next (Gyro)", "by": "Gyro quantizations by agentionai",
             "about": "Gyro-S (27.6 GB of memory) and Gyro-M (35 GB): the smallest sizes, for PCs with little memory; "
                      "58 and 92 GB downloads (the files include the n-gram table)",
             "hf": hf("agentionai/Qwen3.8-Flash-Next-Gyro-GGUF"), "file": "Qwen3.8-Flash-Next-{q}.gguf", "shards": 1,
             "tag": "gyro-", "name": "qwen3.8-flash-next-gyro", "vision": True, "pack_args": ["--compat-bf16"],
             "mmproj_hf": hf("ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF"), "mmproj": "mmproj-Qwen3.8-Flash-Next-BF16.gguf",
             "sha256": GYRO_FILES,
             "license": "Qwen Community License 1.0 (Qwen3.8-Flash-Next's; the Gyro files are agentionai's quantization): "
                        "https://huggingface.co/agentionai/Qwen3.8-Flash-Next-Gyro-GGUF"},
    # huihui-ai's abliterated copies (HUIHUI_FILES): Swift 1.5's and Unsloth's files with the refusals removed, in
    # folders of one repository ("dirs": the folder of each size); after the regular families, never the default
    "huihui-swift": {"title": "Swift 1.5 (abliterated)", "by": "huihui-ai's uncensored version of Swift 1.5",
                     "about": "Swift 1.5 with its refusals removed (abliteration): far fewer refusals, and its safety "
                              "filtering is reduced, so check what it writes",
                     "hf": hf(HUIHUI) + "swift-{q}/",
                     "file": "Swift-Qwen3.8-Flash-Next-GSQ-RCO-{q}-0000{i}-of-00002.gguf", "tag": "huihui-swift-",
                     "mmproj_hf": hf(HUIHUI), "mmproj": "mmproj-Swift-Qwen3.8-Flash-Next-BF16.gguf",
                     "name": "swift-1.5-abliterated",
                     "license": "Swift Open License 1.0 (Swift 1.5's; huihui-ai's abliterated copy): " + HUIHUI_URL},
    "huihui-unsloth": {"title": "Qwen3.8-Flash-Next (abliterated)",
                       "by": "huihui-ai's uncensored version, Unsloth's sizes",
                       "about": "Qwen3.8-Flash-Next with its refusals removed (abliteration), as Unsloth's 4- and "
                                "8-bit files: far fewer refusals, and its safety filtering is reduced, so check what "
                                "it writes",
                       "hf": hf(HUIHUI) + "{d}/",
                       "dirs": {"UD-IQ4_XS": "unsloth-UD-IQ4_XS", "UD-Q4_K_XL": "unsloth-UD-Q4_K_XL", "Q8_0": "Q8_0"},
                       "file": "Qwen3.8-Flash-Next-{q}-0000{i}-of-00004.gguf", "shards": 4, "tag": "huihui-unsloth-",
                       "mmproj_hf": hf(HUIHUI), "mmproj": "mmproj-Qwen3.8-Flash-Next-BF16.gguf",
                       "name": "qwen3.8-flash-next-abliterated", "vision": False, "pack_args": ["--compat-bf16"],
                       "sha256": HUIHUI_FILES,
                       "license": "Qwen Community License 1.0 (Qwen3.8-Flash-Next's; huihui-ai's abliterated copy): "
                                  + HUIHUI_URL},
}
# The models the engine runs other than Qwen3.8-Flash-Next (src/core/plain_model.cpp: `strata --native` with another
# architecture): one GGUF file each, its size and SHA-256 at the pinned revision (the Hub's LFS pointers), or its
# "parts" (a model in several files: each one's path in the repository, size and SHA-256; "file" is the first, which
# the engine is given), no pack, no PLE table and no images yet.  "tested": the files this release was checked with
# (the rest use the same tensor types, checked on those files and in the kernels' tests).
_ORNITH = "ornith-ai/Ornith-1.5-35B-A3B-GGUF"
_ORNITH_GSQ = "pfeifferj/Ornith-1.5-35B-A3B-GSQ-RCO-GGUF"
_LLMJP = "llm-jp/llm-jp-4.1-32b-a3b-thinking-gguf"
_QWEN36 = "unsloth/Qwen3.6-35B-A3B-MTP-GGUF"
_GLM53 = "unsloth/GLM-5.3-Flash-GGUF"


def _glm53_parts(quant: str, parts: list[tuple[int, str]]) -> list[dict[str, Any]]:
    """Unsloth's files of one GLM-5.3-Flash version: <quant>/GLM-5.3-Flash-<quant>-0000i-of-0000n.gguf"""
    n = len(parts)
    return [{"path": f"{quant}/GLM-5.3-Flash-{quant}-{i:05d}-of-{n:05d}.gguf", "size": size, "sha256": sha}
            for i, (size, sha) in enumerate(parts, 1)]


_GLM53_IQ3 = _glm53_parts("UD-IQ3_XXS", [
    (9429984, "632f4fabe03ea73d20c299c8ef00c4a16e47dd9ab3f1750a8585b92eb70dfa74"),
    (49261511584, "a4dba331fe92ffbd71317839cc1452c57f0b5b3f971a9e96ee5107f9a615cdac"),
    (49075832480, "5b728b5b263c662201ef4a4a2b12fb509fe230d012418d0ed37c220a8a5aa230"),
    (22020797792, "4b6d16e0d1381e1b4b7eeb6c9799671bf98153a995be12e75e3da93cd97981d2")])
_GLM53_IQ1 = _glm53_parts("UD-IQ1_S", [
    (9429984, "909a8a2dedb493c5a694facfd1e0e9a3309ac66fbb9d270c024ff5d12e0d565f"),
    (49621122496, "b99c4dd929601884ff95d9ddeb581a5ef93fd281c37c162e48b2981bf23c0830"),
    (43456692608, "9bb0ff754968d588793d795c715cc2a7d5292280ff9d0df46b7e1edd57da34a1")])
_GLM53_IQ4 = _glm53_parts("UD-IQ4_XS", [
    (9429984, "c2f3b6ab98d3df844f322ea376059202d2eaeedcee1f0eff455345b86a137dbd"),
    (49989334176, "7d64cf0395672c4322012841abec502ea7e20518299bb5e3069003f06f9e6de9"),
    (49607025280, "7c2c63c9c30f8060428fdf2ac935dbf2ee9ad8f771d62b6ae47a7f7f2c1520e7"),
    (49486530144, "06c90f191871317c92dd9d25a353b687aed44c50f3ac6c713e9fe410bc2d26dd"),
    (7729791616, "66ebf9ec85e04d3f44af674ae4f694acbc89cc53db75e42f2f4d3646bf321c0d")])
PLAIN_FAMILIES: dict[str, dict[str, Any]] = {
    "ornith": {"title": "Ornith-1.5-35B-A3B", "by": "Ornith AI (MIT)",
               "about": "35B, 3B active; a Qwen3.5 MoE: Q4_K_M to BF16, and community GSQ-RCO 3 and 3.5 bits",
               "tag": "ornith-", "name": "ornith-1.5-35b-a3b", "max_context": 262144, "plain": True,
               "profile": "expert-profile-ornith.bin",
               "models": {
                   "Q4_K_M": {"repo": _ORNITH, "file": "Ornith-1.5-35B-Q4_K_M.gguf", "size": 21713463040,
                              "sha256": "42739874cc2ccfdb8523b23fbe52e29b2a7555c8176737ca9ca0b5d59859d41f",
                              "about": "4-bit", "tested": True},
                   "Q5_K_M": {"repo": _ORNITH, "file": "Ornith-1.5-35B-Q5_K_M.gguf", "size": 25347532544,
                              "sha256": "91df97de5845100e850b4b5ec5ff35695382020b880fad6f7f51787b3a953bd0",
                              "about": "5-bit"},
                   "Q6_K": {"repo": _ORNITH, "file": "Ornith-1.5-35B-Q6_K.gguf", "size": 29208731392,
                            "sha256": "15d4658bbfc9c6034621729c15bbb50662c82b32a7ddd9624a1e545a74bdbb4b",
                            "about": "6-bit", "tested": True},
                   "Q8_0": {"repo": _ORNITH, "file": "Ornith-1.5-35B-Q8_0.gguf", "size": 37802149280,
                            "sha256": "de46c4baf4b4dd85ea438bb0f757f21c38841a353506579979bba114311658c3",
                            "about": "8-bit"},
                   "BF16": {"repo": _ORNITH, "file": "Ornith-1.5-35B-BF16.gguf", "size": 71066994400,
                            "sha256": "044d7f8b55580720dae0d0d8b58f824024901ed5da62f93c011f6bd8dc45a42b",
                            "about": "the unquantized weights", "tested": True},
                   "GSQ-RCO-3BIT": {"repo": _ORNITH_GSQ, "file": "Ornith-1.5-35B-A3B-GSQ-RCO-3bit.gguf",
                                    "size": 12992461216,
                                    "sha256": "9cae3b59a34308664b53e5b80fd74914cd0c1cf504bcd05609498b0f9126a74f",
                                    "about": "3-bit GSQ-RCO by pfeifferj (a community reproduction of the method, not "
                                             "IST-DASLab's)", "tested": True},
                   "GSQ-RCO-3.5BIT": {"repo": _ORNITH_GSQ, "file": "Ornith-1.5-35B-A3B-GSQ-RCO-3.5bit.gguf",
                                      "size": 15163013536,
                                      "sha256": "69191d3d2c402f7c13950815bf20d826d7066c8d7f1bef4594cf70c13ea56ccc",
                                      "about": "3.5-bit GSQ-RCO by pfeifferj (as above)"},
               }},
    "llmjp": {"title": "llm-jp-4.1-32b-a3b-thinking", "by": "LLM-jp (Apache-2.0)",
              "about": "32B, 3B active; Japanese and English, a thinking model", "tag": "llmjp-",
              "name": "llm-jp-4.1-32b-a3b-thinking", "max_context": 262144, "plain": True,
              "profile": "expert-profile-llmjp.bin",
              "models": {
                  "Q4_K_M": {"repo": _LLMJP, "file": "llm-jp-4.1-32b-a3b-thinking-Q4_K_M.gguf", "size": 21522488192,
                             "sha256": "52fea46f306928802ef189f1483b022a4431a97af7fb9f48dbc56e957713f561",
                             "about": "4-bit", "tested": True},
                  "BF16": {"repo": _LLMJP, "file": "llm-jp-4.1-32b-a3b-thinking-BF16.gguf", "size": 64304224896,
                           "sha256": "52ffbf4ffb021b68d0341e7d7cd0f7a15f4beb6b4bff748042ba249c3b5e6a39",
                           "about": "the unquantized weights"},
              }},
    # Qwen3.6-35B-A3B (qwen35moe, as Ornith-1.5): Unsloth's GGUFs with the MTP block, the three upstream offers (its own
    # CUDA engine path there, 0.1.44; here the same plain path as Ornith's).  Their tensors: Q4_K, Q5_K, Q6_K and Q8_0
    # experts, Q8_0 dense, F32, and the MTP block's two routers in BF16
    "qwen36": {"title": "Qwen3.6-35B-A3B", "by": "Qwen (Apache-2.0), GGUFs with the MTP layer by Unsloth",
               "about": "35B, 3B active; a Qwen3.5 MoE with the Qwen tokenizer: Unsloth's 4-, 6- and 8-bit files",
               "tag": "qwen36-", "name": "qwen3.6-35b-a3b", "max_context": 262144, "plain": True,
               "profile": "expert-profile-qwen36.bin",
               "draft_vocab": True,   # the vocabulary of Qwen3.8's draft head subsets (data/draft_vocab*.bin)
               "models": {
                   "UD-Q4_K_XL": {"repo": _QWEN36, "file": "Qwen3.6-35B-A3B-UD-Q4_K_XL.gguf", "size": 22853663008,
                                  "sha256": "55983c5a75a1ab969824077b3bb3de4146e82a9234072b48ad4e8f92ad3fe9f1",
                                  "about": "4-bit (Unsloth Dynamic)", "tested": True},
                   "UD-Q6_K_XL": {"repo": _QWEN36, "file": "Qwen3.6-35B-A3B-UD-Q6_K_XL.gguf", "size": 32611711264,
                                  "sha256": "35fce994cd36104a7dc1bd8a4bdf13778145664c00fdef6773aebc9246e5019c",
                                  "about": "6-bit (Unsloth Dynamic), closer to the full model", "tested": True},
                   "Q8_0": {"repo": _QWEN36, "file": "Qwen3.6-35B-A3B-Q8_0.gguf", "size": 37801097504,
                            "sha256": "c1283d8b80c3e38b2735ddbc9766d3b3126f44d6c484be419d4e101d09a76131",
                            "about": "8-bit, the closest to the full model"},
               }},
}
# GLM-5.3-Flash (glm5-next): 320B, 18B active, KDA and DSA attention with four residual streams (mHC), its MTP layer
# not read yet; Unsloth's files in several parts
PLAIN_FAMILIES["glm53"] = {
    "title": "GLM-5.3-Flash", "by": "Z.ai (MIT), GGUFs by Unsloth",
    "about": "320B, 18B active; a large MoE for the PCs whose RAM and VRAM hold 95 GB or more",
    "tag": "glm53-", "name": "glm-5.3-flash", "max_context": 262144, "plain": True,
    "profile": "expert-profile-glm53.bin",
    "models": {
        "UD-IQ3_XXS": {"repo": _GLM53, "file": _GLM53_IQ3[0]["path"], "parts": _GLM53_IQ3,
                       "size": sum(x["size"] for x in _GLM53_IQ3), "about": "3-bit (Unsloth Dynamic)", "tested": True},
        "UD-IQ1_S": {"repo": _GLM53, "file": _GLM53_IQ1[0]["path"], "parts": _GLM53_IQ1,
                     "size": sum(x["size"] for x in _GLM53_IQ1), "about": "1-bit (Unsloth Dynamic), the smallest",
                     "tested": True},
        "UD-IQ4_XS": {"repo": _GLM53, "file": _GLM53_IQ4[0]["path"], "parts": _GLM53_IQ4,
                      "size": sum(x["size"] for x in _GLM53_IQ4), "about": "4-bit (Unsloth Dynamic), the best quality"},
    }}
FAMILIES.update(PLAIN_FAMILIES)


def plain_parts(d: dict) -> list[dict[str, Any]]:
    """A PLAIN_FAMILIES model's files: its "parts", or its one file"""
    return d.get("parts") or [{"path": d["file"], "size": d["size"], "sha256": d["sha256"]}]


# DeepSeek model pins and pack recipes from the fixed Strata 870aedd9 snapshot.
DSV41_REPO = "unsloth/DeepSeek-V4.1-Flash-1017-GGUF"
DSV41_SHARD = "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-{i:05d}-of-00009.gguf"
DSV41_FILES = {
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00001-of-00009.gguf": (
        5780589, "cc15d470afcb030558bbc4d8e2ccd840182e2e95de1a95198138efe63a5fd99f"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00002-of-00009.gguf": (
        50536121984, "9cb2047676bd20e448be2377b480080c97fb38fae117f4846e07de2c65bb8522"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00003-of-00009.gguf": (
        50536121984, "17d398dd327e7ff1991b382677814db75d970b074661757564b6f2ac3d0c8d95"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00004-of-00009.gguf": (
        50536122016, "7ea8da1143b9a6bf1424a361eb1b0d6f66c7ce79eac9711162f212cc4f39c319"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00005-of-00009.gguf": (
        50536122016, "1952da19a841176b46f9681c99ea57c674f8a8861e16d76fb35cec4befe039b2"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00006-of-00009.gguf": (
        50536122016, "d6711781d8effab79b410af9c40920bffcc0c28976e509bc1227ff0c6669c33a"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00007-of-00009.gguf": (
        36097230048, "2ebc8d198d03a14865e8a85df637285ceb5dd79b1ffc78424bd3c3e06df57823"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00008-of-00009.gguf": (
        202758032592, "12df293355efbd104b088a77e13ee22410fb1ec3f7ab3863947f09896e64bec7"),
    "DeepSeek-V4.1-Flash-1017-UD-Q8_K_XL-00009-of-00009.gguf": (
        16835109952, "df33722d1dcf5ffe0347ed8406f7acb3b18061f4ded2c13c2b0a184b8d41c9ea"),
    "dspark-DeepSeek-V4.1-Flash-1017-Q8_0.gguf": (
        7976914240, "6ba6ac1b331c540691a209e7fc97dec2a24e295acb1e755c84c7d24a4373927a"),
    "mmproj-BF16.gguf": (972208288, "9a1ef7c40d0d702c7ed8c5f863f60abae64091387ba3fce0ad19ce9beeda3bf9"),
}
DSV41_ISTA_REPO = "ISTA-DASLab/DeepSeek-V4.1-Flash-1017-GSQ-RCO-GGUF"
DSV41_ISTA_ENGRAM = "DeepSeek-V4.1-Flash-Engram-IQ4_NL.gguf"
DSV41_ISTA_SHARD = "DeepSeek-V4.1-Flash-1017-GSQ-RCO-{quant}-{i:05d}-of-00004.gguf"
DSV41_DSPARK = "dspark-DeepSeek-V4.1-Flash-1017-Q8_0.gguf"
DSV41_ISTA_FILES = {
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ1_M-00001-of-00004.gguf": (
        39358830464, "6e3f0d5ff53d00428ec32c079db9e8255cb410ccaa435e5342aaa8a47fe1339d"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ1_M-00002-of-00004.gguf": (
        39176113248, "34d68c99fdae9948f9f0af0dafe308e805ce0a78d2c48641b24cc57242fdc0af"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ1_M-00003-of-00004.gguf": (
        39997334720, "a08468c83955e0c4d3a9eb3f7b86c45b7bbac55d99c4640039a296a8a4b327ea"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ1_M-00004-of-00004.gguf": (
        2188841824, "b05f26a92325aa6845cebcb3ec1f93d2e65ebf89bdc3f805695960d2f0681832"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XS-00001-of-00004.gguf": (
        39535776992, "4c65307992ab586c527ca1f6f64062aa96a33b23c02b7fed103f45f75e854798"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XS-00002-of-00004.gguf": (
        39494617536, "933461a974fcccee741bf2f9798201e72ab4aa3f8a952be56f849896ca6ea30e"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XS-00003-of-00004.gguf": (
        39423838496, "bbf91fa346a85ebaf32dd4fd5c456b534d780d381e54f46ac90783a481373240"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XS-00004-of-00004.gguf": (
        36771591232, "e5b2f8781fab688cd4bc3bc7a69651b5dbb90ed94965657c6bead8bb4774f3cf"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XXS-00001-of-00004.gguf": (
        39075714624, "d46efb67ccffd8fb5d7f18b423896381b9e06d8491e161c370ddf3b05b07e050"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XXS-00002-of-00004.gguf": (
        39388449504, "cec1b2c3da429dc768b8bb9bc4dc4403d81f74d34db660a6a34ee3e555bf2c70"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XXS-00003-of-00004.gguf": (
        39246891616, "9d9c2140fcb134a0b9a74dedd0e5167e68077af6d08ce7f856bce112f0a35dd3"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XXS-00004-of-00004.gguf": (
        20527837312, "9b790a2297ed3cdede379fc984f4a52bb95f3b23724c797af11d1fa6a69db059"),
    "DeepSeek-V4.1-Flash-Engram-IQ4_NL.gguf": (
        110595290816, "eb19f30d368d393784e1fc54fdfaffc427ebb2110bf3762fdf5a8fbb9a2d740a"),
}
DSV41_NEW_SHARD1 = {
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ1_M-00001-of-00004.gguf": (
        39358841536, "a7be0d5a48e4d1c13c5535f9123d9131ab8964e5acf8a0c01d14970e4b7f4df9"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XS-00001-of-00004.gguf": (
        39535788064, "d9b949d55e27242b8afc7c2928749b888372d4c39682f9a131670d1c2555155e"),
    "DeepSeek-V4.1-Flash-1017-GSQ-RCO-IQ2_XXS-00001-of-00004.gguf": (
        39075725728, "2dfe9711eac1f7814aa59154d11e8f27739f8b96875dc1e667eac9f8c756e1fe"),
}
DSV41_LEGACY_FILES = {
    "model-2.00bpw-00001-of-00004.gguf": (
        39075713728, "78ab9efc46a26647c3e94b322c99cd7e2af261dd28b38f2712e128562db1ef47"),
    "model-2.00bpw-00002-of-00004.gguf": (
        39388449504, "cec1b2c3da429dc768b8bb9bc4dc4403d81f74d34db660a6a34ee3e555bf2c70"),
    "model-2.00bpw-00003-of-00004.gguf": (
        39246891616, "9d9c2140fcb134a0b9a74dedd0e5167e68077af6d08ce7f856bce112f0a35dd3"),
    "model-2.00bpw-00004-of-00004.gguf": (
        20527837312, "9b790a2297ed3cdede379fc984f4a52bb95f3b23724c797af11d1fa6a69db059"),
    "model-2.25bpw-00001-of-00004.gguf": (
        39535776064, "ddd13aca16faa23b08f5196b5e0daddf90f04688a271f5889eb22fa7d7d65526"),
    "model-2.25bpw-00002-of-00004.gguf": (
        39494617536, "933461a974fcccee741bf2f9798201e72ab4aa3f8a952be56f849896ca6ea30e"),
    "model-2.25bpw-00003-of-00004.gguf": (
        39423838496, "bbf91fa346a85ebaf32dd4fd5c456b534d780d381e54f46ac90783a481373240"),
    "model-2.25bpw-00004-of-00004.gguf": (
        36771591232, "e5b2f8781fab688cd4bc3bc7a69651b5dbb90ed94965657c6bead8bb4774f3cf"),
    "engram-IQ4_NL.gguf": (110595290720, "1f17d8ae37e9df3bb45f7ef1b4fcd1706d7b759af0413c117bf8e92aed459281"),
}
DSV41_LEGACY_NAMES = {
    **{DSV41_ISTA_SHARD.format(quant="IQ2_XXS", i=i): "model-2.00bpw-%05d-of-00004.gguf" % i for i in range(1, 5)},
    **{DSV41_ISTA_SHARD.format(quant="IQ2_XS", i=i): "model-2.25bpw-%05d-of-00004.gguf" % i for i in range(1, 5)},
    DSV41_ISTA_ENGRAM: "engram-IQ4_NL.gguf",
}
DSV41_ALL_FILES = {**DSV41_FILES, **DSV41_ISTA_FILES, **DSV41_LEGACY_FILES}
DSV41_PROFILES = ROOT / "data" / "dsv41"
DSV41_CONTEXT = 8192
DSV41_SHARED = {
    DSV41_ISTA_ENGRAM: hf(DSV41_ISTA_REPO),
    DSV41_SHARD.format(i=1): hf(DSV41_REPO) + "UD-Q8_K_XL/",
    DSV41_DSPARK: hf(DSV41_REPO),
}
MULTI_FILE_FAMILIES: dict[str, dict[str, Any]] = {
    "deepseek41": {
        "title": "DeepSeek-V4.1-Flash", "by": "DeepSeek; GGUFs by IST-DAS and Unsloth", "arch": "deepseek41",
        "about": "text-only DeepSeek with a separate engine and an Engram table read from the model files",
        "hf": hf(DSV41_REPO) + "UD-Q8_K_XL/", "tag": "deepseek-v4.1-flash-", "name": "deepseek-v4.1-flash",
        "license": "DeepSeek's model license: https://huggingface.co/unsloth/DeepSeek-V4.1-Flash-1017-GGUF",
        "sha256": DSV41_ALL_FILES, "vision": False, "experimental": True, "multi_file": True,
        "max_context": 1048576,
        "models": {
            "IST-DAS-2.00bpw": {
                "about": "IQ2_XXS experts; 138 GB of model files, a shared 111 GB Engram table and 8 GB drafter",
                "ram_gb": 40, "recipe": "ista", "legacy_subdir": "2.00bpw", "profile": "profile-2.00.bin",
                "hf": hf(DSV41_ISTA_REPO),
                "shards": [DSV41_ISTA_SHARD.format(quant="IQ2_XXS", i=i) for i in range(1, 5)],
                "shared": [DSV41_ISTA_ENGRAM, DSV41_SHARD.format(i=1), DSV41_DSPARK]},
            "IST-DAS-2.25bpw": {
                "about": "IQ2_XS experts; 155 GB of model files, the shared Engram table and drafter",
                "ram_gb": 44, "recipe": "ista", "legacy_subdir": "2.25bpw", "profile": "profile-2.25.bin",
                "hf": hf(DSV41_ISTA_REPO),
                "shards": [DSV41_ISTA_SHARD.format(quant="IQ2_XS", i=i) for i in range(1, 5)],
                "shared": [DSV41_ISTA_ENGRAM, DSV41_SHARD.format(i=1), DSV41_DSPARK]},
            "IST-DAS-1.75bpw": {
                "about": "IQ1_M experts; 121 GB of model files, the shared Engram table and drafter",
                "ram_gb": 34, "recipe": "ista", "profile": "profile-2.00.bin", "hf": hf(DSV41_ISTA_REPO),
                "shards": [DSV41_ISTA_SHARD.format(quant="IQ1_M", i=i) for i in range(1, 5)],
                "shared": [DSV41_ISTA_ENGRAM, DSV41_SHARD.format(i=1), DSV41_DSPARK]},
            "UD-Q8_K_XL": {
                "about": "MXFP4 experts and BF16 dense tensors; 508 GB of model files including the Engram table",
                "ram_gb": 306, "recipe": "ud", "subdir": "UD-Q8_K_XL",
                "shards": [DSV41_SHARD.format(i=i) for i in range(1, 10)], "shared": []},
        },
    },
}
FAMILIES.update(MULTI_FILE_FAMILIES)


# Every model file XeStrata downloads has a fixed size and SHA-256: (repository, file name) -> (bytes, sha256).
# download() verifies them, and rejects a different size before fetching. Revisions are fixed in HF_REVISIONS.
REPO_PINS: dict[str, dict[str, tuple[int, str]]] = {
    DSV41_REPO: DSV41_FILES,
    DSV41_ISTA_REPO: DSV41_ISTA_FILES,
    "ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-GGUF": ISTA_FILES,
    "ukisai/Swift-1.5-Qwen3.8-Flash-Next-GSQ-RCO-GGUF": SWIFT_FILES,
    "ISTA-DASLab/Qwen3.8-Flash-Next-GSQ-RCO-Coder-GGUF": CODER_FILES,
    "unsloth/Qwen3.8-Flash-Next-GGUF": {**UNSLOTH_SHARDS, **UNSLOTH_IQ4_XS_SHARDS, **UNSLOTH_BIG_SHARDS},
    "agentionai/Qwen3.8-Flash-Next-Gyro-GGUF": GYRO_FILES,
    "huihui-ai/Huihui-Qwen3.8-Flash-Next-abliterated-GGUF": HUIHUI_FILES,
}
for _fam in PLAIN_FAMILIES.values():                 # the other models' files, from their own tables
    for _d in _fam["models"].values():
        for _x in plain_parts(_d):
            REPO_PINS.setdefault(_d["repo"], {})[_x["path"].rsplit("/", 1)[-1]] = (_x["size"], _x["sha256"])

MMPROJ = "mmproj-Qwen3.8-Flash-Next-BF16.gguf"
# EXPERIMENTAL, off by default (setup asks): a control vector shipped with the repository, see its README
# under the Qwen Community License, so in third_party/nonfree (XeStrata runs without that folder)
ESP_VECTOR = (ROOT / "third_party" / "nonfree" / "experimental-speed-projection" /
              "Qwen3.8-Flash-Next-experimental-speed-projection.gguf")
ESP_SIZE, ESP_SHA256 = 483520, "ef0724c5b79297e481017be85769832bc26eb220c984ecba2b0e1b0c8426312b"


def esp_release_url(name: str) -> str:
    """A file of the vector's folder at the installed version's tag on GitHub: the package leaves third_party/nonfree
    out, so its setup downloads the vector from there."""
    return (f"https://raw.githubusercontent.com/MistVVK/XeStrata/xe{source_version()}/"
            f"third_party/nonfree/experimental-speed-projection/{name}")


def esp_download(data: Path) -> Path | None:
    """The package's copy of ESP_VECTOR in the data folder, downloaded with its license; None when the version's tag
    is not on GitHub (a package built from an unreleased tree)."""
    dst = data / "experimental-speed-projection" / ESP_VECTOR.name
    if not (dst.exists() and done(dst)) and not reachable(esp_release_url(ESP_VECTOR.name), timeout=30):
        warn(f"the experimental speed projection's vector is not at {esp_release_url(ESP_VECTOR.name)}: left off. "
             "Pass --experimental-speed-projection <its GGUF>")
        return None
    download(esp_release_url("LICENSE"), dst.with_name("LICENSE"), "the experimental speed projection's license")
    download(esp_release_url(ESP_VECTOR.name), dst, "the experimental speed projection's vector")
    verify_sha256(dst, ESP_SIZE, ESP_SHA256)
    return dst


# the image encoder on the GPU (~1.2 GB at 1024 image tokens) warms up before the engine starts, so the engine
# sizes its expert slots around it and the default reserve (700 MiB) is enough; engines before 0.1.2 need more
VISION = {"gpu": {"max_tokens": 1024, "reserve_mib": 700},
          "cpu": {"max_tokens": 300, "reserve_mib": 700}}
EXE = "strata.exe" if WIN else "strata"
IMAGE_EXE = "strata-image.exe" if WIN else "strata-image"   # the image engine (serve/images.py), built with it
# the image encoder, one binary per place it runs: the configs of different models may use different ones
# the image encoders: on the CPU, and on the GPU through Vulkan
VEXE = {k: v + (".exe" if WIN else "") for k, v in
        {"cpu": "strata-vision-cpu", "vulkan": "strata-vision-vulkan"}.items()}


# ------------------------------------------------------------------------------------------------ output
# --json: for a front end (the Windows launcher, xestrata.exe), every message is one JSON object a line on stdout:
#   {"type": "say" | "ok" | "warn", "text": ...}, {"type": "step", "n": ..., "title": ...},
#   {"type": "fail", "text": ..., "hint": ...} (then setup exits with 1),
#   {"type": "progress", "what": ..., "done": bytes, "total": bytes or 0},
#   {"type": "log", "text": ...} (a line a program setup runs printed),
#   {"type": "ask", "question": ..., "choices": [...], "default": ...}: the answer is one line on stdin;
#   --describe: {"type": "describe", ...} (describe()); --check-update: {"type": "update", "current": ...,
#   "latest": ..., "newer": ..., "url": ..., "how": ...}.
# A line that is not a JSON object is plain log text (the server's own lines, once setup starts it).  Read from the
# command line before anything is printed.
JSON_OUT = "--json" in sys.argv[1:]


def emit(obj: dict) -> None:
    print(json.dumps(obj, ensure_ascii=False), flush=True)


def say(msg=""):
    if JSON_OUT:
        emit({"type": "say", "text": msg})
    else:
        print(msg, flush=True)


def step(n, title):
    if JSON_OUT:
        emit({"type": "step", "n": n, "title": title})
        return
    say()
    say(f"=== Step {n}: {title} ===")


def ok(msg):
    if JSON_OUT:
        emit({"type": "ok", "text": msg})
    else:
        say(f"  [ok] {msg}")


def warn(msg):
    if JSON_OUT:
        emit({"type": "warn", "text": msg})
    else:
        say(f"  [!]  {msg}")


def fail(msg, hint=None) -> NoReturn:
    if JSON_OUT:
        emit({"type": "fail", "text": msg, "hint": hint})
        sys.exit(1)
    say(f"\n  [X]  {msg}")
    if hint:
        say(f"       {hint}")
    say("\nSetup stopped. Fix the item above and run it again - everything already done is kept and skipped.")
    sys.exit(1)


def progress(what: str, have: int, total: int) -> None:
    """A download's progress: a line rewritten in place, or a progress object."""
    if JSON_OUT:
        emit({"type": "progress", "what": what, "done": have, "total": total})
        return
    size = f"{have / 1e9:6.2f} / {total / 1e9:.2f} GB ({100 * have / total:.0f}%)" if total else f"{have / 1e6:7.1f} MB"
    print(f"\r  {what}: {size}   ", end="", flush=True)


def progress_end() -> None:
    if not JSON_OUT:
        print()


def flush_typed_ahead() -> None:
    """Upstream #841: keys pressed while setup was busy (a download, a build) are not answers to the next question:
    Enter pressed to "wake" a slow step answered "Go on anyway?" with its default.  Dropped before a question is asked,
    on a terminal only (a pipe or a test keeps its input)."""
    try:
        if not sys.stdin.isatty():
            return
        import termios
        termios.tcflush(sys.stdin.fileno(), termios.TCIFLUSH)
    except (ImportError, OSError, ValueError, AttributeError):
        pass


def ask(question, choices, default, yes):
    if yes:
        return default
    flush_typed_ahead()
    while True:
        try:
            if JSON_OUT:
                emit({"type": "ask", "question": question, "choices": list(choices), "default": default})
                a = input().strip()
            else:
                a = input(f"{question} [{default}]: ").strip()
        except EOFError:
            return default
        if not a:
            return default
        if a.lower() in [c.lower() for c in choices]:
            return next(c for c in choices if c.lower() == a.lower())
        say(f"  please answer one of: {', '.join(choices)}")


def run(cmd, cwd=None, env=None, check=True, quiet=False):
    say("  > " + " ".join(str(c) for c in cmd))
    if JSON_OUT and not quiet:                         # the program's lines as log objects, not loose on stdout
        with subprocess.Popen([str(c) for c in cmd], cwd=cwd, env=env, stdout=subprocess.PIPE,
                              stderr=subprocess.STDOUT, text=True, errors="replace") as p:
            for line in p.stdout or []:
                emit({"type": "log", "text": line.rstrip("\n")})
        r = subprocess.CompletedProcess(p.args, p.returncode)
        if check and r.returncode != 0:
            fail(f"command failed (exit {r.returncode}): {Path(str(cmd[0])).name}")
        return r
    r = subprocess.run([str(c) for c in cmd], cwd=cwd, env=env,
                       stdout=subprocess.PIPE if quiet else None, stderr=subprocess.STDOUT if quiet else None,
                       text=True)
    env = dict(os.environ if env is None else env)
    env.setdefault("STRATA_EXIT_WITH_PARENT", "1")     # mtp_fetch.py ends with setup (upstream #3257: a cancel left it)
    if check and r.returncode != 0:
        if quiet and r.stdout:
            say(r.stdout[-4000:])
        fail(f"command failed (exit {r.returncode}): {Path(str(cmd[0])).name}")
    return r


def fetch_mtp(mtp: Path, env: dict, tries: int = 3):
    """The ~5 GB of MTP tensors (tools/mtp_fetch.py).  A timeout or a dropped connection stops one run, not the
    install (upstream #3214 #3193): it is run again, and each run continues where the last one stopped."""
    cmd = [sys.executable, str(ROOT / "tools" / "mtp_fetch.py"), "fetch", "--out", str(mtp)]
    env = {**env, "STRATA_SOURCE": model_source()}
    for n in range(1, tries + 1):
        r = run(cmd, env=env, check=False)
        rc = 0 if r is None else r.returncode              # (a test double answers None)
        if rc == 0:
            return
        if n < tries:
            warn(f"the draft layer's download stopped (exit {rc}); trying again, it continues where it stopped "
                 f"({n + 1} of {tries})")
            time.sleep(5)
    fail(f"the draft layer's download keeps stopping (exit {rc}): the connection to Hugging Face is slow or drops",
         "run setup again - what is downloaded is kept. If it still stops, set STRATA_SOURCE=modelscope "
         "(setup --source modelscope) to read the same files from ModelScope")


def out(cmd):
    try:
        return subprocess.run(cmd, capture_output=True, text=True, timeout=60).stdout
    except (OSError, subprocess.TimeoutExpired):
        return ""


def done(path: Path) -> bool:
    """A step's finish mark: <path>.done exists (written only after the step completed)."""
    return path.with_name(path.name + ".done").exists()


def mark(path: Path, text=""):
    """Write the finish mark.  A folder that cannot be written (--gguf-dir on a read-only share, upstream #570) only
    costs the mark: setup says so and goes on (the step is repeated on the next run), it does not stop."""
    try:
        path.with_name(path.name + ".done").write_text(text or time.strftime("%Y-%m-%d %H:%M"), encoding="utf-8")
    except OSError as e:
        warn(f"the finish mark of {path.name} cannot be written ({e}): the next run does this step again")


# ------------------------------------------------------------------------------------------------ the PC
def wsl_version() -> int:
    """0 on native Linux; 1 or 2 under WSL (WSL 2's kernel is Microsoft's build of Linux, "...-microsoft-standard-WSL2";
    WSL 1 has no Linux kernel and reports "...-Microsoft")."""
    release = platform.uname().release.lower()
    if "microsoft" not in release:
        return 0
    return 2 if "wsl2" in release or "microsoft-standard" in release else 1


def _memory_status():
    """Windows' GlobalMemoryStatusEx: RAM, and the commit limit (ullTotalPageFile = RAM + page file)."""
    import ctypes

    class MS(ctypes.Structure):
        _fields_ = [("dwLength", ctypes.c_ulong), ("dwMemoryLoad", ctypes.c_ulong),
                    ("ullTotalPhys", ctypes.c_ulonglong), ("ullAvailPhys", ctypes.c_ulonglong),
                    ("ullTotalPageFile", ctypes.c_ulonglong), ("ullAvailPageFile", ctypes.c_ulonglong),
                    ("ullTotalVirtual", ctypes.c_ulonglong), ("ullAvailVirtual", ctypes.c_ulonglong),
                    ("ullAvailExtendedVirtual", ctypes.c_ulonglong)]
    m = MS()
    m.dwLength = ctypes.sizeof(MS)
    ctypes.windll.kernel32.GlobalMemoryStatusEx(ctypes.byref(m))  # type: ignore[attr-defined]
    return m


def ram_gb():
    if WIN:
        return _memory_status().ullTotalPhys / 2**30
    for line in open("/proc/meminfo"):
        if line.startswith("MemTotal"):
            return int(line.split()[1]) * 1024 / 2**30
    return 0.0


def cpu_info():
    """(name, avx2, avx512): avx512 means everything Strata's fast AVX-512 kernels use (F, BW, VL, VNNI, VBMI),
    the same test the engine makes (cpu_avx512_ok), not just AVX-512F."""
    name, avx2, avx512 = platform.processor() or "unknown CPU", False, False
    if WIN:                                            # no /proc/cpuinfo: the engine's own tests (strata-device --cpu)
        try:
            c = json.loads(engine_tool("--cpu"))
            return c.get("name") or name, bool(c.get("avx2")), bool(c.get("avx512"))
        except (OSError, ValueError, subprocess.SubprocessError):
            return name, False, False
    try:
        txt = open("/proc/cpuinfo").read()
        flags = set(re.search(r"^flags\s*:\s*(.*)$", txt, re.M).group(1).split())
        avx2 = "avx2" in flags
        avx512 = {"avx512f", "avx512bw", "avx512vl", "avx512_vnni", "avx512vbmi"} <= flags
        m = re.search(r"^model name\s*:\s*(.*)$", txt, re.M)
        name = m.group(1) if m else name
    except OSError:
        pass
    return name, avx2, avx512


GPU_PICK = None                                         # --gpu N (issue #51); None: the card with the most VRAM
ARGS = None                                             # the command line (--license decides which cards can be used)


def _drm_iowr(nr: int, size: int) -> int:
    return (3 << 30) | (size << 16) | (ord("d") << 8) | nr


def drm_memory(render: str, driver: str):
    """(VRAM bytes, of it visible to the CPU) as the kernel driver reports its memory regions (xe's
    DRM_IOCTL_XE_DEVICE_QUERY, i915's DRM_IOCTL_I915_QUERY), or None when it cannot be asked.  (0, 0) for a GPU that
    has only system memory (the processor's own graphics)."""
    import ctypes
    import fcntl
    try:
        fd = os.open(render, os.O_RDWR)
    except OSError:
        return None
    try:
        vram = vis = 0
        if driver == "xe":
            # struct drm_xe_device_query; DRM_XE_DEVICE_QUERY_MEM_REGIONS = 1; regions of 88 bytes after 8
            q = bytearray(struct.pack("QIIQQQ", 0, 1, 0, 0, 0, 0))
            req = _drm_iowr(0x40, len(q))
            fcntl.ioctl(fd, req, q)
            buf = ctypes.create_string_buffer(struct.unpack_from("I", q, 12)[0])
            struct.pack_into("Q", q, 16, ctypes.addressof(buf))
            fcntl.ioctl(fd, req, q)
            for i in range(struct.unpack_from("I", buf, 0)[0]):
                cls, _, _, total, _, cpu_vis, _ = struct.unpack_from("HHIQQQQ", buf, 8 + 88 * i)
                if cls == 1:                                # DRM_XE_MEM_REGION_CLASS_VRAM
                    vram, vis = vram + total, vis + cpu_vis
        elif driver == "i915":
            # struct drm_i915_query with one DRM_I915_QUERY_MEMORY_REGIONS (4) item; regions of 88 bytes after 16
            item = ctypes.create_string_buffer(struct.pack("QiIQ", 4, 0, 0, 0))
            q = bytearray(struct.pack("IIQ", 1, 0, ctypes.addressof(item)))
            req = _drm_iowr(0x79, len(q))
            fcntl.ioctl(fd, req, q)
            length = struct.unpack_from("i", item, 8)[0]
            if length <= 0:
                return None
            buf = ctypes.create_string_buffer(length)
            struct.pack_into("Q", item, 16, ctypes.addressof(buf))
            fcntl.ioctl(fd, req, q)
            for i in range(struct.unpack_from("I", buf, 0)[0]):
                cls, _, _, probed, _, cpu_vis = struct.unpack_from("HHIQQQ", buf, 16 + 88 * i)
                if cls == 1:                                # I915_MEMORY_CLASS_DEVICE
                    vram, vis = vram + probed, vis + (cpu_vis or probed)
        else:
            return None
        return vram, vis
    except (OSError, struct.error):
        return None
    finally:
        os.close(fd)


def drm_graphics_ip(render: str) -> int | None:
    """The graphics IP's major version the xe driver reports for the GPU's main GT (DRM_XE_DEVICE_QUERY_GT_LIST: 20 on
    Xe2, 30 on Xe3; 0 on a GPU without GMD_ID, Alchemist and older), or None when it cannot be asked."""
    import ctypes
    import fcntl
    try:
        fd = os.open(render, os.O_RDWR)
    except OSError:
        return None
    try:
        # struct drm_xe_device_query; DRM_XE_DEVICE_QUERY_GT_LIST = 3; GTs of 96 bytes after 8, type at 0 (MAIN = 0),
        # ip_ver_major at 32
        q = bytearray(struct.pack("QIIQQQ", 0, 3, 0, 0, 0, 0))
        req = _drm_iowr(0x40, len(q))
        fcntl.ioctl(fd, req, q)
        buf = ctypes.create_string_buffer(struct.unpack_from("I", q, 12)[0])
        struct.pack_into("Q", q, 16, ctypes.addressof(buf))
        fcntl.ioctl(fd, req, q)
        for i in range(struct.unpack_from("I", buf, 0)[0]):
            if struct.unpack_from("H", buf, 8 + 96 * i)[0] == 0:
                return struct.unpack_from("H", buf, 8 + 96 * i + 32)[0]
        return None
    except (OSError, struct.error):
        return None
    finally:
        os.close(fd)


def pci_name(vendor: int, device: int) -> str:
    """The card's name from the PCI ID database (hwdata), or its IDs."""
    maker = {0x8086: "Intel", 0x1002: "AMD"}.get(vendor, f"0x{vendor:04x}")
    for f in ("/usr/share/hwdata/pci.ids", "/usr/share/misc/pci.ids"):
        try:
            text = Path(f).read_text(encoding="utf-8", errors="replace")
        except OSError:
            continue
        m = re.search(r"^%04x .*?$(.*?)^[0-9a-f]{4} " % vendor, text, re.M | re.S)
        if m:
            d = re.search(r"^\t%04x  (.+)$" % device, m.group(1), re.M)
            if d:
                n = d.group(1).strip()                  # "Battlemage G21 [Arc B580]", "Battlemage G31 [Intel Graphics]"
                b = re.search(r"\[(.+)\]", n)
                short = b.group(1) if b else n
                if short.startswith("Intel"):            # a bracket that names no product: the chip's name too
                    return f"{short} ({n[:n.find('[')].strip() or n})"
                return f"{maker} {short}"
        break
    return f"{maker} GPU 0x{device:04x}"


def host_link(dev: Path):
    """The PCIe link between the card and the CPU, from sysfs: that of the first device below the root port.  A B70
    sits behind its own switch, whose inner links report 2.5 GT/s x1.  Upstream #912: the card's and the board's top
    speeds when they differ (the root port is the board's end), and a note when the link has fewer lanes now than both
    ends have."""
    parts = dev.resolve().parts
    i = next((k for k, x in enumerate(parts) if x.startswith("pci")), None)
    if i is None or len(parts) < i + 3:
        return None
    root, top = Path(*parts[:i + 2]), Path(*parts[:i + 3])

    def read(d: Path, name: str) -> str:
        return (d / name).read_text(encoding="utf-8").strip()

    try:
        line = f"{read(top, 'current_link_speed')} x{read(top, 'current_link_width')}"
    except OSError:
        return None
    try:
        card, board = read(top, "max_link_speed"), read(root, "max_link_speed")
        if card != board:
            line += f" (the card supports {card}, the board {board})"
        width, most = int(read(top, "current_link_width")), min(int(read(top, "max_link_width")),
                                                                int(read(root, "max_link_width")))
        if width < most:
            # read now: some cards and laptops narrow the link while idle - a hint, not a verdict
            line += (f"; {width} of {most} lanes right now (some cards narrow the link when idle). If it stays "
                     "narrow under load: is the card in the slot wired x16, fully seated, not sharing lanes with an "
                     "M.2 drive?")
    except (OSError, ValueError):
        pass
    return line


def nvidia_smi() -> dict:
    """What NVIDIA's driver reports of each NVIDIA GPU, by PCI address ("0000:09:00.0"): its name, memory (MiB) and
    compute capability ("8.9").  Empty without nvidia-smi."""
    exe = shutil.which("nvidia-smi")
    if exe is None:
        return {}
    try:
        r = subprocess.run([exe, "--query-gpu=pci.bus_id,name,memory.total,compute_cap",
                            "--format=csv,noheader,nounits"], capture_output=True, text=True, timeout=60)
    except (OSError, subprocess.SubprocessError):
        return {}
    found = {}
    for line in r.stdout.splitlines():
        f = [x.strip() for x in line.split(",")]
        if len(f) == 4:
            mib = float(f[2]) if re.fullmatch(r"[\d.]+", f[2]) else 0.0
            found[f[0].lower()[-12:]] = {"name": f[1], "mib": mib, "cc": f[3]}   # "00000000:09:00.0" -> "0000:09:00.0"
    return found


# The AMD GPUs the engine's kernels run on, as cmake/StrataHip.cmake checks them: RDNA2 and later (wave32 and the
# integer dot instructions)
AMD_ARCH = re.compile(r"gfx(103[0-9a-f]|11[0-9a-f]{2}|12[0-9a-f]{2})")


def kfd_nodes() -> dict:
    """Each AMD GPU the kernel's KFD (amdgpu's compute part) has, by PCI address ("0000:0c:00.0"): its ISA name
    ("gfx1200"; gfx_target_version is major * 10000 + minor * 100 + stepping, the last two in hex in the name, as
    cmake/StrataHip.cmake reads it) and whether it is a processor's own graphics (the node has CPU cores as well)."""
    found = {}
    for props in Path("/sys/class/kfd/kfd/topology/nodes").glob("*/properties"):
        try:
            f = dict(line.split(None, 1) for line in props.read_text().splitlines() if " " in line)
            v, loc = int(f.get("gfx_target_version", "0")), int(f.get("location_id", "0"))
        except (OSError, ValueError):
            continue
        if v == 0:
            continue
        pci = f"{int(f.get('domain', '0')):04x}:{loc >> 8:02x}:{(loc >> 3) & 0x1f:02x}.{loc & 7:x}"
        found[pci] = {"gfx": f"gfx{v // 10000}{(v // 100) % 100:x}{v % 100:x}",
                      "integrated": int(f.get("cpu_cores_count", "0")) > 0, "simds": int(f.get("simd_count", "0"))}
    return found


# AMD's APUs share one memory between the CPU and the GPU (upstream c4a329fe).  The GPU's own part is a BIOS
# carve-out (amdgpu's mem_info_vram_total: RAM the OS does not see, so it is room beside the RAM), and it also reaches
# the shared GTT pool (mem_info_gtt_total; the kernel's default is about half of the RAM), which is the RAM itself.  The
# Ryzen AI Max "Strix Halo" APUs are told apart by name (gfx1151, an exception the owner allowed): one PCI id for the
# three, their KFD SIMD count (two per CU) names them.
UMA_OS_LEFT_GB = 6             # the unified memory kept for the OS (the engine keeps the same out of its figure)
STRIX_HALO_GFX = "gfx1151"
STRIX_HALO_BY_SIMDS = {80: "8060S", 64: "8050S", 32: "8040S"}
STRIX_HALO_MODEL = "UD-IQ4_XS"  # upstream's Strix Halo guide measures it; its experts stay in memory from ~80 GB
STRIX_HALO_MIN_GB = 80


def amd_uma(carve_gb: float, gtt_gb: float, ram: float) -> dict:
    """An AMD APU's memory: the BIOS carve-out, the shared pool the GPU reaches (the GTT pool, else half the RAM; at
    most the RAM less what the OS keeps) and their sum, the memory the GPU can use in all."""
    shared = gtt_gb if gtt_gb > 0 else ram / 2
    shared = max(0.0, min(shared, ram - UMA_OS_LEFT_GB))
    return {"carve_gb": max(0.0, carve_gb), "shared_gb": shared, "uma_gb": max(0.0, carve_gb) + shared}


def strix_halo_notes(gpu, ram) -> list:
    """What setup tells a Strix Halo owner (a leading "!" = a warning): nothing is changed or refused."""
    notes = [f"  Strix Halo (gfx1151, Ryzen AI Max): the CPU and the GPU share one memory ({ram:.0f} GB seen by the "
             f"OS + a {gpu.get('carve_gb', 0.0):.1f} GB BIOS carve-out); the model's experts live in it."]
    if gpu.get("shared_gb", 0.0) < 0.75 * ram - 1:
        notes.append(f"!the GPU reaches {gpu.get('shared_gb', 0.0):.0f} GB of shared memory (the GTT pool; the "
                     "kernel's default is about half of the RAM). The kernel options ttm.pages_limit and "
                     "ttm.page_pool_size give it more (docs/DETAILS.md, AMD APUs); setup changes no host setting")
    if gpu.get("carve_gb", 0.0) > 16:
        notes.append(f"!the BIOS carve-out is {gpu['carve_gb']:.0f} GB: that memory is taken from the OS, while the "
                     "GPU reaches the shared memory anyway. A small carve-out (512 MB - 2 GB) leaves the RAM to the "
                     "model")
    if ram + gpu.get("carve_gb", 0.0) >= STRIX_HALO_MIN_GB:
        notes.append(f"  Recommended model: {STRIX_HALO_MODEL} (Unsloth); the menus list the others.")
    return notes


def rocm_roots() -> list:
    """AMD's ROCm tree the build takes, as one ([] without one), so that two installed versions are not mixed: /opt/rocm
    where it holds lib/ or include/ (ROCm 7.2's alternatives link to /opt/rocm-<version>, or ROCm 7.14's links into
    /opt/rocm/core-7.14 that its amdrocm-core packages make), else /opt/rocm/core (their alternatives link), else the
    newest /opt/rocm/core-<version> (ROCm 7.14's packages without amdrocm-core: nothing of /opt/rocm's own), else the
    newest /opt/rocm-<version>.  The newest by the version's numbers: core-10.1 after core-7.14."""
    def newest(paths):
        return sorted(paths, key=lambda p: [int(n) for n in re.findall(r"\d+", p.name)], reverse=True)
    opt = Path("/opt/rocm")
    for root in [opt, opt / "core", *newest(opt.glob("core-*")), *newest(Path("/opt").glob("rocm-*"))]:
        if (root / "lib").is_dir() or (root / "include").is_dir():
            return [root.resolve() if root.is_symlink() else root]
    return []


def rocm_lib_dirs() -> list:
    """The folders of AMD's ROCm libraries the engine needs on its library path: none where the loader finds
    libamdhip64 (a distribution's, or a ROCm that installs an ld.so.conf); ROCm 7.14's packages install none, and the
    SYCL runtime's HIP adapter then did not load (no GPU listed) until its lib/ was on LD_LIBRARY_PATH."""
    try:
        cached = subprocess.run(["ldconfig", "-p"], capture_output=True, text=True).stdout
    except OSError:
        cached = ""
    if "libamdhip64.so" in cached:
        return []
    return [str(r / "lib") for r in rocm_roots() if any((r / "lib").glob("libamdhip64.so*"))][:1]


def rocblas_archs() -> set | None:
    """The AMD architectures the distribution's rocBLAS has code for (its kernels' file names), None without rocBLAS:
    the engine's dense matrix products run in it, so an AMD GPU it has no code for cannot run the engine."""
    dirs = [d for d in (Path("/usr/lib64/rocblas/library"), *(r / "lib/rocblas/library" for r in rocm_roots()),
                        *Path("/usr/lib").glob("*/rocblas/*/library")) if d.is_dir()]
    if not dirs:
        return None
    return {m.group(0) for d in dirs for f in d.iterdir() if (m := re.search(r"gfx[0-9a-f]+", f.name))}


def distro_id() -> str:
    """The distribution's ID in /etc/os-release ("ubuntu", "fedora"), empty when it cannot be read."""
    try:
        m = re.search(r"^ID=\"?([^\"\n]*)", Path("/etc/os-release").read_text(), re.M)
    except OSError:
        return ""
    return m.group(1) if m else ""


def distro_family() -> str:
    """Which list of PACKAGES this PC's packages come from ("ubuntu", "fedora", "arch"): the ID in /etc/os-release, or
    ID_LIKE for a distribution whose own ID names nothing there (CachyOS: ID=cachyos, ID_LIKE=arch).  A distribution
    neither names gets Ubuntu's list (apt), which its package names are usually close to."""
    try:
        text = Path("/etc/os-release").read_text()
    except OSError:
        return "ubuntu"
    ids = " ".join(re.findall(r"^ID(?:_LIKE)?=\"?([^\"\n]*)", text, re.M)).split()
    for family in PACKAGES:
        if any(i == family or i.startswith(family) for i in ids):
            return family
    return "ubuntu"


def amd_elsewhere() -> str:
    """Where an AMD GPU that this distribution's rocBLAS lacks runs: Fedora 44's rocBLAS has code for more of them
    (README.md, "AMD GPUs")."""
    return ("see README.md (AMD GPUs)" if distro_id() == "fedora" else
            "Fedora 44's has code for more AMD GPUs (README.md, AMD GPUs)")


# The distribution packages that building and running XeStrata from the source needs (docs/BUILD.md, "Packages"), by
# distribution and part: "base" for the free and contrib modes (intel/llvm's build tools, the image encoders' and the
# optional conversation compression's), and each GPU maker's (Intel's oneMKL in the contrib mode only, NVIDIA's in the
# contrib mode only).  On Arch the
# Vulkan ICD is the GPU maker's own package, not one mesa-vulkan-drivers carries for both.
# oneMKL's series the contrib mode takes, and only it (Intel's repositories carry several side by side): one whose SYCL
# library runs on the SYCL runtime XeStrata builds with, which tools/intel_llvm_build.py's TAG fixes (2026.2's needs
# functions intel/llvm v7.1.1's libsycl.so.9 lacked, sycl::detail::defaultAsyncHandler among them: v7.2.0).  Raised
# with TAG.  The packages take it too (tools/package/container.sh, windows.sh), and setup takes a oneMKL of it only
# (mkl_root, windows_intel_libs; on Windows the engine, which reads its series from the oneMKL it was built with).
ONEMKL_SERIES = "2026.2"
PACKAGES = {
    "ubuntu": {
        "base": "python3-venv git cmake ninja-build build-essential lld libhwloc-dev libzstd-dev libvulkan-dev glslc "
                "spirv-headers mesa-vulkan-drivers libblosc2-dev",
        "intel": "libze1 libze-intel-gpu1 libigc2 libigdfcl2",
        "intel-contrib": f"intel-oneapi-mkl-sycl-devel-{ONEMKL_SERIES}",
        "amd": "libamdhip64-dev rocm-device-libs-21 clang-21 libclang-rt-21-dev librocblas-dev libhipblaslt-dev "
               "libhipblas-common-dev",
        "nvidia": "nvidia-cuda-toolkit",
    },
    "fedora": {
        "base": "python3 git cmake ninja-build gcc-c++ lld hwloc-devel libzstd-devel libzstd-static "
                "vulkan-loader-devel glslc spirv-headers-devel mesa-vulkan-drivers blosc2-devel",
        "intel": "oneapi-level-zero oneapi-level-zero-devel intel-level-zero",
        "intel-contrib": f"intel-oneapi-mkl-sycl-devel-{ONEMKL_SERIES}",
        "amd": "rocm-hip-devel rocm-device-libs rocm-clang rocm-clang-runtime-devel rocblas-devel hipblaslt-devel "
               "hipblas-common-devel",
        "nvidia": "cuda-toolkit-13-4",
    },
    "arch": {
        # Arch and its derivatives (ID_LIKE=arch).  Intel's oneAPI repository has no Arch packages: there is no oneMKL
        # (Intel's offline installer is the way to it), so an Intel GPU's dense products stay in XeStrata's own
        # kernels.  zstd's package has no libzstd.a, so
        # intel/llvm's build links the shared one (tools/intel_llvm_build.py).
        # opencl-headers: intel/llvm's SYCL tools (sycl-ls, part of what its build installs) include CL/cl.h, and they
        # get no include for the OpenCL headers the configuration fetches (those are the runtime's own objects'); Arch's
        # clang does not bring the header in, Ubuntu's and Fedora's builds have it
        "base": "python base-devel git cmake ninja lld hwloc zstd vulkan-headers vulkan-icd-loader shaderc "
                "spirv-headers opencl-headers blosc2",
        "intel": "level-zero-loader intel-compute-runtime vulkan-intel",
        "intel-contrib": "",
        # ROCm's clang (rocm-llvm) carries clang's runtime builtins too, which HIP's CMake package asks for where
        # PACKAGES' other lists name a package of their own for them (Debian's libclang-rt-21-dev)
        "amd": "hip-runtime-amd rocm-device-libs rocm-llvm rocm-llvm rocblas hipblaslt hipblas-common vulkan-radeon",
        "nvidia": "cuda",
    },
}

# The packages of the tools setup does not install itself, for its messages, by distro_family()
TOOL_PACKAGES = {
    "ubuntu": {"g++": "build-essential", "glslc": "glslc", "vulkan": "libvulkan-dev", "spirv": "spirv-headers"},
    "fedora": {"g++": "gcc-c++", "glslc": "glslc", "vulkan": "vulkan-loader-devel", "spirv": "spirv-headers-devel"},
    "arch": {"g++": "base-devel", "glslc": "shaderc", "vulkan": "vulkan-headers", "spirv": "spirv-headers"},
}

# The command that installs distribution packages on this PC, by distro_family()
INSTALLERS = {"ubuntu": "sudo apt install ", "fedora": "sudo dnf install ", "arch": "sudo pacman -S --needed "}


def install_cmd(packages) -> str:
    """The command that installs these packages (PACKAGES' names) on this PC."""
    return INSTALLERS[distro_family()] + " ".join(packages)


def tool_pkg(kind: str) -> str:
    """The package of one of the tools setup does not install itself (TOOL_PACKAGES), for this PC."""
    return TOOL_PACKAGES[distro_family()][kind]


def packages_for(distro: str, makers: set, mode: str) -> tuple:
    """The packages (PACKAGES) for a distribution ("ubuntu", "fedora", "arch"), the GPU makers ("intel", "amd",
    "nvidia") and the build mode, and the notes that go with them (the repositories, what a mode cannot build)."""
    p = PACKAGES[distro]
    names = p["base"].split()
    notes = []
    if "intel" in makers:
        names += p["intel"].split() + (p["intel-contrib"].split() if mode == "contrib" else [])
        if distro == "arch" and mode == "contrib":
            notes.append("Arch: oneMKL (Intel's oneAPI repository) is not there, and the contrib mode hands "
                         "the Intel GPU's dense products to it: Intel's offline installer, or --license free")
    if "amd" in makers:
        names += p["amd"].split()
    if "nvidia" in makers:
        if mode == "contrib":
            names += p["nvidia"].split()
            notes.append("NVIDIA GPUs: NVIDIA's driver as well" +
                         (" (cuda-toolkit-13-4 is in NVIDIA's CUDA repository)" if distro == "fedora" else ""))
        else:
            notes.append("NVIDIA GPUs: the contrib mode only (--license contrib)")
    if any(n.startswith("intel-oneapi-") for n in names):
        notes.append("intel-oneapi-* are in Intel's oneAPI repository (docs/BUILD.md, Packages)")
    return list(dict.fromkeys(names)), notes


def print_packages(spec: str, mode: str) -> int:
    """setup --packages [DISTRO/MAKERS]: the install command for a distribution, GPU makers and build mode; without
    DISTRO/MAKERS, this PC's distribution and GPUs."""
    if PACKAGED and not spec:                          # the package's engine: what this PC's GPUs need
        makers = {g["vendor"] for g in gpus() if gpu_problem(g) is None}
        lines = runtime_commands(*runtime_missing(makers))
        say("Packages for your GPUs:" if lines else "Your GPUs have the packages they need.")
        for line in lines:
            say(line)
        return 0
    if spec:
        distro, _, makers_s = spec.partition("/")
        makers = {m.strip() for m in makers_s.split(",") if m.strip()}
        distro = next((f for f in PACKAGES if distro.startswith(f)), distro)
    else:
        distro, makers = distro_family(), {g["vendor"] for g in gpus()}
    if distro not in PACKAGES:
        fail(f"--packages: no list for {distro or 'this distribution'}",
             "the lists are for Ubuntu 26.04, Fedora 44 and Arch: e.g. --packages ubuntu26.04/intel,amd")
    if not makers or not makers <= {"intel", "amd", "nvidia"}:
        fail("--packages: the GPU makers are intel, amd and nvidia" + ("" if spec else " (no GPU of theirs found)"),
             "e.g. --packages fedora44/intel,amd")
    names, notes = packages_for(distro, makers, mode)
    say(f"Packages for {distro}, {', '.join(sorted(makers))} GPUs, the {mode} build:")
    say("  " + INSTALLERS[distro] + " ".join(names))
    for n in notes:
        say(f"  - {n}")
    return 0


# Intel's graphics packages newer than the distribution's, from the PPA the compute-runtime project names
# (launchpad.net/~kobuk-team/+archive/ubuntu/intel-graphics; the same packages' .deb are on its GitHub releases).
# Ubuntu 26.04 ships compute-runtime 26.05 and IGC 2.28: below the 26.22 that fixes Level Zero refusing device
# memory while the VRAM is free (intel/compute-runtime #916, XeStrata #34 - only a host reboot clears it), and in
# the IGC 2.27-2.30 the engine has to work around.  The PPA's resolute suite carries 26.31 and IGC 2.40.
INTEL_GRAPHICS_REPO = {
    "ubuntu": "sudo add-apt-repository -y ppa:kobuk-team/intel-graphics\n"
              "  sudo apt update\n"
              "  sudo apt install libze-intel-gpu1 libze1 intel-metrics-discovery intel-opencl-icd clinfo intel-gsc\n"
              "  sudo apt install libze-dev intel-ocloc",
}


# Adding Intel's oneAPI repository (oneMKL) and NVIDIA's CUDA one on Fedora (cuBLAS), as tools/package/container.sh
# does
INTEL_REPO = {
    "ubuntu": ("wget -O- https://apt.repos.intel.com/intel-gpg-keys/GPG-PUB-KEY-INTEL-SW-PRODUCTS.PUB \\\n"
               "    | gpg --dearmor | sudo tee /usr/share/keyrings/oneapi-archive-keyring.gpg > /dev/null\n"
               "  echo \"deb [signed-by=/usr/share/keyrings/oneapi-archive-keyring.gpg] "
               "https://apt.repos.intel.com/oneapi all main\" \\\n"
               "    | sudo tee /etc/apt/sources.list.d/oneAPI.list\n"
               "  sudo apt update"),
    "fedora": ("printf '%s\\n' '[oneAPI]' 'name=Intel oneAPI repository' \\\n"
               "    'baseurl=https://yum.repos.intel.com/oneapi' 'enabled=1' 'gpgcheck=1' 'repo_gpgcheck=1' \\\n"
               "    'gpgkey=https://apt.repos.intel.com/intel-gpg-keys/GPG-PUB-KEY-INTEL-SW-PRODUCTS.PUB' \\\n"
               "    | sudo tee /etc/yum.repos.d/oneAPI.repo > /dev/null"),
}


def pkg_installed(name: str) -> bool:
    """Whether the distribution package (or, on Fedora and Arch, what provides the capability) is installed."""
    family = distro_family()
    cmd = (["rpm", "-q", "--whatprovides", name] if family == "fedora" else
           ["pacman", "-T", name] if family == "arch" else
           ["dpkg-query", "-W", "-f", "${db:Status-Abbrev}", name])
    try:
        r = subprocess.run(cmd, capture_output=True, text=True)
    except OSError:
        return True                                    # no package manager to ask: nothing is said
    return r.returncode == 0 and (family in ("fedora", "arch") or r.stdout.startswith("ii"))


def repo_added(url: str) -> bool:
    """Whether apt's or dnf's sources name the repository at `url`."""
    files = [Path("/etc/apt/sources.list"), *Path("/etc/apt/sources.list.d").glob("*"),
             *Path("/etc/yum.repos.d").glob("*.repo")]
    for f in files:
        try:
            if url in f.read_text(errors="replace"):
                return True
        except OSError:
            continue
    return False


def runtime_missing(makers: set) -> tuple:
    """For the package's engine: the GPU makers' packages (BUILD.json's runtime) that the GPUs of `makers` need and
    are not installed, those that would make them faster (OpenCL, which oneDNN's attention runs on; oneMKL, cuBLAS:
    contrib; pip's are linux_nvidia_libs'), and the commands that add the repositories those come from.  Empty for an
    engine without the record."""
    rt = packaged_engine().get("runtime") or {}
    need = [n for m in ("intel", "amd") if m in makers for n in rt.get(m, []) if not pkg_installed(n)]
    fast = [n for m, k in (("intel", "onednn"), ("intel", "onemkl"), ("nvidia", "cublas")) if m in makers
            for n in rt.get(k, []) if not pkg_installed(n)]
    d = distro_family()
    repos = []
    if any(n in rt.get("onemkl", []) for n in fast) and d in INTEL_REPO and \
            not repo_added("repos.intel.com/oneapi"):
        repos.append(INTEL_REPO[d])
    return need, fast, repos


def runtime_commands(need: list, fast: list, repos: list) -> list:
    """The lines that install them: the repositories first, then the packages in one command."""
    return [f"  {r}" for r in repos] + ([f"  {install_cmd(need + fast)}"] if need or fast else [])


def igc_version() -> str | None:
    """The version of the Intel Graphics Compiler the loader finds (libigc.so.2 -> libigc.so.2.28.4+0: "2.28.4"), None
    when there is none or its file name carries no version."""
    if WIN:
        return None
    try:
        out = subprocess.run(["ldconfig", "-p"], capture_output=True, text=True, timeout=30).stdout
    except (OSError, subprocess.SubprocessError):
        return None
    for line in out.splitlines():
        if "libigc.so.2 " in line and " => " in line:
            name = os.path.basename(os.path.realpath(line.split(" => ", 1)[1].strip()))
            m = re.fullmatch(r"libigc\.so\.(\d+(?:\.\d+)+).*", name)
            return m.group(1) if m else None
    return None


def level_zero_build() -> int | None:
    """The Level Zero driver's build number (libze_intel_gpu.so.1.14.37020 -> 37020; compute-runtime 26.05.37020),
    None when the loader finds none or its file name carries no number.  The distributions' compute-runtime can be
    older than Intel's: 26.22.38646.4 is where a kernel xe bug's fallout was worked around on the runtime side
    (intel/compute-runtime #916; XeStrata #34, #15)."""
    if WIN:
        return None
    try:
        out = subprocess.run(["ldconfig", "-p"], capture_output=True, text=True, timeout=30).stdout
    except (OSError, subprocess.SubprocessError):
        return None
    for line in out.splitlines():
        if "libze_intel_gpu.so.1 " in line and " => " in line:
            name = os.path.basename(os.path.realpath(line.split(" => ", 1)[1].strip()))
            m = re.fullmatch(r"libze_intel_gpu\.so\.\d+\.\d+\.(\d+)", name)
            return int(m.group(1)) if m else None
    return None


#: The first compute-runtime build with the Level Zero allocation fix of intel/compute-runtime #916 (26.22.38646.4):
#: below it, a driver state can refuse device memory while the VRAM is free, and only a host reboot clears it.
LEVEL_ZERO_FIXED_BUILD = 38646


def igc_affected(version: str | None) -> bool:
    """IGC 2.27 to 2.30 miscompile some reads for Xe2 and later GPUs (2.24 and 2.32 on do not): the engine turns their
    GEP simplification off, which costs decode speed on short prompts (AGENTS.md, "Intel Graphics Compiler")."""
    if not version:
        return False
    parts = version.split(".")
    try:
        major, minor = int(parts[0]), int(parts[1])
    except (IndexError, ValueError):
        return False
    return major == 2 and 25 <= minor < 32


def ubuntu_lts() -> str | None:
    """Ubuntu 24.04 or 26.04 ("26.04"), the two LTS releases the graphics PPA serves; None elsewhere."""
    if distro_id() != "ubuntu":
        return None
    try:
        m = re.search(r"^VERSION_ID=\"?(\d+\.\d+)", Path("/etc/os-release").read_text(), re.M)
    except OSError:
        return None
    return m.group(1) if m and m.group(1) in ("24.04", "26.04") else None


def hwe_kernel(v: str) -> bool:
    """Whether the HWE kernel of Ubuntu release `v` is installed (its meta package, linux-generic-hwe-26.04): the
    kernel the graphics PPA's driver is meant to run on.  The GA kernel's xe driver is older: on 24.04 it has no code
    for an Arc B-series, on 26.04 (7.0) it carries the xe bug the driver update only covers (XeStrata #34)."""
    return pkg_installed(f"linux-generic-hwe-{v}")


def graphics_repo() -> str | None:
    """The lines that bring Intel's graphics PPA in (INTEL_GRAPHICS_REPO), when this distribution has one; without
    the add-apt-repository line when it was added already."""
    d = distro_family()
    if d not in INTEL_GRAPHICS_REPO:
        return None
    if repo_added("kobuk-team/intel-graphics"):
        return "\n".join(INTEL_GRAPHICS_REPO[d].split("\n")[1:])   # only the update and install lines
    return INTEL_GRAPHICS_REPO[d]


_g_driver_update_said = False


def say_driver_update(lts: str) -> None:
    """The commands that bring the driver up: the HWE kernel first on the GA one, then the graphics PPA.  Both the
    IGC check and the Level Zero check send the user here, and when both fire - the usual case on Ubuntu 26.04,
    whose IGC 2.28 and compute-runtime 26.05 are both old - they are said once, not twice."""
    global _g_driver_update_said
    if _g_driver_update_said:
        return
    _g_driver_update_said = True
    if not hwe_kernel(lts):
        say(f"  sudo apt install --install-recommends linux-generic-hwe-{lts}")
    for line in (graphics_repo() or "").split("\n"):
        if line.strip():
            say(line)


def check_igc(makers: set) -> None:
    """Says, without stopping, when an Intel GPU of Xe2 or later (the xe driver's graphics IP 20 or later, as the
    engine asks it: xe_gpu_from_xe2 in src/core/device.cpp) runs with a compiler the engine works around
    (igc_affected), and sends the user to Fedora 44, whose IGC is a fixed one, or to the Podman container (Fedora
    44 inside).  Ubuntu 24.04/26.04 is sent to the graphics PPA too - with the HWE kernel straight to it, from the
    GA kernel to the HWE kernel first (the PPA installs the driver with the IGC, and that driver is the one for the
    HWE kernel)."""
    if WIN or "intel" not in makers:
        return
    v = igc_version()
    if not igc_affected(v):
        return
    if not any(g["vendor"] == "intel" and (g.get("ip") or 0) >= 20 for g in gpus()):
        return
    warn(f"Intel's compiler (IGC {v}) has a bug XeStrata works around at the engine's start: the decode of short "
         "prompts is up to 10% slower. For full speed, use Fedora 44 (its IGC is 2.32 or later), or install "
         "with Podman (Fedora 44 inside: README, Install)")
    lts = ubuntu_lts()
    if lts:
        if hwe_kernel(lts):
            say("  or update the driver from the graphics PPA (its IGC is a fixed one):")
        else:
            say("  or move to the HWE kernel and update the driver from the graphics PPA (its IGC is a fixed one):")
        say_driver_update(lts)


def check_level_zero(makers: set, yes: bool = False, explicit: bool = False) -> None:
    """When the Level Zero driver is older than the build that fixed it refusing device memory while the VRAM is
    free (intel/compute-runtime #916; XeStrata #34 and #15: every allocation on the card can fail that way after a
    GPU fault, and only a host reboot clears it).  On Ubuntu 24.04/26.04 with the HWE kernel the graphics PPA
    brings the fixed driver, and the start is stopped until it is updated or the user asks to go on (confirm_risk,
    --old-driver as the explicit consent); on the GA kernel, where the PPA's driver does not belong, the user is
    sent to the HWE kernel and the PPA, or to Fedora 44, and the start goes on.  Elsewhere nothing is said: no
    repository to point at."""
    if WIN or "intel" not in makers:
        return
    build = level_zero_build()
    if build is None or build >= LEVEL_ZERO_FIXED_BUILD:
        return
    lts = ubuntu_lts()
    if lts and hwe_kernel(lts):
        say_driver_update(lts)   # nothing when the IGC check, which fired first, already said the commands
        confirm_risk(f"the Level Zero driver (build {build}) predates the fix for refusing device memory while "
                     "the VRAM is free: the engine can fail to start, and only a host reboot clears the card "
                     "(XeStrata #34). Update it from the graphics PPA (compute-runtime 26.22 or later; the "
                     "commands above), then reboot:",
                     explicit, yes,
                     "not starting with a Level Zero driver that old: update it (the commands above), reboot, and "
                     "run this again",
                     "or, to start anyway, run this again with --old-driver",
                     "  Start with this driver anyway?")
    elif lts:
        again = " - the commands above" if _g_driver_update_said else ""
        warn(f"the Level Zero driver (build {build}) predates the fix for refusing device memory while the VRAM is "
             "free (the engine can fail to start; only a host reboot clears the card), and the GA kernel's xe "
             "driver is the older one: move to the HWE kernel and the graphics PPA, or use Fedora 44 / Podman "
             f"(README, Install){again}")
        say_driver_update(lts)
    else:
        warn(f"the Level Zero driver (build {build}) predates the fix for refusing device memory while the VRAM is "
             "free: the engine can fail to start, and only a host reboot clears the card (XeStrata #34, "
             "intel/compute-runtime #916). Update the driver (compute-runtime 26.22 or later), or use Fedora 44 / "
             "Podman (their drivers are newer)")


def windows_nvidia_libs() -> list:
    """The NVIDIA libraries the engine would not find on Windows, where it looks (add_library_dirs in
    src/prefill/gemm.cpp, open_cudnn in src/image/qi_sdpa.cpp): the PATH, the CUDA toolkit's (CUDA_PATH), NVIDIA's
    cuDNN installer's folders, the Python beside the engine (pip's nvidia-*-cu12).  Their pip packages' names."""
    path = [Path(d) for d in os.environ.get("PATH", "").split(os.pathsep) if d]
    if os.environ.get("CUDA_PATH"):
        path.append(Path(os.environ["CUDA_PATH"]) / "bin")
    pip = Path(sys.executable).parent / "Lib" / "site-packages" / "nvidia"
    missing = []
    for pkg, sub, dll in (("nvidia-cublas-cu12", "cublas", "cublas64_12.dll"),
                          ("nvidia-cuda-runtime-cu12", "cuda_runtime", "cudart64_12.dll"),
                          ("nvidia-cudnn-cu12", "cudnn", "cudnn64_9.dll")):
        dirs = path + [pip / sub / "bin"]
        if sub == "cudnn":
            root = Path(os.environ.get("ProgramFiles", r"C:\Program Files")) / "NVIDIA" / "CUDNN"
            dirs += [p.parent for p in root.glob("*/bin/**/cudnn64_9.dll")] if root.is_dir() else []
        if not any((d / dll).is_file() for d in dirs):
            missing.append(pkg)
    return missing


def windows_intel_libs() -> list:
    """pip's packages of oneMKL (BUILD.json's runtime "onemkl_pip": the version the 7z was built with, without the
    SYCL runtime they depend on, which the 7z carries) when the engine would not find oneMKL of that series on Windows
    where it looks first (add_library_dirs in src/prefill/gemm.cpp): pip's in the Python beside the engine (its
    dist-info's version), oneAPI's installer's folder of the series (ONEAPI_ROOT, its default); empty when it would.
    Another series (the PATH's, MKLROOT's, oneAPI's latest) is not counted: its SYCL library may not load."""
    names = (packaged_engine().get("runtime") or {}).get("onemkl_pip") or []
    version = next((n.split("==", 1)[1] for n in names if n.startswith("onemkl-sycl-blas==")), "")
    series = ".".join(version.split(".")[:2])
    site = Path(sys.executable).parent / "Lib" / "site-packages"
    if version and any(site.glob(f"onemkl_sycl_blas-{version}.dist-info")):
        return []
    for root in (os.environ.get("ONEAPI_ROOT"), r"C:\Program Files (x86)\Intel\oneAPI"):
        d = Path(root) / "mkl" / series / "bin" if root and series else None
        if d and d.is_dir() and next(d.glob("mkl_sycl_blas*.dll"), None):
            return []
    return names


# AMD's Python packages for Windows with rocBLAS and hipBLASLt (rocm-sdk-libraries-<family>, free software), one per
# GPU family: the release whose DLLs export what the engine's rocBLAS backend imports (tools/package/win_rocm.sh)
ROCM_WIN_INDEX = "https://repo.amd.com/rocm/whl/"
ROCM_WIN_VERSION = "7.13.0"


def rocm_win_family(gfx: str):
    """The family of AMD's Windows packages (their index's folder) that has rocBLAS's and hipBLASLt's code for `gfx`,
    or None."""
    if gfx in ("gfx1150", "gfx1151", "gfx1152"):
        return gfx
    for prefix, family in (("gfx103", "gfx103X-all"), ("gfx110", "gfx110X-all"), ("gfx120", "gfx120X-all")):
        if gfx.startswith(prefix):
            return family
    return None


def windows_amd_libs(gfx: set) -> list:
    """pip's commands for AMD's rocBLAS and hipBLASLt the engine would not find on Windows for the AMD GPUs of `gfx`,
    where it looks (add_library_dirs in src/prefill/gemm.cpp): the PATH, the Python beside the engine."""
    path = [Path(d) for d in os.environ.get("PATH", "").split(os.pathsep) if d]
    site = Path(sys.executable).parent / "Lib" / "site-packages"
    commands = []
    for family in sorted({f for g in gfx if g and (f := rocm_win_family(g))}):
        dirs = path + [site / f"_rocm_sdk_libraries_{family.replace('-', '_')}" / "bin"]
        if not any((d / "rocblas.dll").is_file() and (d / "libhipblaslt.dll").is_file() for d in dirs):
            # --no-deps: the HIP runtime is the AMD driver's (amdhip64_7.dll), not the SDK's core package
            commands.append(f'"{sys.executable}" -m pip install --no-deps --index-url {ROCM_WIN_INDEX}{family}/ '
                            f"rocm-sdk-libraries-{family.lower()}=={ROCM_WIN_VERSION}")
    return commands


def nvidia_libs_dir(data: Path) -> Path:
    """Linux: where NVIDIA's libraries go that neither Ubuntu's nor Fedora's own repositories have (NVIDIA's
    repositories are not used): cuDNN and the CUDA runtime cudnn-frontend opens, and Fedora's cuBLAS, from pip, in the
    data folder's nvidia-libs/, beside the models (a container mounts it at the same path)."""
    return Path(data) / "nvidia-libs"


def nvidia_lib_dirs(data: Path) -> list:
    """The folders of nvidia_libs_dir's libraries for the engine's library path (a folder that is not there is skipped
    where the server starts the engine, so what is installed later is taken from the next start): cuDNN's, and CUDA
    13's (nvidia-cuda-runtime, nvidia-cublas) and 12's CUDA runtime (nvidia-cuda-runtime-cu12)."""
    nv = nvidia_libs_dir(data) / "nvidia"
    return [str(nv / "cudnn" / "lib"), str(nv / "cu13" / "lib"), str(nv / "cuda_runtime" / "lib")]


def cuda_major(root: str) -> int | None:
    """The major version of the CUDA toolkit in `root`: its version.json, else its nvcc's (Debian's has no file)."""
    try:
        return int(json.loads((Path(root) / "version.json").read_text())["cuda"]["version"].split(".")[0])
    except (OSError, ValueError, KeyError, TypeError):
        pass
    nvcc = Path(root) / "bin" / "nvcc"
    try:
        out = subprocess.run([str(nvcc) if nvcc.exists() else "nvcc", "--version"], capture_output=True, text=True,
                             timeout=30).stdout
    except (OSError, subprocess.SubprocessError):
        return None
    m = re.search(r"release (\d+)\.", out)
    return int(m.group(1)) if m else None


def nvidia_pip_names(major: int) -> list:
    """pip's packages of cuDNN and the CUDA runtime for a CUDA major version, for an engine compiled here (whose cuBLAS
    is the CUDA toolkit's); tools/package/container.sh names the packages' (BUILD.json's runtime "nvidia_pip")."""
    if major == 12:
        return ["nvidia-cudnn-cu12", "nvidia-cuda-runtime-cu12"]
    return [f"nvidia-cudnn-cu{major}", f"nvidia-cuda-runtime=={major}.*"]


def linux_nvidia_libs(makers: set, data: Path, names: list) -> None:
    """Names pip's command for NVIDIA's libraries (`names`) when one of them is neither on the system nor in
    nvidia_libs_dir: into nvidia_libs_dir, which the engine's library path holds (nvidia_lib_dirs), with --target
    (Ubuntu's Python refuses --user, PEP 668), --upgrade (a target folder's packages are otherwise kept as they are)
    and --no-deps (what the distribution has, it gives)."""
    import ctypes.util
    import importlib.util
    import shlex
    if WIN or "nvidia" not in makers or not names:
        return
    dirs = [Path(d) for d in nvidia_lib_dirs(data)]

    def found(lib: str) -> bool:
        return bool(ctypes.util.find_library(lib)) or any(next(d.glob(f"lib{lib}.so.*"), None) for d in dirs
                                                          if d.is_dir())
    missing = [what for what, lib, want in (("cuBLAS for the matrix products", "cublas",
                                             any(n.startswith("nvidia-cublas") for n in names)),
                                            ("cuDNN for the image engine's attention", "cudnn", True))
               if want and not found(lib)]
    if not missing:
        return
    warn(f"faster with NVIDIA's {' and '.join(missing)} (not free software; without them XeStrata's own kernels do "
         "the work), into the data folder:")
    if importlib.util.find_spec("pip") is None:
        say(f"  {install_cmd(['python3-pip'])}")
    say(f"  python3 -m pip install --target {shlex.quote(str(nvidia_libs_dir(data)))} --upgrade --no-deps "
        + " ".join(shlex.quote(n) for n in names))


def check_runtime(makers: set, gfx: set, data: Path, yes: bool = False, explicit: bool = False) -> None:
    """Stops when the GPUs of `makers` lack their makers' packages, and says how to install them; names oneMKL and
    cuBLAS too when they are missing, without stopping (XeStrata's own kernels do their work).  Windows: the GPU
    makers' drivers bring what the engine runs on (Level Zero, the CUDA driver), the 7z the rest, and the launcher
    checks the Visual C++ runtime.  Intel's oneMKL, NVIDIA's cuBLAS, CUDA runtime and cuDNN, and AMD's rocBLAS and
    hipBLASLt for the AMD GPUs' families (`gfx`, their gfx names), are named when the engine would not find them, with
    pip's command for the Python the 7z carries."""
    if WIN:
        mkl = windows_intel_libs() if "intel" in makers and packaged_engine().get("license") == "contrib" else []
        if mkl:
            warn("faster with Intel's oneMKL for the matrix products (not free software; without it XeStrata's own "
                 "kernels do the work):")
            say(f'  "{sys.executable}" -m pip install --no-deps ' + " ".join(f'"{n}"' for n in mkl))
        missing = windows_nvidia_libs() if "nvidia" in makers and packaged_engine().get("license") == "contrib" else []
        if missing:
            warn("faster with NVIDIA's " + ", ".join(missing) + " (not free software: cuBLAS for the matrix products, "
                 "cuDNN for the image engine's attention; without them XeStrata's own kernels do the work):")
            say(f'  "{sys.executable}" -m pip install ' + " ".join(missing))
        amd = windows_amd_libs(gfx) if "amd" in makers else []
        if amd:
            warn("faster with AMD's rocBLAS and hipBLASLt for the matrix products (without them XeStrata's own kernels "
                 "do the work):")
            for c in amd:
                say("  " + c)
        return
    check_igc(makers)
    check_level_zero(makers, yes, explicit)
    linux_nvidia_libs(makers, data, (packaged_engine().get("runtime") or {}).get("nvidia_pip") or [])
    need, fast, repos = runtime_missing(makers)
    if not need and not fast:
        return
    lines = runtime_commands(need, fast, repos)
    if need:
        fail("the GPU's libraries are missing: " + ", ".join(need),
             "install them, then run it again:\n" + "\n".join(lines))
    warn("faster with " + ", ".join(fast) + " (without them XeStrata's own kernels do the work):")
    for line in lines:
        say(line)


def rocm_missing() -> list:
    """The ROCm packages building the AMD code needs that are not installed (PACKAGES' AMD part): HIP's headers
    (intel/llvm's HIP target), the device libraries the code links, ROCm's clang with its runtime (HIP's CMake package
    asks it for clang's runtime builtins, which intel/llvm lacks: cmake/StrataHip.cmake), rocBLAS and hipBLASLt
    (oneMath's rocBLAS backend: the dense products), and hipblas-common, which hipBLASLt's CMake package needs and its
    distribution package does not depend on."""
    import glob
    roots = rocm_roots()
    inc = [Path("/usr/include"), *(r / "include" for r in roots)]
    clang_ok = False
    for cxx in [str(c) for r in roots for c in (r / "llvm/bin/clang++", r / "lib/llvm/bin/clang++") if c.exists()] + \
            glob.glob("/usr/lib64/rocm/llvm/bin/clang++") + glob.glob("/usr/lib/llvm-*/bin/clang++"):
        r = subprocess.run([cxx, "-print-libgcc-file-name", "--rtlib=compiler-rt"], capture_output=True, text=True)
        clang_ok = clang_ok or (r.returncode == 0 and Path(r.stdout.strip()).is_file())
    # in the order of PACKAGES' AMD part
    have = [any((d / "hip" / "hip_runtime_api.h").exists() for d in inc),
            # (an intel/llvm built here has its own: tools/intel_llvm_build.py; Arch's ROCm keeps it in its clang's
            # tree)
            any((r / d / "ockl.bc").exists() for r in roots for d in ("amdgcn/bitcode", "lib/llvm/amdgcn/bitcode")) or
            any(glob.glob(g) for g in (*(str(r / "lib/llvm/lib/clang/*/lib/amdgcn/bitcode/ockl.bc")
                                         for r in roots),
                                       "/usr/lib64/rocm/llvm/lib/clang/*/lib/amdgcn/bitcode/ockl.bc",
                                       "/usr/lib/llvm-*/lib/clang/*/amdgcn/bitcode/ockl.bc",
                                       "/usr/lib/llvm-*/lib/clang/*/lib/amdgcn/bitcode/ockl.bc",
                                       str(INTEL_LLVM_DEFAULT / "amdgcn/bitcode/ockl.bc"),
                                       str(INTEL_LLVM_CONTRIB / "amdgcn/bitcode/ockl.bc"))),
            clang_ok, clang_ok,
            any((d / "rocblas" / "rocblas.h").exists() for d in inc),
            any((d / "hipblaslt" / "hipblaslt.h").exists() for d in inc),
            any((d / "hipblas-common" / "hipblas-common.h").exists() for d in inc)]
    # the names follow PACKAGES' AMD part position by position (its other lists name one package for both clang and
    # clang's runtime builtins; ROCm's clang carries both on Arch, so its name is there twice)
    names = PACKAGES[distro_family()]["amd"].split()
    return list(dict.fromkeys(n for n, ok_ in zip(names, have) if not ok_))


def gpus():
    """Every Intel GPU on the xe or i915 driver in PCI order (the order Level Zero numbers them), then every NVIDIA GPU
    on NVIDIA's driver and every AMD GPU on amdgpu (after them, so that the Intel cards keep the numbers saved configs
    know them by), from sysfs, the Intel driver's memory query, nvidia-smi and the KFD topology: no tool of Strata's is
    needed before the engine is built.  Nothing is decided from the device ID: the engine checks at start what the
    card reports (AGENTS.md).  Windows has no sysfs: there the engine lists the GPUs (gpus_from_engine)."""
    if WIN:
        return gpus_from_engine()
    found, nvidia, amd = [], [], []
    kfd = None
    smi = None
    cards = [c for c in Path("/sys/class/drm").glob("card*") if re.fullmatch(r"card\d+", c.name)]
    for card in sorted(cards, key=lambda c: (c / "device").resolve().name):
        dev = card / "device"
        try:
            driver = (dev / "driver").resolve().name
            vendor = (dev / "vendor").read_text().strip()
            if (vendor, driver) not in (("0x8086", "xe"), ("0x8086", "i915"), ("0x10de", "nvidia"),
                                        ("0x1002", "amdgpu")):
                continue
            did = int((dev / "device").read_text().strip(), 16)
            if vendor == "0x1002":
                # amdgpu reports its memory and how much of it the CPU sees (the BAR) in sysfs
                vram_b = int((dev / "mem_info_vram_total").read_text())
                vis_b = int((dev / "mem_info_vis_vram_total").read_text())
            # the BAR the CPU sees the memory through: BAR 2 on Intel's cards, BAR 1 on NVIDIA's
            bar = (dev / "resource").read_text().splitlines()[2 if vendor == "0x8086" else 1].split()
            bar_gb = (int(bar[1], 16) - int(bar[0], 16) + 1) / 2 ** 30 if int(bar[1], 16) else 0.0
        except (OSError, ValueError, IndexError):
            continue
        pci = dev.resolve().name
        if vendor == "0x1002":
            kfd = kfd_nodes() if kfd is None else kfd
            node = kfd.get(pci, {})
            render = next(iter(sorted((dev / "drm").glob("renderD*"))), None)
            integrated = bool(node.get("integrated"))
            name = f"{pci_name(0x1002, did)} ({node.get('gfx') or 'no KFD node'})"
            if node.get("gfx") == STRIX_HALO_GFX and node.get("simds") in STRIX_HALO_BY_SIMDS:
                name = f"AMD Radeon {STRIX_HALO_BY_SIMDS[node['simds']]} (Ryzen AI Max, Strix Halo, gfx1151)"
            g = {"name": name, "vram_gb": 0.0 if integrated else vram_b / 2 ** 30,
                 "device_id": did, "driver": driver, "integrated": integrated, "supported": True, "pci": pci,
                 "bar_gb": vis_b / 2 ** 30, "link": host_link(dev),
                 "render": f"/dev/dri/{render.name}" if render else None, "vendor": "amd", "gfx": node.get("gfx")}
            if integrated:                             # an APU: the carve-out and the shared pool (upstream c4a329fe)
                try:
                    gtt_gb = int((dev / "mem_info_gtt_total").read_text()) / 2 ** 30
                except (OSError, ValueError):
                    gtt_gb = 0.0
                g.update(amd_uma(vram_b / 2 ** 30, gtt_gb, ram_gb()))
            amd.append(g)
            continue
        if vendor == "0x10de":
            smi = nvidia_smi() if smi is None else smi
            info = smi.get(pci, {})
            vram = info.get("mib", 0.0) / 1024 or bar_gb
            node = "/dev/nvidiactl" if Path("/dev/nvidiactl").exists() else None
            nvidia.append({"name": info.get("name") or f"NVIDIA GPU 0x{did:04x}", "vram_gb": vram,
                           "device_id": did, "driver": driver, "integrated": False, "supported": True, "pci": pci,
                           "bar_gb": bar_gb, "link": host_link(dev), "render": node, "vendor": "nvidia",
                           "cc": info.get("cc")})
            continue
        render = next(iter(sorted((dev / "drm").glob("renderD*"))), None)
        node = f"/dev/dri/{render.name}" if render else None
        mem = drm_memory(node, driver) if node else None
        integrated = mem is not None and mem[0] == 0
        vram = mem[0] / 2 ** 30 if mem else bar_gb             # the BAR when the driver cannot be asked
        visible = mem[1] / 2 ** 30 if mem else bar_gb
        found.append({"index": len(found), "name": pci_name(0x8086, did), "vram_gb": vram, "device_id": did,
                      "driver": driver, "integrated": integrated, "supported": True, "pci": pci,
                      "bar_gb": visible, "link": host_link(dev), "render": node, "vendor": "intel",
                      "ip": drm_graphics_ip(node) if node and driver == "xe" else None})
    if not (found or nvidia or amd) and wsl_version() == 2:
        return gpus_wsl()
    return found + [{"index": len(found) + i, **g} for i, g in enumerate(nvidia + amd)]


def gpus_wsl():
    """WSL 2 has no DRM card in sysfs: its GPU is Windows' own, behind /dev/dxg (a report: an RTX 2050 that the
    Linux listing did not find).  An installed engine lists them as on Windows (gpus_from_engine); before an engine is
    built, nvidia-smi names the NVIDIA ones (an Intel GPU under WSL is listed by the engine only)."""
    dxg = "/dev/dxg" if Path("/dev/dxg").exists() else None   # the device the GPU is opened through
    if PACKAGED:
        return [{**g, "render": dxg} for g in gpus_from_engine()]
    found = []
    for pci, info in sorted(nvidia_smi().items()):
        vram = info.get("mib", 0.0) / 1024
        found.append({"index": len(found), "name": info.get("name") or "NVIDIA GPU", "vram_gb": vram,
                      "device_id": 0, "driver": "nvidia (WSL 2)", "integrated": False, "supported": True,
                      "pci": pci, "bar_gb": vram, "link": None, "render": dxg, "vendor": "nvidia",
                      "cc": info.get("cc")})
    return found


def gpus_from_engine():
    """The GPUs as the engine sees them (strata-device --list-devices), in its order (the card it would take first), in
    gpus()'s form.  What sysfs alone gives on Linux is not known here: the PCIe link, a small BAR (taken as the whole
    VRAM); an AMD card's gfx name is the HIP runtime's (its "arch"), the render node is not needed (no device files to
    open)."""
    vendors = {0x8086: "intel", 0x10DE: "nvidia", 0x1002: "amd"}
    try:
        lines = [json.loads(x) for x in engine_tool("--list-devices").splitlines() if x.strip()]
    except (OSError, ValueError, subprocess.SubprocessError) as e:
        warn(f"the engine could not list the GPUs: {e}")
        return []
    found = []
    for d in lines:
        integrated = bool(d.get("integrated"))
        vram = 0.0 if integrated else d.get("total_bytes", 0) / 2 ** 30
        found.append({"index": len(found), "name": d.get("name") or "GPU", "vram_gb": vram,
                      "device_id": d.get("device_id", 0), "driver": d.get("backend"), "integrated": integrated,
                      "supported": True, "pci": d.get("pci"), "bar_gb": vram, "link": None, "render": None,
                      "vendor": vendors.get(d.get("vendor_id"), "other"), "gfx": d.get("arch") or None})
    return found


def gpu_problem(g, together=False):
    """Why Strata cannot use this card, in plain words (None: it can).  What the card can do (16-wide sub-groups,
    FP16, the matrix engines) is checked by the engine and the compiler's probe, not here."""
    if together:
        return "not supported together with other GPUs - the Xe engine runs on one GPU"
    if g.get("vendor") == "nvidia" and PACKAGED:
        meta = packaged_engine()
        archs = [int(x[3:]) for x in meta.get("cuda_archs", []) if x[3:].isdigit()]   # "sm_75" -> 75
        if not archs:
            return (f"{meta.get('package', 'this package')} has no NVIDIA code: an NVIDIA GPU needs "
                    "xestrata-contrib-cuda<version> in its place")
        # unknown without nvidia-smi: the engine says so if it has no code for the card
        cc = g.get("cc") or ""
        if re.fullmatch(r"\d+\.\d+", cc) and round(float(cc) * 10) < min(archs):
            return (f"compute capability {g.get('cc')} is older than the sm_{min(archs)} {meta.get('package')} has "
                    "code for: xestrata-contrib-cuda12.4 in its place has code for it (from Pascal, sm_60)")
        return None
    if g.get("vendor") == "nvidia" and license_mode(ARGS) != "contrib":
        return "an NVIDIA GPU needs the contrib build (--license contrib: NVIDIA's CUDA toolkit, not free software)"
    if g.get("vendor") == "amd":
        gfx = g.get("gfx")
        if not gfx:
            return ("AMD's driver does not report its architecture (its HIP runtime, amdhip64_7.dll)" if WIN else
                    "the kernel's KFD (amdgpu's compute part, /dev/kfd) does not list it")
        if not AMD_ARCH.fullmatch(gfx):
            return f"{gfx}: the engine needs an RDNA2 or later AMD GPU (gfx103x, gfx11xx, gfx12xx)"
        if PACKAGED:
            meta = packaged_engine()
            if gfx not in meta.get("hip_archs", []):
                where = "" if WIN else ": " + amd_elsewhere()
                return f"{meta.get('package', 'this package')} has no code for {gfx}{where}"
        elif (have := rocblas_archs()) is not None and gfx not in have:
            return (f"this distribution's rocBLAS, which the engine's dense matrix products run in, has no code for "
                    f"{gfx}: " + amd_elsewhere())
    return None


def gpu_name(g) -> str:
    return f"GPU {g['index']} ({g['name']}, " + ("shares the system RAM" if g.get("integrated") else
                                                 f"{g['vram_gb']:.0f} GB") + ")"


def gpu_table(found) -> None:
    say("  Your GPUs:")
    for g in found:
        p = gpu_problem(g)
        mem = "no VRAM of its own" if g.get("integrated") else f"{g['vram_gb']:.0f} GB VRAM"
        say(f"    GPU {g['index']}: {g['name']}, {mem} - " + ("can be used" if p is None else p))


def parse_gpus(text, found) -> list:
    """--gpus 0,2: a layer split across these cards (numbered as --check lists them), the first one running the early
    layers (docs/MULTIGPU.md).  Two or more distinct cards that can be used."""
    try:
        sel = [int(x) for x in str(text).split(",") if x.strip() != ""]
    except ValueError:
        sel = []
    if len(sel) < 2 or len(set(sel)) != len(sel):
        fail(f"--gpus {text}: two or more different GPU numbers, as --check lists them, e.g. --gpus 0,1",
             "use --gpu N for one card")
    check_gpus(sel, found)
    return sel


def check_gpus(sel, found, what="") -> None:
    """Stops with a plain message when a chosen card is missing or cannot be used, and says what can."""
    for i in sel:
        g = next((x for x in found if x["index"] == i), None)
        p = "not found on this PC" if g is None else gpu_problem(g)
        if p is None:
            continue
        say()
        gpu_table(found)
        single = [x for x in found if gpu_problem(x) is None]
        hint = ("use " + " or ".join(f"--gpu {x['index']}" for x in single)) if single else \
            "Strata's Xe engine needs an Intel GPU on the xe or i915 driver, an RDNA2 or later AMD GPU on amdgpu, " \
            "or with --license contrib an NVIDIA GPU"
        fail(f"GPU {i}{'' if g is None else ' (' + g['name'] + ')'} {what}cannot be used: {p}", hint)


def choose_gpus(a, found) -> list:
    """Which cards this install uses: --gpus (a layer split, the first card first), else --gpu, else the supported
    card with the most VRAM.  Returns their numbers."""
    if a.gpus:
        return parse_gpus(a.gpus, found)
    if a.gpu is not None:
        check_gpus([a.gpu], found)
        return [a.gpu]
    single = sorted([g for g in found if gpu_problem(g) is None], key=lambda x: (-round(x["vram_gb"]), x["index"]))
    if not single:
        gpu_table(found)
        fail("none of your GPUs can run Strata",
             "it needs an Intel GPU on the xe or i915 driver, an RDNA2 or later AMD GPU on amdgpu, or with --license "
             "contrib an NVIDIA GPU")
    return [single[0]["index"]]


def gpu_info(pick=None):
    """The GPU Strata runs on: `pick` (its number in gpus()) if given, else the one with the most VRAM (ties: the
    lower number).  None when gpus() finds none.  The dict also says how many there are
    ("count")."""
    found = gpus()
    if not found:
        return None
    pick = GPU_PICK if pick is None else pick
    if pick is not None:
        g = next((x for x in found if x["index"] == pick), None)
        if g is None:
            fail(f"there is no GPU {pick}: " + ", ".join(f"{x['index']} = {x['name']}" for x in found))
    else:
        g = max(found, key=lambda x: (round(x["vram_gb"]), -x["index"]))
    return {**g, "count": len(found)}


def find_tool(name):
    """A tool on PATH, or the one pip installed next to this Python (cmake, ninja).  A PATH copy that does not run
    (a pip launcher whose Python is gone) is skipped for the one next to this Python."""
    p = shutil.which(name)
    if p:
        try:
            if subprocess.run([p, "--version"], capture_output=True, timeout=30).returncode == 0:
                return p
        except (OSError, subprocess.SubprocessError):
            pass
    for d in (Path(sys.executable).parent, Path.home() / ".local" / "bin"):
        c = d / name
        if c.exists():
            return str(c)
    return None


def free_gb(path):
    path.mkdir(parents=True, exist_ok=True)
    return shutil.disk_usage(path).free / 1e9


# ------------------------------------------------------------------------------------------------ downloads
# Parallel ranged downloads (upstream 04221c3e2).  One TCP stream often cannot fill a fast line (a long or lossy route,
# a CDN that limits each connection): download() takes the file in DL_CHUNK pieces over several connections, writes each
# piece at its own offset, and keeps the finished pieces in <name>.part.chunks so a stopped download continues where it
# was.  Anything that is not a ranged file of known length (no Range support, no length, a small file) is one stream,
# as before.
DL_CONNECTIONS = 16             # STRATA_DL_CONNECTIONS=1 restores one stream (for testers)
DL_CHUNK = 32 << 20             # bytes per piece: what the piece list records and what a failed request loses at most
# pieces one request asks for (4 x 32 MiB): a new connection per piece spends its first seconds in TCP slow start
# (upstream's measurement: 8 connections 66 MB/s with a request per piece, 73 with 128 MiB)
DL_RUN = 4
DL_MIN_PARALLEL = 256 << 20     # smaller files are one stream
DL_CHUNK_TRIES = 5              # tries per request (1, 2, 4, 8 s apart) before the round is given up and run again
DL_ROUNDS = 30                  # rounds (10 s apart) before the download is given up, like the 30 tries of one stream
DL_BACKOFF = 1.0                # seconds before the second try of a request, doubled each time (tests set 0)
DL_SAVE_EVERY = 5.0             # seconds between writes of the progress file


def dl_connections() -> int:
    """How many connections a big download uses: STRATA_DL_CONNECTIONS, else DL_CONNECTIONS (1 = one stream)."""
    raw = (os.environ.get("STRATA_DL_CONNECTIONS") or "").strip()
    try:
        n = int(raw) if raw else DL_CONNECTIONS
    except ValueError:
        n = DL_CONNECTIONS
    return max(1, min(n, 32))


class _NoRange(Exception):
    """The server does not answer a byte range with that range (no 206, or another range): one stream instead."""


class _DiskError(Exception):
    """The .part file cannot be written (disk full, no permission): retrying would not help."""


class _PieceFailed(Exception):
    """A piece failed DL_CHUNK_TRIES times."""


class _Changed(Exception):
    """The server's file is not the one the first pieces came from (another ETag): what was written cannot be
    trusted."""


_CONTENT_RANGE = re.compile(r"\s*bytes (\d+)-(\d+)/(\d+)\s*$")


def _etag(headers) -> str | None:
    """The object identity a response names: ETag without the weak mark and quotes; None when it sends none."""
    raw = (headers.get("ETag") or "").strip()
    if raw[:2] in ("W/", "w/"):
        raw = raw[2:]
    return raw.strip('"') or None


def _check_ranged(r, pos: int, end: int, total: int, etag: str | None):
    """A ranged answer is trusted only when it is exactly the bytes asked for: status 206, Content-Range `pos-end/total`
    (a 200 with the whole file, another range or another total is the server not honouring the request), a
    Content-Length that fits, and the same object (ETag) as the first answer.  _NoRange: this server cannot be used with
    ranges; OSError: a bad answer worth asking again (another edge)."""
    if r.status != 206:
        raise _NoRange(f"HTTP {r.status}")
    m = _CONTENT_RANGE.match(r.headers.get("Content-Range") or "")
    if not m or (int(m.group(1)), int(m.group(2)), int(m.group(3))) != (pos, end, total):
        raise _NoRange(f"Content-Range {(r.headers.get('Content-Range') or '')!r} for bytes {pos}-{end}/{total}")
    cl = (r.headers.get("Content-Length") or "").strip()
    if cl and cl.isdigit() and int(cl) != end - pos + 1:
        raise OSError(f"Content-Length {cl} for {end - pos + 1} bytes asked")
    got = _etag(r.headers)
    if etag and got and got != etag:
        raise OSError("the server answered with another version of the file")


def _write_all(f, pos: int, data):
    """Write `data` at `pos`; a raw unbuffered file may take fewer bytes than it was given, so go on until all are
    down."""
    view = memoryview(data)
    f.seek(pos)
    done_n = 0
    while done_n < len(view):
        n = f.write(view[done_n:])
        if not n:
            raise OSError("the disk took no more bytes")
        done_n += n


def _read_exact(f, pos: int, n: int) -> bytes:
    f.seek(pos)
    parts = []
    while n > 0:
        b = f.read(n)
        if not b:
            break
        parts.append(b)
        n -= len(b)
    return b"".join(parts)


def _url_ttl(url: str):
    """Seconds a signed URL (the CDN's, after the redirect) is still valid by its own query, else None."""
    q = urllib.parse.parse_qs(urllib.parse.urlsplit(url).query)
    try:
        if "Expires" in q:
            ttl = float(q["Expires"][0]) - time.time()
        elif "X-Amz-Expires" in q and "X-Amz-Date" in q:
            t0 = calendar.timegm(time.strptime(q["X-Amz-Date"][0], "%Y%m%dT%H%M%SZ"))
            ttl = t0 + float(q["X-Amz-Expires"][0]) - time.time()
        else:
            return None
    except (ValueError, OverflowError):
        return None
    return ttl if 0 < ttl < 30 * 86400 else None       # a PC clock that is far off says nothing: a 403 re-resolves


class _Source:
    """The URL the pieces are read from: the redirect (Hugging Face answers with a signed, time-limited CDN address) is
    resolved once and reused; it is resolved again a little before it expires and after a 401/403/410."""

    def __init__(self, url: str, total: int):
        self.url, self.total = url, total
        self.final: str | None = None
        self.deadline: float | None = None
        self.etag: str | None = None                     # the object the first answer named; every later one must match
        self.lock = threading.Lock()

    def resolve(self, stale=None) -> str:
        with self.lock:
            if stale is not None and self.final is not None and self.final != stale:
                return self.final                        # another connection already got a fresh address
            req = urllib.request.Request(self.url, headers={"User-Agent": "strata-setup", "Range": "bytes=0-0"})
            with urllib.request.urlopen(req, timeout=60) as r:
                cr = (r.headers.get("Content-Range") or "").strip()
                if r.status != 206 or cr != f"bytes 0-0/{self.total}":
                    raise _NoRange(f"HTTP {r.status}, Content-Range {cr!r}")
                tag = _etag(r.headers)
                if self.etag and tag and tag != self.etag:
                    raise _Changed(f"the file on the server changed while it was downloaded "
                                   f"({self.etag[:12]} -> {tag[:12]})")
                self.etag = self.etag or tag
                r.read(1)
                final = r.geturl() or self.url
            ttl = _url_ttl(final)
            self.final = final
            self.deadline = time.monotonic() + max(ttl - 120, 0) if ttl else None
            return final

    def get(self) -> str:
        with self.lock:
            cur, expired = self.final, self.deadline is not None and time.monotonic() >= self.deadline
        return self.resolve(stale=cur) if cur is None or expired else cur


class _Pieces:
    """The shared state of one parallel download: finished pieces, bytes of the pieces in flight, the stop flags."""

    def __init__(self, total: int, done: set, conns: int = 1):
        self.total, self.n, self.conns = total, -(-total // DL_CHUNK), conns
        self.done = set(done)
        self.flight: dict[int, int] = {}
        self.lock = threading.Lock()
        self.stop = threading.Event()                    # the whole download stops (Ctrl-C, a fatal error)
        self.abort_round = threading.Event()             # a piece failed for good: end this round, run the next
        self.fatal: Exception | None = None
        self.errors: list[Exception] = []

    def size(self, i: int) -> int:
        return min((i + 1) * DL_CHUNK, self.total) - i * DL_CHUNK

    def add(self, i: int, n: int):
        with self.lock:
            self.flight[i] = self.flight.get(i, 0) + n

    def finish(self, i: int):
        with self.lock:
            self.flight.pop(i, None)
            self.done.add(i)

    def have(self) -> int:
        with self.lock:
            return sum(self.size(i) for i in self.done) + sum(self.flight.values())

    def snapshot(self) -> set:
        with self.lock:
            return set(self.done)


def _ranges(done) -> list:
    out: list[list[int]] = []
    for i in sorted(done):
        if out and out[-1][1] == i:
            out[-1][1] = i + 1
        else:
            out.append([i, i + 1])
    return out


def _prefix_bytes(done: set, total: int) -> int:
    """Bytes of the unbroken run of finished pieces from the start of the file."""
    i = 0
    while i in done:
        i += 1
    return min(i * DL_CHUNK, total)


def _load_pieces(part: Path, total: int) -> set:
    """The finished pieces of an earlier run.  <name>.part.chunks lists them; a .part without it comes from one stream
    (an older setup, or STRATA_DL_CONNECTIONS=1): its bytes are a run from the start, so those pieces are finished."""
    side = part.with_name(part.name + ".chunks")
    n = -(-total // DL_CHUNK)
    try:
        size = part.stat().st_size if part.is_file() else None
    except OSError:
        size = None
    if side.is_file():
        try:
            data = json.loads(side.read_text(encoding="utf-8"))
            if data.get("v") == 1 and data.get("total") == total and data.get("chunk") == DL_CHUNK and size is not None:
                done = {i for a, b in data["done"] for i in range(int(a), min(int(b), n))}
                return {i for i in done if min((i + 1) * DL_CHUNK, total) <= size}
        except (OSError, ValueError, TypeError, KeyError):
            pass
        side.unlink(missing_ok=True)                    # not this file's list: start the file over
        part.unlink(missing_ok=True)
        return set()
    if size is None:
        return set()
    if size > total:
        part.unlink(missing_ok=True)
        return set()
    return set(range(n)) if size >= total else set(range(size // DL_CHUNK))


def _save_pieces(part: Path, total: int, done: set) -> bool:
    """Flush the data first, then record the pieces: a list never names bytes the disk does not have.  False when the
    list could not be written (an older list stays, which only costs re-downloading a few pieces after a stop)."""
    try:
        with open(part, "r+b") as g:
            os.fsync(g.fileno())
        side = part.with_name(part.name + ".chunks")
        tmp = side.with_name(side.name + ".tmp")
        tmp.write_text(json.dumps({"v": 1, "total": total, "chunk": DL_CHUNK, "done": _ranges(done)}), encoding="utf-8")
        with open(tmp, "r+b") as g:
            os.fsync(g.fileno())
        os.replace(tmp, side)
        return True
    except OSError:
        return False


def _claim_part(part: Path, url: str, etag: str | None = None):
    """Record where a .part's bytes come from (<name>.part.src: the address asked, and the file's ETag when the server
    names one).  A .part written from another address (the other mirror, another revision) or from another version of
    the file is dropped with its piece list: two sources are not mixed inside one file, even when they should hold the
    same bytes.  A .part from an older setup has no record and is kept as before."""
    src = part.with_name(part.name + ".src")
    try:
        old = json.loads(src.read_text(encoding="utf-8")) if src.is_file() else None
    except (OSError, ValueError):
        old = {}
    if old is not None:
        same = isinstance(old, dict) and old.get("url") == url and \
            not (old.get("etag") and etag and old.get("etag") != etag)
        if not same:
            part.unlink(missing_ok=True)
            part.with_name(part.name + ".chunks").unlink(missing_ok=True)
            src.unlink(missing_ok=True)
            old = None
    if old is None or (etag and not old.get("etag")):
        try:
            src.write_text(json.dumps({"url": url, "etag": etag}), encoding="utf-8")
        except OSError:
            pass


def _single_ready(part: Path):
    """Before one stream continues a .part: keep only the unbroken run from the start of the file (what a parallel
    download left may have gaps behind it) and drop the list."""
    side = part.with_name(part.name + ".chunks")
    if not side.is_file():
        return
    try:
        data = json.loads(side.read_text(encoding="utf-8"))
        keep = _prefix_bytes({i for a, b in data["done"] for i in range(int(a), int(b))}, int(data["total"]))
        if data.get("chunk") != DL_CHUNK:
            keep = 0
    except (OSError, ValueError, TypeError, KeyError):
        keep = 0
    try:
        if part.is_file():
            with open(part, "r+b") as g:
                g.truncate(min(keep, part.stat().st_size))
    except OSError:
        part.unlink(missing_ok=True)
    side.unlink(missing_ok=True)


def _take_run(st: _Pieces, todo: list) -> list:
    """The next request's pieces: up to DL_RUN neighbours from the front of `todo`; fewer near the end, so the last
    pieces are spread over every connection and no single slow one holds the finish."""
    with st.lock:
        if not todo:
            return []
        n = max(1, min(DL_RUN, len(todo) // (2 * st.conns)))
        run = [todo.pop(0)]
        while len(run) < n and todo and todo[0] == run[-1] + 1:
            run.append(todo.pop(0))
        return run


def _fetch_run(src: _Source, st: _Pieces, f, run: list):
    """One ranged request for the neighbouring pieces in `run`, written at their offsets; each piece counts as
    finished when its last byte is down.  Every answer is checked to be exactly the range asked for (status,
    Content-Range, length, ETag); a connection that breaks continues from the byte it reached."""
    start = run[0] * DL_CHUNK
    end = min((run[-1] + 1) * DL_CHUNK, st.total) - 1
    pos, tries = start, 0
    with st.lock:
        for i in run:
            st.flight[i] = 0
    while True:
        if st.stop.is_set():
            return
        url: str | None = None
        err: Exception | None = None
        wait: float | None = None
        ra = 0.0
        attempt_pos = pos
        try:
            url = src.get()
            req = urllib.request.Request(url, headers={"User-Agent": "strata-setup", "Range": f"bytes={pos}-{end}"})
            with urllib.request.urlopen(req, timeout=60) as r:
                _check_ranged(r, pos, end, st.total, src.etag)
                while pos <= end:
                    if st.stop.is_set():
                        return
                    cur = pos // DL_CHUNK
                    cur_end = min((cur + 1) * DL_CHUNK, st.total)             # one past the piece's last byte
                    b = r.read(min(1 << 20, cur_end - pos))
                    if not b:
                        raise IOError("the connection closed early")
                    try:
                        _write_all(f, pos, b)
                    except OSError as e:
                        raise _DiskError(str(e)) from e
                    pos += len(b)
                    st.add(cur, len(b))
                    if pos == cur_end:
                        st.finish(cur)
                        if pos <= end and st.abort_round.is_set():    # a piece failed for good: stop at its edge
                            with st.lock:
                                for i in run:
                                    if i not in st.done and st.flight.get(i) == 0:
                                        st.flight.pop(i, None)
                            return
            return
        except (_NoRange, _DiskError, _Changed):
            raise
        except urllib.error.HTTPError as e:
            err = e
            if e.code in (401, 403, 410) and url is not None:       # the signed address ran out: ask for a new one
                try:
                    src.resolve(stale=url)
                    wait = 0
                except (_NoRange, _Changed):
                    raise
                except (OSError, http.client.HTTPException):
                    pass
            elif e.code in (429, 503):
                try:
                    ra = min(float(e.headers.get("Retry-After") or 0), 60)
                except (TypeError, ValueError):
                    pass
        except (OSError, http.client.HTTPException) as e:
            err = e
        # A try that moved forward is not a failed one.  The request goes on from the byte it reached: what came before
        # the break is exactly the range that was asked for (the answer's status, Content-Range, length and ETag were
        # checked and every byte was written in full), and writing a piece again from its start would make a route that
        # resets more often than every DL_CHUNK bytes unable to finish any piece.  The whole-file SHA-256 and the repair
        # are the net behind it.
        tries = 1 if pos > attempt_pos else tries + 1
        if tries >= DL_CHUNK_TRIES:
            raise _PieceFailed(str(err))
        st.stop.wait(max(DL_BACKOFF * 2 ** (tries - 1), ra) if wait is None else wait)


def _piece_worker(src: _Source, st: _Pieces, todo: list, part: Path):
    try:
        with open(part, "r+b", buffering=0) as f:
            while not (st.stop.is_set() or st.abort_round.is_set()):
                run = _take_run(st, todo)
                if not run:
                    return
                _fetch_run(src, st, f, run)
    except _PieceFailed as e:
        st.errors.append(e)
        st.abort_round.set()
    except (_NoRange, _DiskError, _Changed) as e:
        st.fatal = st.fatal or e
        st.stop.set()
    except OSError as e:                                # the .part itself could not be opened
        st.fatal = st.fatal or _DiskError(str(e))
        st.stop.set()


def parallel_download(url: str, part: Path, total: int, label: str, conns: int, name: str) -> bool:
    """Fill `part` (total bytes) over `conns` ranged connections.  True when every byte is there; False when the server
    does not do ranges (the caller reads the file in one stream)."""
    src = _Source(url, total)
    try:
        src.resolve()
    except _NoRange:
        return False
    except (OSError, http.client.HTTPException):
        return False                                    # the one-stream path has its own retries and messages
    part.parent.mkdir(parents=True, exist_ok=True)
    _claim_part(part, url, src.etag)                    # a .part from another address or version is dropped here
    done = _load_pieces(part, total)
    st = _Pieces(total, done, conns)
    if not part.exists():
        part.touch()
    if not part.with_name(part.name + ".chunks").is_file() and not _save_pieces(part, total, done):
        return False                                    # no piece list can be kept: pieces would not be told from holes
    last_print = last_save = 0.0

    def report(force=False):
        nonlocal last_print, last_save
        now = time.time()
        if now - last_print > 2 or force:
            last_print = now
            progress(label, st.have(), total)
        if now - last_save > DL_SAVE_EVERY:
            last_save = now
            _save_pieces(part, total, st.snapshot())

    try:
        for rnd in range(DL_ROUNDS):
            todo = [i for i in range(st.n) if i not in st.done]
            if not todo:
                break
            st.abort_round.clear()
            st.errors.clear()
            threads = [threading.Thread(target=_piece_worker, args=(src, st, todo, part), daemon=True)
                       for _ in range(min(conns, len(todo)))]
            for t in threads:
                t.start()
            while any(t.is_alive() for t in threads):
                for t in threads:
                    t.join(0.25)
                report()
            if st.fatal is not None:
                break
            if st.errors:
                progress_end()
                warn(f"download interrupted ({st.errors[0]}); retrying in 10 s ...")
                _save_pieces(part, total, st.snapshot())
                time.sleep(10)
    except BaseException:
        st.stop.set()                                   # Ctrl-C: let the connections stop, keep what is finished
        _save_pieces(part, total, st.snapshot())
        raise
    report(force=True)
    progress_end()
    if isinstance(st.fatal, _Changed):
        part.unlink(missing_ok=True)
        part.with_name(part.name + ".chunks").unlink(missing_ok=True)
        part.with_name(part.name + ".src").unlink(missing_ok=True)
        fail(f"{name} changed on the server while it was downloading: the part that was there was deleted",
             "run it again (the download starts over with the file that is there now)")
    if isinstance(st.fatal, _DiskError):
        _save_pieces(part, total, st.snapshot())
        fail(f"cannot write {part.name}: {st.fatal}",
             "free some disk space (or pick another --models-dir) and run it again")
    if isinstance(st.fatal, _NoRange):
        _save_pieces(part, total, st.snapshot())
        return False                                    # the server stopped doing ranges: one stream from the start
    if len(st.done) < st.n:
        _save_pieces(part, total, st.snapshot())
        have = st.have()
        fail(f"could not finish downloading {name}: {have:,} of {total:,} bytes",
             "check your internet connection and run it again (the download resumes where it stopped)")
    try:
        with open(part, "r+b") as g:
            g.truncate(total)
            os.fsync(g.fileno())
    except OSError:
        pass
    part.with_name(part.name + ".chunks").unlink(missing_ok=True)
    return True


def _repair_piece(src: _Source, st: _Pieces, f, i: int, stats: dict):
    """Read piece `i` from the server in 1 MiB blocks and compare each with what is on the disk; a block that differs is
    written again.  A broken connection asks again from the block it reached (every block is final once compared)."""
    pos, end = i * DL_CHUNK, min((i + 1) * DL_CHUNK, st.total) - 1
    tries = 0
    err: Exception | None = None
    while pos <= end:
        if st.stop.is_set():
            return
        url: str | None = None
        wait: float | None = None
        ra = 0.0
        before = pos
        try:
            url = src.get()
            req = urllib.request.Request(url, headers={"User-Agent": "strata-setup", "Range": f"bytes={pos}-{end}"})
            with urllib.request.urlopen(req, timeout=60) as r:
                _check_ranged(r, pos, end, st.total, src.etag)
                while pos <= end:
                    if st.stop.is_set():
                        return
                    b = r.read(min(1 << 20, end + 1 - pos))
                    if not b:
                        raise IOError("the connection closed early")
                    try:
                        if _read_exact(f, pos, len(b)) != b:
                            _write_all(f, pos, b)
                            with st.lock:
                                stats["bytes"] += len(b)
                                stats["pieces"].add(i)
                    except OSError as e:
                        raise _DiskError(str(e)) from e
                    pos += len(b)
                    st.add(i, len(b))
            return
        except (_NoRange, _DiskError, _Changed):
            raise
        except urllib.error.HTTPError as e:
            if e.code in (401, 403, 410) and url is not None:
                try:
                    src.resolve(stale=url)
                    wait = 0
                except (_NoRange, _Changed):
                    raise
                except (OSError, http.client.HTTPException):
                    pass
            elif e.code in (429, 503):
                try:
                    ra = min(float(e.headers.get("Retry-After") or 0), 60)
                except (TypeError, ValueError):
                    pass
            err = e
        except (OSError, http.client.HTTPException) as e:
            err = e
        tries = 1 if pos > before else tries + 1
        if tries >= DL_CHUNK_TRIES:
            raise _PieceFailed(str(err))
        st.stop.wait(max(DL_BACKOFF * 2 ** (tries - 1), ra) if wait is None else wait)


def repair_download(url: str, path: Path, total: int, label: str, conns: int):
    """A finished file whose SHA-256 is wrong is not thrown away: read it again from the server piece by piece, compare
    each block with the disk and write only the blocks that differ.  Returns (damaged pieces, pieces), or None when the
    server cannot do it (no ranges, or the file there is another one); the caller checks the SHA-256 again."""
    if not total or path.stat().st_size != total:
        return None
    src = _Source(url, total)
    try:
        src.resolve()
    except (_NoRange, _Changed, OSError, http.client.HTTPException):
        return None
    st = _Pieces(total, set(), conns)
    stats: dict = {"bytes": 0, "pieces": set()}
    todo = list(range(st.n))
    errors: list[Exception] = []

    def worker():
        try:
            with open(path, "r+b", buffering=0) as f:
                while not st.stop.is_set():
                    with st.lock:
                        if not todo:
                            return
                        i = todo.pop(0)
                    _repair_piece(src, st, f, i, stats)
                    st.finish(i)
        except (_PieceFailed, _NoRange, _DiskError, _Changed, OSError) as e:
            errors.append(e)
            st.stop.set()

    threads = [threading.Thread(target=worker, daemon=True) for _ in range(min(conns, st.n))]
    for t in threads:
        t.start()
    last = 0.0
    try:
        while any(t.is_alive() for t in threads):
            for t in threads:
                t.join(0.25)
            if time.time() - last > 2:
                last = time.time()
                progress(label, st.have(), total)
    except BaseException:
        st.stop.set()
        raise
    progress_end()
    if errors:
        warn(f"could not compare {path.name} with the server again ({errors[0]})")
        return None
    try:
        with open(path, "r+b") as g:
            os.fsync(g.fileno())
    except OSError:
        pass
    return len(stats["pieces"]), st.n


def download_single(url: str, part: Path, total: int, label: str):
    """One stream with a Range resume from the size of `part` (the way every download worked before parallel pieces).
    A resumed answer is used only when it is a 206 that starts at the byte asked for; anything else starts the file
    over."""
    _single_ready(part)
    for attempt in range(30):
        have = part.stat().st_size if part.exists() else 0
        if total and have >= total:                    # stopped after the last byte, before the rename: nothing to
            break                                      # ask for (a range past the end is a 416, retried 30 times)
        try:
            req = urllib.request.Request(url, headers={"User-Agent": "strata-setup", "Range": f"bytes={have}-"})
            with urllib.request.urlopen(req, timeout=60) as r:
                if have:
                    m = _CONTENT_RANGE.match(r.headers.get("Content-Range") or "")
                    if r.status != 206 or not m or int(m.group(1)) != have or (total and int(m.group(3)) != total):
                        if r.status != 200:            # another range: its bytes are not the file's; ask again from 0
                            part.unlink(missing_ok=True)
                            raise OSError(f"the server answered another range than bytes {have}- (HTTP {r.status})")
                        have = 0                       # the server ignored the range, sent the whole file: start over
                elif r.status not in (200, 206):
                    raise OSError(f"HTTP {r.status}")
                with open(part, "ab" if have else "wb") as f:
                    last = 0.0
                    while True:
                        b = r.read(8 << 20)
                        if not b:
                            break
                        if total and have + len(b) > total:
                            raise OSError("the server sent more bytes than the file has")
                        f.write(b)
                        have += len(b)
                        if time.time() - last > 2:
                            last = time.time()
                            progress(label, have, total)
                    f.flush()
                    os.fsync(f.fileno())
            progress_end()
            if not total or have >= total:
                break
        except (OSError, http.client.HTTPException) as e:
            progress_end()
            if part.exists() and total and part.stat().st_size > total:
                part.unlink(missing_ok=True)           # more than the file has can only be wrong bytes
            warn(f"download interrupted ({e}); retrying in 10 s ...")
            time.sleep(10)


def range_total(url: str) -> int:
    """The file's length from a one-byte ranged GET (Content-Range: bytes 0-0/N), for a server whose HEAD gives none
    (ModelScope's: #1915); 0 when it does not say.  With the length known the file comes over several connections."""
    try:
        req = urllib.request.Request(url, headers={"User-Agent": "strata-setup", "Range": "bytes=0-0"})
        with urllib.request.urlopen(req, timeout=60) as r:
            m = re.match(r"\s*bytes 0-0/(\d+)\s*$", r.headers.get("Content-Range") or "")
            return int(m.group(1)) if r.status == 206 and m else 0
    except (OSError, http.client.HTTPException):
        return 0


def download(url, dst: Path, what=None):
    """Resumable HTTP(S) download with a progress line; `file://` and plain paths are copied (tests, mirrors).
    A finished file gets a <name>.done mark, so a later run skips it without asking the server."""
    dst.parent.mkdir(parents=True, exist_ok=True)
    if dst.exists() and done(dst):
        ok(f"{what or dst.name} already downloaded")
        return
    if not url.startswith(("http://", "https://")):
        src = Path(url[7:] if url.startswith("file://") else url)
        if not src.exists():
            fail(f"not found: {src}")
        shutil.copyfile(src, dst)
        mark(dst)
        ok(f"{what or dst.name} copied")
        return
    ms = ms_file(url) if model_source() == "modelscope" else None
    if ms is not None:
        if reachable(ms_url(*ms), timeout=30):
            url = ms_url(*ms)
        else:
            warn(f"{what or dst.name}: ModelScope does not answer; downloading it from {hf_endpoint()}")
            ms = None
    part = dst.with_name(dst.name + ".part")
    total = 0
    # the file's pinned size and SHA-256, when it has them (ModelScope's copy is checked against the same pin)
    pin = REPO_PINS.get(ms[0], {}).get(ms[1].rsplit("/", 1)[-1]) if ms is not None else file_pin(url)
    for attempt in range(5):
        try:
            req = urllib.request.Request(url, method="HEAD", headers={"User-Agent": "strata-setup"})
            total = int(urllib.request.urlopen(req, timeout=60).headers.get("Content-Length", 0))
            break
        except urllib.error.HTTPError as e:
            if e.code == 404 and hf_unpinned(url) != url:  # the pinned revision is gone from the repository
                if not allow_unpinned():
                    fail(f"the pinned version of {what or dst.name} is no longer on Hugging Face",
                         "update XeStrata: a newer version pins the files that are there now")
                warn(f"{what or dst.name}: not at the pinned revision any more; downloading the repository's "
                     "current file (not checked against a SHA-256)")
                url = hf_unpinned(url)
                pin = None
                continue
            if attempt == 4:
                fail(f"cannot reach {url.split('/')[2]} ({e})",
                     "check your internet connection and run it again" + source_hint(url))
            time.sleep(5)
        except OSError as e:
            if attempt == 4:
                fail(f"cannot reach {url.split('/')[2]} ({e})",
                     "check your internet connection and run it again" + source_hint(url))
            time.sleep(5)
    if not total:
        total = range_total(url)
    if pin and total and total != pin[0]:              # not the pinned file: stop before the download, not after
        fail(f"{what or dst.name} is {total:,} bytes on {url.split('/')[2]}, not the pinned {pin[0]:,}",
             "update XeStrata (the file there has changed since this version pinned it)")
    label = what or dst.name
    conns = dl_connections()
    meta = ms_meta(*ms) if ms is not None else None
    fixed = pin if pin else (meta if meta is not None and meta[1] else None)
    again = (lambda: repair_download(url, dst, total, label, conns)) if total >= DL_MIN_PARALLEL and conns > 1 else None
    if dst.exists() and total and dst.stat().st_size == total:    # finished by an older setup (no mark yet), or
        if fixed:                                                 # stopped before the check: a file that has a
            verify_sha256(dst, fixed[0], fixed[1], repair=again)  # fixed hash is checked, not just marked
        else:
            mark(dst)
        ok(f"{what or dst.name} already downloaded")
        return
    if not (total >= DL_MIN_PARALLEL and conns > 1 and parallel_download(url, part, total, label, conns, dst.name)):
        _claim_part(part, url)
        download_single(url, part, total, label)
    if total and part.stat().st_size != total:
        fail(f"could not finish downloading {dst.name}: {part.stat().st_size:,} bytes on disk, "
             f"the server says {total:,}",
             "check your internet connection and run it again (the download resumes where it stopped)")
    part.replace(dst)
    for side in (".chunks", ".src"):
        part.with_name(part.name + side).unlink(missing_ok=True)
    if pin:
        verify_sha256(dst, pin[0], pin[1], repair=again)   # the fixed hash: a wrong file is repaired, else deleted
    elif meta is not None and meta[1]:
        verify_sha256(dst, meta[0], meta[1], repair=again)   # ModelScope's published hash; kept in the finish mark
    else:
        if ms is not None:
            warn(f"{what or dst.name}: ModelScope publishes no SHA-256 for it: the file is not verified")
        mark(dst)
    ok(f"{what or dst.name} downloaded")


def whole_shard(s: Path) -> bool:
    """A shard as long as its own tensor directory says (check_shards' test, without stopping setup)."""
    sys.path.insert(0, str(ROOT / "tools"))
    from gguf_reader import GGUFFile
    try:
        g = GGUFFile(s)
        end = max((t.offset + (t.expected_bytes() or 0) for t in g.tensors), default=0)
        return s.stat().st_size >= g.data_start + end
    except (OSError, ValueError, struct.error):
        return False


SHARD_NAME = re.compile(r"-(\d{5})-of-(\d{5})\.gguf$")


def gguf_dir_shards(folder: Path, fam: dict, model: str) -> list[Path]:
    """--gguf-dir's shards (upstream 5a18f83a1, #305): every -0000i-of-0000N file of the model, N read from the first
    shard's name as the engine and tools/iq_pack.py do.  The published name first; else the one first shard in the
    folder whose name has the size in it (an upload split or named differently).  A missing shard is check_shards'
    error later, as before."""
    first = folder / model_file(fam, model, 1)
    if not first.exists():
        found = sorted(p for p in folder.glob("*-00001-of-*.gguf") if SHARD_NAME.search(p.name))
        mine = [p for p in found if model.lower() in p.name.lower()]
        pick = mine if mine else found
        if len(pick) == 1:
            first = pick[0]
    m = SHARD_NAME.search(first.name)
    total = int(m.group(2)) if m else 1
    if not m or total < 1:
        return [first]
    stem = first.name[:m.start()]
    return [first.with_name("%s-%05d-of-%05d.gguf" % (stem, i, total)) for i in range(1, total + 1)]


# upstream 6cc16bee0, #444: the quantization in a GGUF's name (Unsloth's UD-IQ3_XXS, a K-quant's Q2_K_XL, a GSQ-RCO
# IQ3_S, ...)
GGUF_QUANT = re.compile(r"(?<![A-Za-z0-9])((?:UD-)?(?:I?Q\d+(?:_[A-Za-z0-9]+)*|BF16|F16|F32))"
                        r"(?=-\d{5}-of-\d{5}\.gguf$|\.gguf$)", re.I)
SUPPORTED_GGUFS = ("XeStrata runs ISTA-DASLab's GSQ-RCO files (Qwen3.8-Flash-Next Q2_0, IQ2_XS, IQ3_XXS, IQ3_S; Swift "
                   "1.5's; the Coder's IQ1_M) and Unsloth's UD-IQ4_XS and UD-Q4_K_XL only: other GGUFs (Unsloth's "
                   "UD-IQ3_XXS or UD-Q2_K_XL, K-quants) cannot be used")


def gguf_unsupported(name: str) -> str | None:
    """#444: the quantization a GGUF's name says, when it is one XeStrata cannot run (not a setup size); else None."""
    if any(name in md["shards"] for fam in MULTI_FILE_FAMILIES.values() for md in fam["models"].values()):
        return None
    m = GGUF_QUANT.search(name)
    return m.group(1) if m and m.group(1).upper() not in MODELS and not name.lower().startswith("mmproj") else None


def gguf_choice(name: str) -> tuple | None:
    """#444: (--family, --model) whose published first shard this file is, or None (the Coder's IQ1_M is named like
    the original's sizes: the size tells them apart)."""
    for f, d in MULTI_FILE_FAMILIES.items():
        for m, md in d["models"].items():
            if name in (md["shards"][0], DSV41_LEGACY_NAMES.get(md["shards"][0])):
                return f, m
    for f, d in FAMILIES.items():
        for m in MODELS:
            if f in MODELS[m].get("families", ("qwen", "swift")) and name == model_file(d, m, 1):
                return f, m
    return None


def gguf_dir_problem(folder: Path, first: Path, fam: dict, model: str) -> tuple | None:
    """#444: (message, hint) when --gguf-dir has no file setup can use for this choice: the chosen shard is a GGUF
    XeStrata cannot run (Unsloth's UD-IQ3_XXS taken for IQ3_XXS by its name), or it is missing and the folder holds
    other GGUFs - then the hint names the --family/--model of the usable ones.  None otherwise (a missing shard in a
    folder without GGUFs stays check_shards' "missing")."""
    bad = gguf_unsupported(first.name) if first.exists() else None
    if bad:
        return f"{first.name} is {bad}, a GGUF XeStrata cannot run", SUPPORTED_GGUFS
    if first.exists():
        return None

    def first_shard(name: str) -> bool:                 # not split, or the first shard of a split
        m = SHARD_NAME.search(name)
        return m is None or m.group(1) == "00001"
    firsts = sorted(p.name for p in folder.glob("*.gguf")
                    if not p.name.lower().startswith("mmproj") and first_shard(p.name))
    usable = list(dict.fromkeys(c for c in map(gguf_choice, firsts) if c))
    unusable = [n for n in firsts if gguf_unsupported(n)]
    if not usable and not unusable:
        return None
    hint = SUPPORTED_GGUFS
    if unusable:
        hint += ".\n       Not usable here: " + ", ".join(unusable)
    if usable:
        hint += ".\n       Usable here: " + ", ".join(f"--family {f} --model {m}" for f, m in usable)
    return f"{folder} has no {fam['title']} {model} file", hint


def check_shards(shards):
    """Every shard present and whole, or setup stops naming the file and the numbers.  Whole means as long as
    its own tensor directory says (the header is read, the data is not): a truncated copy (--gguf-dir, a .part
    renamed by hand, a download finished by an older setup) otherwise passes as a model file and the engine
    fails much later, at the first tensor that runs past the end."""
    sys.path.insert(0, str(ROOT / "tools"))
    from gguf_reader import GGUFFile
    for s in shards:
        if not s.exists():
            fail(f"missing {s}")
        try:
            g = GGUFFile(s)
        except (ValueError, struct.error) as e:
            fail(f"{s.name} is not a whole GGUF shard ({e})", "delete it and run setup again")
        need = g.data_start + max((t.offset + (t.expected_bytes() or 0) for t in g.tensors), default=0)
        have = s.stat().st_size
        if not g.tensors:
            # #2346: a metadata-only shard (Unsloth's UD-Q5_K_XL 00001, 10,946,618 bytes) ends at its header: the
            # alignment padding before an empty data section is not in the file, so data_start can be past its end
            need = min(need, have)
        if have < need:
            fail(f"{s.name} is short: {have:,} of {need:,} bytes ({need - have:,} missing)",
                 "delete it and run setup again (or copy the whole file into --gguf-dir)")
        if len(g.tensors) == 1 and have - need >= 64:       # (a few bytes may be the last tensor's alignment padding)
            # upstream #657: a shard that holds one tensor (the PLE table) is exactly as long as that tensor; extra
            # bytes are a damaged or wrong file that the engine would refuse at start ("PLE table size mismatch")
            fail(f"{s.name} is longer than its tensor: {have:,} bytes, {need:,} expected ({have - need:,} extra)",
                 f"delete {s.name} and its .done mark and run setup again")


def _hash_file(s: Path, size: int) -> str:
    h = hashlib.sha256()
    seen, last = 0, 0.0
    with open(s, "rb") as f:
        while True:
            b = f.read(16 << 20)
            if not b:
                break
            h.update(b)
            seen += len(b)
            if time.time() - last > 2 and size >= (1 << 30):    # hashing 60 GB takes minutes (upstream d298999c3)
                last = time.time()
                progress(f"checking {s.name}", seen, size)
    if seen >= (1 << 30):
        progress_end()
    return h.hexdigest()


def verify_sha256(s: Path, size: int, sha: str, own: bool = False, repair=None) -> None:
    """A shard's size and SHA-256 against the pinned values (the Unsloth file); the result is kept in its finish mark,
    so the minutes of hashing 111 GB happen once.  A wrong file is deleted, so the next run downloads it again.
    `repair` (a downloaded file's own re-reader, see repair_download): the wrong file is first compared with the server
    piece by piece and only the damaged pieces are written again, then it is checked a second time."""
    m = s.with_name(s.name + ".done")
    if m.exists() and f"sha256 {sha}" in m.read_text(encoding="utf-8", errors="replace"):
        return
    have = s.stat().st_size if s.exists() else -1
    if have != size:
        if own:                                        # --gguf-dir: the person's own file is never deleted by setup
            fail(f"{s.name} is {have:,} bytes; the published file is {size:,}",
                 "it may be cut short or another version; your file was left as it is. "
                 "Copy the whole published file into the folder")
        fail(f"{s.name} is {have:,} bytes, not {size:,}", "delete it and run setup again (the download restarts)")
    say(f"  checking {s.name} (SHA-256, {size / 1e9:.1f} GB) ...")
    digest = _hash_file(s, size)
    if digest != sha and repair is not None and not own:
        say(f"  Some parts of {s.name} were damaged; downloading only those parts again.")
        res = repair()
        if res is not None:
            say(f"  {res[0]} of {res[1]} parts were different and have been written again; checking the whole file "
                "again ...")
            digest = _hash_file(s, size)
        else:
            say("  The damaged parts could not be found this way.")
    if digest != sha:
        if own:
            fail(f"{s.name} does not match the published file (SHA-256 {digest}, expected {sha})",
                 "it may be damaged or another version; your file was left as it is. "
                 "Copy the whole published file into the folder")
        s.unlink(missing_ok=True)
        m.unlink(missing_ok=True)
        fail(f"{s.name} has the wrong SHA-256 ({digest}, expected {sha}): deleted",
             "run setup again to download it again")
    mark(s, f"sha256 {sha}")


def tree_sha256(top: Path) -> str:
    """#32: a folder's files as one SHA-256 - each file's path (relative, with /) and its SHA-256, in path order."""
    items = []
    for root, _dirs, files in os.walk(top):
        for f in files:
            p = Path(root) / f
            h = hashlib.sha256()
            with open(p, "rb") as fh:
                for block in iter(lambda: fh.read(1 << 20), b""):
                    h.update(block)
            items.append((p.relative_to(top).as_posix(), h.hexdigest()))
    total = hashlib.sha256()
    for rel, digest in sorted(items):
        total.update(f"{rel}\0{digest}\n".encode())
    return total.hexdigest()


def get_llama_cpp():
    """llama.cpp at the pinned commit (ggml for the build, gguf-py for the tools, mtmd for images), as a zip: no git."""
    llama = ROOT / "third_party" / "main" / "llama.cpp"
    if (llama / "ggml" / "CMakeLists.txt").exists() and (llama / "gguf-py").is_dir() and \
            (llama / "tools" / "mtmd" / "CMakeLists.txt").exists():   # a copy without mtmd cannot build the encoder
        return llama
    z = ROOT / "third_party" / "main" / f"llama.cpp-{LLAMA_CPP_COMMIT[:7]}.zip"
    download(LLAMA_CPP_ZIP, z, "llama.cpp source")
    tmp = ROOT / "third_party" / "main" / "_unpack"
    shutil.rmtree(tmp, ignore_errors=True)
    try:
        with zipfile.ZipFile(z) as f:
            f.extractall(tmp)
    except zipfile.BadZipFile:
        # upstream #1797: do not let the .done mark make every later run reuse a damaged source archive.
        try:
            z.unlink(missing_ok=True)
            z.with_name(z.name + ".done").unlink(missing_ok=True)
        except OSError as e:
            warn(f"cannot remove damaged {z.name} ({e}): delete it and its .done mark before running setup again")
        raise
    top = next(tmp.iterdir())
    if (got := tree_sha256(top)) != LLAMA_CPP_TREE_SHA256:   # #32: before anything of it is used or compiled
        shutil.rmtree(tmp, ignore_errors=True)
        z.unlink(missing_ok=True)
        z.with_name(z.name + ".done").unlink(missing_ok=True)
        fail(f"the llama.cpp source from {LLAMA_CPP_ZIP.split('/')[2]} is not the pinned commit's (its files' "
             f"SHA-256 {got[:16]}..., expected {LLAMA_CPP_TREE_SHA256[:16]}...)",
             "run setup again; if it says so again, the download is being changed on its way: update XeStrata")
    if llama.exists():
        shutil.rmtree(llama)
    top.replace(llama)
    shutil.rmtree(tmp, ignore_errors=True)
    z.unlink(missing_ok=True)
    z.with_name(z.name + ".done").unlink(missing_ok=True)
    return llama


def req_name(line: str) -> str:
    """The distribution name of a requirement line ("numpy==2.5.3; python_version >= '3.12'" -> "numpy")."""
    return re.split(r"[\s<>=!~;\[]", line.strip(), maxsplit=1)[0].lower().replace("_", "-")


def requirement_lines(path: Path | None = None) -> list[str]:
    """A requirements file's requirements, comments and blank lines left out."""
    lines = []
    for raw in (path or REQUIREMENTS).read_text(encoding="utf-8").splitlines():
        line = raw.split("#", 1)[0].strip()
        if line:
            lines.append(line)
    return lines


def _installed(name: str) -> bool:
    try:
        import importlib.metadata as md
        md.distribution(name)
        return True
    except Exception:
        return False


def pip_install(packages, what):
    """pip install into .venv, skipped when the same list was installed before.  An install from before the pinned
    requirements recorded bare names: those packages are kept as they are (nothing is reinstalled), and the pinned
    dependencies it already has count as installed."""
    # a Python whose prefix this user cannot write (the system's, run without setup.sh's .venv): pip installs into the
    # user's site, and the list is kept there
    stamp = (Path(sys.prefix) if os.access(sys.prefix, os.W_OK) else Path(site.getuserbase())) / ".strata-pip.json"
    have = json.loads(stamp.read_text()) if stamp.exists() else []
    bare = {p.lower() for p in have if req_name(p) == p.lower()}
    need = [p for p in packages if p not in have and req_name(p) not in bare
            and not (bare and "==" in p and _installed(req_name(p)))]
    if not need:
        ok(f"{what} already installed")
        return
    say(f"  Installing {what} ...")
    run([sys.executable, "-m", "pip", "install", "--quiet", "--disable-pip-version-check", *need])
    try:
        stamp.parent.mkdir(parents=True, exist_ok=True)
        stamp.write_text(json.dumps(sorted(set(have) | set(need)), indent=0))
    except OSError as e:                                 # only costs asking pip again next time
        warn(f"could not record the installed packages in {stamp} ({e}): the next run checks them again")
    ok(f"{what} installed")


# ------------------------------------------------------------------------------------------------ the engine
ONEAPI_ROOT = Path(os.environ.get("ONEAPI_ROOT", "/opt/intel/oneapi"))
_ONEAPI_ENV: dict | None = None


def oneapi_env() -> dict | None:
    """The environment oneAPI's setvars.sh sets up (its compilers, its libraries and the SYCL runtime on the paths), or
    None when oneAPI is not installed.  The engine is built with it."""
    global _ONEAPI_ENV
    if _ONEAPI_ENV is None:
        sv = ONEAPI_ROOT / "setvars.sh"
        if not sv.is_file():
            return None
        # the path goes in as $1: setvars.sh takes a $0 equal to its own path for "run, not sourced" and exits
        r = subprocess.run(["bash", "-c", 'source "$1" >/dev/null 2>&1; env -0', "_", str(sv)], capture_output=True)
        if r.returncode != 0:
            return None
        _ONEAPI_ENV = dict(x.split("=", 1) for x in r.stdout.decode(errors="replace").split("\0") if "=" in x)
    return _ONEAPI_ENV


# ------------------------------------------------------------------------------------------------ the SYCL compiler
# AGENTS.md, "Free and non-free builds": two build modes (--license).  free uses free software only:
# intel/llvm's DPC++ 7 or later, the distribution's (dpclang++) or one built from source (tools/intel_llvm_build.py,
# --intel-llvm-build; setup offers to build it when the distribution's is older), for Intel GPUs.  contrib (the
# default): intel/llvm built with its CUDA target (.tools/intel-llvm-contrib), for Intel and NVIDIA GPUs, with oneMKL
# and cuBLAS for the dense products.  Intel oneAPI's icpx is not taken (the contrib-icpx mode was removed on
# 2026-10-15).  Whether the Intel GPU has its matrix engines (XMX) for a compiler is asked of the GPU itself
# (tools/xmx_probe.cpp), not read from a version number.  Without XMX the engine still runs, its prompt path about 1.6
# times slower (the 2026-10-02-dp4a record); setup asks before building it so.
LICENSES = ("free", "contrib")
INTEL_LLVM_BUILD = ROOT / "tools" / "intel_llvm_build.py"
INTEL_LLVM_DEFAULT = ROOT / ".tools" / "intel-llvm" / "install"
INTEL_LLVM_CONTRIB = ROOT / ".tools" / "intel-llvm-contrib" / "install"
FREE_HOW = ("intel/llvm's DPC++ 7 or later (free software): build it here: ./setup.sh --intel-llvm-build (13 minutes "
            "on 28 threads, 3.5 GB), or a distribution's package of version 7 or later")
MKL_HOW = ("oneMKL (not free software; Intel's apt repository, set up as docs/BUILD.md#packages says): "
           f"sudo apt install intel-oneapi-mkl-sycl-devel-{ONEMKL_SERIES}")
# Intel's repositories carry apt and dnf packages, not Arch's: on Arch the oneAPI packages come from Intel's offline
# installer, if they are wanted at all (the free and contrib modes build intel/llvm from the source)
ONEAPI_ARCH = ("Intel oneAPI is not in Arch's repositories (only apt's and dnf's): either install it with Intel's "
               "offline installer, or use --license free, which builds intel/llvm from the source and keeps the Intel "
               "GPU's dense products in XeStrata's own kernels")


def license_mode(a=None) -> str:
    """The build mode: --license, else the one kept in the settings.  Settings of icpx's builds (the removed
    contrib-icpx mode, or "nonfree": true from before the modes) take the contrib mode."""
    if PACKAGED:
        return packaged_engine().get("license", "free")
    if a is not None and getattr(a, "license", None):
        return a.license
    st = load_settings()
    mode = st.get("license") or "contrib"
    if mode == "contrib-icpx" or (st.get("nonfree") and not st.get("license")):
        global _ICPX_SAID
        if not _ICPX_SAID:
            _ICPX_SAID = True
            warn("the settings name the contrib-icpx mode (Intel oneAPI's icpx), which was removed: the engine is "
                 "built in the contrib-llvm mode (--license contrib) instead; --license free chooses the free mode")
        return "contrib"
    return mode


_ICPX_SAID = False


def new_process_group() -> dict:
    """Popen's arguments for a program started in a process group of its own (the server and the engine it starts),
    so end_process_group ends them together."""
    if WIN:
        return {"creationflags": subprocess.CREATE_NEW_PROCESS_GROUP}  # type: ignore[attr-defined]
    return {"start_new_session": True}


def end_process_group(proc) -> None:
    """Ends a program started with new_process_group and what it started: SIGTERM to the group, SIGKILL after a minute;
    on Windows the whole tree at once (taskkill /T /F)."""
    if WIN:
        subprocess.run(["taskkill", "/PID", str(proc.pid), "/T", "/F"], stdout=subprocess.DEVNULL,
                       stderr=subprocess.DEVNULL, timeout=60)
        proc.wait()
        return
    try:
        os.killpg(proc.pid, 15)
    except ProcessLookupError:                         # the server and its engine have ended already
        return
    try:
        proc.wait(timeout=60)
    except subprocess.TimeoutExpired:
        try:
            os.killpg(proc.pid, 9)
        except ProcessLookupError:
            pass
        proc.wait()


def packaged_engine_dir() -> Path:
    """The installed engine's folder: the PACKAGED record's (relative to this folder in the Windows 7z, which can be
    unpacked anywhere), else engine/ next to this file."""
    return ROOT / PACKAGED["engine"] if PACKAGED else ROOT / "engine"


def engine_tool(*args: str) -> str:
    """strata-device's output for `args` (--list-devices, --cpu): where setup has no sysfs or /proc to read (Windows),
    the engine reports the GPUs and the CPU itself."""
    exe = packaged_engine_dir() / ("strata-device.exe" if WIN else "strata-device")
    r = subprocess.run([str(exe), *args], capture_output=True, text=True, timeout=120)
    if r.returncode != 0:
        raise subprocess.SubprocessError((r.stderr or r.stdout).strip() or f"{exe.name} {' '.join(args)} failed")
    return r.stdout


def packaged_engine() -> dict:
    """The installed package's engine record (BUILD.json): its license, NVIDIA architectures and library folders."""
    eng = packaged_engine_dir()
    try:
        meta = json.loads((eng / "BUILD.json").read_text(encoding="utf-8"))
    except (OSError, ValueError):
        meta = {}
    if not meta or not (eng / EXE).is_file():
        fail("the XeStrata package has no engine (its files are missing)",
             "install it again: sudo apt install --reinstall <package> (Ubuntu), sudo dnf reinstall <package> (Fedora)")
    return meta


def mkl_series(root) -> str | None:
    """The series of the oneMKL in `root` ("2026.2"): its folder's name (/opt/intel/oneapi/mkl/2026.2), else its
    mkl_version.h's INTEL_MKL_VERSION (20260200)."""
    name = Path(root).resolve().name
    if re.fullmatch(r"\d{4}\.\d+", name):
        return name
    try:
        text = (Path(root) / "include" / "mkl_version.h").read_text(errors="replace")
        v = int(re.search(r"#define\s+INTEL_MKL_VERSION\s+(\d+)", text).group(1))   # type: ignore[union-attr]
    except (OSError, AttributeError, ValueError):
        return None
    return f"{v // 10000}.{v // 100 % 100}"


def mkl_root() -> str | None:
    """Where oneMKL of ONEMKL_SERIES is (the contrib modes' dense products, the SYCL image encoder): the first of
    oneAPI's MKLROOT, oneAPI's folder of the series and its latest that is of the series, else None (another series's
    SYCL library may not load on the engine's runtime: ONEMKL_SERIES)."""
    for root in ((oneapi_env() or {}).get("MKLROOT"), f"/opt/intel/oneapi/mkl/{ONEMKL_SERIES}",
                 "/opt/intel/oneapi/mkl/latest"):
        if root and Path(root, "lib").is_dir() and mkl_series(root) == ONEMKL_SERIES:
            return root
    return None


def compiler_version(cxx, env) -> str:
    r = subprocess.run([str(cxx), "--version"], capture_output=True, text=True, env=env)
    lines = [x.strip() for x in r.stdout.splitlines()] or ["?"]
    # dpclang's first line ends "build based on:", the clang version is on the next
    return f"{lines[0]} {lines[1]}" if lines[0].endswith(":") and len(lines) > 1 else lines[0]


def free_compiler(install: Path, license: str = "free") -> dict:
    """intel/llvm built from source (`install` holds bin/clang++ and lib/libsycl.so); "contrib": one with its CUDA
    target."""
    lib = install / "lib"
    env = dict(os.environ, LD_LIBRARY_PATH=os.pathsep.join([str(lib), os.environ.get("LD_LIBRARY_PATH", "")]))
    return {"kind": "intel-llvm", "cxx": str(install / "bin" / "clang++"), "cc": str(install / "bin" / "clang"),
            "env": env, "lib_dirs": [str(lib)], "license": license, "cuda_archs": [], "hip_archs": [], "onemkl": False}


def new_enough(comp: dict) -> bool:
    """Whether the compiler is intel/llvm 7 or later: its SYCL runtime is libsycl 9 (the distribution's dpclang++ 6.2
    has libsycl 8, and gives the Arc Pro B70 no XMX)."""
    r = subprocess.run([comp["cxx"], "-fsycl", "-dM", "-E", "-x", "c++", "-"], input="#include <sycl/sycl.hpp>\n",
                       capture_output=True, text=True, env=comp["env"])
    m = re.search(r"#define __LIBSYCL_MAJOR_VERSION (\d+)", r.stdout)
    return m is not None and int(m.group(1)) >= 9


def os_compiler() -> dict | None:
    """The distribution's intel/llvm DPC++ (dpclang++, or the newest dpclang++-N)."""
    cxx = shutil.which("dpclang++")
    if cxx is None:
        names = {p.name for d in os.environ.get("PATH", "").split(os.pathsep) if Path(d).is_dir()
                 for p in Path(d).glob("dpclang++-*")}
        for n in sorted(names, key=lambda n: [int(x) for x in re.findall(r"\d+", n)], reverse=True):
            cxx = shutil.which(n)
            if cxx:
                break
    if cxx is None:
        return None
    cc = shutil.which(Path(cxx).name.replace("dpclang++", "dpclang")) or cxx
    return {"kind": "os", "cxx": cxx, "cc": cc, "env": dict(os.environ), "lib_dirs": [], "license": "free",
            "cuda_archs": [], "hip_archs": [], "onemkl": False}


def amd_archs() -> list:
    """The ISA names of this PC's AMD GPUs the engine can run on: the build makes their code (STRATA_HIP_ARCHS)."""
    return sorted({g["gfx"] for g in gpus() if g.get("vendor") == "amd" and gpu_problem(g) is None})


def intel_gpu_present() -> bool:
    """Whether this PC has an Intel GPU Strata can use: the contrib build then gets the oneMKL backend."""
    return any(g.get("vendor") == "intel" for g in gpus())


def cuda_toolkits() -> list:
    """The CUDA toolkits on this PC, as cmake/StrataCuda.cmake looks for them (which chooses the one the contrib build
    uses): CUDA_PATH / CUDA_HOME / CUDA_ROOT, /usr/local/cuda-X.Y, /opt/cuda, Debian's /usr/lib/cuda and the nvcc on
    PATH; a folder counts when it has the libdevice clang needs."""
    import glob
    dirs = [os.environ.get(v, "") for v in ("CUDA_PATH", "CUDA_HOME", "CUDA_ROOT")]
    dirs += sorted(glob.glob("/usr/local/cuda-*")) + sorted(glob.glob("/opt/cuda-*"))
    dirs += ["/usr/local/cuda", "/opt/cuda", "/usr/lib/cuda"]
    nvcc = shutil.which("nvcc")
    if nvcc:
        dirs.append(str(Path(nvcc).resolve().parent.parent))
    found = []
    for d in dirs:
        if d and Path(d).is_dir() and glob.glob(str(Path(d) / "nvvm" / "libdevice" / "libdevice*.bc")):
            r = str(Path(d).resolve())
            if r not in found:
                found.append(r)
    return found


def cuda_archs() -> list:
    """The NVIDIA architectures of this PC's NVIDIA GPUs (sm_89 for compute capability 8.9), as nvidia-smi reports
    them: the contrib build makes their code (CMake's STRATA_CUDA_ARCHS=auto reads them again and maps one the
    compiler does not know to the newest it builds)."""
    return sorted({"sm_" + g["cc"].replace(".", "") for g in nvidia_smi().values()
                   if re.fullmatch(r"\d+\.\d+", g["cc"])})


def probe_gpu(comp: dict, pci: str | None) -> dict | None:
    """What the Intel GPU at `pci` reports to this compiler's SYCL runtime (tools/xmx_probe.cpp): its fields ("fp16",
    "bf16": "1" for the matrix engines), {} when the runtime lists no such GPU, None when the probe did not build."""
    with tempfile.TemporaryDirectory() as d:
        exe = Path(d) / "xmx_probe"
        r = subprocess.run([comp["cxx"], "-fsycl", str(ROOT / "tools" / "xmx_probe.cpp"), "-o", str(exe)],
                           capture_output=True, text=True, env=comp["env"])
        if r.returncode != 0:
            warn(f"{Path(comp['cxx']).name} could not build the XMX probe: {(r.stderr or r.stdout).strip()[-300:]}")
            return None
        r = subprocess.run([str(exe)], capture_output=True, text=True, env=comp["env"], timeout=120)
    seen = {}
    for line in r.stdout.splitlines():
        f = dict(x.split("=", 1) for x in line.split(" name=")[0].split() if "=" in x)
        if pci is None or f.get("pci") == pci:
            if has_xmx(f):
                return f
            seen = f
    return seen


def has_xmx(probed: dict | None) -> bool:
    return probed is not None and probed.get("fp16") == "1" and probed.get("bf16") == "1"


def build_intel_llvm(a, contrib: bool = False) -> Path:
    """tools/intel_llvm_build.py (--contrib: with the CUDA target): a finished build is used as it is, an interrupted
    one continued."""
    flags = [f for f, on in (("--contrib", contrib), ("--rebuild", a.intel_llvm_rebuild),
                             ("--keep-build", a.intel_llvm_keep_build), ("--yes", a.yes)) if on]
    run([sys.executable, INTEL_LLVM_BUILD, *flags])
    return INTEL_LLVM_CONTRIB if contrib else INTEL_LLVM_DEFAULT


def contrib_compiler(a, st: dict) -> tuple:
    """intel/llvm with its CUDA target: --intel-llvm DIR, the one kept in the settings, or the one built here (built
    now when there is none).  Returns it and its folder."""
    d = Path(a.intel_llvm or st.get("intel_llvm_contrib") or INTEL_LLVM_CONTRIB).expanduser().resolve()
    if not (d / "bin" / "clang++").exists():
        if a.intel_llvm:
            fail(f"--intel-llvm {d}: no bin/clang++ there", "give the folder intel/llvm was installed to")
        say("  The contrib build needs intel/llvm with its CUDA target (NVIDIA's CUDA toolkit, not free software); "
            "it is built here from source (about 25 minutes on 28 threads, 4 GB).")
        if ask("Build it now?", ["y", "n"], "y", a.yes) != "y":
            fail("stopped: no intel/llvm with the CUDA target", "python3 tools/intel_llvm_build.py --contrib")
        d = build_intel_llvm(a, contrib=True)
    if not any((d / "lib").glob("libur_adapter_cuda.so*")):
        fail(f"{d}: this intel/llvm has no CUDA target", "build one: python3 tools/intel_llvm_build.py --contrib")
    comp = free_compiler(d, "contrib")
    # every maker's GPUs on this PC: the NVIDIA ones' code and cuBLAS, the Intel ones' oneMKL
    comp["cuda_archs"] = cuda_archs()
    comp["onemkl"] = intel_gpu_present()
    if comp["cuda_archs"] and not cuda_toolkits():
        fail("NVIDIA's CUDA toolkit is missing (the contrib build makes the NVIDIA GPUs' code with it, and their "
             "dense products go to its cuBLAS)",
             "install it: " + install_cmd([PACKAGES[distro_family()]["nvidia"]]))
    return comp, d


def choose_compiler(a, gpu: dict) -> dict:
    """The SYCL compiler the engine is built with, for the build mode (--license; the order in docs/XE.md, "The SYCL
    compiler").  The mode, --intel-llvm DIR and an accepted build without XMX are kept in the settings for the next
    runs."""
    st = load_settings()
    mode = license_mode(a)
    pci = gpu["pci"]
    allow_no_xmx = a.allow_no_xmx or bool(st.get("allow_no_xmx"))
    kept = {}                                          # the intel/llvm folder to keep in the settings
    if mode == "contrib" and cuda_archs():
        comp, d = contrib_compiler(a, st)
        kept = {"intel_llvm_contrib": str(d)}
    else:
        # free, and contrib on a PC without NVIDIA GPUs: no CUDA target is needed, so the free mode's compiler
        llvm_dir = a.intel_llvm or st.get("intel_llvm")
        comp = None
        if llvm_dir:
            d = Path(llvm_dir).expanduser().resolve()
            if not (d / "bin" / "clang++").exists():
                fail(f"--intel-llvm {d}: no bin/clang++ there", "give the folder intel/llvm was installed to")
            comp = free_compiler(d)
            if not new_enough(comp):
                fail(f"--intel-llvm {d}: older than intel/llvm 7", FREE_HOW)
        elif not a.intel_llvm_build and not amd_archs() and (c := os_compiler()) is not None:
            # (AMD GPUs take intel/llvm built here, which gets the HIP target from the ROCm installed)
            if new_enough(c):
                comp = c
            else:
                say(f"  {Path(c['cxx']).name} ({compiler_version(c['cxx'], c['env'])}) is older than intel/llvm 7, "
                    "which the engine needs")
        if comp is None:
            if not a.intel_llvm_build and ask("Build intel/llvm here now (13 minutes on 28 threads, 3.5 GB)?",
                                              ["y", "n"], "y", a.yes) != "y":
                fail("no SYCL compiler for the engine", FREE_HOW)
            comp = free_compiler(build_intel_llvm(a))
            llvm_dir = str(INTEL_LLVM_DEFAULT)
        kept = {"intel_llvm": llvm_dir} if llvm_dir else {}
        if mode == "contrib":
            comp["license"], comp["onemkl"] = "contrib", intel_gpu_present()
    if comp["onemkl"] and mkl_root() is None:
        fail(f"--license {mode} hands the Intel GPU's dense matrix products to oneMKL, which is not installed",
             ONEAPI_ARCH if distro_family() == "arch" else MKL_HOW)
    comp["hip_archs"] = amd_archs()
    if comp["hip_archs"]:
        if missing := rocm_missing():
            fail("building for the AMD GPU needs ROCm's " + ", ".join(missing),
                 "install them: " + install_cmd(missing) + ", then run it again")
        comp["lib_dirs"] = list(dict.fromkeys(comp["lib_dirs"] + rocm_lib_dirs()))
        if not any(Path(d).glob("libur_adapter_hip.so*") for d in comp["lib_dirs"]):
            # intel/llvm gets the HIP target only when ROCm's HIP is there as it is built
            llvm = Path(comp["cxx"]).parent.parent
            if llvm.resolve() not in (INTEL_LLVM_DEFAULT.resolve(), INTEL_LLVM_CONTRIB.resolve()):
                fail(f"{llvm}: this intel/llvm has no HIP target (AMD GPUs)",
                     "build it with ROCm's HIP installed (tools/intel_llvm_build.py)")
            say("  The intel/llvm built here has no HIP target (AMD GPUs): it was built before ROCm was installed.")
            if ask("Build it again with the HIP target now?", ["y", "n"], "y", a.yes) != "y":
                fail("stopped: no HIP target for the AMD GPU", "python3 tools/intel_llvm_build.py --rebuild" +
                     (" --contrib" if llvm.resolve() == INTEL_LLVM_CONTRIB.resolve() else ""))
            a.intel_llvm_rebuild = True
            build_intel_llvm(a, contrib=llvm.resolve() == INTEL_LLVM_CONTRIB.resolve())
    if gpu.get("vendor") in ("nvidia", "amd"):
        # the tensor cores through cuBLAS and joint_matrix, AMD's WMMA and dot instructions: the XMX question is
        # Intel's
        xmx = False
    else:
        probed = probe_gpu(comp, pci)
        if probed == {}:
            # no compiler makes the engine run on a GPU its driver does not list (seen on openSUSE Leap 16, whose
            # compute-runtime 25.18 lists no Arc Pro B70)
            fail(f"the SYCL runtime of {Path(comp['cxx']).name} lists no GPU at PCI {pci}" if pci else
                 f"the SYCL runtime of {Path(comp['cxx']).name} lists no GPU",
                 "the GPU's Level Zero driver (libze-intel-gpu1, Intel's compute-runtime) is missing or too old for "
                 "this GPU: install a newer one (docs/BUILD.md#packages) and run setup again")
        xmx = has_xmx(probed)
        if not xmx and not allow_no_xmx:
            say(f"\n  {Path(comp['cxx']).name} ({compiler_version(comp['cxx'], comp['env'])}) gives this GPU no XMX "
                "(its matrix engines): the engine would run, but its prompt processing about 1.6 times slower.")
            choices = {"1": "build without XMX", "2": "stop"}
            for k, v in choices.items():
                say(f"  {k}) {v}")
            if ask("Which?", list(choices), "2", a.yes) == "2":
                fail("stopped: no XMX for this GPU", "accept the slower prompt path (--allow-no-xmx)")
            allow_no_xmx = True
    st = {k: v for k, v in load_settings().items() if k != "nonfree"}
    save_settings({**st, "license": mode, "allow_no_xmx": allow_no_xmx, **kept})
    comp["version"] = compiler_version(comp["cxx"], comp["env"])
    comp["xmx"] = xmx
    what = ("NVIDIA's tensor cores" if gpu.get("vendor") == "nvidia" else "an AMD GPU" if gpu.get("vendor") == "amd"
            else "XMX" if xmx else "no XMX: the slower prompt path")
    ok(f"SYCL compiler: {comp['version']} ({mode}; {what}" +
       (f"; NVIDIA code for {', '.join(comp['cuda_archs'])}" if comp["cuda_archs"] else "") +
       (f"; AMD code for {', '.join(comp['hip_archs'])}" if comp["hip_archs"] else "") + ")")
    return comp


def check_build_tools(comp: dict) -> None:
    """What the build needs besides the SYCL compiler: g++ for the CPU image encoder (glslc and the Vulkan headers for
    the Vulkan one: vulkan_missing).  Setup does not install them (no apt or sudo from setup): it says what is
    missing."""
    missing = []
    if shutil.which("g++") is None:
        missing.append(tool_pkg("g++"))
    if missing:
        fail("missing: " + ", ".join(missing), "install them, then run it again (docs/XE.md lists the packages)")


def vulkan_missing() -> list:
    """The packages the Vulkan image encoder (ggml-vulkan) needs that are not installed."""
    need = []
    if shutil.which("glslc") is None:
        need.append(tool_pkg("glslc"))
    if not Path("/usr/include/vulkan/vulkan.h").exists():
        need.append(tool_pkg("vulkan"))
    if not Path("/usr/include/spirv/unified1/spirv.hpp").exists():
        need.append(tool_pkg("spirv"))
    return need


def cmake_build(src, bdir, target, defs, env=None):
    """Configure `src` in `bdir` and build `target` (a name, or a list of names).  The build helpers already there
    are used (the distribution's, offline too); a missing one is installed from requirements-build.txt."""
    build_packages = requirement_lines(BUILD_REQUIREMENTS) if BUILD_REQUIREMENTS.exists() else BUILD_PACKAGES
    missing = [package for package in build_packages if find_tool(req_name(package)) is None]
    if missing:
        pip_install(missing, "CMake and Ninja build tools")
    cmake, ninja = find_tool("cmake"), find_tool("ninja")
    if cmake is None or ninja is None:
        fail("cmake / ninja not found after installing them",
             "run: .venv python -m pip install -r requirements-build.txt")
    conf = [cmake, "-G", "Ninja", f"-DCMAKE_MAKE_PROGRAM={ninja}", "-S", str(src), "-B", str(bdir),
            "-DCMAKE_BUILD_TYPE=Release", *defs]
    # the tools on PATH too: ggml's Vulkan backend configures its shader generator as a separate CMake project
    # (ExternalProject) that asks for Ninja by name, which fails on a clean system where only pip's ninja exists
    env = dict(env or os.environ)
    env["PATH"] = os.pathsep.join(dict.fromkeys([str(Path(ninja).parent), str(Path(cmake).parent),
                                                 env.get("PATH", "")]))
    # a SYCL translation unit takes several GB to compile: as many jobs as the RAM allows, at most half the threads
    jobs = max(2, min((os.cpu_count() or 4) // 2, int(ram_gb() // 12)))
    run(conf, env=env)
    targets = [target] if isinstance(target, str) else list(target)
    run([cmake, "--build", str(bdir), "--target", *targets, "-j", str(jobs)], env=env)


ENGINE_SOURCES = ("CMakeLists.txt", "cmake", "src", "include", "third_party/main/ggml")
VISION_SOURCES = ("tools/vision",)


def source_hash(parts) -> str:
    """A fingerprint of the files a compiled engine is built from, kept in engine/BUILD.json: when a `git pull`
    changes them, the engine is compiled again (issue #31)."""
    h = hashlib.sha256(LLAMA_CPP_COMMIT.encode())
    for part in parts:
        base = ROOT / part
        for f in [base] if base.is_file() else sorted(x for x in base.rglob("*") if x.is_file()):
            h.update(f.relative_to(ROOT).as_posix().encode() + b"\0" + f.read_bytes().replace(b"\r\n", b"\n"))
    return h.hexdigest()[:16]


def install_binary(src: Path, dst: Path) -> None:
    """Replace a running executable by renaming a complete copy over its old inode."""
    fd, name = tempfile.mkstemp(prefix=dst.name + ".", suffix=".new", dir=dst.parent)
    os.close(fd)
    tmp = Path(name)
    try:
        shutil.copy2(src, tmp)
        os.replace(tmp, dst)
    finally:
        tmp.unlink(missing_ok=True)


def engine_is_xe(meta: dict) -> bool:
    """An engine in engine/ is this port's only if setup compiled it here for Xe: anything else there is upstream's
    CUDA build (a ready-made download or an older copy of Strata) and cannot run on an Intel GPU."""
    return meta.get("source") == "local" and meta.get("backend") == "xe"


def engine_cmake_args() -> list:
    """--cmake-arg KEY=VALUE: CMake options of the user's for the engine's build (a ROCm or toolkit in a place CMake
    does not look, for example; a user could not hand setup one and changed setup.py), kept in the settings so that
    later builds (an update) take them again; --cmake-arg "" clears them."""
    st = load_settings()
    given = getattr(ARGS, "cmake_arg", None)
    if given is None:
        return list(st.get("cmake_args", []))
    keep = [x for x in given if x]
    save_settings({**st, "cmake_args": keep})
    return keep


def build_engine(visions, llama, comp: dict, data: Path) -> Path:
    """Compile the engine with `comp` (choose_compiler) and the image encoders in `visions` ("cpu", "vulkan"); the
    results go to engine/.  A compiled engine or encoder whose source files or compiler changed since (a
    `git pull`, another intel/llvm) is compiled again.  Each encoder has its own binary, so installing one never
    replaces the other."""
    eng = ROOT / "engine"
    eng.mkdir(exist_ok=True)
    stamp = eng / "BUILD.json"
    meta = json.loads(stamp.read_text()) if stamp.exists() else {}
    xe = engine_is_xe(meta)
    src, vsrc = source_hash(ENGINE_SOURCES), source_hash(VISION_SOURCES)
    used = {"cxx": comp["cxx"], "version": comp["version"], "kind": comp["kind"], "xmx": comp["xmx"],
            "license": comp["license"], "cuda_archs": comp["cuda_archs"], "onemkl": comp["onemkl"],
            "hip_archs": comp.get("hip_archs", [])}
    if extra := engine_cmake_args():                   # (only when given: a build without them stays as it was)
        used["cmake_args"] = extra
    # cuDNN's headers where pip put them (nvidia_libs_dir), for the image engine's attention on NVIDIA GPUs: the
    # engine is compiled again once they are there
    cudnn = nvidia_libs_dir(data) / "nvidia" / "cudnn"
    if comp["license"] == "contrib" and comp["cuda_archs"] and (cudnn / "include" / "cudnn.h").exists():
        used["cudnn_root"] = str(cudnn)
    engine_ok = (xe and (eng / EXE).exists() and (eng / IMAGE_EXE).exists() and meta.get("src") == src
                 and meta.get("compiler") == used)
    built = dict(meta.get("vision_srcs") or {}) if xe else {}
    missing = [v for v in dict.fromkeys(visions)
               if v in VEXE and not ((eng / VEXE[v]).exists() and built.get(v) == vsrc)]
    if engine_ok and not missing:
        ok("engine already built for this PC")
        return eng
    check_build_tools(comp)
    if "vulkan" in missing and (need := vulkan_missing()):
        fail("the Vulkan image encoder needs: " + ", ".join(need), "install them: " + install_cmd(need))
    if not engine_ok:
        bdir = ROOT / "build-xe"
        cache = bdir / "CMakeCache.txt"
        if cache.exists() and (f"CMAKE_CXX_COMPILER:FILEPATH={comp['cxx']}" not in cache.read_text(errors="replace")
                               or (meta.get("compiler") or {}).get("cmake_args") != used.get("cmake_args")):
            shutil.rmtree(bdir)                        # CMake keeps the compiler and the -D values it configured with
        say("  The engine's source changed: compiling it again (only what changed) ..." if xe and (eng / EXE).exists()
            and bdir.exists() else "  Compiling the Strata engine for the GPU (20-40 minutes, once) ...")
        cmake_build(ROOT, bdir, ["strata", "strata-image"],
                    [f"-DCMAKE_CXX_COMPILER={comp['cxx']}", f"-DCMAKE_C_COMPILER={comp['cc']}",
                     f"-DSTRATA_LICENSE={comp['license']}",
                     f"-DSTRATA_CUDA_ARCHS={'auto' if comp['cuda_archs'] else ''}",
                     f"-DSTRATA_HIP_ARCHS={';'.join(comp.get('hip_archs', []))}",
                     f"-DSTRATA_ONEMKL={'ON' if comp['onemkl'] else 'OFF'}",
                     *([f"-DMKL_ROOT={mkl_root()}"] if comp["onemkl"] else []), "-DSTRATA_ENABLE_XE=ON",
                     "-DSTRATA_NATIVE_EXPERTS=ON", "-DSTRATA_BUILD_TESTS=OFF", "-DSTRATA_PORTABLE=ON",
                     f"-DSTRATA_GGML_DIR={llama}", *(f"-D{x}" for x in used.get("cmake_args", [])),
                     *([f"-DSTRATA_CUDNN_ROOT={used['cudnn_root']}"] if "cudnn_root" in used else [])], comp["env"])
        install_binary(bdir / EXE, eng / EXE)
        install_binary(bdir / IMAGE_EXE, eng / IMAGE_EXE)
    for v in missing:
        llama_def = f"-DLLAMA_DIR={llama}"
        if v == "vulkan":
            say("  Compiling the image encoder for the GPU (Vulkan; 5-15 minutes, once) ...")
            bdir = ROOT / "build-vision-vulkan"
            cmake_build(ROOT / "tools" / "vision", bdir, "strata-vision",
                        [llama_def, "-DSTRATA_VISION_VULKAN=ON", "-DSTRATA_PORTABLE=ON"])
        else:
            say("  Compiling the image encoder for the CPU ...")
            bdir = ROOT / "build-vision-cpu"
            cmake_build(ROOT / "tools" / "vision", bdir, "strata-vision", [llama_def, "-DSTRATA_PORTABLE=ON"])
        install_binary(bdir / "bin" / "strata-vision", eng / VEXE[v])
        built[v] = vsrc
    stamp.write_text(json.dumps({"source": "local", "backend": "xe", "version": source_version(), "compiler": used,
                                 "lib_dirs": comp["lib_dirs"], "src": src, "vision_srcs": built}, indent=1))
    ok(f"engine compiled: {eng / EXE}")
    return eng


def recorded_compiler(meta: dict) -> dict:
    """The compiler an installed engine was built with, for building it again after a `git pull` without asking.  An
    engine icpx built (the removed contrib-icpx mode, or one from before the free build, with no record) is built
    again by the compiler setup chooses (./setup.sh --setup)."""
    rec = meta.get("compiler") or {"kind": "icpx", "xmx": True}
    comp: dict | None
    if rec["kind"] == "intel-llvm":
        comp = free_compiler(Path(rec["cxx"]).parent.parent, rec.get("license", "free"))
        if comp["license"] == "contrib":
            comp["cuda_archs"] = cuda_archs()
            comp["onemkl"] = intel_gpu_present()
        comp["hip_archs"] = amd_archs()
    elif rec["kind"] == "os":
        comp = os_compiler()
        if comp is not None and not new_enough(comp):
            fail(f"the engine was built with {Path(comp['cxx']).name}, older than intel/llvm 7 (which it now needs)",
                 "run ./setup.sh --setup to build it with intel/llvm 7 or later")
    else:
        fail("the engine was built with Intel oneAPI's icpx, which XeStrata no longer takes (the contrib-icpx mode was "
             "removed)", "run ./setup.sh --setup to build it with intel/llvm (free or contrib)")
    if comp is None or not Path(comp["cxx"]).exists():
        fail("the compiler the engine was built with is gone", "run ./setup.sh --setup to choose one")
    comp["version"] = compiler_version(comp["cxx"], comp["env"])
    comp["xmx"] = bool(rec.get("xmx"))
    return comp


def update_installed_engine() -> None:
    """An engine or image encoder whose sources changed since it was compiled (a `git pull`) is compiled again before
    the model starts.  If that fails, a previous Xe engine is kept and starts as before; upstream's CUDA engine cannot
    run here.  A package's engine is updated by apt or dnf."""
    if PACKAGED:
        return
    remove_old_image_engine()
    eng = ROOT / "engine"
    info = eng / "BUILD.json"
    if not info.exists() or not (eng / EXE).exists():
        return
    meta = json.loads(info.read_text())
    visions = list((meta.get("vision_srcs") or {}).keys())
    vsrc = source_hash(VISION_SOURCES)
    if engine_is_xe(meta) and meta.get("src") == source_hash(ENGINE_SOURCES) and \
            all(meta["vision_srcs"][v] == vsrc for v in visions):
        return

    try:
        build_engine(visions, get_llama_cpp(), recorded_compiler(meta), data_folder_path(None, load_settings()))
    except (Exception, SystemExit) as e:
        why = "" if isinstance(e, SystemExit) else f" ({e})"
        if not engine_is_xe(meta):
            fail(f"the installed engine is not the Xe build and compiling it failed{why}", "run ./setup.sh --setup")
        warn(f"could not compile the updated engine{why}: starting the installed one")


# ---- image generation: Qwen-Image-2.1-Turbo on XeStrata's own image engine (strata-image, built with the text
# engine; serve/images.py).  upstream 0.1.44 (a5b3b6c2) runs stable-diffusion.cpp's sd-cli instead.
# what XeStrata's earlier image generator (stable-diffusion.cpp's sd-cli, before strata-image) left in the install
OLD_IMAGE_ENGINE = ("engine-image", "build-image-vulkan", "build-image-cpu", "third_party/stable-diffusion.cpp")


def remove_old_image_engine() -> None:
    """The earlier sd-cli build, its build folders and its source, which nothing uses now: removed (a few GB)."""
    if PACKAGED:
        return
    for rel in OLD_IMAGE_ENGINE:
        p = ROOT / rel
        if p.is_dir():
            shutil.rmtree(p, ignore_errors=True)
            ok(f"removed {rel}/: the earlier image generator (sd-cli), which XeStrata's own image engine replaced")


def _qimage():
    if str(ROOT / "tools" / "image") not in sys.path:
        sys.path.insert(0, str(ROOT / "tools" / "image"))
    import qimage
    return qimage


def text_ram_gb(args: list, ram: float, model: str | None = None) -> float:
    """The RAM (GB) the text model's run config keeps for itself, the OS's room included: its RAM budget and the
    OS's room (--resident-budget-gib), all of it when its experts are read through the file cache (--mmap-experts),
    else the size's RAM (MODELS' "ram_gb") and a KV cache streamed into RAM (--kv-resident)."""
    def val(flag):
        return args[args.index(flag) + 1] if flag in args and args.index(flag) + 1 < len(args) else None
    if "--mmap-experts" in args:
        return ram
    if val("--resident-budget-gib") is not None:
        return float(val("--resident-budget-gib")) + UNSLOTH_RAM_LEFT_GB
    gb = float(MODELS[model].get("ram_gb", ram)) if model in MODELS else ram
    if "--kv-resident" in args and val("--max-context"):
        gb += kv_streaming_ram_gb(int(val("--max-context")), val("--kv") or "int8")
    return gb


def setup_images(a, gpu: dict, models_dir: Path, eng: Path, text_gb: float | None = None) -> dict | None:
    """--images (qimage.IMAGE_MODELS): the image model's four files for the image engine in `eng` -> the run
    config's "images" section (serve/images.py); None for --images no, or when not wanted after all.  `text_gb`:
    the RAM the text model keeps (text_ram_gb): the denoiser's and the text encoder's quants are the largest whose
    files fit the rest (the user's decision of 2026-10-15), the encoder lowered first (2026-10-19), or the ones asked
    for with --image-ssd-offload on (what does not fit read from the SSD)."""
    if not a.images or a.images == "no":
        return None
    remove_old_image_engine()
    QI = _qimage()
    exe = eng / IMAGE_EXE
    if not exe.exists():
        fail(f"the image engine is missing ({exe})", "run setup again to compile the engine (it builds both)")
    _, dit, enc = QI.IMAGE_MODELS[a.images]
    label, steps, _ = QI.DITS[dit]
    asked = a.image_quant or QI.DEFAULT_QUANT
    if QI.is_mage(dit):   # Mage-Flow's DiT comes in one size (bf16: the engine's FP16 or 8 bits of it, --image-dit-q8)
        if a.image_quant:
            warn(f"--image-quant {a.image_quant}: {label} comes in one size, which the engine quantizes itself "
                 "(--image-dit-q8 auto|on|off)")
        asked = QI.dit_quants(dit)[-1]
    dit_q8 = {"on": True, "off": False}.get(getattr(a, "image_dit_q8", None) or "auto")   # None: by the VRAM
    dit_keep = getattr(a, "image_dit_keep", None) != "off"
    tasked = QI.DEFAULT_TEXT_QUANT
    ssd = getattr(a, "image_ssd_offload", None) == "on"
    quant, tquant = asked, tasked
    lowered = None
    if not ssd and text_gb is not None:
        left = ram_gb() - text_gb
        quant, tquant, fits = QI.fit_ram(left, enc, asked, tasked, dit, dit_keep)
        if (quant, tquant) != (asked, tasked):
            # kept in the config: the server says it at start and on the web page (the user's decision, 2026-10-15)
            need = QI.ram_need_gb(asked, enc, tasked, dit, dit_keep)
            lowered = {"from": asked, "to": quant, "text_from": tasked, "text_to": tquant,
                       "need_gb": round(need, 1), "ram_left_gb": round(max(left, 0.0), 1)}
            warn(f"image model lowered from {asked} (text encoder {tasked}) to {quant} (text encoder {tquant}): "
                 f"{asked} with a {tasked} text encoder needs ~{need:.0f} GB of RAM beside the text model, which "
                 f"leaves ~{max(left, 0):.0f} GB. --image-ssd-offload on keeps both and reads what does not fit "
                 "from the SSD (slower)")
        if not fits:
            least = QI.ram_need_gb(quant, enc, tquant, dit, dit_keep)
            warn(f"even {quant} with a {tquant} text encoder (~{least:.0f} GB) "
                 f"does not fit the ~{max(left, 0):.0f} GB of RAM the text model leaves: images read part of the model "
                 "from the SSD (slower), and the PC may run short of RAM while one is made")
    elif ssd:
        ok(f"image model {quant} (text encoder {tquant}) with SSD offload: what does not fit in RAM is read from "
           "the SSD")
    say(f"  Image generation: {label} {quant} on XeStrata's image engine ({steps} steps; "
        "POST /v1/images/generations)")
    tfile = QI.FILES[QI.text_file(enc, tquant)]
    say(f"  Text encoder: {Path(tfile[1]).name} ({tfile[0]}"
        + (f", Qwen3-VL-{'4B' if QI.is_mage(dit) else '8B'} with its refusal direction removed)"
           if enc.endswith("uncensored") else ")"))
    say("  " + QI.license_note(dit))
    names = QI.file_names(quant, enc, tquant, dit)
    need = sum(QI.FILES[k][2] for k in names) / 1e9
    if ask(f"Download the image model ({need:.1f} GB) and set up image generation?", ["y", "n"], "y", a.yes) != "y":
        return None
    models_dir.mkdir(parents=True, exist_ok=True)
    if free_gb(models_dir) < need + 5:
        warn(f"less than {need + 5:.0f} GB free for the image model: the download may run out of disk space")
    for name in names:
        repo, path, size, sha = QI.FILES[name]
        dst = QI.local_path(models_dir, name)
        download(QI.file_url(name, hf_endpoint()), dst, f"image model: {Path(path).name}")
        verify_sha256(dst, size, sha)
    cfg = QI.image_config(quant, exe, models_dir, model=a.images, uma=bool((gpu or {}).get("integrated")),
                          policy=a.image_gpu_policy or "auto", ssd_offload=ssd, text_quant=tquant, dit_q8=dit_q8,
                          dit_keep=dit_keep)
    if lowered:
        cfg["quant_lowered"] = lowered
    ok(f"image generation: {quant}, text encoder {tquant}, GPU policy {cfg['gpu_policy']}")
    return cfg


# ------------------------------------------------------------------------------------------------ the data folder
# The model files - the GGUFs, the prepared packs and the MTP layer, 70-120 GB - live in a data folder NEXT TO the
# Strata folder (`XeStrata-data`), not inside it: updating Strata by unzipping a new copy used to give a new, empty
# folder and a full download again.  Where it is, and which Strata folders this user ran, is kept in a small
# per-user file, so every Strata folder on the PC finds the same files.
DATA_ITEMS = ("models", "packs", "mtp")


def confirm_risk(msg, explicit, yes, stop, hint=None, question="  Go on anyway?", default="n") -> None:
    """Setup recommends, it never forces (upstream #406).  A choice setup expects to fail or run badly is said plainly
    (msg), then asked (default n), or with --yes taken as consent when it was asked for explicitly (a flag such as
    --model): --yes alone keeps the stop (stop, hint).  Returns when it goes on; the caller says what it does."""
    warn(msg)
    if yes and explicit:
        return
    if ask(question, ["y", "n"], default, yes) != "y":
        fail(stop, hint)


def ctx_ram_need(model, ctx, low_ram=False):
    """The RAM (GB) setup estimates for a long context with IQ3_XXS / IQ3_S: their experts + the context's 8-bit KV
    cache + 24 GB of room for everything else.  None where the context does not count against RAM by this rule: the
    other sizes, and the low-RAM mode (its KV cache stays in VRAM)."""
    if model not in ("IQ3_XXS", "IQ3_S") or low_ram:
        return None
    return MODELS[model]["arena_gb"] + ctx * 13 * 1056 / 1e9 + 24


def ram_ctx(model, ram, low_ram=False) -> int:
    """The longest context the RAM rule recommends: 128K, or longer where the estimate fits this PC's RAM.  It is part
    of the recommended default (the smaller of it and the GPU's rule); a longer choice is kept, with a note.
    The 200K menu step is never the recommendation (upstream #608)."""
    # 204800 is a menu step between 128K and 256K, never the recommendation: where 256K does not fit, 128K stays
    return max(c for c in CONTEXTS if c <= 131072 or (c != 204800 and (ctx_ram_need(model, c, low_ram) or 0) <= ram))


# The low-RAM mode (upstream de159b5 / 872af82): a PC whose GPU holds much of a model's experts but whose RAM cannot
# hold them all.  The engine reads the experts from the model files instead of copying them into RAM
# (--mmap-experts: a native pack's from the GGUF files in place, the AVX-512 Q2_0 pack's from its experts.bin), and
# with --resident-experts copies the ones the GPU does not hold into RAM once.
LOW_RAM_HEADROOM_GB = 10   # RAM beside the experts: the OS, the engine's other buffers, the server
# low_ram_gpu_gb's room below which the engine finds no VRAM for its expert cache.  On an RX 9060 XT limited to 8 GB
# (IQ3_XXS, the KV cache in VRAM) 128K with 8-bit KV (1.65 by that estimate) started with 178 slots and 262K with
# 4-bit KV (1.28) was 267 MiB short: the estimate leaves out the engine's reserve, the draft head and the matrix
# library.
MIN_CACHE_GB = 1.5


SMALL_CARD_GB = 7.5            # #496: a card under 8 GB gets a tip (an 8 GB card lists 7.99)


DISPLAY_RESERVE_MIB = 1500     # upstream #779: the tip for an NVIDIA card that also drives a display
DESKTOP_RESERVE_MIB = 3072     # upstream #560 #516: what kept a KDE/Wayland desktop alive beside a full expert cache


def linux_desktop(env=None) -> bool:
    """A graphical session on Linux (Wayland or X)."""
    env = os.environ if env is None else env
    return sys.platform.startswith("linux") and bool(env.get("WAYLAND_DISPLAY") or env.get("DISPLAY"))


def desktop_reserve_note() -> list[str]:
    """upstream #560 #516: an AMD card that also drives a Linux desktop - with the default 700 MiB reserve the expert
    cache fills it, and when the desktop needs more VRAM amdgpu moves the cache to system RAM, where the OOM killer then
    ends the compositor.  A recommendation, setup changes nothing."""
    return [f"If this AMD card also drives your desktop and the desktop or apps crash once the model is loaded, keep "
            f"more VRAM free: {SETUP_CMD} --vram-reserve-mib {DESKTOP_RESERVE_MIB}",
            "  (remembered for this model; the expert cache gets ~2.3 GB less, a few % of speed)"]


def gpu_drives_display(g) -> bool:
    """upstream #779: True when nvidia-smi says this NVIDIA card has a display attached (display_active Enabled): its
    desktop needs VRAM too, and a full expert cache beside it has crashed laptops."""
    if g.get("vendor") != "nvidia" or not g.get("pci"):
        return False
    text = out(["nvidia-smi", "-i", str(g["pci"]), "--query-gpu=display_active", "--format=csv,noheader"])
    return (text or "").strip().lower() == "enabled"


def small_card_note(ctx: int, draft_vocab: str | None) -> list[str]:
    """#496 (upstream e1ee248, 4731a9b): what frees VRAM on a card under 8 GB when the start stops with "no VRAM is
    left for the expert cache" (the engine already lowers its own reserve on such a card) - a recommendation, setup
    changes none of it.  (The draft layer stays: the server needs it.)"""
    tips = []
    if ctx > 8192:
        tips.append("an 8K context (a smaller KV cache)")
    if draft_vocab != "en":
        tips.append("--draft-vocab en (a smaller draft head)")
    lines = ["If the start stops with \"no VRAM is left for the expert cache\" (the engine's log says how much is "
             "short):"]
    if tips:
        lines.append(f"  run {SETUP_CMD} again with " + " and ".join(tips) +
                     ", or close other programs that use the GPU.")
    else:
        lines.append("  close other programs that use the GPU.")
    return lines


IMAGES_GPU_ENCODER_MIN_VRAM_GB = 23.5   # upstream 45752724 (#2406): below this the images answer "yes" gets the CPU
# encoder (a card of 12-16 GB: the GPU encoder's ~1.1-1.4 GB is ~850 expert slots lost, 3-5% of decode and prompt on a
# P100 / A4000 16 GB, upstream's measurement; the cost is the VRAM the experts lose, whatever the card's maker)


def images_encoder(asked: str, gpu: dict) -> str:
    """Which encoder an images answer gets: "yes" (the question's y, or --vision yes) means the GPU encoder on a card of
    24 GB and more and the CPU encoder below that (a picture then takes a few seconds, the text keeps the ~1 GB of VRAM
    for experts).  --vision gpu is always kept (with a note on a small card); --vision cpu is kept."""
    vram = gpu_expert_vram(gpu or {"vram_gb": 0.0})
    small = 0 < vram < IMAGES_GPU_ENCODER_MIN_VRAM_GB
    if asked == "gpu" and small:
        warn(f"the GPU image encoder keeps ~1.4 GB of VRAM that a {vram:.0f} GB card would use for experts (upstream "
             "measured 3-5% of decode on 16 GB cards, #2406): kept as you chose; --vision cpu reads pictures on the "
             "CPU instead (a few seconds each)")
    if asked == "yes":
        return "cpu" if small else "gpu"
    return asked


def gpu_expert_vram(gpu) -> float:
    """The VRAM (GB) that can hold experts instead of RAM: none on the processor's graphics (its memory is the RAM),
    but an AMD APU's BIOS carve-out, which the OS does not see (upstream c4a329fe)."""
    return gpu.get("carve_gb", 0.0) if gpu.get("integrated") else gpu["vram_gb"]


def low_ram_needed(model, ram) -> bool:
    """The model's experts do not fit this PC's RAM with room left for the rest."""
    return ram < MODELS[model]["arena_gb"] + LOW_RAM_HEADROOM_GB


def kv_streaming_ram_gb(ctx, kv) -> float:
    """The RAM a streamed KV cache takes: ~13.7 KB per context token with 8-bit KV, 10.6 KB with K8V4, 7.5 KB with
    4-bit (12 QSA layers + the draft layer)."""
    return ctx * (13 * KV_CELL_BYTES.get(kv, 1056)) / 1e9


def kv_streaming_wanted(model, ctx, kv, ram) -> bool:
    """Does setup stream this model's KV cache on this PC (--kv-resident): from 64K up, when the RAM holds the cache
    beside the model's experts (+1 GB).  The merges' and the release's measurements ask it too (tools/bench_core.py)."""
    return ctx >= 65536 and ram >= MODELS[model]["ram_gb"] + kv_streaming_ram_gb(ctx, kv) + 1


#: The draft layer (MTP) takes about 1 GB of graphics memory out of the expert cache (upstream 671f4573d): its files
#: and the draft head (809 + 184 MiB in the engine's start log on the B70 and the RTX 4070, Qwen3.8, 2026-10-20).
MTP_VRAM_GB = 1.0


def low_ram_gpu_gb(model, vram_gb, ctx=32768, kv="int8") -> float:
    """About how many GB of the model's experts the GPU's cache holds: its VRAM less ~5 GB for the dense weights,
    buffers and a 32K context's KV cache (upstream's figure, not measured on an Arc card: unverified), less the KV
    cache of a longer context (in VRAM in the low-RAM mode: its RAM has no room for KV streaming) and ~1 GB for the
    draft layer."""
    kv_tok = 13 * KV_CELL_BYTES.get(kv, 1056)           # bytes per context token: 12 QSA layers + the draft layer
    longer = max(0, ctx - 32768) * kv_tok / 1e9
    return max(0.0, min(MODELS[model]["arena_gb"], vram_gb - 5 - MTP_VRAM_GB - longer))


def low_ram_gpu_share(model, vram_gb, ctx=32768, kv="int8") -> float:
    """About how much of the model's experts the GPU holds."""
    return low_ram_gpu_gb(model, vram_gb, ctx, kv) / MODELS[model]["arena_gb"]


def low_ram_resident(model, ram, vram_gb, ctx=32768, kv="int8") -> bool:
    """In the low-RAM mode: the experts the GPU does not hold fit the RAM with the usual room beside them, so they are
    copied into RAM once (--resident-experts) instead of being read through the OS file cache (--mmap-experts, which
    a PC this short of RAM keeps re-reading from the SSD)."""
    rest = MODELS[model]["arena_gb"] - low_ram_gpu_gb(model, vram_gb, ctx, kv)
    return ram >= rest + LOW_RAM_HEADROOM_GB


def low_ram_fits(model, ram, vram_gb) -> bool:
    """In the low-RAM mode: the experts the GPU does not hold fit the RAM left beside the rest (as file cache)."""
    return ram - 6 + max(0.0, vram_gb - 5 - MTP_VRAM_GB) >= MODELS[model]["arena_gb"]


def model_file(fam: dict, model: str, i: int) -> str:
    """Shard i's file name: the family's pattern, or the model's own (UD-IQ4_XS has three shards, not four)."""
    return MODELS.get(model, {}).get("file", fam["file"]).format(q=model, i=i)


def model_shards(fam: dict, model: str) -> int:
    return MODELS.get(model, {}).get("shards", fam.get("shards", 2))


def resident_budget_gib(model, ram, kv_ram_gb=0.0) -> int:
    """UD-Q4_K_XL, UD-IQ4_XS: the GiB of experts the engine keeps in RAM (--resident-budget-gib): the RAM (GB,
    ram_gb()) less 24 for the OS, the engine and the file cache the other experts are read through, less a KV cache
    streamed to RAM; at most all of them, at least 8.  A 64 GB PC (~62 GiB): 38, 36 with a 128K context
    (the 2026-10-03-ud-low-ram record)."""
    gib = round(ram) - UNSLOTH_RAM_LEFT_GB - math.ceil(kv_ram_gb)
    return max(8, min(gib, int(MODELS[model]["arena_gb"] / 1.073741824)))


UMA_EXPERTS = 24576            # the Flash-Next model's experts (48 layers x 512): the most an expert cache can hold


def uma_expert_cache(model, ram, budget_gib, kv_ram_gb=0.0):
    """On a unified-memory APU the GPU's expert cache and the RAM budget of experts are both RAM (upstream #1715).
    `--expert-cache auto` sizes the cache from the memory the OS can give back at start, which counts all the RAM the
    budget has not taken yet: a 128 GB box with a 55 GiB budget and the desktop open was killed by the OOM killer.  So
    there setup writes a number, not `auto`: the RAM less UNSLOTH_RAM_LEFT_GB less the budget (and a KV cache streamed
    to RAM), in slots (an expert is priced at 1.1x the average one: the Q8_0 downs are bigger).  None when no room is
    left (the config keeps `auto`).  A recommendation: the number is in the config's args, and --expert-cache N there
    sets it."""
    slot_gib = MODELS[model]["arena_gb"] * 1e9 / UMA_EXPERTS * 1.1 / 2**30
    room = ram - UNSLOTH_RAM_LEFT_GB - budget_gib - math.ceil(kv_ram_gb)
    slots = min(UMA_EXPERTS, int(room / slot_gib))
    return slots if slots >= 256 else None


def budget_choice(model, ram, asked) -> float:
    """UD-Q4_K_XL's or UD-IQ4_XS's RAM budget: --resident-budget-gib N as given, else the recommendation
    (resident_budget_gib).  More than the recommendation is kept, with what it risks (setup recommends, it never
    forces)."""
    rec = resident_budget_gib(model, ram)
    if asked is None:
        return rec
    if asked > rec:
        warn(f"a {asked:g} GiB RAM budget is more than setup recommends for this PC ({rec} GiB: the RAM less "
             f"{UNSLOTH_RAM_LEFT_GB} GB for the OS, the engine and the file cache that reads the other experts). Kept "
             "as you chose: the engine clamps it to the RAM it finds free at start (less 8 GiB), and the file cache "
             "gets less room - it may be slower, or run the PC out of RAM under load")
    return int(asked) if asked == int(asked) else asked


def memlock_gib() -> float:
    """The RAM (GiB) this user may lock (ulimit -l): the engine locks its resident copy of the experts so the OS does
    not swap it out; with a lower limit the copy stays unlocked (the engine says so).  Windows has no such limit: the
    engine raises its working set's minimum instead."""
    if WIN:
        return float("inf")
    import resource
    soft = resource.getrlimit(resource.RLIMIT_MEMLOCK)[0]
    return float("inf") if soft == resource.RLIM_INFINITY else soft / 2 ** 30


def settings_path() -> Path:
    return places.settings_path()


def load_settings() -> dict:
    try:
        return json.loads(settings_path().read_text(encoding="utf-8"))
    except (OSError, ValueError):
        return {}


def save_settings(s: dict) -> None:
    try:
        settings_path().parent.mkdir(parents=True, exist_ok=True)
        write_private(settings_path(), json.dumps(s, indent=1))
    except OSError as e:
        warn(f"could not save {settings_path()} ({e})")


def has_data(folder: Path) -> bool:
    for d in DATA_ITEMS:
        try:
            if (folder / d).is_dir() and any((folder / d).iterdir()):
                return True
        except OSError:
            pass
    return False


def in_trash(path: str | os.PathLike) -> bool:
    """#3410: True when ``path`` is inside a Trash / Recycle Bin folder (a Strata folder that was deleted with the file
    manager is still a folder there, and was remembered as an install): ~/.local/share/Trash/files/.., /.Trash-1000/..,
    ~/.Trash/.., $RECYCLE.BIN\\.."""
    # a Windows-shaped path read on Linux has no separators for Path
    parts = [x.lower() for p in Path(path).parts for x in str(p).split("\\")]
    for i, x in enumerate(parts):
        if x in (".trash", "$recycle.bin", "recycler", "$recycle.bin.old") or x.startswith(".trash-"):
            return True
        if x == "trash" and i + 1 < len(parts) and parts[i + 1] in ("files", "info", "expunged"):
            return True                                  # the XDG Trash: ~/.local/share/Trash/files
    return False


def other_installs(settings: dict) -> list:
    """Strata folders besides this one that may hold model files: the ones this user ran before, and Strata* folders
    next to this one (a zip unpacked again lands in e.g. `Strata-main (1)\\Strata-main`)."""
    cands = [Path(p) for p in settings.get("installs", []) if not in_trash(p)]
    for base in dict.fromkeys((ROOT.parent, ROOT.parent.parent)):
        try:
            for d in base.iterdir():
                if d.is_dir() and d.name.lower().startswith("strata"):
                    cands.append(d)
                    cands += [c for c in d.iterdir() if c.is_dir() and c.name.lower().startswith("strata")]
        except OSError:
            pass
    found = []
    for d in cands:
        try:
            d = d.resolve()
            if d != ROOT and d not in found and (d / "setup.py").is_file():
                found.append(d)
        except OSError:
            pass
    return found


def same_drive(a: Path, b: Path) -> bool:
    try:
        return os.stat(a).st_dev == os.stat(b).st_dev
    except OSError:
        return False


def move_into(src: Path, dst: Path) -> None:
    """A rename into the data folder (same drive: instant); a folder merges into one already there, keeping what the
    destination has.  Whatever cannot be moved (a file in use) stays where it is."""
    if not dst.exists():
        try:
            dst.parent.mkdir(parents=True, exist_ok=True)
            os.replace(src, dst)
            return
        except OSError:
            if not src.is_dir():
                return
            dst.mkdir(parents=True, exist_ok=True)
    if src.is_dir() and dst.is_dir():
        for c in list(src.iterdir()):
            move_into(c, dst / c.name)
        try:
            src.rmdir()
        except OSError:
            pass


def repoint_config(cfg_file: Path, old: Path, new: Path) -> None:
    """A config whose model files moved from `old` to `new` points at them there (each path only if its file is
    now there and no longer at the old place)."""
    try:
        cfg = json.loads(cfg_file.read_text(encoding="utf-8-sig"))
    except (OSError, ValueError):
        return

    def fix(v):
        if isinstance(v, list):
            return [fix(x) for x in v]
        if isinstance(v, dict):
            return {k: fix(x) for k, x in v.items()}
        if isinstance(v, str):
            for d in DATA_ITEMS:
                o = str(old / d)
                if v == o or v.startswith(o + os.sep):
                    n = str(new / d) + v[len(o):]
                    if Path(n).exists() and not Path(v).exists():
                        return n
        return v

    new_cfg = fix(cfg)
    if new_cfg != cfg:
        write_config(cfg_file, new_cfg)


def default_data_dir() -> Path:
    """Where the model files go unless the settings name a folder: next to this Strata folder, or for a package (whose
    folder is read-only) in the user's data folder (serve/places.py)."""
    return places.user_dir("data") if PACKAGED else ROOT.parent / "XeStrata-data"


def data_folder_path(requested: str | None, settings: dict) -> Path:
    """The data folder --data-dir names, else the one the settings name, else the default; nothing is made."""
    return Path(requested).expanduser().resolve() if requested else \
        Path(settings["data_dir"]) if settings.get("data_dir") else default_data_dir()


def library_size_gb(folder: Path) -> float:
    """The GB of model files (models, packs, mtp) in a data folder."""
    return sum(folder_size(folder / d) for d in ("models", "packs", "mtp") if (folder / d).exists()) / 1e9


def same_folder(a: Path, b: Path) -> bool:
    """The same folder, however it is spelled (a different case, a short 8.3 name, a link)."""
    try:
        return os.path.samefile(a, b)
    except OSError:
        return os.path.normcase(os.path.abspath(a)) == os.path.normcase(os.path.abspath(b))


def data_folder(requested: str | None, move: bool = False, yes: bool = True, set_default: bool = False) -> tuple:
    """(the data folder, folders that still hold model files and are used where they are).

    Without --data-dir, or with the folder in use: moves the model files of this folder and of earlier Strata folders
    on the same drive into the data folder, and points their configs there.  upstream 9d2cb4f6d: a --data-dir that
    names a NEW folder moves nothing by itself.  When model files already exist elsewhere (the remembered data folder
    among them), they are kept where they are and found from there, and the new folder takes the new downloads (the
    answer with --yes or when nobody can answer); `move` (--move-data, or the answer "move") moves them in.  Only a
    move, --set-default-data-dir, or a PC with no model files changes the remembered data folder."""
    settings = load_settings()
    remembered = data_folder_path(None, settings)
    dest = data_folder_path(requested, settings)
    try:
        dest.mkdir(parents=True, exist_ok=True)
    except OSError as e:                                # e.g. no write access next to the Strata folder
        if PACKAGED:
            fail(f"cannot use {dest} for the model files ({e})", "choose another folder with --data-dir")
        warn(f"cannot use {dest} for the model files ({e}): keeping them in {ROOT}")
        dest = ROOT
    sources = [*([] if PACKAGED else [ROOT]), *other_installs(settings)]
    if requested and not same_folder(dest, remembered):
        sources.append(remembered)
        held: list = []
        for folder in sources:
            if not same_folder(folder, dest) and has_data(folder) and not any(same_folder(folder, h) for h in held):
                held.append(folder)
        movable = [f for f in held if same_drive(f, dest)]
        if movable and not move and not yes:
            gb = sum(library_size_gb(f) for f in movable)
            size = f"{gb:.0f} GB" if gb >= 10 else f"{gb:.1f} GB"
            say()
            say(f"  Your models are in {', '.join(str(f) for f in movable)} ({size}).")
            say(f"  keep) leave them there and use {dest} only for new downloads")
            say(f"  move) move your {size} of models to {dest}")
            move = ask(f"Move your {size} of models to the new folder, or use it only for new downloads?",
                       ["keep", "move"], "keep", False) == "move"
        if held and not move:
            for folder in held:
                say(f"  your model files stay in {folder}; {dest} is used for new downloads")
            if set_default:
                save_settings({**settings, "data_dir": str(dest)})
            return dest, held
    elsewhere = []
    for folder in dict.fromkeys(sources):
        if same_folder(folder, dest) or not has_data(folder):
            continue
        if not same_drive(folder, dest):
            elsewhere.append(folder)                    # another drive: used where it is (no 70 GB copy)
            continue
        # the downloads merge file by file (the same file wherever it came from); a prepared pack or MTP layer moves
        # whole or not at all, so two copies are never mixed
        if (folder / "models").is_dir():
            move_into(folder / "models", dest / "models")
        for item in [*((folder / "packs").glob("*") if (folder / "packs").is_dir() else []), folder / "mtp"]:
            rel = item.relative_to(folder)
            if item.exists() and not (dest / rel).exists():
                move_into(item, dest / rel)
        for d in ("packs",):
            try:
                (folder / d).rmdir()                    # empty now
            except OSError:
                pass
        for c in model_config_files(folder):
            repoint_config(c, folder, dest)
        if has_data(folder):
            elsewhere.append(folder)                    # in use, or a copy the data folder already has
            warn(f"some model files are still in {folder} (in use, or already in {dest})")
        else:
            ok(f"model files from {folder} moved to {dest} (a new copy of Strata finds them there)")
    # the Strata folders this user ran (a package's folder holds no model files or configs: not one of them)
    installs = [*([] if PACKAGED else [str(ROOT)])] + \
        [p for p in settings.get("installs", []) if p != str(ROOT) and Path(p).is_dir() and not in_trash(p)]
    save_settings({**settings, "data_dir": str(dest), "installs": installs[:20]})
    return dest, elsewhere


def folder_size(path: Path) -> int:
    total = 0
    for dirpath, _, files in os.walk(path):
        for f in files:
            try:
                total += (Path(dirpath) / f).lstat().st_size
            except OSError:
                pass
    return total


def remove_data() -> int:
    """--remove-data: what XeStrata keeps for this user, which apt and dnf leave when they remove the program - the
    model files, the prepared packs and the MTP layer in the data folder, the settings and model configs, the logs -
    listed with their sizes and deleted after a yes typed at the question (--yes is not one).  GGUF files given with
    --gguf-dir are the user's own and stay; in a Strata folder (no package), its own files stay too."""
    settings = load_settings()
    data = Path(settings["data_dir"]) if settings.get("data_dir") else default_data_dir()
    targets = [data / d for d in DATA_ITEMS] + [settings_path().parent]
    if PACKAGED:
        targets += [CONF, STATE]
    targets = [t for t in dict.fromkeys(targets) if t.exists()]
    if not targets:
        say("Nothing of XeStrata's is kept for this user.")
        return 0
    say("These folders hold what XeStrata keeps for you:")
    for t in targets:
        say(f"  {t}  ({folder_size(t) / 1e9:.1f} GB)")
    if not sys.stdin.isatty() or input("Delete them? Type yes to delete: ").strip().lower() != "yes":
        say("Nothing was deleted.")
        return 1
    for t in targets:
        shutil.rmtree(t, ignore_errors=True)
        if t.exists():
            warn(f"could not delete all of {t}")
    try:
        data.rmdir()                                   # the data folder, when nothing else is in it
    except OSError:
        pass
    ok("deleted")
    return 0


def model_config_files(folder: Path) -> list:
    """Upstream #346: the xestrata-*.json files of a folder that can be model configs. The server keeps a config's Chat
    settings next to it as xestrata-<model>.shared-settings.json: it matches the pattern but is no config."""
    return [p for p in folder.glob("xestrata-*.json") if not p.name.endswith(".shared-settings.json")]


def write_private(path: Path, text: str) -> None:
    """`text` into `path`, written whole (a temporary file moved over the old one) and readable by this user only
    (#33: a run config holds the server's api_key, and the umask's 0644 let every local account read it)."""
    tmp = path.with_name(path.name + ".tmp")
    with os.fdopen(os.open(tmp, os.O_WRONLY | os.O_CREAT | os.O_TRUNC, 0o600), "w", encoding="utf-8") as f:
        f.write(text)
    os.chmod(tmp, 0o600)                               # a .tmp left from before keeps its own mode through O_CREAT
    os.replace(tmp, path)


def copy_private(src: Path, dst: Path) -> None:
    """A copy of `src` readable by this user only (#33: the .bak of a run config holds its api_key too)."""
    shutil.copyfile(src, dst)
    os.chmod(dst, 0o600)


def write_config(path: Path, cfg: dict):
    """A run config, written whole or not at all (upstream #459): to a temporary file first, then moved over the old
    one, so a setup stopped half-way (a closed window, a full disk) never leaves an empty config behind."""
    write_private(path, json.dumps(cfg, indent=1))


def readable_config(path: Path) -> bool:
    """#459: a config that parses as a JSON object; any other gets a one-line warning naming it."""
    text = None
    try:
        text = path.read_text(encoding="utf-8-sig")
        if isinstance(json.loads(text), dict):
            return True
        why = "not a JSON object"
    except OSError as e:
        why = e.strerror or str(e)
    except ValueError:                                 # JSONDecodeError, or bytes that are not UTF-8
        why = "the file is empty" if text is not None and not text.strip() else "not valid JSON"
    warn(f"skipped the earlier config {path} ({why}): setting this copy up without it")
    return False


def previous_config(elsewhere_first: list, settings: dict):
    """The most recently used model config of another Strata folder on this PC, for a folder that has none yet.  One
    that does not parse (an empty or cut-off file, upstream #459) is skipped with a warning: the newest readable one is
    used, and with none this copy is set up as a fresh install."""
    cands = []
    for folder in [*elsewhere_first, *other_installs(settings)]:
        cands += model_config_files(folder)
    cands = [c for c in dict.fromkeys(cands) if c.is_file()]
    return next((c for c in sorted(cands, key=lambda p: p.stat().st_mtime, reverse=True) if readable_config(c)), None)


def installed_size(family: str, names: list, have: list) -> str | None:
    """The size of this family already installed (the most recently used config first), or None.  setup run again
    pre-selects it (upstream de9115fa): Enter must not move an installed model to another size and download it."""
    for c in have:
        try:
            ch = choices_from_config(c)
        except (OSError, ValueError, KeyError, TypeError, IndexError):
            continue
        if ch.get("family") == family and ch.get("model") in names:
            return ch["model"]
    return None


def choices_from_config(cfg_path: Path) -> dict:
    """The setup answers a config was written with (family, size, context, KV, images, projection, network)."""
    cfg = json.loads(cfg_path.read_text(encoding="utf-8-sig"))
    tag = cfg_path.stem[len("xestrata-"):]
    family = next((f for f, d in FAMILIES.items() if d["tag"] and tag.startswith(d["tag"])), "qwen")
    suffix = tag[len(FAMILIES[family]["tag"]):]
    model = next((m for m in FAMILIES[family].get("models", MODELS) if m.lower() == suffix.lower()), None)
    a = cfg.get("args", [])
    val = lambda k: a[a.index(k) + 1] if k in a and a.index(k) + 1 < len(a) else None   # noqa: E731
    vis = cfg.get("vision")
    esp = val("--control-vector-scaled")
    rv = val("--vram-reserve-mib") or ""
    reserve = int(rv) if rv.isdigit() else None
    esp_path = esp.rsplit(":", 1)[0] if esp else None
    return {"family": family, "model": model if model in FAMILIES[family].get("models", MODELS) else None,
            "context": int(ctx) if (ctx := val("--max-context")) else None,
            "kv": val("--kv") if val("--kv") in ("int8", "q4_0", "k8v4") else None,
            "vision": ("gpu" if vis.get("gpu") else "cpu") if isinstance(vis, dict) else "none",
            "esp": ("on" if Path(esp_path).name == ESP_VECTOR.name else esp_path) if esp_path else "off",
            "host": cfg.get("host"), "api_key": cfg.get("api_key"), "port": cfg.get("port"), "gpu": cfg.get("gpu"),
            "layer_split": cfg.get("layer_split"),
            "split_pci": [cfg.get("gpu_pci"), *cfg["split_pci"]] if cfg.get("split_pci") else None,
            # #493: --vram-reserve-mib given at setup (images write the default 700 themselves)
            "vram_reserve_mib": reserve if reserve is not None and (
                vis is None or reserve != VISION["gpu"]["reserve_mib"]) else None}


def calibration_targets(have: list, model: str | None, family: str | None) -> list:
    """Upstream #2036: the installed configs `--calibrate --model X` (and/or --family) means; every config with
    neither."""
    if not (model or family):
        return list(have)
    out = []
    for c in have:
        ch = choices_from_config(c)
        if (not model or ch["model"] == model) and (not family or ch["family"] == family):
            out.append(c)
    return out


def find_in(roots: list, rel: str):
    """The first of roots/rel that exists."""
    for r in roots:
        if (r / rel).exists():
            return r / rel
    return None


# ------------------------------------------------------------------------------------------------ start
def model_config(path: Path) -> bool:
    """#549 (upstream 067bfda): a model's run config (a JSON object with "exe" and "args"). Any other xestrata-*.json
    in the folder (a file of the user's own, a cut-off one) is skipped with a warning naming it instead of stopping
    setup."""
    try:
        cfg = json.loads(path.read_text(encoding="utf-8-sig"))
        if isinstance(cfg, dict) and cfg.get("exe") and isinstance(cfg.get("args"), list):
            return True
        why = 'no "exe" or "args"'
    except OSError as e:
        why = e.strerror or str(e)
    except ValueError:
        why = "not valid JSON"
    warn(f"skipped {path.name} ({why}): it is not a XeStrata model config")
    return False


def installed_configs():
    return [p for p in sorted(model_config_files(CONF), key=lambda p: p.stat().st_mtime, reverse=True)
            if model_config(p)]


def source_version() -> str:
    """The engine version the source tree builds, or the package's (serve/release_check.py)."""
    return release_check.current_version(ROOT)


def engine_version(exe: Path) -> tuple:
    """The version in the engine folder's BUILD.json, or else the one compiled into the binary.  A locally compiled
    engine is not necessarily the source's version: when compiling a `git pull` fails, the previous engine is kept
    (issue #49)."""
    try:
        meta = json.loads((Path(exe).parent / "BUILD.json").read_text())
    except (OSError, ValueError):
        meta = {}
    v = str(meta.get("version") or "")
    if not v:                                          # the version compiled into the binary: 0.1.13 and newer
        try:                                           # carry it, so a binary without it is older
            # XeStrata's binaries say engine=xe<version>-<revision> (before 2026-10-13: xe<version>, another release
            # on the same upstream version a fifth number); a hotfix version has a fourth number (upstream 511b6467)
            m = re.search(rb"engine=(?:xe)?(\d+\.\d+\.\d+)(?:\.\d+)*(?:-\d+)?\n", Path(exe).read_bytes())
            v = m.group(1).decode() if m else "0.1.12"
        except OSError:
            v = "0"
    return tuple(int(x) for x in v.split(".")[:3] if x.isdigit())


def check_update() -> int:
    """--check-update: this copy's version against GitHub's latest release; 1 when GitHub cannot be asked."""
    current = source_version()
    try:
        latest = release_check.fetch_latest(current)
    except (OSError, ValueError) as e:
        say(f"This is XeStrata xe{current}. {release_check.error_text(e)}: see {release_check.RELEASES}")
        return 1
    newer = release_check.is_newer(latest, current)
    if JSON_OUT:                                       # the launcher's banner
        emit({"type": "update", "current": f"xe{current}", "latest": latest["tag"], "newer": bool(newer),
              "url": latest["url"], "how": release_check.how_to_update(ROOT)})
        return 0
    if not newer:
        say(f"XeStrata xe{current} is up to date (the latest release is {latest['tag']}).")
        return 0
    say(f"XeStrata {latest['tag']} is out (this is xe{current}): {latest['url']}")
    say(f"To update: {release_check.how_to_update(ROOT)}.")
    return 0


def rotational_disk(path) -> str | None:
    """upstream #605 (Linux): the disk's name when `path` is on a rotational disk (sysfs queue/rotational), else None.
    None under WSL too, whose virtual disk says rotational."""
    if "microsoft" in platform.uname().release.lower():
        return None
    try:
        st = os.stat(path)
        p = Path(f"/sys/dev/block/{os.major(st.st_dev)}:{os.minor(st.st_dev)}").resolve()
        for q in (p, p.parent):                        # a partition has its disk's queue
            f = q / "queue" / "rotational"
            if f.exists():
                return q.name if f.read_text().strip() == "1" else None
    except (OSError, ValueError, AttributeError):
        pass
    return None


def cpu_cores():
    """upstream #642: (performance cores, efficiency cores) of a hybrid CPU (Intel 12th gen+, AMD Zen 5 + Zen 5c),
    counted as physical cores from the kernel's reports (Intel's hybrid PMU lists, else cpu_capacity); None on a CPU
    whose cores are all alike, or when the kernel does not say."""
    try:
        classes = linux_core_classes()
    except (OSError, ValueError):
        return None
    if not classes or max(classes) == min(classes):
        return None
    p = sum(1 for c in classes if c == max(classes))
    return p, len(classes) - p


def linux_core_classes(sys_root: str = "/sys"):
    """One class per physical core on Linux: 1 for a P-core, 0 for an E-core; None when the kernel does not say.
    #798: Intel's hybrid PMU lists (cpu_core/cpus, cpu_atom/cpus) when they exist; else cpu_capacity, where an E-core is
    one under 90% of the largest - Turbo Boost Max 3.0 gives the "favored" P-cores a slightly higher capacity (1024
    against 1012), so "below the maximum" counted 2 of a Core Ultra 7 270K Plus's 8 P-cores."""
    pmu = linux_hybrid_pmu(sys_root + "/devices")
    seen: dict = {}
    top = 0
    for cpu in sorted((Path(sys_root) / "devices" / "system" / "cpu").glob("cpu[0-9]*"), key=lambda p: int(p.name[3:])):
        cap = cpu / "cpu_capacity"
        pkg, core = cpu / "topology" / "physical_package_id", cpu / "topology" / "core_id"
        if not cap.exists() and pmu is None:
            return None
        key = (pkg.read_text(encoding="utf-8").strip(), core.read_text(encoding="utf-8").strip()) \
            if pkg.exists() and core.exists() else cpu.name
        num = int(cpu.name[3:])
        capacity = int(cap.read_text(encoding="utf-8").strip()) if cap.exists() else 0
        top = max(top, capacity)
        if pmu is not None and num in pmu[1]:
            seen.setdefault(key, None)           # a listed E-core (the atom list and, #3262, the LP-E list)
        elif pmu is not None and num in pmu[0]:
            seen.setdefault(key, False)          # a listed P-core
        else:                                    # in no list (or no lists at all): its capacity decides
            seen.setdefault(key, capacity)
    # an E-core is under 90% of the largest capacity; the PMU lists (None: E, False: P) decide where they say
    return [0 if c is None else 1 if c is False else (1 if c * 10 >= top * 9 else 0) for c in seen.values()]


def cpulist(text: str) -> set:
    """A kernel cpulist ("0-7,16") as a set of CPU numbers."""
    out: set = set()
    for part in text.strip().split(","):
        lo, _, hi = part.strip().partition("-")
        if lo.isdigit():
            out.update(range(int(lo), int(hi or lo) + 1))
    return out


def linux_hybrid_pmu(root: str = "/sys/devices"):
    """upstream #798: (P-core CPUs, E-core CPUs) from Intel's hybrid PMU lists (cpu_core/cpus, cpu_atom/cpus), or None
    on a CPU that has no such lists."""
    try:
        p = cpulist((Path(root) / "cpu_core" / "cpus").read_text(encoding="utf-8"))
        e = cpulist((Path(root) / "cpu_atom" / "cpus").read_text(encoding="utf-8"))
    except OSError:
        return None
    try:   # #3262: Meteor Lake / Arrow Lake-H list their LP-E cores in a third set, in neither of the two above
        e |= cpulist((Path(root) / "cpu_lowpower" / "cpus").read_text(encoding="utf-8"))
    except OSError:
        pass
    return (p, e) if p and e else None


def hybrid_pool_workers(cores) -> int | None:
    """upstream #642 (Hardin22's measurement): on a hybrid CPU the expert pool runs best on the P-cores but the host
    loop's one plus HALF of the E-cores - an E-core runs the expert kernels ~2.2x slower and each layer waits for its
    slowest part (i9-14900KF, 8P + 16E: 15 workers decoded 165 / 116 tok/s against 106 / 84 with all 23). Only on a
    CPU with more E-cores than P-cores: on an i7-13700KF (8P + 8E, docs/AMD_HIP.md's gfx1030 report) all 15 workers
    decoded 38-42 tok/s against 36 with 8, so there the engine's own count stays. None: the engine's own default
    (one worker per physical core but the host's) stays."""
    if not cores:
        return None
    p, e = cores
    if e <= p:
        return None
    return max(1, p - 1 + e // 2)


def recommend_pool_workers(args: list) -> list:
    """`args` with setup's recommended `--pool-workers` for a hybrid CPU, unless they set one already (a calibration's
    measured count, or the user's own).  A recommendation: the config line can be edited or removed."""
    n = hybrid_pool_workers(cpu_cores())
    if n is None or "--pool-workers" in args:
        return args
    p, e = cpu_cores()
    ok(f"hybrid CPU ({p} performance + {e} efficiency cores): {n} CPU expert workers - the performance cores and half "
       f"of the efficiency cores (--pool-workers in the config; {SETUP_CMD} --calibrate measures it on this PC)")
    return [*args, "--pool-workers", str(n)]


def linux_sockets(sys_root: str = "/sys"):
    """(sockets, physical cores per socket) from the kernel's topology files, or None when they do not say."""
    cores: dict = {}
    for cpu in (Path(sys_root) / "devices" / "system" / "cpu").glob("cpu[0-9]*"):
        pkg, core = cpu / "topology" / "physical_package_id", cpu / "topology" / "core_id"
        try:
            socket = pkg.read_text(encoding="utf-8").strip()
            cores.setdefault(socket, set()).add(core.read_text(encoding="utf-8").strip())
        except OSError:
            return None
    return (len(cores), min(len(c) for c in cores.values())) if cores else None


def two_socket_note(sockets) -> list[str]:
    """upstream bench #674 #707 (2-socket Xeons: 17-18 workers beat 35 by ~20%): a tip to keep the expert pool on one
    socket's cores, one fewer for the host loop.  Nothing is written to the config."""
    if not sockets or sockets[0] < 2 or sockets[1] < 3:
        return []
    n = sockets[1] - 1
    return [f"tip: this PC has {sockets[0]} CPU sockets of {sockets[1]} cores. Expert workers on the other socket have "
            f"been measured slower than fewer, local ones (35 vs 17-18 on 2-socket Xeons): try --pool-workers {n} in "
            f"the config's args ({SETUP_CMD} --calibrate measures it on this PC)"]


def gpu_sel(value) -> list:
    """A config's "gpu" as a list of card numbers: 0, [0, 2] or the string form "0,2" (which serve splits
    the same way).  [] when it names none.  Without this, a string "0,1" reached gpu_info() whole and
    calibrate died with "there is no GPU 0,1" on a dual-GPU config."""
    if value is None or value == "":
        return []
    items = value if isinstance(value, (list, tuple)) else str(value).split(",")
    sel = []
    for x in items:
        x = str(x).strip()
        if x == "":
            continue
        sel.append(int(x) if x.isdigit() else x)
    return sel


def hardware_key(cfg: dict) -> str:
    """What a calibration is valid for: this GPU, CPU and RAM, and the model with its context and images setting
    (the context's KV cache and the image encoder take VRAM from the expert cache)."""
    sel = cfg.get("gpu")
    if isinstance(sel, str):
        sel = gpu_sel(sel)
    gl = [gpu_info(i) or {} for i in sel] if isinstance(sel, list) else [gpu_info(sel) or {}]
    if cfg.get("split_pci"):                             # a layer split (setup --gpus): its other cards
        gl += [next((x for x in gpus() if x["pci"] == pci), {}) for pci in cfg["split_pci"]]
    g = {"name": " + ".join(x.get("name", "?") for x in gl), "vram_gb": sum(x.get("vram_gb", 0) for x in gl)}
    a = cfg.get("args", [])
    ctx = a[a.index("--max-context") + 1] if "--max-context" in a else "?"
    return "|".join([g.get("name", "?"), f"{g.get('vram_gb', 0):.0f}GB", cpu_info()[0], f"{ram_gb():.0f}GB",
                     cfg.get("model_name", "?"), ctx, "images" if "--vision" in a else "text"])


# What the engine and setup fit to the PC by themselves, said wherever the tuning is offered or asked for
CALIBRATE_NOT_NEEDED = ("The engine and setup already fit these settings to this PC from what they measure (the PCIe "
                        "share, the verify window, the CPU threads, the expert cache's swaps), so it is usually not "
                        "needed.")


def calibrate_config(cfg_path: Path) -> bool:
    """Measure the engine's hardware-dependent settings on this PC (tools/calibrate.py), write them into the run
    config and remember them per PC and model in the settings file, so an update or a reinstall keeps them."""
    sys.path.insert(0, str(ROOT / "tools"))
    import calibrate as CAL
    cfg = json.loads(cfg_path.read_text(encoding="utf-8-sig"))
    say()
    say("  Tuning Strata for this PC: the output speed is measured with a few engine settings (the PCIe share, the")
    say("  CPU threads, the expert cache). It takes roughly 15-30 minutes (3 rounds of each value); "
        "the PC is busy meanwhile.")
    try:
        since = os.path.getsize(cfg["log"]) if cfg.get("log") and os.path.isfile(cfg["log"]) else 0
    except OSError:
        since = 0
    try:
        res = CAL.run(cfg, say=say)
    except Exception as e:                             # never stops an install: the defaults stay
        warn(f"the tuning did not finish ({e}): the default settings stay")
        why = CAL.engine_error(cfg.get("log"), since)  # upstream #447: the engine's own reason, not only "see the log"
        if why:
            say(f"       the engine said: {why}")
        return False
    cfg["args"] = CAL.apply(cfg["args"], res["settings"])
    write_config(cfg_path, cfg)
    st = load_settings()
    st.setdefault("calibration", {})[hardware_key(cfg)] = {"settings": res["settings"],
                                                           "tok_s": res["report"].get("tok_s"),
                                                           "date": time.strftime("%Y-%m-%d")}
    save_settings(st)
    if res["settings"]:
        ok("tuned for this PC: " + ", ".join(f"{k} {v}" for k, v in res["settings"].items())
           + (f" ({res['report']['tok_s']} tok/s)" if res["report"].get("tok_s") else ""))
    else:
        ok("tuned for this PC: the default settings are already the fastest here"
           + (f" ({res['report']['tok_s']} tok/s)" if res["report"].get("tok_s") else ""))
    return True


def bench_config(cfg_path: Path, data: Path, verbose: bool, original: str | None, rounds: int,
                 temperature: float) -> int:
    """Measure the model `cfg_path` sets up (tools/bench.py) and say where the record is."""
    sys.path.insert(0, str(ROOT / "tools"))
    BENCH = importlib.import_module("bench")           # tools/bench.py (to mypy, `bench` is the records' folder)
    cfg = json.loads(cfg_path.read_text(encoding="utf-8-sig"))
    found = gpus()
    pcis = [cfg.get("gpu_pci"), *(cfg.get("split_pci") or [])]
    chosen = ([x for p in pcis if p for x in found if x["pci"] == p] or [gpu_info()]) if found else []
    say()
    say(f"  Measuring {cfg.get('model_name', cfg_path.stem)} on this PC: the engine is started many times, about "
        f"{20 * rounds} minutes" + (" and more with --bench-verbose" if verbose else "") +
        (f", twice that with upstream {original}" if original else "") + ". The PC is busy meanwhile.")
    try:
        md = BENCH.run(cfg_path, data, chosen, verbose, original, say, rounds, temperature)
    except (BENCH.BenchError, BENCH.C.EngineLeft) as e:
        fail(str(e))
    say()
    say(md.read_text(encoding="utf-8"))
    ok(f"the record: {md.parent} (summary.md to paste into a report, record.json with everything; read them first: "
       "nothing is sent anywhere)")
    return 0


def saved_calibration(cfg: dict) -> dict | None:
    """The settings an earlier calibration found for this PC and model, if any."""
    return (load_settings().get("calibration") or {}).get(hardware_key(cfg))


def repoint_engine(cfg_path: Path, cfg: dict) -> dict:
    """A packaged engine runs the config: its engine and image encoders are this package's, pointed here on every start
    (the settings and the model files, in the user's folders, stay as they are).  Windows: the 7z is unpacked
    anywhere, a new release in a folder of its own.  Linux: the deb on the host and the rpm in the Podman container
    (container/) share the settings, and keep the engine in different folders (lib vs lib64); the engine finds its
    libraries by its RPATH, so a config's other package's lib_dirs, missing here, are skipped."""
    if not PACKAGED:
        return cfg
    eng = packaged_engine_dir()
    changed = False
    for part in (cfg, cfg.get("vision"), (cfg.get("vision") or {}).get("fallback")):
        if isinstance(part, dict) and part.get("exe"):
            new = str(eng / Path(part["exe"]).name)
            if part["exe"] != new:
                part["exe"] = new
                changed = True
    if changed:
        write_config(cfg_path, cfg)
    return cfg


def upgrade_config(cfg_path: Path, cfg: dict) -> dict:
    """Configs written before v0.1.13 read prompts in fixed 2048-token chunks; the engine now picks the chunk
    itself (`--prefill auto`: up to 32768, as the free VRAM allows - about 2x faster on long prompts)."""
    try:
        if engine_is_xe(json.loads((Path(cfg["exe"]).parent / "BUILD.json").read_text())):
            return cfg             # the Xe engine (versions xe0.1.39 and on) reads --prefill auto
    except (OSError, ValueError):
        pass
    a = cfg.get("args", [])
    changed = False
    ver = engine_version(cfg["exe"]) if "--prefill" in a else (0, 0, 0)
    if "--prefill" in a and a[a.index("--prefill") + 1] == "2048" and ver >= (0, 1, 13):
        a[a.index("--prefill") + 1] = "auto"
        changed = True
        ok("prompt reading: the engine now picks its chunk size (--prefill auto)")
    elif "--prefill" in a and a[a.index("--prefill") + 1] == "auto" and (0, 0, 0) < ver < (0, 1, 13):
        a[a.index("--prefill") + 1] = "2048"           # an older engine kept after a failed update (issue #49)
        changed = True
        warn(f"the installed engine is {'.'.join(map(str, ver))}: prompts are read in 2048-token chunks until it is "
             "updated")
    if changed:
        write_config(cfg_path, cfg)
    return cfg


# The draft layer's token subsets (data/, written by tools/draft_vocab.py; upstream 6e153c9, 0fc1a1e, cbd0522): cjk
# = with Chinese, Japanese and Korean (the default), en = English and code only (the subset before it), cyrillic =
# English, code and the Cyrillic script.  The ones setup copied before are replaced; a subset made by hand is kept.
DRAFT_VOCABS = {"cjk": "draft_vocab.bin", "en": "draft_vocab_en.bin", "cyrillic": "draft_vocab_cyrillic.bin",
                "fr": "draft_vocab_fr.bin"}


def vision_tokens(asked: int | None, vision: str, earlier: Path) -> int:
    """The most image tokens a picture becomes (the config's vision.max_tokens; upstream #625): --vision-tokens N, else
    what this model's config chose earlier for the same encoder device (a setup run again keeps it), else the
    device's default (VISION).  More is allowed with a note on the time it takes: setup recommends, it does not cap."""
    default = VISION[vision]["max_tokens"]
    if asked is None and earlier.is_file():
        try:
            v = json.loads(earlier.read_text(encoding="utf-8-sig")).get("vision")
        except (OSError, ValueError, AttributeError):
            v = None
        mt = v.get("max_tokens") if isinstance(v, dict) and bool(v.get("gpu")) == (vision == "gpu") else None
        if isinstance(mt, int) and mt > 0 and mt != default:
            asked = mt
    if asked is None:
        return default
    note = ""
    if vision == "cpu" and asked > default:
        note = (" - on the CPU a picture takes longer to encode the more tokens it gets (several seconds more at "
                "1,024 than at 300)")
    elif asked > VISION["gpu"]["max_tokens"]:
        note = " - more than the encoder's default needs more VRAM and context per picture"
    ok(f"images: up to {asked} image tokens per picture (--vision-tokens; default {default}){note}")
    return asked


def saved_draft_vocab(cfg_path: Path) -> str | None:
    """The draft subset a model's config chose earlier (--draft-vocab), or None: a setup run again without the flag
    rewrites the config, and would otherwise put the default subset back."""
    try:
        v = json.loads(cfg_path.read_text(encoding="utf-8-sig")).get("draft_vocab")
    except (OSError, ValueError, AttributeError):
        return None
    return v if v in DRAFT_VOCABS else None


# the draft head's VRAM per subset (IQ3_S: the largest)
DRAFT_VOCAB_MIB = {"cjk": 348, "cyrillic": 193, "fr": 151, "en": 133}
SMALL_DRAFT_VRAM_GB = 14   # #474: below this the default subset's head can be what does not fit


def draft_vocab_note(vram_gb: float, chosen: str | None) -> list[str]:
    """#474 (upstream f2aaba1): on a card under 14 GB, the default draft subset (cjk, ~348 MiB of VRAM) can be what
    does not fit at the start ("the draft head does not fit"), and the engine's expert cache gets what a smaller one
    leaves.  Setup RECOMMENDS a smaller one here and changes nothing: a subset chosen with --draft-vocab, or kept from
    an earlier install, gets no note.  [] for every other case."""
    if chosen or not 0 < vram_gb < SMALL_DRAFT_VRAM_GB:
        return []
    return [f"Tip for a {vram_gb:.0f} GB card: the draft layer's default token subset (with Chinese, Japanese and "
            f"Korean) needs up to ~{DRAFT_VOCAB_MIB['cjk']} MiB of VRAM.",
            f"  For English and code answers, {SETUP_CMD} --draft-vocab en needs up to ~{DRAFT_VOCAB_MIB['en']} MiB "
            f"(cyrillic: ~{DRAFT_VOCAB_MIB['cyrillic']}) and leaves the rest to the expert cache - and it is the",
            "  fix when the start stops with \"the draft head does not fit\". The model keeps the choice."]


def mtp_corrupt(mtp: Path, env=None) -> bool:
    """#327: True when the MTP tensors an install fetched are not the pinned checkpoint's (tools/mtp_fetch.py verify,
    which hashes only files that changed since they last checked out).  A mirror that ignored range requests left the
    shards' starts there instead, and the draft layer built from them accepted nothing - with no error anywhere."""
    if not (mtp / "tensors").is_dir():
        return False
    r = subprocess.run([sys.executable, str(ROOT / "tools" / "mtp_fetch.py"), "verify", "--out", str(mtp)], env=env,
                       stdout=subprocess.PIPE, stderr=subprocess.STDOUT, text=True)
    return r.returncode == 3


def refresh_draft_vocab(rt: Path, choice: str = "cjk") -> None:
    """The chosen subset into the MTP folder: copied when missing or when another shipped subset is there."""
    new, dst = ROOT / "data" / DRAFT_VOCABS.get(choice, "draft_vocab.bin"), rt / "draft_vocab.bin"
    if not new.exists() or not rt.is_dir():
        return
    if dst.exists():
        old = hashlib.sha256(dst.read_bytes()).hexdigest()
        shipped = {hashlib.sha256((ROOT / "data" / f).read_bytes()).hexdigest()
                   for f in DRAFT_VOCABS.values() if (ROOT / "data" / f).exists()}
        if old not in shipped or old == hashlib.sha256(new.read_bytes()).hexdigest():
            return
        what = {"cjk": "with Chinese, Japanese and Korean", "cyrillic": "with the Cyrillic script", "fr": "for French"}
        ok("draft layer: the token subset " + what.get(choice, "for English and code"))
    shutil.copyfile(new, dst)


def refresh_shared_draft_vocab(cfg: dict, done: set) -> None:
    """update_install's draft subset of one config, for configs taken most recently used first (installed_configs'
    order): an MTP folder already in `done` is left alone.  Several configs can name one MTP folder (a second config of
    the same model: another GPU mode, another context), each with its own "draft_vocab".  Refreshed once per config,
    the folder ended with the subset of the config used LONGEST ago (upstream c0462733: a config without the key put
    the default subset over the cyrillic one of the config in use).  The folder takes the subset of the most recently
    used config that names it; a start still installs its own config's."""
    args = cfg.get("args") or []
    if "--mtp" not in args[:-1]:
        return
    rt = Path(args[args.index("--mtp") + 1])
    key = os.path.normcase(os.path.abspath(rt))
    if key in done:
        return
    done.add(key)
    refresh_draft_vocab(rt, cfg.get("draft_vocab", "cjk"))


def update_install(have: list) -> int:
    """#475 (upstream 64987c8): `setup.py --update` (update.sh, after its git pull): what a plain ./setup.sh does to an
    install before it starts the model, without starting it - the Python packages, the engine compiled again when its
    source changed, each installed model's config upgrades and its draft subset.  No question is asked and the model
    files are not touched."""
    have = [p for p in have if model_config(p)]        # #549: an xestrata-*.json that is no model config is skipped
    if not have:
        say(f"  No model is installed in this XeStrata folder yet: run {SETUP_CMD} to set it up - it finds an "
            "earlier")
        say("  install's model files next to it and reuses them.")
        return 0
    if not PACKAGED:
        pip_install(requirement_lines() if REQUIREMENTS.exists() else PY_PACKAGES,
                    "numpy, jinja2, regex, pyyaml, tqdm, requests, pillow, psutil")
    update_installed_engine()
    mtp_done: set = set()
    for cfg_path in have:
        cfg = upgrade_config(cfg_path, json.loads(cfg_path.read_text(encoding="utf-8-sig")))
        refresh_shared_draft_vocab(cfg, mtp_done)
        ok(f"{cfg.get('model_name', cfg_path.stem)}: up to date")
    say()
    ok(f"XeStrata is updated. Start the model with {SETUP_CMD} when you want it.")
    return 0


def settings_summary(cfg: dict, port=None) -> str:
    """#564 (upstream ae6dd61): the settings a start uses, in one line: the config's engine options (the model's file
    paths left out) and the server's own fields, so a change made by hand to xestrata-<model>.json can be checked
    without the log.  The API key itself is never printed."""
    a, out, i = [str(x) for x in cfg.get("args") or []], [], 0
    while i < len(a):
        flag = a[i]
        val = a[i + 1] if i + 1 < len(a) and not a[i + 1].startswith("--") else None
        i += 1 if val is None else 2
        if not flag.startswith("--"):
            continue                                   # a positional: the model file
        if val is not None and ("/" in val or "\\" in val or val.lower().endswith((".gguf", ".bin"))):
            continue                                   # a path: --native, --mtp, --expert-profile ...
        out.append(flag if val is None else f"{flag} {val}")
    srv = [f"{cfg.get('host', '127.0.0.1')}:{port or cfg.get('port', 8095)}"]
    if cfg.get("api_key"):
        srv.append("api key set")
    if cfg.get("open_browser") is False:               # #609
        srv.append("no browser")
    for k in ("gpu", "draft_vocab", "fit_max_tokens", "reasoning_budget_tokens", "anthropic_thinking"):
        if cfg.get(k) is not None:
            v = cfg[k]
            v = ",".join(map(str, v)) if isinstance(v, list) else str(v).lower() if isinstance(v, bool) else v
            srv.append(f"{k} {v}")
    return " ".join(out) + ("; " if out else "") + "server " + ", ".join(srv)


def start(cfg_path: Path, port: int | None, gpu: int | list | None = None, open_browser=True, yes=False,
          layer_split=None, keep=None) -> int:
    """keep: settings given on this start that the model keeps from now on (--host, --api-key, --draft-vocab,
    --vram-reserve-mib)."""
    cfg = repoint_engine(cfg_path, json.loads(cfg_path.read_text(encoding="utf-8-sig")))
    cfg = upgrade_config(cfg_path, cfg)
    if cfg.get("arch") == "deepseek41" and (cfg.get("split_pci") or isinstance(gpu, list) and len(gpu) > 1):
        fail("DeepSeek's SYCL prototype supports one GPU",
             "choose a single --gpu or run --setup to replace a split config")
    missing = [p for p in [cfg["exe"], *[a for a in cfg["args"] if a.endswith(".gguf")]] if not Path(p).exists()]
    if missing:
        fail(f"{cfg_path.name} refers to missing files: {missing[0]}", "run it again with --setup to repair")
    keep = {k: v for k, v in (keep or {}).items() if v is not None}
    reserve = keep.pop("vram_reserve_mib", None)       # #493: an engine argument, kept in the config's args
    if reserve is not None:
        args = cfg["args"]
        reserve_flag = "--reserve-mib" if cfg.get("arch") == "deepseek41" else "--vram-reserve-mib"
        if reserve_flag in args[:-1]:
            args[args.index(reserve_flag) + 1] = str(reserve)
        else:
            args += [reserve_flag, str(reserve)]
        write_config(cfg_path, cfg)
        ok(f"saved for this model: {reserve} MiB of VRAM kept free for other programs (--vram-reserve-mib)")
    if keep and any(cfg.get(k) != v for k, v in keep.items()):   # #179: a --host/--api-key on a start was ignored
        cfg.update(keep)
        write_config(cfg_path, cfg)
        ok("saved for this model: " + ", ".join(
            "api key" if k == "api_key" else ("the browser opens" if v else "no browser") if k == "open_browser"
            else f"{k.replace('_', ' ')} {v}" for k, v in keep.items()))
    cfg_path.touch()                                     # the most recently used model
    if "--mtp" in cfg["args"][:-1]:
        refresh_draft_vocab(Path(cfg["args"][cfg["args"].index("--mtp") + 1]), cfg.get("draft_vocab", "cjk"))
    cmd = [sys.executable, str(ROOT / "serve" / "server.py"), "--engine", "strata", "--config", str(cfg_path),
           "--port", str(port or cfg.get("port", 8095))]
    found = gpus()
    env = None
    usable = [x for x in found if gpu_problem(x) is None]
    if isinstance(gpu, list) and len(gpu) > 1:        # --gpus: a layer split, saved for this model
        check_gpus(gpu, found)
        cards = [next(x for x in found if x["index"] == i) for i in gpu]
        cfg["gpu_pci"], cfg["split_pci"] = cards[0]["pci"], [x["pci"] for x in cards[1:]]
        if layer_split:
            cfg["layer_split"] = str(layer_split)
        write_config(cfg_path, cfg)
        ok("saved for this model: the layers split across " + " + ".join(gpu_name(x) for x in cards) +
           f" ({cfg.get('layer_split') or 'auto'})")
    elif gpu is not None:                              # --gpu N: this start only, by the card's PCI address
        check_gpus(gpu if isinstance(gpu, list) else [gpu], found)
        g = next(x for x in found if x["index"] == (gpu[0] if isinstance(gpu, list) else gpu))
        env = dict(os.environ, STRATA_GPU_PCI=g["pci"])
        if cfg.get("split_pci"):                       # one card for this start, the saved split kept
            env["STRATA_LAYER_SPLIT"] = "off"
        ok("GPU: " + gpu_name(g) + " (this start)")
    elif cfg.get("split_pci"):
        cards = [next((x for x in found if x["pci"] == pci), None) for pci in [cfg.get("gpu_pci"), *cfg["split_pci"]]]
        if None in cards:
            fail("a GPU of this model's layer split is missing: " +
                 ", ".join(pci for pci, x in zip([cfg.get("gpu_pci"), *cfg["split_pci"]], cards) if x is None),
                 "start it with --gpus (the cards to use, as --check lists them) or --gpu N for one card")
        ok("GPUs: " + " + ".join(gpu_name(x) for x in cards) + f" (layer split, {cfg.get('layer_split') or 'auto'})")
    elif usable:
        g = next((x for x in usable if x["pci"] == cfg.get("gpu_pci")), usable[0])
        ok("GPU: " + gpu_name(g))
    open_browser = open_browser and cfg.get("open_browser") is not False   # #609: "open_browser": false
    if open_browser:
        cmd.append("--open")
    gb = 0.0
    if "--native" in cfg["args"]:
        try:
            gb = Path(cfg["args"][cfg["args"].index("--native") + 1]).stat().st_size / 1e9
        except (OSError, IndexError):
            pass
    say()
    say("  " + "-" * 100)
    size = f'about {gb:.0f} GB' if gb >= 1 else '34-55 GB'
    a_ = cfg["args"]
    if "--mmap-experts" in a_ and "--resident-budget-gib" not in a_ and "--resident-experts" not in a_:
        # #505: the mapped low-RAM mode loads nothing into RAM up front (the server's narrator says the same)
        say(f"  Starting {cfg.get('model_name', 'the model')}: it maps {size} of experts from the model files (the OS "
            "file cache reads them).")
    else:
        say(f"  Starting {cfg.get('model_name', 'the model')}: it loads {size} into RAM and locks part of it for the "
            "GPU.")
    say("  While it does, YOUR PC CAN BE SLOW OR STOP RESPONDING FOR 1-3 MINUTES (longer the first time after a")
    say("  restart). That is normal: please wait and don't close this window - " + (
        "the browser opens when it is ready." if open_browser else "the server says when it is ready."))
    say("  Later, closing this window stops the model.")
    say("  " + "-" * 100)
    for n, line in enumerate(textwrap.wrap(f"Settings ({cfg_path.name}): {settings_summary(cfg, port)}", 100,
                                           break_on_hyphens=False)):   # #564: what this start uses
        say(("  " if n == 0 else "    ") + line)
    return subprocess.call(cmd, env=env)


def tiny_png(w=64, h=48) -> bytes:
    """A small two-colour PNG, for the warm-up's image request."""
    import zlib
    rows = b"".join(b"\x00" + b"".join(bytes((200, 30, 30) if x < w // 2 else (30, 30, 200)) for x in range(w))
                    for _ in range(h))
    chunk = lambda t, d: struct.pack(">I", len(d)) + t + d + struct.pack(">I", zlib.crc32(t + d))   # noqa: E731
    return (b"\x89PNG\r\n\x1a\n" + chunk(b"IHDR", struct.pack(">IIBBBBB", w, h, 8, 2, 0, 0, 0))
            + chunk(b"IDAT", zlib.compress(rows)) + chunk(b"IEND", b""))


def warm_up(cfg_path: Path) -> None:
    """Start the model once and answer a long prompt (and a picture): the GPU code is SPIR-V that the driver compiles
    on first use and keeps in its cache (~/.cache/neo_compiler_cache), so the first real request does not wait for it
    (on the B70 about 30 s more for the first reply, 11 s more to start: the 2026-09-30-xe-setup record).
    Best effort: a failure is reported and setup goes on."""
    import base64
    import socket
    import urllib.error
    cfg = json.loads(cfg_path.read_text(encoding="utf-8"))
    with socket.socket() as sk:
        sk.bind(("127.0.0.1", 0))
        port = sk.getsockname()[1]
    log = STATE / (cfg_path.stem + "-warmup.log")
    base = f"http://127.0.0.1:{port}"
    # #19: a server with a key answers 401 to a request without it (the warm-up waited out its 15 minutes): the first
    # of the keys it takes, in its order (STRATA_API_KEY, else "api_key": a string "k1,k2" or a list)
    key = os.environ.get("STRATA_API_KEY") or cfg.get("api_key") or ""
    keys = [k.strip() for k in (key if isinstance(key, list) else str(key).split(",")) if str(k).strip()]
    auth = {"Authorization": f"Bearer {keys[0]}"} if keys else {}
    elog = cfg.get("log")                              # the engine's own log: the prompt's CPU share it measured
    try:
        since = os.path.getsize(elog) if elog and os.path.isfile(elog) else 0
    except OSError:
        since = 0
    share = None
    say("  Compiling the GPU code for this model: starting it once and asking two questions (1-3 minutes) ...")
    t0 = time.time()
    with open(log, "w", encoding="utf-8") as out:
        proc = subprocess.Popen([sys.executable, str(ROOT / "serve" / "server.py"), "--engine", "strata", "--config",
                                 str(cfg_path), "--port", str(port)], stdout=out, stderr=subprocess.STDOUT,
                                stdin=subprocess.DEVNULL, **new_process_group())
        try:
            deadline = time.time() + 900
            while True:
                if proc.poll() is not None:
                    raise RuntimeError(f"the model stopped while starting (see {log.name})")
                try:
                    urllib.request.urlopen(urllib.request.Request(base + "/v1/models", headers=auth), timeout=5).read()
                    break
                except (urllib.error.URLError, OSError):
                    if time.time() > deadline:
                        raise RuntimeError(f"the model did not start within 15 minutes (see {log.name})")
                    time.sleep(2)
            notes = " ".join(f"Note {i}: the {c} sensor read {i * 7 % 100} at step {i}."
                             for i, c in zip(range(60), ["red", "blue", "green", "amber"] * 15))
            asks: list[list[dict[str, Any]]] = [
                [{"role": "user", "content": "Summarize these notes in two sentences.\n" + notes}]]
            if cfg.get("vision"):
                url = "data:image/png;base64," + base64.b64encode(tiny_png()).decode()
                asks.append([{"role": "user", "content": [{"type": "text", "text": "What colours are in this picture?"},
                                                          {"type": "image_url", "image_url": {"url": url}}]}])
            for messages in asks:
                req = urllib.request.Request(base + "/v1/chat/completions",
                                             headers={"Content-Type": "application/json", **auth},
                                             data=json.dumps({"messages": messages, "max_tokens": 32,
                                                              "temperature": 0}).encode())
                json.loads(urllib.request.urlopen(req, timeout=900).read())
            ok(f"GPU code compiled for this model ({time.time() - t0:.0f} s)")
            # a text prompt of the same length again, the code compiled (other numbers: no cached prefix): the CPU's
            # share of its experts measured now is the one kept
            notes2 = " ".join(f"Note {i}: the {c} sensor read {i * 11 % 100} at step {i}."
                              for i, c in zip(range(60), ["red", "blue", "green", "amber"] * 15))
            again = [{"role": "user", "content": "Summarize these notes in two sentences.\n" + notes2}]
            req = urllib.request.Request(base + "/v1/chat/completions",
                                         headers={"Content-Type": "application/json", **auth},
                                         data=json.dumps({"messages": again, "max_tokens": 1,
                                                          "temperature": 0}).encode())
            json.loads(urllib.request.urlopen(req, timeout=900).read())
            share = measured_cpu_share(elog, since)
        except (RuntimeError, OSError, ValueError) as e:
            warn(f"the warm-up did not finish ({e}): the first request will take longer")
        finally:
            end_process_group(proc)
    if share is not None:
        fix_prefill_share(cfg_path, share)
    free = start_free_mib(elog, since)
    if free is not None:
        fix_vram_free(cfg_path, free)


def start_free_mib(elog: str | None, since: int) -> int | None:
    """The VRAM free at the engine's start ("strata generate: N MiB of VRAM free at the start") in its log after byte
    `since`, the lowest if it started more than once; None when the log has none."""
    if not elog:
        return None
    try:
        with open(elog, "rb") as f:
            f.seek(since)
            text = f.read().decode("utf-8", "replace")
    except OSError:
        return None
    found = re.findall(r"strata generate: ([0-9]+) MiB of VRAM free at the start", text)
    return min(int(v) for v in found) if found else None


VRAM_FREE_MARGIN_MIB = 32   # the free VRAM moved by up to ~20 MiB between starts on the B70 (2026-10-17)


def fix_vram_free(cfg_path: Path, free_mib: int) -> None:
    """Write the free VRAM the warm-up's start saw, less a margin, into the config (--vram-free-mib): the auto expert
    cache was sized from what was free at each start, which moved by a few MiB, the cache's slots with it, which
    experts the prompt's CPU share took, and two greedy runs of one prompt parted (the B70, 2026-10-17)."""
    cfg = json.loads(cfg_path.read_text(encoding="utf-8"))
    a = list(cfg.get("args", []))
    v = str(max(0, free_mib - VRAM_FREE_MARGIN_MIB))
    if "--vram-free-mib" in a[:-1]:
        a[a.index("--vram-free-mib") + 1] = v
    else:
        a += ["--vram-free-mib", v]
    cfg["args"] = a
    write_config(cfg_path, cfg)
    st = load_settings()
    st.setdefault("vram_free_mib", {})[hardware_key(cfg)] = v
    save_settings(st)
    ok(f"the expert cache is sized from at most {v} MiB of free VRAM (what this start saw, less "
       f"{VRAM_FREE_MARGIN_MIB}; kept in the config, so it holds the same experts every run)")


def saved_vram_free(cfg: dict) -> str | None:
    """The free VRAM an earlier warm-up saw for this PC and model, less the margin (fix_vram_free), if any."""
    return (load_settings().get("vram_free_mib") or {}).get(hardware_key(cfg))


def measured_cpu_share(elog: str | None, since: int) -> float | None:
    """The last prompt's CPU share the engine measured ("strata serve: prefill CPU share X (measured)") in its log
    after byte `since`; None when it measured none (the share is not armed, or fixed already)."""
    if not elog:
        return None
    try:
        with open(elog, "rb") as f:
            f.seek(since)
            text = f.read().decode("utf-8", "replace")
    except OSError:
        return None
    found = re.findall(r"strata serve: prefill CPU share ([0-9.]+) \(measured\)", text)
    return float(found[-1]) if found else None


def fix_prefill_share(cfg_path: Path, share: float) -> None:
    """Write the measured prompt CPU share into the config (--prefill-cpu-share): measured anew in every run, it moved
    a little, which experts the CPU took with it, and two greedy runs of one prompt parted (2026-10-16).  A
    "--prefill-cpu-share auto" in the args is the user's and stays."""
    cfg = json.loads(cfg_path.read_text(encoding="utf-8"))
    a = list(cfg.get("args", []))
    v = f"{share:.2f}"
    if "--prefill-cpu-share" in a[:-1]:
        i = a.index("--prefill-cpu-share")
        if a[i + 1] == "auto":
            return
        a[i + 1] = v
    else:
        a += ["--prefill-cpu-share", v]
    cfg["args"] = a
    write_config(cfg_path, cfg)
    st = load_settings()
    st.setdefault("prefill_cpu_share", {})[hardware_key(cfg)] = v
    save_settings(st)
    ok(f"the CPU's share of a short prompt's experts, measured here: {v} (kept in the config, so a prompt is read the "
       "same way every run)")


def saved_prefill_share(cfg: dict) -> str | None:
    """The prompt CPU share an earlier warm-up measured for this PC and model (fix_prefill_share), if any."""
    return (load_settings().get("prefill_cpu_share") or {}).get(hardware_key(cfg))


# upstream #629: the run config's keys setup writes itself (and rewrites on every setup run); any other key is the
PARALLEL_MAX = 8               # #465: the engine's batch window holds at most 8 requests
PARALLEL_SHARE = 0.2           # #465: the slots' sessions may take this share of the VRAM the expert cache would hold
PARALLEL_HELD = 0.5            # #465: ... and only where the cache still holds this share of the experts beside them
PARALLEL_COST_NOTE = ("parallel N reduces waiting for several users but costs about 10-25% speed per request on this "
                      "card")


def parallel_slot_gb(ctx: int, kv: str, streaming: bool) -> float:
    """#465: the VRAM one batch slot's session takes: its KV cache (12 QSA layers; with KV streaming only the 32K
    positions the attention reads stay in VRAM) and the DeltaNet state (~0.17 GB).  Measured (upstream): 0.56 GiB at
    32K int8."""
    kv_tok = 12 * KV_CELL_BYTES.get(kv, 1056)
    return (min(ctx, 32768) if streaming else ctx) * kv_tok / 1e9 + 0.17


def parallel_recommend(vram_gb: float, arena_gb: float, ctx: int, kv: str, streaming: bool) -> int:
    """#465: how many requests at once ("parallel") to recommend: 0 = none (one at a time).  Only where the experts
    mostly fit in VRAM - the expert cache (the card's VRAM less ~5 GB) still holds PARALLEL_HELD of the model's experts
    beside the slots' sessions, which take at most PARALLEL_SHARE of it, up to 4.  Where the experts mostly run on the
    CPU a batch reads about as many experts as the requests one by one and every slot's VRAM is expert cache lost
    (upstream measured a 12 GB card: a request alone 11-24% slower with 2-4 slots; docs/BATCHING.md)."""
    cache_gb = max(0.0, vram_gb - 5)
    slot = parallel_slot_gb(ctx, kv, streaming)
    best = 0
    for n in (2, 3, 4):
        if n * slot <= PARALLEL_SHARE * cache_gb and (cache_gb - n * slot) >= PARALLEL_HELD * arena_gb:
            best = n
    return best


def parallel_note(asked: int | None, vram_gb: float, arena_gb: float, ctx: int, kv: str, streaming: bool,
                  batch_mtp: bool = False) -> list[str]:
    """#465: what setup says about "parallel": the recommendation (or, where it would cost speed, why it is left at
    one), or how the asked count compares with it (kept as asked: recommend, never force).  `batch_mtp`: the engine
    runs with --batch-mtp (the server's default with --mtp), which takes every slot asked, past PARALLEL_MAX."""
    rec = parallel_recommend(vram_gb, arena_gb, ctx, kv, streaming)
    slot = parallel_slot_gb(ctx, kv, streaming)
    if asked is None or asked <= 1:
        if not rec:
            return [f"Several requests at once: left at one at a time - {PARALLEL_COST_NOTE} (docs/BATCHING.md)."]
        return [f"Several requests at once (opt-in): --parallel {rec} decodes up to {rec} together instead of one "
                f"after the other (each takes ~{slot:.1f} GB of VRAM from the expert cache; docs/BATCHING.md)."]
    lines = [f"parallel requests: {asked} at once (each takes ~{slot:.1f} GB of VRAM from the expert cache, "
             f"{asked * slot:.1f} GB in all)"]
    used = asked if batch_mtp else min(asked, PARALLEL_MAX)
    if used < asked:
        lines.append(f"the engine runs at most {PARALLEL_MAX} at once; it will use {PARALLEL_MAX}")
    if not rec or used > rec:
        # every slot's session (and with --batch-mtp its drafter) is allocated before the expert cache: a user's 32 on
        # a 24 GB card left it nothing; the engine then runs the slots that leave it a working cache
        left = max(0.0, vram_gb - 5 - used * slot)
        lines.append(f"{used} slots leave the expert cache ~{left:.1f} GB of VRAM; where that is too little the engine "
                     "runs fewer, as many as fit")
    if not rec:
        lines.append(f"recommended for this card: one at a time - {PARALLEL_COST_NOTE}; kept as you chose")
    elif asked > rec:
        lines.append(f"recommended for this card: {rec} - more slots leave fewer experts in VRAM, which can make every "
                     "request slower; kept as you chose")
    return lines


# user's - a "sampling" or "mcp_servers" block, "cors_origins", "open_browser" - and is kept when setup runs again, as
# are "host" and "api_key" when this run does not give them
SETUP_KEYS = frozenset({"exe", "args", "cwd", "tokenizer", "model_name", "log", "lib_dirs", "port", "gpu_pci",
                        "draft_vocab", "vision"})
SPLIT_KEYS = frozenset({"split_pci", "layer_split"})
SETUP_VISION = frozenset({"exe", "mmproj", "model", "gpu", "gpu_pci", "max_tokens", "threads", "onednn", "fallback"})


def carry_over(old: dict, cfg: dict, gpus_chosen: bool = False) -> list[str]:
    """Setup run again for an installed model keeps what the user added to its run config: every key setup does not
    write (`SETUP_KEYS`), and in "vision" the keys setup does not write plus an mmproj of their own that still exists.
    `cfg` (the new config) is updated in place; the names of what was kept are returned.  Engine options added by
    hand to "args" are not merged (setup chooses those): `args_dropped` names them.  The earlier layer split
    (`SPLIT_KEYS`) is kept only when this run chose no GPU (`gpus_chosen`: --gpu or --gpus), and then with its own
    first card: issue #12, --gpu 0 kept a split onto that same card, --gpu 1 a split it did not ask for."""
    kept = []
    for k, v in old.items():
        if cfg.get("arch") == "deepseek41" and k in {"gpu", "cuda", "split_pci", "layer_split", "vision"}:
            continue
        if k in SPLIT_KEYS and gpus_chosen:
            continue
        if k not in SETUP_KEYS and k not in cfg:
            cfg[k] = v
            kept.append(k)
    if "split_pci" in kept and old.get("gpu_pci"):
        cfg["gpu_pci"] = old["gpu_pci"]
    ov, nv = old.get("vision"), cfg.get("vision")
    if isinstance(ov, dict) and isinstance(nv, dict):
        for k, v in ov.items():
            if k not in SETUP_VISION and k not in nv:
                nv[k] = v
                kept.append(f"vision {k}")
        mm = ov.get("mmproj")                          # a file of the user's own: not the one setup downloads
        if isinstance(mm, str) and Path(mm).name != Path(str(nv.get("mmproj"))).name and Path(mm).is_file():
            nv["mmproj"] = mm
            kept.append("vision mmproj")
    kept += carry_profile_args(old, cfg)
    return kept


def flag_value(args: list, flag: str):
    """The value after `flag` in an argument list, or None."""
    for i, a in enumerate(args[:-1]):
        if a == flag:
            return str(args[i + 1])
    return None


def carry_profile_args(old: dict, cfg: dict) -> list[str]:
    """Upstream #775: a learned expert profile the user wired in by hand (--expert-profile <their file>,
    --expert-profile-save <file>) survives a setup run: setup writes the shipped profile, which a measured one of
    their own beats.  Their --expert-profile replaces the shipped one only when it is another file that still exists;
    --expert-profile-save is kept when the new config has none.  The names kept are returned."""
    oargs, nargs = old.get("args"), cfg.get("args")
    if not isinstance(oargs, list) or not isinstance(nargs, list):
        return []
    kept = []
    mine, shipped = flag_value(oargs, "--expert-profile"), flag_value(nargs, "--expert-profile")
    if mine and shipped and Path(mine).name != Path(shipped).name and Path(mine).is_file():
        nargs[nargs.index("--expert-profile") + 1] = mine
        kept.append("args --expert-profile")
    save = flag_value(oargs, "--expert-profile-save")
    if save and flag_value(nargs, "--expert-profile-save") is None:
        nargs += ["--expert-profile-save", save]
        kept.append("args --expert-profile-save")
    return kept


def args_dropped(old: dict, cfg: dict) -> list[str]:
    """The engine options of the earlier run config that the new one has no more (by flag name): options added by
    hand, which a setup run does not carry over - the start of the line that names them."""
    def flags(c):
        a = c.get("args") if isinstance(c.get("args"), list) else []
        return [str(x) for x in a if str(x).startswith("--")]
    new = set(flags(cfg))
    return list(dict.fromkeys(f for f in flags(old) if f not in new))


def write_setup_config(cfg_path: Path, cfg: dict, source: Path | None = None, gpus_chosen: bool = False) -> None:
    """Setup's run config, written over an earlier one for the same model without losing what the user added to it:
    the keys setup does not write are carried over (carry_over; `gpus_chosen`: this run chose its GPUs), and the
    earlier file is kept as xestrata-<model>.json.bak when it changes.  `source`: an earlier install's config to carry
    the keys over from when this folder has none yet (a copy set up like the last one).  A line says what was kept,
    one what was not."""
    old_path = cfg_path if cfg_path.is_file() else source
    old = None
    if old_path is not None and old_path.is_file():
        try:
            old = json.loads(old_path.read_text(encoding="utf-8-sig"))
        except (OSError, ValueError):
            pass
        if not isinstance(old, dict):
            old = None
    kept = carry_over(old, cfg, gpus_chosen) if old is not None else []
    bak = None
    if cfg_path.is_file() and old != cfg:
        bak = cfg_path.with_name(cfg_path.name + ".bak")
        try:
            copy_private(cfg_path, bak)
        except OSError as e:
            warn(f"could not keep a copy of the earlier {cfg_path.name} ({e.strerror or e})")
            bak = None
    write_config(cfg_path, cfg)
    if kept and old_path is not None:
        ok(f"kept from your earlier {old_path.name}: " + ", ".join(kept))
    if bak is not None:
        dropped = args_dropped(old, cfg) if old is not None else []
        say(f"  the earlier run config is kept as {bak.name}" + (
            f"; engine options it had that this one has not (setup chooses those): {' '.join(dropped)}"
            if dropped else ""))


def write_run_script(model, cfg_path, port, open_browser=True):
    """run-<model>.sh: the server with this config; `open_browser` False (--no-browser) leaves --open out."""
    serve = [sys.executable, str(ROOT / "serve" / "server.py"), "--engine", "strata", "--config", str(cfg_path),
             "--port", str(port)] + (["--open"] if open_browser else [])
    script = ROOT / f"run-{model.lower()}.sh"
    script.write_text("#!/bin/sh\ncd \"" + str(ROOT) + "\"\nexec " + " ".join(f'"{x}"' for x in serve) + "\n",
                      encoding="utf-8")
    script.chmod(0o755)
    return script


# ------------------------------------------------------------------------------------------------ main
def derived_factor(ctx: int, trained: int = 262144) -> float:
    """The automatic extension factor: the final context over the trained one, at least 1 (upstream 04949fe)."""
    return max(1.0, float(ctx) / float(trained))


def resolve_rope(ctx: int, scaling, scale, trained: int = 262144):
    """The rope configuration for the context actually served: (scaling, scale); scaling None = no flags.

    An explicit --rope-scaling / --rope-scale wins, a given factor verbatim.  Past the trained range an omitted method
    is yarn and an omitted factor final / trained; inside it nothing turns on by itself and a chosen method without a
    factor gets 1 (the trained angles).  An explicit none past the trained range is refused, not overridden.
    """
    if ctx <= trained:
        if scale is not None and scaling in (None, "none"):
            raise ValueError("--rope-scale needs --rope-scaling linear or yarn (the chosen context fits the "
                             "trained 262144, so there is nothing to scale)")
        if scaling in (None, "none"):
            return None, None
        return scaling, scale if scale is not None else derived_factor(ctx, trained)
    if scaling == "none":
        raise ValueError(f"a {ctx // 1024}K context is past the model's trained 262144, and --rope-scaling none "
                         "keeps the stock angles there - the model has never seen those positions, so setup "
                         "refuses the combination. Pick --rope-scaling yarn or linear, or rerun with --context "
                         "262144 or lower")
    return scaling or "yarn", scale if scale is not None else derived_factor(ctx, trained)


def prepare_engine(a, gpu: dict, vision: str) -> tuple[Path, Path, str, list]:
    """Steps 3 and 4: the Python packages, and the engine (the package's, or compiled here with the image encoders
    `vision` needs) -> (llama.cpp's folder, the engine's folder, the image encoder's kind, the engine's library
    folders)."""
    # ---- 3. python packages
    step(3, "Python packages")
    if PACKAGED:                                       # the distribution's, which the package depends on
        ok("the distribution's Python packages (installed with XeStrata's package)")
    else:
        pip_install(requirement_lines() if REQUIREMENTS.exists() else PY_PACKAGES,
                    "numpy, jinja2, regex, pyyaml, tqdm, requests, pillow, psutil")

    # ---- 4. the engine
    step(4, "the Strata engine")
    if PACKAGED:                                       # the package's: nothing is compiled
        llama = ROOT / "third_party" / "main" / "llama.cpp"   # gguf-py, for the tools below
        eng = packaged_engine_dir()
        meta = packaged_engine()
        enc = "vulkan"
        # the engine's SYCL runtime, and oneMKL's folder when it is installed (oneMath opens its backend at run time;
        # without it the engine takes its own kernels)
        lib_dirs = list(meta.get("lib_dirs", []))
        if meta.get("license") == "contrib" and (mkl := mkl_root()):
            lib_dirs.append(str(Path(mkl) / "lib"))
        if meta.get("license") == "contrib" and not WIN:
            lib_dirs += nvidia_lib_dirs(data_folder_path(a.data_dir, load_settings()))
        ok(f"engine: {eng / EXE} ({meta.get('package', 'package')})")
    else:
        llama = get_llama_cpp()
        ok(f"llama.cpp {LLAMA_CPP_COMMIT[:7]} (gguf-py, ggml, mtmd)")
        comp = choose_compiler(a, gpu)
        enc = "vulkan"
        data = data_folder_path(a.data_dir, load_settings())
        eng = build_engine({"none": [], "gpu": [enc, "cpu"], "cpu": ["cpu"]}[vision], llama, comp, data)
        # the runtime of the compiler the engine was built with (none for the distribution's), and pip's NVIDIA ones
        nvidia_libs = nvidia_lib_dirs(data) if comp["license"] == "contrib" else []
        lib_dirs = list(dict.fromkeys(comp["lib_dirs"] + nvidia_libs))
        ok(f"engine: {eng / EXE}")
    return llama, eng, enc, lib_dirs


def dsv41_context_limit(pack: Path) -> int | None:
    """The pack's positional limit, from Strata's dsv41_context.py and Project Maya's model metadata."""
    try:
        text = (pack / "ds4.txt").read_text(encoding="utf-8", errors="replace")
    except OSError:
        return None
    match = re.search(r"^max_position_embeddings\s+(\d+)\s*$", text, re.MULTILINE)
    value = int(match.group(1)) if match else 0
    return value if value >= 1024 else None


def dsv41_context_problem(context: int, limit: int | None = None) -> str:
    cap = min(limit or 1048576, 1048576)
    if context < 1024:
        return "DeepSeek context must be at least 1024 tokens."
    if context > cap:
        return f"DeepSeek context {context} exceeds the model's limit of {cap} tokens."
    return ""


def dsv41_exe(eng: Path) -> Path | None:
    """An explicitly selected local build, or the SYCL executable beside XeStrata's other engines."""
    own = (os.environ.get("STRATA_DSV41_EXE") or "").strip()
    exe = Path(own).expanduser() if own else eng / ("strata-dsv41.exe" if WIN else "strata-dsv41")
    return exe.resolve() if exe.is_file() else None


def build_dsv41_engine(llama: Path, comp: dict, data: Path) -> Path:
    """Build only the DeepSeek SYCL target with XeStrata's normal compiler and license selection."""
    eng = ROOT / "engine"
    eng.mkdir(exist_ok=True)
    name = "strata-dsv41.exe" if WIN else "strata-dsv41"
    stamp = eng / "BUILD-dsv41.json"
    try:
        meta = json.loads(stamp.read_text(encoding="utf-8"))
    except (OSError, ValueError):
        meta = {}
    fields = ("cxx", "version", "kind", "xmx", "license", "cuda_archs", "onemkl", "hip_archs")
    used: dict[str, Any] = {k: comp.get(k) for k in fields}
    extra = engine_cmake_args()
    used["cmake_args"] = extra
    src = source_hash(ENGINE_SOURCES)
    if engine_is_xe(meta) and meta.get("src") == src and meta.get("compiler") == used and (eng / name).is_file():
        return eng / name
    check_build_tools(comp)
    bdir = ROOT / "build" / ("contrib-llvm" if comp["license"] == "contrib" else "free")
    defs = [f"-DCMAKE_CXX_COMPILER={comp['cxx']}", f"-DCMAKE_C_COMPILER={comp['cc']}",
            f"-DSTRATA_LICENSE={comp['license']}", f"-DSTRATA_CUDA_ARCHS={'auto' if comp['cuda_archs'] else ''}",
            f"-DSTRATA_HIP_ARCHS={';'.join(comp.get('hip_archs', []))}",
            f"-DSTRATA_ONEMKL={'ON' if comp['onemkl'] else 'OFF'}",
            *([f"-DMKL_ROOT={mkl_root()}"] if comp["onemkl"] else []), "-DSTRATA_ENABLE_XE=ON",
            "-DSTRATA_NATIVE_EXPERTS=ON", "-DSTRATA_BUILD_TESTS=OFF", "-DSTRATA_PORTABLE=ON",
            f"-DSTRATA_GGML_DIR={llama}", *(f"-D{x}" for x in extra), "-DSTRATA_BUILD_DSV41=ON"]
    cmake_build(ROOT, bdir, "strata-dsv41", defs, comp["env"])
    install_binary(bdir / name, eng / name)
    record = {"source": "local", "backend": "xe", "version": source_version(),
              "compiler": used, "src": src, "lib_dirs": comp["lib_dirs"]}
    stamp.write_text(json.dumps(record, indent=1), encoding="utf-8")
    return eng / name


def prepare_dsv41_engine(a, gpu: dict) -> tuple[Path, list]:
    """Use XeStrata's package or local SYCL build; no upstream CUDA/HIP engine packages are fetched."""
    step(3, "Python packages")
    if not PACKAGED:
        pip_install(requirement_lines() if REQUIREMENTS.exists() else PY_PACKAGES,
                    "numpy, jinja2, regex, pyyaml, tqdm, requests, pillow, psutil")
    step(4, "the DeepSeek SYCL engine")
    eng = packaged_engine_dir() if PACKAGED else ROOT / "engine"
    exe = dsv41_exe(eng)
    if os.environ.get("STRATA_DSV41_EXE"):
        if exe is None:
            fail("STRATA_DSV41_EXE does not name an executable file", "point it at your strata-dsv41 SYCL build")
        return exe, []
    if PACKAGED:
        if exe is None:
            fail("this XeStrata package does not include the DeepSeek engine",
                 "use a XeStrata build with STRATA_BUILD_DSV41=ON, or set STRATA_DSV41_EXE to that executable")
        meta = packaged_engine()
        dirs = list(meta.get("lib_dirs", []))
        if meta.get("license") == "contrib" and (mkl := mkl_root()):
            dirs.append(str(Path(mkl) / "lib"))
        if meta.get("license") == "contrib" and not WIN:
            dirs += nvidia_lib_dirs(data_folder_path(a.data_dir, load_settings()))
        return exe, dirs
    comp = choose_compiler(a, gpu)
    data = data_folder_path(a.data_dir, load_settings())
    exe = build_dsv41_engine(get_llama_cpp(), comp, data)
    dirs = list(comp["lib_dirs"])
    if comp["license"] == "contrib":
        dirs += nvidia_lib_dirs(data)
    return exe, list(dict.fromkeys(dirs))


def dsv41_folder(a, fam: dict, tag: str, model: str = "UD-Q8_K_XL") -> Path:
    """The selected set, in --gguf-dir itself or its named subdirectory; otherwise its download folder."""
    if not a.gguf_dir:
        return Path(a.models_dir) / tag
    folder = Path(a.gguf_dir)
    md = fam["models"][model]
    names = [n for s in md["shards"] for n in (s, DSV41_LEGACY_NAMES.get(s)) if n]
    if any((folder / n).exists() for n in names):
        return folder
    return next((folder / sub for sub in (md.get("subdir"), md.get("legacy_subdir"), model)
                 if sub and (folder / sub).is_dir()), folder)


def dsv41_pick(folder: Path, name: str) -> Path:
    """Keep an already present legacy filename; these files have their own pinned hashes."""
    old = DSV41_LEGACY_NAMES.get(name)
    return folder / old if old and not (folder / name).exists() and (folder / old).is_file() else folder / name


def dsv41_shared_dir(a, fam: dict) -> Path:
    return Path(a.models_dir) / (fam["tag"] + "shared")


def dsv41_find_shared(a, name: str, folder: Path, shared: Path) -> Path:
    """Find a complete shared Engram, metadata shard or drafter without copying it."""
    names = [n for n in (name, DSV41_LEGACY_NAMES.get(name)) if n]
    roots = [shared, folder]
    if a.gguf_dir:
        base = Path(a.gguf_dir)
        roots += [base, base.parent, base.parent.parent]
    for root in dict.fromkeys(roots):
        try:
            children = [root] + ([d for d in root.iterdir() if d.is_dir()] if a.gguf_dir and root != shared else [])
        except OSError:
            continue
        for child in children:
            for n in names:
                f = child / n
                try:
                    if f.is_file() and f.stat().st_size == DSV41_ALL_FILES[n][0]:
                        return f
                except OSError:
                    pass
    return shared / name


def dsv41_pack_cmd(folder: Path, shards: list, engram: Path, meta: Path, dspark: Path, pack: Path) -> list:
    """The official IST-DAS recipe: explicit shards plus Engram metadata and DSpark's model constants."""
    return [sys.executable, str(ROOT / "tools" / "dsv41" / "pack_gguf.py"), "--model", str(folder),
            "--shards", *[Path(n).name for n in shards], "--engram", str(engram), "--engram-meta", str(meta),
            "--dspark-gguf", str(dspark), "--dspark-noise-token", "128799", "--dspark-markov-rank", "256",
            "--out", str(pack)]


def dsv41_pack_info(exe: Path, pack: Path, lib_dirs: list) -> tuple[bool, str]:
    """Inspect the pack's file references through the engine's host-only --pack-info mode."""
    env = dict(os.environ)
    key = "PATH" if WIN else "LD_LIBRARY_PATH"
    if lib_dirs:
        env[key] = os.pathsep.join([*map(str, lib_dirs), env.get(key, "")])
    try:
        result = subprocess.run([str(exe), "--pack-info", "--pack", str(pack)], capture_output=True, text=True,
                                encoding="utf-8", errors="replace", timeout=300, env=env)
    except (OSError, subprocess.TimeoutExpired) as exc:
        return False, str(exc)
    text = (result.stdout or "") + (result.stderr or "")
    return result.returncode == 0 and "MISSING" not in text and "all present" in text, text


def dsv41_config(exe: Path, pack: Path, fam: dict, context: int, gpu: dict, lib_dirs: list, port: int) -> dict:
    """The prototype's single GPU, text-only configuration; scheduling sizes stay with the engine."""
    args = ["--pack", str(pack), "--max-context", str(context), "--eos", "1",
            "--vision", "off", "--dspark", "auto", "--tp", "1", "--threads", "off"]
    cfg = {"exe": str(exe), "args": args,
           "cwd": str(STATE), "tokenizer": str(pack / "tokenizer"), "model_name": fam["name"],
           "arch": "deepseek41", "backend": "xe", "env": {}, "log": str(STATE / f"xestrata-{pack.name}.log"),
           "lib_dirs": lib_dirs, "port": port, "engine_ready_s": 3600}
    if gpu.get("pci"):
        cfg["gpu_pci"] = gpu["pci"]
    return cfg


def install_dsv41(a, family: str, gpu: dict, chosen: list, port: int, ram: float, adopted: Path | None) -> int:
    """Download pinned model files, prepare their map and tokenizer, and configure the local SYCL engine."""
    if len(chosen) != 1:
        fail("DeepSeek's SYCL prototype supports one GPU", "choose a single --gpu")
    fam = MULTI_FILE_FAMILIES[family]
    names = list(fam["models"])
    if a.model and a.model not in names:
        fail(f"{fam['title']} has no {a.model} model file", "choose: " + ", ".join(names))
    for i, m in enumerate(names, 1):
        say(f"  {i}) {m}: {fam['models'][m]['about']}")
    model = a.model or names[int(ask("Which size?", [str(i) for i in range(1, len(names) + 1)], "1", a.yes)) - 1]
    md = fam["models"][model]
    ctx = a.context or DSV41_CONTEXT
    if why := dsv41_context_problem(ctx):
        fail(why)
    if a.vision not in (None, "no", "none"):
        warn("DeepSeek's SYCL prototype reads text only: images are off")
    if a.parallel and a.parallel > 1:
        warn("DeepSeek's SYCL prototype serves one request at a time")
    if ram < md["ram_gb"]:
        warn("the model may read a large part of its experts from disk; the engine fits its cache to available memory")
    tag = fam["tag"] + model
    folder = dsv41_folder(a, fam, tag, model)
    shards = [dsv41_pick(folder, name) for name in md["shards"]]
    shared_dir = dsv41_shared_dir(a, fam)
    shared = [dsv41_find_shared(a, name, folder, shared_dir) for name in md["shared"]]
    own = {f: bool(a.gguf_dir) or f.parent != shared_dir for f in shared}
    left = 0
    for f in [*shards, *shared]:
        if f.is_file():
            continue
        part = f.with_name(f.name + ".part")
        left += max(0, fam["sha256"][f.name][0] - (part.stat().st_size if part.is_file() else 0))
    if left and free_gb(folder) * 1e9 < left:
        fail(f"not enough free disk space for {left / 1e9:.1f} GB of model files", "use --models-dir on a larger drive")
    exe, lib_dirs = prepare_dsv41_engine(a, gpu)

    step(5, f"downloading {fam['title']} {model}")
    for f in shards:
        if not f.is_file():
            if a.gguf_dir:
                fail(f"{f} is missing", "supply every shard in --gguf-dir")
            download((md.get("hf") or fam["hf"]) + f.name, f)
        pin = fam["sha256"][f.name]
        newer = DSV41_NEW_SHARD1.get(f.name)
        if newer and a.gguf_dir and f.stat().st_size == newer[0]:
            pin = newer
        verify_sha256(f, pin[0], pin[1], own=bool(a.gguf_dir) or f.name in DSV41_LEGACY_FILES)
    for f in shared:
        if not f.is_file():
            download(DSV41_SHARED[f.name] + f.name, f)
        pin = fam["sha256"][f.name]
        verify_sha256(f, pin[0], pin[1], own=own[f])

    step(6, "preparing the DeepSeek pack")
    data = data_folder_path(a.data_dir, load_settings())
    pack = data / "packs" / tag.lower()
    ready = (pack / "tokenizer" / "vocab.json").is_file() and (pack / "tensors.txt").is_file()
    if ready:
        ready, _ = dsv41_pack_info(exe, pack, lib_dirs)
    if not ready:
        if md["recipe"] == "ista":
            run(dsv41_pack_cmd(folder, [f.name for f in shards], shared[0], shared[1], shared[2], pack))
        else:
            run([sys.executable, str(ROOT / "tools" / "dsv41" / "pack_gguf.py"), "--model", str(folder),
                 "--shards", *[f.name for f in shards], "--out", str(pack)])
    if md.get("profile") and not (pack / "expert-profile.bin").exists():
        profile = DSV41_PROFILES / md["profile"]
        if profile.is_file():
            shutil.copyfile(profile, pack / "expert-profile.bin")
    good, why = dsv41_pack_info(exe, pack, lib_dirs)
    if not good:
        fail("the DeepSeek pack is incomplete: " + why[-600:], "check the model files and run setup again")
    if why := dsv41_context_problem(ctx, dsv41_context_limit(pack)):
        fail(why)

    step(7, "writing the model's settings")
    cfg = dsv41_config(exe, pack, fam, ctx, gpu, lib_dirs, port)
    for name in ("host", "api_key"):
        if getattr(a, name, None):
            cfg[name] = getattr(a, name)
    if a.browser is not None:
        cfg["open_browser"] = a.browser
    CONF.mkdir(parents=True, exist_ok=True)
    STATE.mkdir(parents=True, exist_ok=True)
    cfg_path = CONF / f"xestrata-{tag.lower()}.json"
    write_setup_config(cfg_path, cfg, adopted if adopted is not None and adopted.name == cfg_path.name else None, True)
    if not PACKAGED:
        write_run_script(tag, cfg_path, port, cfg.get("open_browser") is not False)
    ok(f"DeepSeek configuration: {cfg_path}")
    return 0 if a.no_start else start(cfg_path, port)


def setup_plain(a, family: str, fam: dict, gpu: dict, chosen: list, sel: list, found: list, gpu_chosen: bool,
                ram: float, roots: list, elsewhere: list, port: int, adopted: Path | None) -> int:
    """Steps 2-7 for a model of PLAIN_FAMILIES: its size and context, the engine, the GGUF file (size and SHA-256 at
    the pinned revision), its tokenizer and chat template written out, and the config: `strata --native` with no pack,
    PLE table or MTP layer.  Images, the layer split and the Qwen3.8-Flash-Next options (KV precision, low-RAM modes,
    the speed projection) do not apply; --gpus with several cards splits the layers across them (docs/MULTIGPU.md)."""
    models = fam["models"]
    names = list(models)
    if a.model and a.model not in names:
        fail(f"{fam['title']} has no {a.model} model file", "choose one of: " + ", ".join(names))
    # the experts the GPUs hold need no copy in RAM (every card of --gpus: the layer split)
    vram = sum(max(0.0, gpu_info(i).get("vram_gb", 0.0) - 5) for i in sel) if len(sel) > 1 \
        else max(0.0, gpu.get("vram_gb", 0.0) - 5)
    for i, m in enumerate(names, 1):
        d = models[m]
        gb = d["size"] / 1e9
        fit = "" if ram + vram >= gb + 8 else f"   <- {gb:.0f} GB of weights, this PC has {ram:.0f} GB of RAM"
        say(f"  {i}) {m:15s} {d['about']}; download {gb:.0f} GB" + ("" if d.get("tested") else "   [untested]") + fit)
    rec = next((str(i) for i, m in enumerate(names, 1) if models[m].get("tested")), "1")
    model = a.model or names[int(ask("Which size?", [str(i) for i in range(1, len(names) + 1)], rec, a.yes)) - 1]
    d = models[model]
    if not d.get("tested"):
        warn(f"{model} has not been run with this release (its tensor types are checked with the tested files)")
    if ram + vram < d["size"] / 1e9 + 8:
        warn(f"{model}'s {d['size'] / 1e9:.0f} GB of weights do not fit this PC's RAM and GPU with room to spare: "
             "the engine reads the experts neither holds from the model file through the OS file cache (slower)")
    ok(f"size: {model}")
    tag = fam["tag"] + model
    if a.vision not in (None, "no", "none"):
        warn(f"images are not available with {fam['title']} yet: off")
    # the context: up to the model's, recommended by the smallest card's memory as for Qwen3.8-Flash-Next
    contexts = [c for c in CONTEXTS if c <= fam["max_context"]]
    rec_ctx = vram_ctx(chosen)
    if a.context:
        ctx = a.context
        if ctx > fam["max_context"]:
            fail(f"{fam['title']} takes up to {fam['max_context']} tokens of context",
                 f"--context {fam['max_context']}")
    else:
        say()
        say("  Context length = how much text the model can see at once. Longer needs more VRAM for it, so fewer")
        say("  experts fit on the GPU:")
        for i, c in enumerate(contexts, 1):
            say(f"  {i}) {c // 1024}K tokens" + ("   (recommended for your GPU)" if c == rec_ctx else ""))
        ctx = contexts[int(ask("Context?", [str(i) for i in range(1, len(contexts) + 1)],
                               str(contexts.index(rec_ctx) + 1), a.yes)) - 1]
    ok(f"context: {ctx} tokens")
    parts = plain_parts(d)
    names_of = [Path(x["path"]).name for x in parts]   # side by side in one folder: the engine finds them by name
    models_dir = Path(a.gguf_dir) if a.gguf_dir else Path(a.models_dir) / tag

    def all_there(folder: Path) -> bool:
        return all((folder / n).exists() and (done(folder / n) or a.gguf_dir) for n in names_of)
    if not a.gguf_dir and not all_there(models_dir):
        for r in elsewhere:                            # already downloaded in a Strata folder on another drive
            if all_there(r / "models" / tag):
                models_dir = r / "models" / tag
                ok(f"model file found in {models_dir}")
                break
    gguf = models_dir / names_of[0]
    have = all_there(models_dir)
    left = 0 if have else d["size"] / 1e9
    if left and free_gb(models_dir) < left:
        fail(f"not enough free disk space in {models_dir}: need ~{left:.0f} GB, {free_gb(models_dir):.0f} GB free",
             "use --models-dir on a bigger drive")
    if left and free_gb(models_dir) < left + 1:
        warn(f"little free disk space in {models_dir}: {free_gb(models_dir):.1f} GB free for about {left:.1f} GB. "
             "Setup goes on and should fit")

    llama, eng, enc, lib_dirs = prepare_engine(a, gpu, "none")

    # ---- 5. the model file
    step(5, f"downloading {fam['title']} {model}")
    if not have:
        say(f"  The model file{'s go' if len(parts) > 1 else ' goes'} in {models_dir} (a copy you already have: put "
            f"it there with its name, {', '.join(names_of)}, or use --gguf-dir <its folder>)")
    for x, n in zip(parts, names_of):
        if not ((models_dir / n).exists() and (done(models_dir / n) or a.gguf_dir)):
            download(hf(d["repo"]) + x["path"], models_dir / n)
        verify_sha256(models_dir / n, x["size"], x["sha256"], own=bool(a.gguf_dir))
    more = f" and {len(parts) - 1} more beside it" if len(parts) > 1 else ""
    ok(f"model file present: {gguf}{more}")

    # ---- 6. the tokenizer and the chat template, for the server
    step(6, "preparing the model for Strata")
    tok_dir = (find_in(roots, f"tokenizers/{tag.lower()}") or roots[0] / "tokenizers" / tag.lower())
    if not (tok_dir / "tokenizer" / "vocab.json").exists():
        env = dict(os.environ, STRATA_GGUF_PY=str(llama / "gguf-py"))
        run([sys.executable, str(ROOT / "tools" / "strata_tokenizer.py"), "--gguf", str(gguf), "--out", str(tok_dir)],
            env=env)
    ok(f"tokenizer: {tok_dir / 'tokenizer'}")

    # ---- 7. the settings
    step(7, "writing the model's settings" if PACKAGED else "writing the start script")
    args = ["--native", str(gguf), "--max-context", str(ctx)]
    if fam.get("profile"):                             # the experts filled into VRAM at start, most routed first
        args += ["--expert-profile", str(ROOT / "data" / fam["profile"])]
    if fam.get("draft_vocab"):                         # the MTP layer's drafts over a token subset (--draft-vocab)
        args += ["--draft-vocab", str(ROOT / "data" / DRAFT_VOCABS.get(a.draft_vocab or "cjk", "draft_vocab.bin"))]
    if a.vram_reserve_mib is not None:
        args += ["--vram-reserve-mib", str(a.vram_reserve_mib)]
    cfg: dict[str, Any] = {"exe": str(eng / EXE), "args": args, "cwd": str(STATE),
                           "tokenizer": str(tok_dir / "tokenizer"), "model_name": f"{fam['name']}-{model.lower()}",
                           "log": str(STATE / f"xestrata-{tag.lower()}.log"), "lib_dirs": lib_dirs, "port": port}
    if gpu_chosen or sum(1 for x in found if gpu_problem(x) is None) > 1:
        cfg["gpu_pci"] = gpu["pci"]                    # the engine takes its GPU by PCI address (STRATA_GPU_PCI)
    if len(sel) > 1:                                   # --gpus: the layer split's other cards, as Qwen3.8-Flash-Next's
        cfg["gpu_pci"] = gpu["pci"]
        cfg["split_pci"] = [gpu_info(i)["pci"] for i in sel[1:]]
        if a.layer_split:
            cfg["layer_split"] = str(a.layer_split)
    if a.host:
        cfg["host"] = a.host
    if a.api_key:
        cfg["api_key"] = a.api_key
    if a.browser is not None:
        cfg["open_browser"] = a.browser
    if a.parallel is not None and a.parallel >= 2:
        warn("--parallel is not available for this model yet: one request at a time")
    return finish_setup(a, cfg, tag, port, adopted, False, tune=False)


def finish_setup(a, cfg: dict, tag: str, port: int, adopted: Path | None, images: bool, tune: bool = True,
                 notes: list[str] | tuple = ()) -> int:
    """The end of an install: the model's config written, its start script, the warm-up, what to do next, and the
    start.  `tune`: Qwen3.8-Flash-Next's engine options, where an earlier calibration's settings for this PC apply.
    `notes`: the model's own tips, printed with the CPU's."""
    cfg_path = CONF / f"xestrata-{tag.lower()}.json"
    CONF.mkdir(parents=True, exist_ok=True)
    STATE.mkdir(parents=True, exist_ok=True)
    cal = saved_calibration(cfg) if tune else None
    if cal is not None:
        sys.path.insert(0, str(ROOT / "tools"))
        import calibrate as CAL
        cfg["args"] = CAL.apply(cfg["args"], cal.get("settings") or {})
        ok("the settings tuned for this PC earlier are used" + (f" ({cal['date']})" if cal.get("date") else ""))
    else:                                              # upstream #642: a calibration's measured count wins
        cfg["args"] = recommend_pool_workers(cfg["args"])
        for line in two_socket_note(linux_sockets()):  # tips: text only, the config is not touched
            say("  " + line)
    for line in notes:
        say("  " + line)
    share = saved_prefill_share(cfg)                   # measured once per PC and model: the warm-up then keeps it
    if share is not None and "--prefill-cpu-share" not in cfg["args"]:
        cfg["args"] = [*cfg["args"], "--prefill-cpu-share", share]
    free = saved_vram_free(cfg)                        # the same for the free VRAM the cache is sized from
    if free is not None and "--vram-free-mib" not in cfg["args"]:
        cfg["args"] = [*cfg["args"], "--vram-free-mib", free]
    write_setup_config(cfg_path, cfg, adopted if adopted is not None and adopted.name == cfg_path.name else None,
                       getattr(a, "gpus_chosen", False))
    script = None if PACKAGED else write_run_script(tag, cfg_path, port, cfg.get("open_browser") is not False)
    if not a.no_warmup:
        warm_up(cfg_path)
    # no tuning is offered here: the engine and setup fit these settings by themselves (--calibrate still measures them)
    if script is not None:
        ok(f"start script: {script.name}")

    say()
    say("All set.")
    say(f"  API (OpenAI):     http://127.0.0.1:{port}/v1   (any API key; model name: anything)")
    say(f"  API (Anthropic):  http://127.0.0.1:{port}/v1/messages")
    if a.host and a.host not in ("127.0.0.1", "localhost"):
        say(f"  Other devices:    the server window prints this PC's address (http://<IP>:{port}/)"
            + ("" if a.api_key else " - no API key set: anyone on your network can use it"))
    say(f"  Next time:        just run {SETUP_CMD}" + (f" (or {script.name})" if script else "") +
        " - it starts right away")
    if images:
        say("  Images:           send them in the chat page, in chat.py (/image <path>) or over the API")
    if a.no_start:
        return 0
    return start(cfg_path, port)


def vram_ctx(cards: list) -> int:
    """The context the GPUs' memory recommends: each card keeps its layers' KV of the whole context, so the smallest
    decides; an AMD APU, in the memory it can use in all."""
    small = min(x.get("uma_gb", x["vram_gb"]) for x in cards)
    return 32768 if small < 14 else 65536 if small < 20 else 131072


def describe() -> dict:
    """What a front end (the Windows launcher) shows before it asks anything, as one object: this PC (RAM, CPU, the
    GPUs and why one cannot be used, the one setup takes by default), every model family and size with the RAM it
    needs, whether it fits and which is recommended (the rules the questions of step 2 use, for that GPU), the data
    folder and the installed models.  It reports only: nothing is made, moved or saved.  The front end passes its
    choices back as --family, --model, --context, --gpu and --data-dir."""
    ram = ram_gb()
    found = gpus()
    # the card choose_gpus takes without --gpu: the supported one with the most VRAM
    usable = sorted([g for g in found if gpu_problem(g) is None], key=lambda x: (-round(x["vram_gb"]), x["index"]))
    gpu = usable[0] if usable else None
    vram = gpu_expert_vram(gpu) if gpu else 0.0
    by_vram = vram_ctx([gpu]) if gpu else 32768
    families = []
    for f, fam in FAMILIES.items():
        models = []
        if fam.get("multi_file"):
            for m, d in fam["models"].items():
                gb = sum(fam["sha256"][name][0] for name in [*d["shards"], *d["shared"]]) / 1e9
                models.append({"id": m, "about": d["about"], "download_gb": round(gb, 1), "ram_gb": d["ram_gb"],
                               "fits": "unknown", "tested": False, "experimental": True,
                               "recommended": m == next(iter(fam["models"])), "context": DSV41_CONTEXT})
            max_ctx = fam["max_context"]
        elif fam.get("plain"):
            names = list(fam["models"])
            rec = next((m for m in names if fam["models"][m].get("tested")), names[0])
            for m in names:
                d = fam["models"][m]
                gb = d["size"] / 1e9
                models.append({"id": m, "about": d["about"], "download_gb": round(gb, 1), "ram_gb": round(gb + 8),
                               "fits": "yes" if ram + vram >= gb + 8 else "slow", "tested": bool(d.get("tested")),
                               "experimental": False, "recommended": m == rec,
                               "context": min(by_vram, fam["max_context"])})
            max_ctx = fam["max_context"]
        else:
            names = sorted((m for m in MODELS if f in MODELS[m].get("families", ("qwen", "swift"))),
                           key=lambda m: bool(MODELS[m].get("experimental")))
            rec = names[names.index("IQ3_XXS")] if ram >= 60 and "IQ3_XXS" in names else names[0]
            for m in names:
                d = MODELS[m]
                low = not d.get("budget") and low_ram_needed(m, ram) and low_ram_fits(m, ram, vram)
                fits = ("budget" if d.get("budget") else "yes" if ram >= d["ram_gb"] else "low-ram" if low else
                        "no")
                models.append({"id": m, "about": d["about"], "download_gb": d["download_gb"], "ram_gb": d["ram_gb"],
                               "fits": fits, "tested": True, "experimental": bool(d.get("experimental")),
                               "recommended": m == rec, "context": min(by_vram, ram_ctx(m, ram, low))})
            max_ctx = CONTEXTS[-1]
        families.append({"id": f, "title": fam["title"], "by": fam["by"], "about": fam["about"],
                         "license": fam.get("license"), "experimental": bool(fam.get("experimental")),
                         "contexts": [c for c in CONTEXTS if c <= max_ctx], "models": models})
    installed = []
    for c in installed_configs():
        ch = choices_from_config(c)
        cfg = json.loads(c.read_text(encoding="utf-8-sig"))
        installed.append({"config": str(c), "model_name": cfg.get("model_name", c.stem), "family": ch["family"],
                          "model": ch["model"], "context": ch["context"], "port": ch["port"] or 8095})
    return {"type": "describe", "version": source_version(), "packaged": bool(PACKAGED),
            "ram_gb": round(ram, 1), "cpu": dict(zip(("name", "avx2", "avx512"), cpu_info())),
            "gpu": gpu["index"] if gpu else None,
            "gpus": [{"index": g["index"], "name": g["name"], "vendor": g.get("vendor"),
                      "vram_gb": round(g["vram_gb"], 1), "integrated": bool(g.get("integrated")), "pci": g.get("pci"),
                      "problem": gpu_problem(g)} for g in found],
            "data_dir": str(data_folder_path(None, load_settings())), "families": families, "installed": installed}


def main() -> int:
    if wsl_version() == 1:
        fail("Strata does not run on WSL 1 (it has no GPU access)", "use WSL 2, or a native Linux installation")
    if wsl_version() == 2:
        warn("WSL 2 has not been tested: XeStrata may work there, or not. If you get it working (or fix what stops "
             "it), a pull request is welcome")
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--family", choices=list(FAMILIES),
                    help="qwen = Qwen3.8-Flash-Next, swift = Swift 1.5, deepseek41 = DeepSeek-V4.1-Flash (text only)")
    plain_models = [m for f in PLAIN_FAMILIES.values() for m in f["models"]]
    multi_models = [m for f in MULTI_FILE_FAMILIES.values() for m in f["models"]]
    ap.add_argument("--model", choices=list(dict.fromkeys([*MODELS, *plain_models, *multi_models])))
    ap.add_argument("--context", type=int)
    ap.add_argument("--rope-scaling", choices=["none", "linear", "yarn"],
                    help="the RoPE extension for a context past the model's trained 262144: linear (position "
                         "interpolation) or yarn, llama.cpp's types. Omitted with such a context, setup takes yarn; "
                         "none is refused there")
    ap.add_argument("--rope-scale", type=float,
                    help="the extension factor (default: the final context over the trained 262144, at least 1: "
                         "1.5 for 384K, 2 for 512K, 1 inside the trained range)")
    ap.add_argument("--kv", choices=["int8", "q4_0", "k8v4"],
                    help="KV cache precision above 8K context: int8 (default), q4_0 (half the memory, a little less "
                         "precise) or k8v4 (8-bit keys and 4-bit values: about three quarters of the memory)")
    ap.add_argument("--vision", choices=["yes", "no", "none", "gpu", "cpu"],
                    help="let the model read images (on by default where the model can; yes = the reader for this "
                         "card: the CPU under 24 GB of VRAM, the GPU from 24 GB; gpu = the encoder on the GPU, the CPU "
                         "encoder taking over when it cannot start; cpu = on the CPU only; no = text only)")
    ap.add_argument("--vision-tokens", type=int, metavar="N",
                    help="the most image tokens a picture becomes (default 1024 with the encoder on the GPU, 300 on "
                         "the CPU): more reads small text and charts better, and takes longer to encode; remembered "
                         "for this model")
    ap.add_argument("--images", metavar="qwen-image-turbo|qwen-image-base|mage-flow-turbo|mage-flow|"
                    "mage-flow-base[-uncensored]|no",
                    help="image generation (POST /v1/images/generations) on XeStrata's image engine: "
                         "qwen-image-turbo (Qwen-Image-2.1-Turbo, 8 steps) or qwen-image-base (its base model "
                         "Qwen-Image-2.1, 40 steps by default, about 5 times as long an image); the text encoder "
                         "Unsloth's Qwen3-VL-8B or, -uncensored, AtomicChat's with its refusal direction removed "
                         "(either Q8_0, lowered first (Q6_K, Q5_K, Q4_K) when the files would not fit the RAM the "
                         "text model leaves); mage-flow-turbo (Mage-Flow-Turbo, 4 steps), mage-flow (20 steps, "
                         "guidance 5) or mage-flow-base (30 steps, guidance 5), the text encoder Unsloth's "
                         "Qwen3-VL-4B or, -uncensored, huihui-ai's abliterated one; no = take it out of the config")
    ap.add_argument("--image-quant", choices=["Q4_K_M", "Q6_K", "Q8_0"],
                    help="the image model's size (default Q8_0, lowered when its files would not fit the RAM the "
                         "text model leaves, after its text encoder; the GPU's memory does not decide it)")
    ap.add_argument("--image-dit-q8", choices=["auto", "on", "off"],
                    help="Mage-Flow: auto (default) keeps its image model in VRAM as 16-bit when it fits there "
                         "with the text encoder (nearer the reference) and quantizes it to 8 bits when it does not "
                         "(half the VRAM and the bytes streamed; int8 products where the GPU's math library has "
                         "them, else Q8_0); on always 8 bits, off always 16-bit")
    ap.add_argument("--image-dit-keep", choices=["on", "off"],
                    help="Mage-Flow: on (default) keeps the image model not in use (the generation's or the edit's) in "
                         "RAM as Q8_0, so switching is quick; off lets it go (about 4.4 GB less RAM) and reads it from "
                         "the file again at each switch")
    ap.add_argument("--image-ssd-offload", choices=["on", "off"],
                    help="on: keep the image model's and its text encoder's sizes even when the RAM is short, and "
                         "read what does not fit from the SSD (slower); off (default): smaller sizes instead")
    ap.add_argument("--image-gpu-policy", choices=["auto", "keep", "shrink", "unload"],
                    help="what the text model does during an image job (default auto: stays loaded when both fit, "
                         "else gives VRAM back or is unloaded and its conversation restored afterwards)")
    ap.add_argument("--experimental-speed-projection", metavar="on|off|GGUF",
                    help="EXPERIMENTAL, off by default: the control vector in "
                         "third_party/nonfree/experimental-speed-projection "
                         "(or another GGUF) as a projection on layers 4-44; see docs/DETAILS.md")
    ap.add_argument("--port", type=int,
                    help="the server's port (default: the one the install was set up with, 8095 for a new one)")
    ap.add_argument("--gpu", help="the GPU, numbered in PCI order as --check lists them (default: the one with "
                                  "the most VRAM); the engine takes it by PCI address")
    ap.add_argument("--gpus", help="a layer split across these GPUs, e.g. 0,1 (numbered as --check lists them; the "
                                   "first runs the early layers; docs/MULTIGPU.md); saved for the model")
    ap.add_argument("--layer-split", help="with --gpus: the first layer of each later GPU's share (e.g. 36, or 16,32 "
                                          "for 3 GPUs), one rising number per GPU after the first - not layers per "
                                          "card; or auto (the default: measured on this PC)")
    ap.add_argument("--host", help="where the server listens: 127.0.0.1 = this PC only (default), 0.0.0.0 = also other "
                                   "devices on your network (issue #26; set --api-key too)")
    ap.add_argument("--no-browser", dest="browser", action="store_false", default=None,
                    help="do not open the chat page in the browser when the model is ready (for a harness or an app "
                         "that uses the API; remembered for this model, also in run-<model>.sh)")
    ap.add_argument("--browser", dest="browser", action="store_true",
                    help="open the chat page again when the model is ready (the default; undoes --no-browser)")
    ap.add_argument("--api-key", help="require this key from clients (recommended with --host 0.0.0.0); several "
                                      "keys: key1,key2")
    ap.add_argument("--data-dir", help="where the model files go (~70-120 GB): default XeStrata-data next to this "
                                       "folder, remembered for every Strata folder on this PC")
    ap.add_argument("--move-data", action="store_true",
                    help="with --data-dir: move the model files already on this PC into the new folder (without it "
                         "nothing is moved: the old files stay usable and the new folder gets the new downloads)")
    ap.add_argument("--set-default-data-dir", action="store_true",
                    help="with --data-dir: remember the new folder as the data folder without moving anything")
    ap.add_argument("--models-dir", help="where the GGUF files go (default: <data folder>/models)")
    ap.add_argument("--gguf-dir", help="use GGUF files you already have (a folder with every shard: "
                                       "<name>-00001-of-0000N.gguf ... -0000N-of-0000N.gguf)")
    ap.add_argument("--inspect", nargs="+", metavar=("SOURCE", "VARIANT"),
                    help="what a GGUF is and whether XeStrata runs it, from its headers only (no download): a file, a "
                         "folder, a URL, ms:owner/repo (ModelScope) or hf:owner/repo, and optionally a variant name")
    ap.add_argument("--source", choices=SOURCES, default=None,
                    help="where the model files come from: auto (default: Hugging Face), huggingface or modelscope "
                         "(mainland China: the same files, checked against ModelScope's published SHA-256; "
                         "STRATA_SOURCE)")
    ap.add_argument("--license", choices=[*LICENSES, "contrib-icpx"],
                    help="the build mode: free builds with free software only, for Intel and AMD GPUs; contrib (the "
                         "default) builds with intel/llvm's CUDA target for Intel, AMD and NVIDIA GPUs, and hands the "
                         "dense matrix products to oneMKL, cuBLAS and rocBLAS. Kept for later runs (contrib-icpx was "
                         "removed: it stops with a pointer to contrib)")
    ap.add_argument("--intel-llvm", metavar="DIR",
                    help="build the engine with the intel/llvm installed in DIR (bin/clang++); kept for later runs")
    ap.add_argument("--cmake-arg", action="append", metavar="KEY=VALUE",
                    help="a CMake option for the engine's build (-DKEY=VALUE; e.g. STRATA_ROCM_DEVICE_LIBS=DIR), once "
                         "for each; kept for later builds, --cmake-arg \"\" clears them")
    ap.add_argument("--intel-llvm-build", action="store_true",
                    help="build intel/llvm from source into .tools/intel-llvm and use it (13 minutes on 28 threads, "
                         "3.5 GB); a finished build is used again, an interrupted one continued")
    ap.add_argument("--intel-llvm-rebuild", action="store_true", help="with --intel-llvm-build: build it again")
    ap.add_argument("--intel-llvm-keep-build", action="store_true",
                    help="with --intel-llvm-build: keep its build tree so the next update is quicker")
    ap.add_argument("--allow-no-xmx", action="store_true",
                    help="build even when the compiler gives the GPU no XMX (prompt processing about 1.6 times slower)")
    ap.add_argument("--low-ram", choices=["auto", "on", "off", "resident", "mmap"], default="auto",
                    help="read the model's experts from its files instead of copying them all into RAM (for a PC with "
                         "a big GPU and little RAM); auto: when the experts would not fit the RAM. In this mode the "
                         "experts the GPU does not hold are copied into RAM once when they fit (resident), else read "
                         "through the OS file cache (mmap); resident / mmap force one of the two")
    ap.add_argument("--resident-budget-gib", type=float, metavar="N",
                    help="UD-Q4_K_XL, UD-IQ4_XS: the GiB of its experts kept in RAM (default: the RAM less 24 GB, "
                         "~38 on 64 GB; more is kept as you choose, with a note)")
    ap.add_argument("--vram-reserve-mib", type=int, metavar="N",
                    help="VRAM in MiB the engine leaves free for other programs (a game, another model; the engine's "
                         "default: 700); the expert cache takes that much less")
    ap.add_argument("--parallel", type=int, metavar="N",
                    help="up to N requests decode together (batch slots, opt-in; default: one at a time, the others "
                         "wait). Each slot takes VRAM from the expert cache; setup says what it recommends")
    ap.add_argument("--replicas", type=int, metavar="N",
                    help="several GPUs (--gpus): run N independent engines, each on its own equal group of the chosen "
                         "cards (2 replicas on 4 cards = two 2-card engines), requests spread over them (opt-in; more "
                         "total throughput for a model that fits fewer cards; each replica holds its own copy of the "
                         "model in RAM and VRAM)")
    ap.add_argument("--yes", action="store_true", help="accept the recommended answers")
    ap.add_argument("--json", action="store_true",
                    help="one JSON object a line for a front end (the Windows launcher): messages, steps, progress and "
                         "questions, whose answers are read as lines on stdin")
    ap.add_argument("--describe", action="store_true",
                    help="print this PC, the model families and sizes (with the RAM they need and the recommended "
                         "ones), the data folder and the installed models as one JSON object, and exit (the Windows "
                         "launcher's first screen)")
    ap.add_argument("--setup", action="store_true", help="install another model or change settings")
    ap.add_argument("--no-start", action="store_true", help="install only, do not start the model")
    ap.add_argument("--old-driver", action="store_true",
                    help="start although the Level Zero driver predates the fix setup stops on (see its message)")
    ap.add_argument("--update", action="store_true",
                    help="update the engine, Python packages and model settings as a start would, without starting "
                         "the model (update.sh runs it after a git pull)")
    ap.add_argument("--no-warmup", action="store_true",
                    help="skip starting the model once at the end of setup to compile its GPU code (the first "
                         "request then compiles it: ~30 s more)")
    ap.add_argument("--build", action="store_true", help=argparse.SUPPRESS)   # the engine is always compiled here
    ap.add_argument("--check", action="store_true", help="only check this PC and exit")
    ap.add_argument("--check-update", action="store_true",
                    help="ask GitHub whether a newer XeStrata release is out and exit (the server also asks at the "
                         "start and every six hours; XESTRATA_UPDATE_CHECK=0 turns that off)")
    ap.add_argument("--packages", nargs="?", const="", metavar="DISTRO/MAKERS",
                    help="print the command that installs the distribution packages building from the source needs, "
                         "for the build mode (--license) and DISTRO/MAKERS, e.g. ubuntu26.04/intel,amd or "
                         "fedora44/nvidia (default: this PC's distribution and GPUs), and exit; with XeStrata's deb or "
                         "rpm, the GPU makers' packages this PC's GPUs lack")
    ap.add_argument("--remove-data", action="store_true",
                    help="delete the model files, settings and logs XeStrata keeps for you (asks first; removing the "
                         "program with apt or dnf leaves them)")
    ap.add_argument("--draft-vocab", choices=list(DRAFT_VOCABS),
                    help="the draft layer's tokens: cjk = with Chinese, Japanese and Korean (default), en = English "
                         "and code only (~110 MiB less VRAM), cyrillic = English, code and the Cyrillic script, fr = "
                         "English, code and French (French answers draft more)")
    ap.add_argument("--calibrate", action="store_true",
                    help="tune the engine's settings for this PC (about 15-30 minutes, longer on a slow card), "
                         "then start the model; usually not needed, the engine and setup fit them by themselves "
                         "(it asks first; --yes skips the question)")
    ap.add_argument("--bench", action="store_true",
                    help="measure the speed of the installed IQ3_XXS (another installed model: --model, --family) on "
                         "this PC (about 40 minutes) and write a record for the developers to the data folder's "
                         "records/; the model is not started")
    ap.add_argument("--bench-verbose", action="store_true",
                    help="--bench, and where the time goes in more detail: the engine's per-stage timings, its "
                         "kernels one by one, the GPU's load and temperature, a fingerprint of the answers")
    ap.add_argument("--original-strata", metavar="TAG",
                    help="with --bench or --bench-verbose: also measure upstream Strata's release TAG (e.g. v0.1.41, "
                         "fetched with git) on the same model files, the two engines taking turns")
    ap.add_argument("--bench-rounds", type=int, default=2, metavar="N",
                    help="with --bench or --bench-verbose: measure each case N times (default 2, about 20 minutes "
                         "each); more rounds, steadier medians")
    ap.add_argument("--bench-temperature", type=float, default=0.7, metavar="T",
                    help="with --bench or --bench-verbose: the temperature of the sampled runs (default 0.7, as Qwen "
                         "recommends; 0 to 2 in steps of 0.1, 0 = greedy only)")
    ap.add_argument("--bench-original-compat", nargs=argparse.REMAINDER, metavar="ARGS",
                    help="measure the installed model the way upstream Strata's benchmark mode (tools/strata_bench.py) "
                         "does, through the server's HTTP API (about 3-10 minutes), and write a report in its "
                         "community format to the data folder's records/; ARGS after it go to that tool (--long, "
                         "--clients N, --compare DIR). --bench is XeStrata's own measurement")
    ap.add_argument("--skip-build", action="store_true", help=argparse.SUPPRESS)
    ap.add_argument("--image-text-encoder", help=argparse.SUPPRESS)   # removed: --images names the encoder
    a = ap.parse_args()
    # A Windows source checkout can use an explicitly supplied DeepSeek SYCL prototype executable.
    local_dsv41 = WIN and a.family == "deepseek41" and bool(os.environ.get("STRATA_DSV41_EXE"))
    if sys.platform != "linux" and not (WIN and PACKAGED) and not local_dsv41:
        fail("XeStrata runs on Linux, and on Windows from its 7z" if WIN else "XeStrata runs on Linux and Windows")
    if a.license == "contrib-icpx":
        fail("--license contrib-icpx: the contrib-icpx mode (Intel oneAPI's icpx) was removed",
             "use --license contrib (contrib-llvm: intel/llvm, for Intel, AMD and NVIDIA GPUs), or --license free")
    images = ("no", *_qimage().IMAGE_MODELS)
    if a.image_text_encoder is not None or (a.images is not None and a.images not in images):
        fail(f"--images {a.images}: no such choice" if a.image_text_encoder is None
             else "--image-text-encoder was removed: --images names the text encoder",
             "use --images " + "|".join(images) + " (qwen-image is qwen-image-turbo, --image-text-encoder "
             "uncensored is qwen-image-turbo-uncensored)")
    if a.source:
        os.environ["STRATA_SOURCE"] = a.source
    if a.inspect:                                      # upstream #911: headers only, nothing is installed
        sys.exit(subprocess.run([sys.executable, str(ROOT / "tools" / "strata_inspect.py"), *a.inspect[:2]]).returncode)
    global ARGS
    ARGS = a
    if a.vision_tokens is not None and a.vision_tokens < 1:
        ap.error("--vision-tokens takes a number of image tokens, 1 or more, e.g. --vision-tokens 768")
    if any(x and "=" not in x for x in a.cmake_arg or []):
        ap.error("--cmake-arg takes KEY=VALUE, e.g. --cmake-arg STRATA_ROCM_DEVICE_LIBS=/opt/rocm-7.1.1/amdgcn/bitcode")
    if a.vram_reserve_mib is not None and a.vram_reserve_mib < 0:
        ap.error("--vram-reserve-mib takes a number of MiB, 0 or more, e.g. --vram-reserve-mib 2048")
    if a.bench_original_compat is not None and (a.bench or a.bench_verbose or a.original_strata):
        ap.error("--bench-original-compat is a measurement of its own: give it without --bench, --bench-verbose and "
                 "--original-strata")
    if a.original_strata and not (a.bench or a.bench_verbose):
        ap.error("--original-strata TAG goes with --bench or --bench-verbose, e.g. --bench --original-strata v0.1.41")
    if not 0 <= a.bench_temperature <= 2 or abs(a.bench_temperature * 10 - round(a.bench_temperature * 10)) > 1e-6:
        ap.error("--bench-temperature takes 0 to 2 in steps of 0.1, e.g. --bench-temperature 1.0")
    if a.bench_rounds < 1:
        ap.error("--bench-rounds takes a number of rounds, 1 or more, e.g. --bench-rounds 3")
    if a.gpu is not None:                              # --gpu 0,2 means --gpus 0,2 (a user tried it: issue report)
        if "," in a.gpu:
            a.gpus, a.gpu = a.gpus or a.gpu, None
        elif a.gpu.strip().isdigit():
            a.gpu = int(a.gpu)
        else:
            ap.error(f"--gpu takes a GPU number as --check lists them, e.g. --gpu 0, not {a.gpu!r}")
    if a.packages is not None:
        return print_packages(a.packages, a.license or "contrib")
    if a.remove_data:
        return remove_data()
    if a.check_update:
        return check_update()
    if a.describe:
        emit(describe())
        return 0
    say("Strata - Qwen3.8-Flash-Next on a normal PC (a GPU + system RAM + CPU)")
    # --check only reports (a user ran it to look, on a work machine): nothing made, moved or saved.  Given with what
    # acts before it (a measurement, an update), the data folder is prepared as for those
    if a.check and not (a.bench or a.bench_verbose or a.bench_original_compat is not None or a.update):
        data, elsewhere = data_folder_path(a.data_dir, load_settings()), []
    else:
        data, elsewhere = data_folder(a.data_dir, a.move_data, a.yes, a.set_default_data_dir)   # found from any copy
    roots = [data, *elsewhere]
    if a.models_dir is None:
        a.models_dir = str(data / "models")

    # ---- 0. already installed: just start it
    have = installed_configs()
    if a.update:                                       # #475: update.sh - never starts the model
        return update_install(have)
    explicit = a.setup or a.model or a.family or a.check or a.no_start
    adopted = None                                     # the earlier install this copy is set up like
    if not have and not explicit:                      # a new copy of Strata (an update unzipped elsewhere): set it
        prev = previous_config(elsewhere, load_settings())   # up like the last one, from the files already here
        if prev is not None:
            ch = choices_from_config(prev)
            if ch["model"]:
                say(f"  Found your earlier install in {prev.parent} ({prev.stem[len('strata-'):]}): setting up this "
                    "copy the same way - the model files are reused, nothing big is downloaded.")
                a.family, a.model, a.context = ch["family"], ch["model"], a.context or ch["context"]
                adopted = prev
                a.kv = a.kv or ch["kv"]
                a.vision = a.vision or ch["vision"]
                a.experimental_speed_projection = a.experimental_speed_projection or ch["esp"]
                a.host, a.api_key = a.host or ch["host"], a.api_key or ch["api_key"]
                a.port = a.port or ch["port"]
                if a.vram_reserve_mib is None:          # #493: an explicit reserve set up before
                    a.vram_reserve_mib = ch.get("vram_reserve_mib")
                by_pci = {x["pci"]: x["index"] for x in gpus()}
                if ch.get("split_pci") and all(pci in by_pci for pci in ch["split_pci"]):
                    # a layer split: set up across the same cards again
                    a.gpus = a.gpus or ",".join(str(by_pci[pci]) for pci in ch["split_pci"])
                    a.layer_split = a.layer_split or ch.get("layer_split")
                else:
                    a.gpu = a.gpu if a.gpu is not None else ch.get("gpu")
                a.yes = True
    global GPU_PICK
    # starting an installed model: --gpus 0,2 (or all) saves those cards for it and starts on them (it used to start
    # on the first one alone unless given with --setup), --gpu N runs this start on one card; neither: the saved
    # choice, and asked once when the PC has cards that could share the model
    run_gpu = (parse_gpus(a.gpus, gpus()) if a.gpus else None) or a.gpu
    port = a.port or 8095                              # a new install's port (issue #32: --port for an existing one)
    if a.bench_original_compat is not None:
        # upstream's benchmark mode (dfaebd9d), as it is: the newest installed model (--model and --family pick
        # another), the server started with its config and stopped after
        if not have:
            fail("no model is installed yet", "run setup first, then --bench-original-compat")
        cfgs = [c for c in have if (not a.model or choices_from_config(c)["model"] == a.model) and
                (not a.family or choices_from_config(c)["family"] == a.family)]
        if not cfgs:
            fail("that model is not installed", "leave out --model and --family to measure the newest one")
        update_installed_engine()
        return subprocess.call([sys.executable, str(ROOT / "tools" / "strata_bench.py"), "--config", str(cfgs[0]),
                                "--out", str(data / "records"), *a.bench_original_compat])
    if a.bench or a.bench_verbose:
        if not have:
            fail("no model is installed yet", "run setup without --bench first, then --bench")
        # the model the release table and the upstream merges measure, so a record compares with theirs; --model and
        # --family pick another installed one (a PC with less RAM)
        family, model = a.family or "qwen", a.model or "IQ3_XXS"
        bench_cfgs = [c for c in have if (ch := choices_from_config(c))["family"] == family and ch["model"] == model]
        if not bench_cfgs:
            installed = "; ".join(f"xestrata --bench --model {ch['model']}" +
                                  (f" --family {ch['family']}" if ch["family"] != "qwen" else "")
                                  for c in have if (ch := choices_from_config(c))["model"])
            fail(f"{FAMILIES[family]['title']} {model} is not installed",
                 f"measure an installed model: {installed}" if installed else
                 f"install it first: xestrata --setup --model {model}")
        update_installed_engine()
        return bench_config(bench_cfgs[0], data, a.bench_verbose, a.original_strata, a.bench_rounds,
                            round(a.bench_temperature, 1))
    if a.calibrate and (a.setup or a.check or not have):    # upstream #2036: said, not dropped
        why = "--setup" if a.setup else "--check" if a.check else "no model is installed yet"
        warn(f"--calibrate does nothing with {why}: it tunes a model that is already installed. Run "
             "xestrata --setup first, then xestrata --calibrate [--model NAME]")
    if have and a.calibrate and not (a.setup or a.check):
        targets = calibration_targets(have, a.model, a.family)
        if not targets:                                # upstream #2036: --model names a model that is not installed
            installed = ", ".join(sorted({choices_from_config(c)["model"] or c.stem for c in have}))
            fail(f"--calibrate: {a.model or a.family} is not installed (installed: {installed})",
                 "calibrate an installed model, or set this one up first without --calibrate")
        have = targets
        # --yes with --calibrate asks for it outright; otherwise the person confirms, since it is rarely worth the time
        if not a.yes and ask(f"{CALIBRATE_NOT_NEEDED} Measure anyway? (about 15-30 minutes, longer on a slow card; "
                             "the PC is busy meanwhile)", ["y", "n"], "n", a.yes) != "y":
            ok("not tuned: the settings the engine and setup pick stay")
            if a.no_start:
                return 0
            run_cfg = have[0]
            if len(have) > 1:
                say()
                for i, c in enumerate(have, 1):
                    say(f"  {i}) {json.loads(c.read_text(encoding='utf-8-sig')).get('model_name', c.stem)}")
                run_cfg = have[int(ask("Start which one?", [str(i) for i in range(1, len(have) + 1)], "1",
                                       a.yes)) - 1]
            return start(run_cfg, a.port, run_gpu, yes=a.yes, layer_split=a.layer_split,
                         keep={"host": a.host, "api_key": a.api_key, "draft_vocab": a.draft_vocab,
                               "vram_reserve_mib": a.vram_reserve_mib, "open_browser": a.browser})
        update_installed_engine()
        pick_cfg = have[0]
        if len(have) > 1:
            say()
            for i, c in enumerate(have, 1):
                say(f"  {i}) {json.loads(c.read_text(encoding='utf-8-sig')).get('model_name', c.stem)}")
            pick_cfg = have[int(ask("Tune which one?", [str(i) for i in range(1, len(have) + 1)], "1", a.yes)) - 1]
        if not calibrate_config(pick_cfg):             # upstream #447: said again where it is not lost above the start
            say()
            warn("this PC is NOT tuned: the tuning failed (the reason is above); the model "
                 + ("keeps" if a.no_start else "starts with") + " the default settings")
        return 0 if a.no_start else start(pick_cfg, a.port, run_gpu, yes=a.yes, layer_split=a.layer_split,
                                          keep={"host": a.host, "api_key": a.api_key, "draft_vocab": a.draft_vocab,
                                                "vram_reserve_mib": a.vram_reserve_mib, "open_browser": a.browser})
    if have and not (a.setup or a.model or a.family or a.check or a.no_start):
        update_installed_engine()
        if len(have) == 1:
            return start(have[0], a.port, run_gpu, yes=a.yes, layer_split=a.layer_split,
                         keep={"host": a.host, "api_key": a.api_key, "draft_vocab": a.draft_vocab,
                               "vram_reserve_mib": a.vram_reserve_mib, "open_browser": a.browser})
        say()
        for i, c in enumerate(have, 1):
            say(f"  {i}) {json.loads(c.read_text(encoding='utf-8-sig')).get('model_name', c.stem)}")
        say(f"  {len(have) + 1}) install another model / change settings")
        pick = int(ask("Which one?", [str(i) for i in range(1, len(have) + 2)], "1", a.yes))
        if pick <= len(have):
            return start(have[pick - 1], a.port, run_gpu, yes=a.yes, layer_split=a.layer_split,
                         keep={"host": a.host, "api_key": a.api_key, "draft_vocab": a.draft_vocab,
                               "vram_reserve_mib": a.vram_reserve_mib, "open_browser": a.browser})

    # ---- 1. the PC
    step(1, "checking your PC")
    found = gpus()
    if not found:
        fail("no Intel GPU on the xe or i915 driver, no AMD GPU on amdgpu and no NVIDIA GPU on NVIDIA's driver found",
             "Strata's Xe engine needs an Intel GPU (Intel Arc, or the processor's graphics) on the xe or i915 kernel "
             "driver, an RDNA2 or later AMD GPU on amdgpu, or with --license contrib an NVIDIA GPU on NVIDIA's driver "
             "(lspci -k shows the driver)")
    if len(found) > 1 or gpu_problem(found[0]) is not None:
        gpu_table(found)
    gpu_chosen = a.gpu is not None                     # --gpu given: the config names the card
    a.gpus_chosen = gpu_chosen or bool(a.gpus)         # and with --gpus, the earlier split is not kept (carry_over)
    sel = choose_gpus(a, found)
    a.gpu = sel[0]
    GPU_PICK = a.gpu
    gpu = gpu_info(a.gpu)
    chosen = [gpu]
    mem = "no VRAM of its own (it shares the system RAM)" if gpu.get("integrated") else f"{gpu['vram_gb']:.0f} GB VRAM"
    if "uma_gb" in gpu:
        mem = (f"unified memory: a {gpu['carve_gb']:.1f} GB BIOS carve-out + {gpu['shared_gb']:.0f} GB shared with the "
               f"RAM, {gpu['uma_gb']:.0f} GB usable by the GPU")
    ok(f"GPU: {gpu['name']}, {mem}, PCI {gpu['pci']}, PCIe link " + (gpu["link"] or "not readable"))
    if gpu.get("gfx") == STRIX_HALO_GFX and "uma_gb" in gpu:
        for line in strix_halo_notes(gpu, ram_gb()):
            (warn if line.startswith("!") else say)(line.lstrip("!"))
    for i in sel[1:]:                                  # --gpus: the later layers' cards
        x = gpu_info(i)
        ok(f"then GPU {i}: {x['name']}, {x['vram_gb']:.0f} GB VRAM, PCI {x['pci']} (layer split, "
           f"{a.layer_split or 'auto'})")
    if not WIN and gpu.get("vendor") == "amd" and not os.access("/dev/kfd", os.R_OK | os.W_OK):
        fail("no access to the GPU's compute device (/dev/kfd)",
             "add yourself to the render group (sudo usermod -aG render $USER), log out and in, and run it again")
    makers = {x["vendor"] for x in chosen} | {gpu_info(i)["vendor"] for i in sel[1:]}
    amd_gfx = {x.get("gfx") for x in [*chosen, *(gpu_info(i) for i in sel[1:])] if x["vendor"] == "amd"}
    if PACKAGED:                                       # the GPU makers' packages the package only suggests
        check_runtime(makers, amd_gfx, data, a.yes, a.old_driver)
    elif not WIN and (majors := [v for t in cuda_toolkits() if (v := cuda_major(t))]):   # a contrib build: its CUDA
        linux_nvidia_libs(makers, data, nvidia_pip_names(max(majors)))
    if not WIN and (gpu["render"] is None or not os.access(gpu["render"], os.R_OK | os.W_OK)):
        fail(f"no access to the GPU ({gpu['render'] or 'no render node'})",
             "NVIDIA's driver is not loaded (nvidia-smi says why)" if gpu.get("vendor") == "nvidia" else
             "add yourself to the render group (sudo usermod -aG render $USER), log out and in, and run it again")
    if gpu["bar_gb"] < gpu["vram_gb"] - 0.5:
        warn(f"Resizable BAR looks off: the card shows {gpu['bar_gb']:.1f} GB of its {gpu['vram_gb']:.0f} GB to the "
             "CPU. "
             "Copies to the GPU will be slower; turn on Re-Size BAR (and Above 4G Decoding) in the BIOS")
    if gpu.get("integrated") and "uma_gb" not in gpu:
        warn("the processor's own graphics: Strata will run, but slowly - its memory is the system RAM, and it has "
             "no matrix engines (XMX) on most processors")
    elif gpu["vram_gb"] < 11:
        warn("less than 12 GB of VRAM: Strata will run, but most experts stay on the CPU and it will be slow")
    ram = ram_gb()
    cpu, avx2, avx512 = cpu_info()
    need = min(d["ram_gb"] for d in MODELS.values())
    low_ok = low_ram_fits("IQ1_M", ram, gpu_expert_vram(gpu)) and a.low_ram != "off"   # the smallest model, mapped
    if ram < need - 4 and not a.check and not low_ok:
        # every model keeps ALL its experts in RAM (23+ GB) unless the GPU holds enough of them for the low-RAM mode
        fail(f"RAM: {ram:.0f} GB - the smallest model (the Coder) needs about {need} GB",
             "Strata keeps the model's experts in RAM (23-50 GB) and the GPU holds a copy of the most-used ones: it "
             "needs 32 GB of RAM or more (48 GB for the full model), or a GPU with the VRAM to hold most of them")
    ok(f"RAM: {ram:.0f} GB" if ram >= need - 4 else
       f"RAM: {ram:.0f} GB (less than the {need} GB the smallest model needs)" +
       ("; the GPU's VRAM makes up for it (the low-RAM mode)" if low_ok else ""))
    ok(f"CPU: {cpu} ({'AVX-512' if avx512 else 'AVX2' if avx2 else 'no AVX2'})")
    if not avx2:
        fail("this CPU has no AVX2; Strata needs at least AVX2")
    if a.check:
        say()
        any_fits = False
        for m, d in MODELS.items():
            verdict = "fits" if ram >= d["ram_gb"] else "tight" if ram >= d["ram_gb"] - 8 else "does not fit"
            vram = gpu_expert_vram(gpu) + sum(max(0.0, gpu_expert_vram(gpu_info(i)) - 5) for i in sel[1:])
            if d.get("budget"):
                fits = f"fits with {resident_budget_gib(m, ram)} GiB of its experts in RAM, the rest read from the SSD"
                verdict = ("EXPERIMENTAL, " if d.get("experimental") else "") + fits if ram >= d["ram_gb"] \
                    else "does not fit"
            elif low_ram_needed(m, ram) and low_ram_fits(m, ram, vram) and a.low_ram != "off":
                verdict = (f"fits in the low-RAM mode (the GPU holds ~{100 * low_ram_gpu_share(m, vram):.0f}% of its "
                           "experts, " + ("the rest stays in RAM)" if low_ram_resident(m, ram, vram)
                                          else "the rest is read from the SSD as needed)"))
            any_fits = any_fits or not verdict.startswith("does not fit")
            say(f"  {m:10s} needs ~{d['ram_gb']} GB RAM: {verdict}")
        # the other models (PLAIN_FAMILIES): their weights and 8 GB beside, in RAM and the GPU together (the experts
        # the GPU holds are not copied into RAM)
        plain_vram = max(0.0, gpu.get("vram_gb", 0.0) - 5)
        for fam in PLAIN_FAMILIES.values():
            for m, d in fam["models"].items():
                gb = d["size"] / 1e9
                verdict = "fits" if ram >= gb + 8 else "fits with the GPU's VRAM" if ram + plain_vram >= gb + 8 \
                    else "slow (the experts that do not fit are read from the SSD)"
                say(f"  {fam['title']} {m}: ~{gb + 8:.0f} GB of RAM and VRAM: {verdict}")
        if not any_fits:
            # upstream #977: every size says "does not fit", so the verdict says so too (and the exit code, for
            # scripts). It only reports: --model NAME --yes still installs one anyway.
            say(f"\nThis PC cannot run Strata yet: no model size fits {ram:.0f} GB of RAM (the smallest needs about "
                f"{need} GB). --model NAME --yes installs one anyway, slowly.")
            return 1
        say("\nThis PC can run Strata. Run it again without --check to install.")
        return 0

    # ---- 2. the questions
    step(2, "your choices")
    fams = list(FAMILIES)
    # a Strix Halo with the memory for it: UD-IQ4_XS is the recommendation, the menus list the rest (upstream c4a329fe)
    halo = gpu.get("gfx") == STRIX_HALO_GFX and "uma_gb" in gpu and ram + gpu.get("carve_gb", 0.0) >= STRIX_HALO_MIN_GB
    halo_fam = (next((f for f in fams if f in MODELS.get(STRIX_HALO_MODEL, {}).get("families", ())), None)
                if halo else None)
    if a.family:
        family = a.family
    else:
        rec_fam = halo_fam or fams[0]
        for i, f in enumerate(fams, 1):
            d = FAMILIES[f]
            say(f"  {i}) {d['title']:20s} {d['by']} - {d['about']}" +
                ("   [experimental]" if d.get("experimental") else "") +
                (f"   (recommended for Strix Halo: {STRIX_HALO_MODEL})" if f == halo_fam and f != fams[0] else ""))
        family = fams[int(ask("Which model?", [str(i) for i in range(1, len(fams) + 1)], str(fams.index(rec_fam) + 1),
                              a.yes)) - 1]
    fam = FAMILIES[family]
    ok(f"model: {fam['title']}")
    if fam.get("license"):
        say(f"  Its license: {fam['license']}")
    if fam.get("multi_file"):
        return install_dsv41(a, family, gpu, chosen, port, ram, adopted)
    if fam.get("plain"):
        return setup_plain(a, family, fam, gpu, chosen, sel, found, gpu_chosen, ram, roots, elsewhere, port, adopted)
    say()
    # an experimental size sorts last (UD-IQ4_XS before UD-Q4_K_XL); --model takes the names as they are
    names = sorted((m for m in MODELS if family in MODELS[m].get("families", ("qwen", "swift"))),
                   key=lambda m: bool(MODELS[m].get("experimental")))
    if a.model and a.model not in names:
        # upstream #444: say which family has that size, and (with --gguf-dir) which files XeStrata can run at all
        elsewhere_fams = [f for f in FAMILIES if f in MODELS.get(a.model, {}).get("families", ())]
        fail(f"{fam['title']} has no {a.model} model file", "choose one of: " + ", ".join(names)
             + (f" (or {a.model}: " + ", ".join(f"--family {f} --model {a.model}" for f in elsewhere_fams) + ")"
                if elsewhere_fams else "")
             + (f".\n       {SUPPORTED_GGUFS}" if a.gguf_dir else ""))
    # the VRAM that holds experts instead of RAM: every card of a layer split holds its own layers' (upstream #642),
    # each less the ~5 GB of dense weights and buffers low_ram_gpu_gb counts once
    vram = gpu_expert_vram(gpu) + sum(max(0.0, gpu_expert_vram(gpu_info(i)) - 5) for i in sel[1:])
    have_size = installed_size(family, names, have)
    for i, m in enumerate(names, 1):
        d = MODELS[m]
        fit = "" if ram >= d["ram_gb"] else f"   <- needs {d['ram_gb']} GB RAM, you have {ram:.0f}"
        if m == have_size:
            fit += "   (installed)"
        if d.get("budget"):
            say(f"  {i}) {m} {d['about']}; download {d['download_gb']:.0f} GB, keeps ~"
                f"{resident_budget_gib(m, ram)} GB of its {d['arena_gb']:.0f} GB of experts in RAM{fit}")
            continue
        if low_ram_needed(m, ram) and low_ram_fits(m, ram, vram) and a.low_ram != "off":
            fit = (f"   <- fits in the low-RAM mode (the GPU holds ~{100 * low_ram_gpu_share(m, vram):.0f}%, "
                   + ("the rest in RAM)" if low_ram_resident(m, ram, vram) else "the rest from the SSD)"))
        say(f"  {i}) {m:8s} {d['about']}; download {d['download_gb']:.0f} GB, uses ~{d['arena_gb']:.0f} GB of RAM{fit}")
    rec = str(names.index("IQ3_XXS") + 1) if ram >= 60 and "IQ3_XXS" in names else "1"
    if family == halo_fam and STRIX_HALO_MODEL in names:
        rec = str(names.index(STRIX_HALO_MODEL) + 1)
    if have_size is not None:   # setup run again: the installed size, whatever is recommended for a first install
        rec = str(names.index(have_size) + 1)
    model = a.model or names[int(ask("Which size?", [str(i) for i in range(1, len(names) + 1)], rec, a.yes)) - 1]
    budget = None
    if MODELS[model].get("budget"):
        # Unsloth's UD-Q4_K_XL and UD-IQ4_XS: a RAM budget of their experts, the rest read from the GGUF files in place
        # (not the low-RAM mode's choice: the budget is set by the RAM, whatever the GPU holds)
        if MODELS[model].get("experimental"):
            warn(f"{model} is EXPERIMENTAL: part of its experts are read from the SSD while it answers, so it is "
                 "slower than the 2-3-bit models")
        if ram < MODELS[model]["ram_gb"]:
            confirm_risk(f"{model} needs {MODELS[model]['ram_gb']} GB of RAM or more; this PC has {ram:.0f} GB: "
                         f"its RAM budget would be {resident_budget_gib(model, ram)} GiB, so nearly every expert is "
                         "read from the SSD while it answers (very slow), and it may run out of RAM",
                         bool(a.model), a.yes, f"{model} needs {MODELS[model]['ram_gb']} GB of RAM or more; this PC "
                         f"has {ram:.0f} GB", f"choose one of the 2-3-bit models, or --model {model} --yes to "
                         "install it anyway", "  Install it anyway?")
            warn(f"installing {model} with {ram:.0f} GB of RAM, as you chose")
        budget = budget_choice(model, ram, a.resident_budget_gib)
        ok(f"RAM budget: {budget:g} GiB of {model}'s experts in RAM, the rest read from the model files on the SSD")
        if a.low_ram not in ("auto", "off"):
            warn(f"--low-ram {a.low_ram} does not apply to {model}: it always reads part of its experts from the files")
    elif a.resident_budget_gib is not None:
        warn(f"--resident-budget-gib is for UD-Q4_K_XL and UD-IQ4_XS: {model} keeps all of its experts in RAM or in "
             "the low-RAM mode")
    low_ram = budget is None and (a.low_ram in ("on", "resident", "mmap") or
                                  (a.low_ram == "auto" and low_ram_needed(model, ram)))
    # (the low-RAM mode's variant is decided once the context is known, below)
    if not low_ram and budget is None and ram < MODELS[model]["ram_gb"] - 4:
        # #125: a warning and a question, not a stop: the user may accept paging (asked, "no" by default, so an
        # unattended --yes install stops here unless the size was asked for with --model)
        need_gb, arena = MODELS[model]["ram_gb"], MODELS[model]["arena_gb"]
        confirm_risk(f"{model} needs about {need_gb} GB of RAM and this PC has {ram:.0f} GB: its experts alone are "
                     f"{arena:.0f} GB and must stay in RAM, so Linux will page part of them from disk. Expect it "
                     "to be much slower, and it may not start at all.\n       A smaller size (Q2_0 or IQ2_XS) fits; "
                     "more RAM fixes it.", bool(a.model), a.yes,
                     f"{model} needs about {need_gb} GB of RAM; this PC has {ram:.0f} GB",
                     f"choose Q2_0 or IQ2_XS, or add RAM; or --model {model} --yes to install it anyway",
                     "  Install it anyway?")
        warn(f"installing {model} with {ram:.0f} GB of RAM, as you chose" + (" (--model)" if a.model else ""))
    ok(f"size: {model}")
    tag = fam["tag"] + model                           # names of the pack, config and start script
    small = min(x.get("uma_gb", x["vram_gb"]) for x in chosen)   # the smallest card's memory, for the KV notes below
    rec_ctx = vram_ctx(chosen)
    # upstream #406: the RAM rule is part of the recommendation (the smaller of the two), not a cap over the choice
    rec_ctx = min(rec_ctx, ram_ctx(model, ram, low_ram))
    if a.context:
        ctx = a.context
    else:
        say()
        say("  Context length = how much text the model can see at once (your chat, files, tool output).")
        say("  Longer needs more VRAM for it, so fewer experts fit on the GPU:")
        for i, c in enumerate(CONTEXTS, 1):
            need_c = ctx_ram_need(model, c, low_ram)
            say(f"  {i}) {c // 1024}K tokens" + ("   (recommended for your GPU)" if c == rec_ctx else "") +
                ("   (experimental: setup adds rope scaling)" if c > 262144 else "") +
                (f"   (needs ~{need_c:.0f} GB RAM, this PC has {ram:.0f}: may run out of memory)"
                 if c > 131072 and need_c is not None and need_c > ram else ""))
        ctx = CONTEXTS[int(ask("Context?", [str(i) for i in range(1, len(CONTEXTS) + 1)],
                               str(CONTEXTS.index(rec_ctx) + 1), a.yes)) - 1]
    # upstream #406 #364: a context past the RAM rule (an explicit --context or a pick in the list) is kept, with
    # what it risks.  It used to become 128K: users ran 256K fine where setup's estimate said no.
    need_gb = ctx_ram_need(model, ctx, low_ram)
    if need_gb is not None and ram < need_gb and ctx > 131072:
        warn(f"{ctx // 1024}K with {model} needs ~{need_gb:.0f} GB of RAM by setup's estimate "
             f"({MODELS[model]['arena_gb']:.0f} GB of experts + the context + room for the rest); this PC has "
             f"{ram:.0f}. Kept as you chose: it may be slower or run out of RAM under load. {rec_ctx // 1024}K is the "
             "recommended size.")
    scaling = a.rope_scaling
    if ctx > 262144 and scaling is None and not a.yes:
        say()
        say(f"  A {ctx // 1024}K context runs the model past its trained 262,144 positions: the rotary angles")
        say("  get rescaled (llama.cpp's RoPE extension). yarn keeps the trained angles on the high-frequency")
        say("  pairs and corrects the magnitudes; linear shrinks every angle. Override any time with")
        say("  --rope-scaling.")
        scaling = ask("RoPE extension method?", ["yarn", "linear"], "yarn", a.yes)
    try:
        scaling, rope_scale = resolve_rope(ctx, scaling, a.rope_scale)
    except ValueError as e:
        fail(str(e))
    if scaling is not None:
        origin = ("final context / trained 262144; override with --rope-scale" if a.rope_scale is None
                  else "as requested")
        ok(f"rope scaling: {scaling}, factor {rope_scale:g} ({origin})")
    ok(f"context: {ctx} tokens")
    # the KV cache (the model's memory of the conversation): 8-bit, or 4-bit after a Hadamard rotation (PR #21)
    kv = "fp16" if ctx <= 8192 else (a.kv or "int8")
    if ctx > 8192 and not a.kv and not a.yes:
        say()
        say("  KV cache precision (the model's memory of the conversation):")
        say("  1) 8-bit   (recommended: what every published number was measured with)")
        say("  2) 4-bit   half the memory (about 4% faster at 128K), but measurably less precise on long")
        say("             documents; long-context lookups (needle tests) still pass")
        kv = ["int8", "q4_0"][int(ask("KV cache?", ["1", "2"], "1", a.yes)) - 1]
    if ctx > 8192:
        ok("KV cache: " + {"int8": "8-bit", "q4_0": "4-bit (Hadamard-rotated)",
                           "k8v4": "8-bit keys, 4-bit values"}[kv])
    if MODELS[model].get("vision", fam.get("vision")) is False:     # a size without images
        vision = "none"
        if a.vision not in (None, "no", "none"):
            warn(f"images are not available with {model} yet: off")
    elif a.vision:
        # yes = the GPU encoder, the CPU encoder its fallback.  Adopted without a tolerance on the embeddings (they
        # differ from the CPU encoder's by a few percent; the answers agree): the 2026-09-30-xe-vision-sycl record
        vision = "none" if a.vision in ("no", "none") else images_encoder(a.vision, gpu)
    else:
        small = 0 < gpu_expert_vram(gpu) < IMAGES_GPU_ENCODER_MIN_VRAM_GB
        say()
        say("  Images: the model can also read pictures (screenshots, photos, scanned pages). This adds a 0.9 GB")
        if small:
            say("  download. On a card under 24 GB the encoder runs on the CPU (a few seconds per picture, nothing")
            say("  taken from the GPU): the GPU encoder keeps ~1.4 GB of VRAM free, which cost 3-5% of text speed on")
            say("  16 GB cards. --vision gpu if you want pictures in under a second.")
        else:
            say("  download; the image encoder runs on the GPU (on the CPU if it cannot start there).")
        # upstream 91baead75: pictures on by default wherever the model reads them, on every make of card (the reader
        # follows images_encoder: the CPU under 24 GB of VRAM, the GPU from 24 GB)
        vision = images_encoder("yes", gpu) if ask("Do you want images?", ["y", "n"], "y", a.yes) == "y" else "none"
    ok("images: " + {"none": "off", "gpu": "on (encoder on the GPU, the CPU encoder as fallback)",
                     "cpu": "on (encoder on the CPU)"}[vision])
    if vision != "none" and MODELS[model].get("vision_untested"):
        warn(f"images with {model} are untested: users report them working upstream, but this file has not been run "
             "with images (upstream #967); tell us if the answers look wrong")
    # The low-RAM mode's two variants.  resident: the experts the GPU's cache does not hold are copied from the model
    # files into RAM once (--resident-experts; the engine keeps what fits the RAM it finds free and reads the rest
    # from the files).  mmap: they are read through the OS file cache.  The GPU's share: its VRAM less the dense
    # weights and buffers, this context's KV cache and the image encoder's room.
    resident = False
    if low_ram:
        arena = MODELS[model]["arena_gb"]
        vram -= VISION[vision]["reserve_mib"] / 1024 if vision != "none" else 0
        share = low_ram_gpu_share(model, vram, ctx, kv)
        rest = arena - low_ram_gpu_gb(model, vram, ctx, kv)
        resident = a.low_ram == "resident" or (a.low_ram != "mmap" and low_ram_resident(model, ram, vram, ctx, kv))
        if resident:
            ok(f"low-RAM mode: the GPU holds ~{100 * share:.0f}% of {model}'s experts ({arena:.0f} GB) and the other "
               f"~{rest:.0f} GB stay in RAM ({ram:.0f} GB), copied once from the model files")
        else:
            ok(f"low-RAM mode: {model}'s experts ({arena:.0f} GB) are read from the model files through the OS file "
               f"cache instead of a copy in RAM ({ram:.0f} GB); the GPU holds ~{100 * share:.0f}% of them")
            if share < 0.6:
                warn("most of the experts are read from the SSD while it answers: expect it to be much slower than "
                     "with enough RAM (a faster SSD and a smaller size help)")
    if (resident or budget is not None) and memlock_gib() < 4:
        warn("the experts kept in RAM cannot be locked (ulimit -l is small), so the OS may swap them out and it gets "
             "slower: raise the memlock limit for your user (memlock in /etc/security/limits.conf, or "
             "DefaultLimitMEMLOCK in systemd's user.conf) and log in again")
    # EXPERIMENTAL: the experimental-speed-projection control vector (ESP_VECTOR), off unless
    # chosen here; with it loaded, the web app and the API switch it off per request
    esp = None
    esp_choice = (a.experimental_speed_projection or "").strip()
    # the Coder and Unsloth's files: the same model's residual stream (Unsloth's: the user's decision of 2026-10-22)
    if family in ("qwen", "coder", "unsloth"):
        if not esp_choice:
            say()
            say("  EXPERIMENTAL - speed projection: a small control vector applied while the model runs (layers 4-44).")
            say("  It changes how the model answers: its package describes it as a refusal-direction projection (the")
            say("  model declines far fewer requests). Off unless you choose it; when on, the web app can switch it")
            say("  off per chat. Details: " + (esp_release_url("README.md") if PACKAGED else
                                               "third_party/nonfree/experimental-speed-projection/README.md"))
            esp_choice = ("on" if ask("Turn on the experimental speed projection?", ["y", "n"], "n", a.yes) == "y"
                          else "off")
        if esp_choice.lower() not in ("off", "no", "n", "0"):
            esp = (ESP_VECTOR if esp_choice.lower() in ("on", "yes", "y", "1")
                   else Path(esp_choice).expanduser().resolve())
            if not esp.is_file() and esp == ESP_VECTOR and PACKAGED:
                esp = esp_download(data)
            elif not esp.is_file() and esp == ESP_VECTOR:   # third_party/nonfree removed: the rest works without it
                warn(f"the experimental speed projection's vector is not here ({esp}): left off. Put the vector "
                     "there, or pass --experimental-speed-projection <its GGUF>")
                esp = None
            elif not esp.is_file():
                fail(f"the experimental speed projection's vector is missing: {esp}")
        ok("experimental speed projection: " + ("ON (experimental)" if esp else "off"))
    elif esp_choice.lower() not in ("", "off", "no", "n", "0"):
        warn(f"the experimental speed projection cannot be used with {fam['title']}: left off")
    models_dir = Path(a.gguf_dir) if a.gguf_dir else Path(a.models_dir) / tag
    shards = gguf_dir_shards(models_dir, fam, model) if a.gguf_dir else \
        [models_dir / model_file(fam, model, i) for i in range(1, model_shards(fam, model) + 1)]
    problem = gguf_dir_problem(models_dir, shards[0], fam, model) if a.gguf_dir else None
    if problem:                                        # upstream #444: files XeStrata cannot run, or another choice's
        fail(*problem)
    if not a.gguf_dir and not all(sh.exists() and done(sh) for sh in shards):
        for r in elsewhere:                            # already downloaded in a Strata folder on another drive
            cand = [r / "models" / tag / sh.name for sh in shards]
            if all(c.exists() and done(c) for c in cand):
                models_dir, shards = cand[0].parent, cand
                ok(f"model files found in {models_dir}")
                break
    for s in shards:   # upstream #173: a whole file copied in by hand has no finish mark (75e6efeb7, 762e58b5b)
        if s.exists() and not done(s) and whole_shard(s):
            try:
                mark(s, "whole (checked against its own tensor directory)")
            except OSError as e:                       # a read-only folder (--gguf-dir on a share): still whole
                warn(f"{s.name} is whole but its finish mark cannot be written ({e})")
    have_model = all(s.exists() and (done(s) or a.gguf_dir) for s in shards)
    # upstream #425: a download that resumes needs room only for what is still missing - the finished shards and the
    # .part files already on the disk count
    on_disk = sum(f.stat().st_size for s in shards for f in (s, s.with_name(s.name + ".part")) if f.is_file()) / 1e9
    to_fetch = 0 if a.gguf_dir or have_model else max(MODELS[model]["download_gb"] - on_disk, 0)
    # upstream ed15a3d0: count only what step 6 will still write - the AVX-512 Q2_0 conversion when its pack is not
    # there yet, a new MTP draft layer only when none is
    pack_now = find_in(roots, f"packs/{tag.lower()}") or data / "packs" / tag.lower()
    pack_bin = (pack_now / "experts.bin").exists() and (pack_now / "index.txt").exists()
    mtp_have = find_in(roots, "mtp/rt/experts.bin") is not None
    q2_avx = model == "Q2_0" and avx512 and family == "qwen"
    margin = 2 if mtp_have else 8                      # working room: a guess, not bytes that will be written
    real = to_fetch + (40 if q2_avx and not pack_bin else 0) + (1 if vision != "none" else 0)
    need = real + margin
    free_now = free_gb(models_dir)
    if free_now < real:                                # upstream 537f8fef8: stop only when the bytes do not fit
        fail(f"not enough free disk space in {models_dir}: need ~{real:.0f} GB, {free_now:.0f} GB free",
             "use --models-dir on a bigger drive")
    if free_now < need:
        warn(f"little free disk space in {models_dir}: {free_now:.0f} GB free for about {real:.0f} GB of files. "
             "Setup goes on and should fit; free up space if it stops")

    llama, eng, enc, lib_dirs = prepare_engine(a, gpu, vision)
    # #24: a package takes only the image encoders it carries (the Windows 7z has the CPU one, no Vulkan one)
    if PACKAGED and vision == "gpu" and not (eng / VEXE[enc]).exists():
        warn("this package has no GPU image encoder: images are read on the CPU")
        vision = "cpu"
    if PACKAGED and vision == "cpu" and not (eng / VEXE["cpu"]).exists():
        warn("this package has no image encoder: images are off")
        vision = "none"

    # ---- 5. the model files
    step(5, f"downloading {fam['title']} {model}")
    if not a.gguf_dir:
        missing = [s.name for s in shards if not (s.exists() and done(s))]
        if missing:                                    # #495: files downloaded by hand go here, or --gguf-dir
            say(f"  The model files go in {models_dir}")
            say(f"  Files you already have: put them here with their original names ({', '.join(missing)}), or use "
                "--gguf-dir <their folder>.")
            if model_source() == "modelscope":
                say(f"  Downloading from ModelScope ({ms_endpoint()}); --source huggingface downloads from Hugging "
                    "Face")
                warn("ModelScope serves the repositories' current files, not the pinned revisions: each file is "
                     "checked against the SHA-256 ModelScope itself publishes (self-attested); the MTP tensors against "
                     "the pinned checkpoint's own hashes")
            elif hf_endpoint() != HF_DEFAULT:
                say(f"  Downloading from {hf_endpoint()} (HF_ENDPOINT)")
        for s in shards:
            if s.exists() and done(s):
                ok(f"{s.name} already downloaded")
                continue
            # the original's shard 2 is the same file for all its sizes and the Coder: reuse one that is already here
            other = [p for p in Path(a.models_dir).glob("*/Qwen3.8-Flash-Next-GSQ-RCO-*-00002-of-00002.gguf")
                     if done(p)]
            if family in ("qwen", "coder") and s.name.endswith("00002-of-00002.gguf") and other and not s.exists():
                try:
                    os.link(other[0], s)
                    mark(s)
                    ok(f"{s.name} shared with {other[0].parent.name} (identical file)")
                    continue
                except OSError:
                    pass
            download(fam["hf"].format(q=model, d=fam.get("dirs", {}).get(model, model)) + s.name, s)
    check_shards(shards)
    for s in shards:                                   # the experimental Unsloth file: pinned sizes and SHA-256
        if s.name in fam.get("sha256", {}):
            pin_size, pin_sha = fam["sha256"][s.name]
            verify_sha256(s, pin_size, pin_sha, own=bool(a.gguf_dir))
    ok("model files present")
    mmproj = Path(a.models_dir) / fam["mmproj"]
    if not mmproj.exists():
        mmproj = find_in(roots, f"models/{fam['mmproj']}") or mmproj
    if vision != "none":
        if not mmproj.exists() and a.gguf_dir and (Path(a.gguf_dir) / fam["mmproj"]).exists():
            mmproj = Path(a.gguf_dir) / fam["mmproj"]
        else:
            download(fam["mmproj_hf"] + fam["mmproj"], mmproj, "vision encoder")
        ok(f"vision encoder: {mmproj}")
        if vision == "cpu" and "BF16" in mmproj.name:       # a tip only (recommend, never force; upstream #625)
            say("       tip: on the CPU a Q8_0 copy of this encoder is a third smaller and about as exact (embedding "
                "cosine 0.999 vs BF16); see 'A Q8_0 encoder' in docs/DETAILS.md")

    # ---- 6. the pack and the MTP draft layer
    step(6, "preparing the model for Strata")
    pack = find_in(roots, f"packs/{tag.lower()}") or data / "packs" / tag.lower()
    env = dict(os.environ, STRATA_GGUF_PY=str(llama / "gguf-py"))
    if model == "Q2_0" and avx512 and family == "qwen":
        # the Q2_0 experts repacked for the AVX-512 kernel (the measured speed): a one-time ~40 GB conversion
        if not (pack / "index.txt").exists() or not (pack / "experts.bin").exists():   # index.txt is written last
            say("  Converting the Q2_0 experts for the AVX-512 kernel (one time, ~40 GB written, 2-5 min) ...")
            run([sys.executable, str(ROOT / "tools" / "strata_pack.py"), "build", "--gguf", str(shards[0]),
                 "--out", str(pack), "--skip-hash", "--force"], env=env)   # --force: #634 refuses an occupied pack
            run([sys.executable, str(ROOT / "tools" / "pack_index.py"), "--pack", str(pack)], env=env)
        if not (pack / "tokenizer" / "vocab.json").exists():
            run([sys.executable, str(ROOT / "tools" / "strata_tokenizer.py"), "--gguf", str(shards[0]),
                 "--out", str(pack)], env=env)   # writes <pack>/tokenizer/
    elif not (pack / "native_experts.txt").exists() or not (pack / "tokenizer" / "vocab.json").exists():
        # every tensor as the GGUF stores it; the experts are read from the GGUF at start (seconds to build)
        # (UD-Q4_K_XL: --compat-bf16 - its Q8_0 hyper-connection projections become BF16, the form the engine reads)
        run([sys.executable, str(ROOT / "tools" / "iq_pack.py"), "--gguf", str(shards[0]), "--out", str(pack),
             *fam.get("pack_args", [])], env=env)
    ok(f"model prepared: {pack}")
    mtp = (find_in(roots, "mtp/rt/experts.bin") or data / "mtp/rt/experts.bin").parent.parent
    rt = mtp / "rt"
    corrupt = (rt / "experts.bin").exists() and mtp_corrupt(mtp, env)
    if corrupt:
        say("  The MTP tensors differ from the pinned checkpoint; fetching and rebuilding them.")
    if corrupt or not (rt / "experts.bin").exists():
        say("  The MTP draft layer (speculative decoding, ~2x faster output) comes from the original Qwen checkpoint:")
        say("  only its ~5 GB of MTP tensors are downloaded.")
        fetch_mtp(mtp, env)
        run([sys.executable, str(ROOT / "tools" / "mtp_pack.py"), "--src", str(mtp), "--experts", "q2_0",
             "--out", str(mtp / "mtp-q2_0.gguf")], env=env)
        run([sys.executable, str(ROOT / "tools" / "mtp_rt.py"), "--gguf", str(mtp / "mtp-q2_0.gguf"), "--out", str(rt)],
            env=env)
    # a setup run again without --draft-vocab keeps the subset this model's config chose before
    draft_vocab = a.draft_vocab or saved_draft_vocab(CONF / f"xestrata-{tag.lower()}.json")
    refresh_draft_vocab(rt, draft_vocab or "cjk")
    ok(f"MTP draft layer: {rt}")
    for line in draft_vocab_note(gpu_expert_vram(gpu), draft_vocab):   # #474: a recommendation, nothing changes
        say("  " + line)

    # ---- 7. the start script
    step(7, "writing the model's settings" if PACKAGED else "writing the start script")
    sys.path.insert(0, str(ROOT / "tools"))
    from gguf_reader import GGUFFile                   # the PLE table's shard: shard 2 (original) or 1 (Swift)
    ple = next((s for s in shards if any(t.name == "per_layer_token_embd.weight" for t in GGUFFile(s).tensors)), None)
    if ple is None:
        fail("the model has no per_layer_token_embd tensor (is this a Qwen3.8-Flash-Next GGUF?)")
    args = ["--pack", str(pack), "--native", str(shards[0]), "--ple-gguf", str(ple),
            "--expert-profile", str(ROOT / "data" / fam.get("profile", "expert-profile.bin")), "--expert-cache", "auto",
            "--prefill", "auto", "--spec", "4", "--spec-min-p", "0.5", "--mtp", str(rt),
            "--max-context", str(ctx)]
    if scaling is not None:     # the resolved configuration: the explicit flags, or yarn and the derived factor
        args += ["--rope-scaling", scaling, "--rope-scale", f"{rope_scale:g}"]
    if ctx > 8192:
        args += ["--kv", kv]
    if low_ram:   # the experts from the model files: the ones the GPU does not hold copied into RAM, or mapped
        args += ["--resident-experts" if resident else "--mmap-experts"]
    disk = rotational_disk(ple)                        # upstream #605
    if disk:
        tensor = next((t for t in GGUFFile(ple).tensors if t.name == "per_layer_token_embd.weight"), None)
        size = getattr(tensor, "expected_bytes", lambda: None)()
        table_gb = size / 1e9 if size else 28.8
        if ram >= MODELS[model]["ram_gb"] + table_gb + 4:
            args += ["--ple-io", "ram"]
            ok(f"the model is on a rotational disk ({disk}): its {table_gb:.0f} GB n-gram table is kept in RAM "
               "(--ple-io ram) - read from the disk at random, it can stall prompts for minutes")
        else:
            warn(f"the model is on a rotational disk ({disk}): its n-gram table is read from it at random, which can "
                 f"stall prompts for minutes. An SSD is recommended; with ~{table_gb:.0f} GB more RAM, "
                 "--ple-io ram in the config's args keeps the table in RAM instead")
    elif not low_ram and not WIN and wsl_version() == 0:
        # upstream b25b30970: on an SSD too, a PC with RAM to spare keeps the n-gram table in RAM, so a new prompt's
        # first chunk does not wait for its table rows (65,536 random SSD reads at 4K tokens).  upstream (RTX PRO 5000,
        # Linux, NVMe): prompt 4K -18%, 20K -9%, decode +0.8%; the B70 (IQ3_XXS 4K, 2026-10-20): prompt +1.9%, decode
        # the same.  Measured on Linux only (Windows locks pages otherwise, WSL pins little), and only with 16 GB to
        # spare beyond the model's own need: a smaller PC keeps reading from the SSD.
        tensor = next((t for t in GGUFFile(ple).tensors if t.name == "per_layer_token_embd.weight"), None)
        size = getattr(tensor, "expected_bytes", lambda: None)()
        table_gb = size / 1e9 if size else 28.8
        if ram >= MODELS[model]["ram_gb"] + table_gb + 16:
            args += ["--ple-io", "ram"]
            ok(f"{ram:.0f} GB of RAM: the {table_gb:.0f} GB n-gram table is kept in RAM (--ple-io ram), so a new "
               "prompt does not wait for its rows from the SSD; remove --ple-io ram from the config's args to read it "
               "from the SSD instead")
    # KV streaming: from 64K up the whole KV cache lives in RAM and only the part the attention reads (32K positions
    # per layer) stays in VRAM; the VRAM it frees holds more experts (+6% at 128K, +23% at 262K with Q2_0). It
    # costs ~13.7 KB of RAM per context token with 8-bit KV (1.7 GB at 128K), 10.6 KB with K8V4, 7.5 KB with 4-bit, so
    # only when it fits.
    kv_ram_gb = kv_streaming_ram_gb(ctx, kv)
    if kv_streaming_wanted(model, ctx, kv, ram):
        args += ["--kv-resident", "32768"]
        ok(f"KV streaming on: the context's KV cache lives in RAM ({kv_ram_gb:.1f} GB), more experts fit in VRAM")
        if budget is not None and a.resident_budget_gib is None:   # its RAM comes out of the experts' budget
            budget = resident_budget_gib(model, ram, kv_ram_gb)
            ok(f"RAM budget: {budget} GiB (less the KV cache's RAM)")
    elif ctx >= 65536:   # #620: say why, so a regenerated config without --kv-resident is no surprise
        ok(f"KV streaming off: it needs ~{kv_ram_gb:.1f} GB of RAM beside the ~{MODELS[model]['ram_gb']} GB {model} "
           f"uses, and this PC has {ram:.0f}; the KV cache stays in VRAM (fewer cached experts)")
        # neither RAM nor VRAM holds that KV cache with the experts: the engine stops at start (no expert cache)
        if low_ram_gpu_gb(model, small, ctx, kv) < MIN_CACHE_GB:
            smaller = [c for c in CONTEXTS if c < ctx and low_ram_gpu_gb(model, small, c, kv) >= MIN_CACHE_GB]
            q4 = kv != "q4_0" and low_ram_gpu_gb(model, small, ctx, "q4_0") >= MIN_CACHE_GB
            warn(f"a {ctx // 1024}K context's KV cache leaves the GPU ({small:.0f} GB) no room for the expert cache, "
                 "and the RAM has none for it either: the engine will not start. " +
                 " or ".join(([f"--context {smaller[-1]}"] if smaller else []) + (["--kv q4_0"] if q4 else [])) +
                 " makes room")
    if budget is not None:     # UD-Q4_K_XL: the experts read from the GGUF in place, the most-used N GiB kept in RAM
        args += ["--resident-budget-gib", f"{budget:g}"]
        if gpu.get("integrated") and "--expert-cache" in args:
            # the cache and the budget draw on the same RAM: a number that leaves the OS its room, not `auto`
            slots = uma_expert_cache(model, ram, budget, kv_ram_gb if "--kv-resident" in args else 0.0)
            if slots is not None:
                args[args.index("--expert-cache") + 1] = str(slots)
                ok(f"expert cache: {slots} slots (not auto): this GPU shares the RAM with the {budget:g} GiB budget, "
                   f"so setup leaves {UNSLOTH_RAM_LEFT_GB} GB of the RAM for the OS and the desktop. "
                   "--expert-cache N in the config's args sets it")
            else:
                warn(f"this GPU shares the RAM, and the {budget:g} GiB RAM budget leaves almost none for the expert "
                     "cache: it stays on auto, which may take the room the OS needs. A smaller "
                     "--resident-budget-gib leaves room")
    if vision != "none":
        args += ["--vision", "--vram-reserve-mib", str(VISION[vision]["reserve_mib"])]
    if a.vram_reserve_mib is not None:                 # #493: VRAM left free for other programs (only when given)
        if "--vram-reserve-mib" in args:
            i = args.index("--vram-reserve-mib") + 1
            if vision == "gpu" and a.vram_reserve_mib < int(args[i]):
                warn(f"--vram-reserve-mib {a.vram_reserve_mib}: the image encoder on the GPU needs ~{args[i]} MiB of "
                     "it; kept as you chose (it may run out of VRAM when it reads a picture)")
            args[i] = str(a.vram_reserve_mib)
        else:
            args += ["--vram-reserve-mib", str(a.vram_reserve_mib)]
        ok(f"VRAM kept free for other programs: {a.vram_reserve_mib} MiB (--vram-reserve-mib; the expert cache takes "
           "that much less)")
    if 0 < gpu_expert_vram(gpu) < SMALL_CARD_GB:
        # #496: on a 6 GB card the expert cache can get no room at all; the engine lowers its own reserve when that
        # is what it takes, and says what is short when even that is not enough.  Setup only says what helps.
        for line in small_card_note(ctx, draft_vocab):   # a recommendation: nothing changes
            say("  " + line)
    elif gpu.get("vendor") == "amd" and a.vram_reserve_mib is None and linux_desktop():
        for line in desktop_reserve_note():              # upstream #560 #516: a recommendation: nothing changes
            say("  " + line)
    if a.vram_reserve_mib is None and gpu_drives_display(gpu):
        say("  tip: this card drives a display. If the PC freezes or the screen goes black once the model is loaded "
            f"(upstream #779), keep more VRAM free: run setup again with --vram-reserve-mib {DISPLAY_RESERVE_MIB}")
    if esp is not None:
        # the package's profile, with llama.cpp's flags (the engine takes the same ones)
        args += ["--control-vector-scaled", f"{esp}:1.0", "--control-vector-layer-range", "4", "44",
                 "--cvec-mode", "project", "--cvec-dir", "per-layer"]
    cfg: dict[str, Any] = {"exe": str(eng / EXE), "args": args, "cwd": str(STATE),
                           "tokenizer": str(pack / "tokenizer"),
                           "model_name": f"{fam['name']}-{model.lower()}",
                           "log": str(STATE / f"xestrata-{tag.lower()}.log"), "lib_dirs": lib_dirs, "port": port}
    if gpu_chosen or sum(1 for x in found if gpu_problem(x) is None) > 1:
        cfg["gpu_pci"] = gpu["pci"]                    # the engine takes its GPU by PCI address (STRATA_GPU_PCI)
    if len(sel) > 1:                                   # --gpus: the layer split's other cards (docs/MULTIGPU.md)
        cfg["gpu_pci"] = gpu["pci"]
        cfg["split_pci"] = [gpu_info(i)["pci"] for i in sel[1:]]
        if a.layer_split:
            cfg["layer_split"] = str(a.layer_split)
    if a.replicas is not None and a.replicas >= 2:      # data-parallel replicas (serve/replicas.py, upstream 8d276c19)
        cards = [cfg.get("gpu_pci"), *(cfg.get("split_pci") or [])] if cfg.get("gpu_pci") else []
        if not cards or len(cards) % a.replicas:
            warn(f"--replicas {a.replicas}: needs the chosen GPUs ({len(cards) or 'one'}) to divide into {a.replicas} "
                 "equal groups; not set (choose the cards with --gpus, or write the groups into the config: "
                 '"replicas": [{"gpus": ["0000:03:00.0"]}, {"gpus": ["0000:09:00.0"]}])')
        else:
            cfg["replicas"] = a.replicas
            per = len(cards) // a.replicas
            ok(f"{a.replicas} replicas of {per} GPU(s) each: "
               f"{' | '.join(','.join(cards[i * per:(i + 1) * per]) for i in range(a.replicas))}")
            if per > 1 and a.layer_split not in (None, "auto"):
                warn("--layer-split is one engine's value; with replicas every group would get it: leave it at auto")
            warn("each replica loads its own copy of the model's experts into RAM and runs its own host threads: "
                 "check that the RAM holds them")
    if draft_vocab:
        cfg["draft_vocab"] = draft_vocab
    if a.host:
        cfg["host"] = a.host
    if a.api_key:
        cfg["api_key"] = a.api_key
    if a.browser is not None:                          # #609: only when given (else an earlier choice is carried over)
        cfg["open_browser"] = a.browser
    # #465: requests at once - written only when given (else an earlier "parallel" is carried over); a recommendation
    streaming = "--kv-resident" in args
    if a.parallel is not None:
        if a.parallel >= 2:
            cfg["parallel"] = a.parallel
            batch_mtp = "--mtp" in args and "--no-batch-mtp" not in args   # as serve/server.py's parallel_args
            for i, line in enumerate(parallel_note(a.parallel, gpu_expert_vram(gpu), MODELS[model]["arena_gb"], ctx, kv,
                                                   streaming, batch_mtp)):
                (ok if i == 0 else warn)(line)
        else:
            cfg["parallel"] = 1
            ok("parallel requests: one at a time (--parallel 1)")
    else:                                              # the opt-in, said once (nothing changes)
        for line in parallel_note(None, gpu_expert_vram(gpu), MODELS[model]["arena_gb"], ctx, kv, streaming):
            say("  " + line)
    if vision != "none":
        vt = vision_tokens(a.vision_tokens, vision, CONF / f"xestrata-{tag.lower()}.json")
        cpu_enc = {"exe": str(eng / VEXE["cpu"]), "gpu": False,
                   "max_tokens": vt if vision == "cpu" else VISION["cpu"]["max_tokens"],
                   "threads": max(1, (os.cpu_count() or 8) // 2)}
        cfg["vision"] = {"mmproj": str(mmproj), "model": str(shards[0]), **cpu_enc}
        if vision == "gpu":
            # the GPU encoder takes the card by PCI address: with Vulkan the first GPU can be another card
            cfg["vision"] = {"mmproj": str(mmproj), "model": str(shards[0]), "exe": str(eng / VEXE[enc]),
                             "gpu": True, "gpu_pci": gpu["pci"], "max_tokens": vt,
                             "fallback": cpu_enc}   # the server starts it when the GPU encoder does not start
    elif a.vision_tokens is not None:
        warn("--vision-tokens: images are off for this model, so it is not used")
    if a.images:                                       # only when given: else an earlier "images" is carried over
        cfg["images"] = setup_images(a, gpu, Path(a.models_dir), Path(cfg["exe"]).parent,
                                     text_ram_gb(cfg["args"], ram, model))
    return finish_setup(a, cfg, tag, port, adopted, vision != "none")


if __name__ == "__main__":
    try:
        sys.exit(main())
    except KeyboardInterrupt:
        say("\nstopped.")
        sys.exit(1)
