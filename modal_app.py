"""
Modal deployment for the pronunciation AI microservice (FastAPI / ASGI).

Development:
    modal serve modal_app.py

Production (does NOT deploy automatically — run explicitly):
    modal deploy modal_app.py

Notes / constraints (see MICROSERVICE_REPORT.md):
  * The SQLite database lives on a Modal Volume at /data/pronunciation_ai.db.
    Modal Volumes are not built for concurrent modification of one SQLite file,
    so this v1 runs single-writer: max_containers=1, one active input,
    600s request timeout. Move to PostgreSQL before scaling to many containers.
  * Secrets carry SERVICE_API_KEY and optional provider keys — never the .env.
  * The 378 MB model weight ships in its own cached image layer.
"""

from __future__ import annotations

import os
import sys
from pathlib import Path

import modal

APP_NAME = "pronunciation-ai-service"
APP_DIR = "/root/pronunciation-ai-service"
PROJECT_DIR = Path(__file__).resolve().parent
MODEL_DIR = PROJECT_DIR / "model" / "my_wav2vec2_phoneme_model"
MODEL_REMOTE_DIR = f"{APP_DIR}/model/my_wav2vec2_phoneme_model"

# Predictive OOV G2P (ByT5). Weights are baked into a cached image layer at
# build time so the running container never reaches the network. Keep this in
# sync with src/core/g2p/oov_g2p.py DEFAULT_MODEL.
HF_CACHE_DIR = "/opt/hf-cache"
OOV_G2P_MODEL = "charsiu/g2p_multilingual_byT5_tiny_16_layers_100"


def _bake_oov_g2p_model() -> None:
    """Download the ByT5 OOV G2P weights into the image's HF cache at build time."""
    import os as _os

    _os.environ["HF_HOME"] = HF_CACHE_DIR
    from transformers import AutoTokenizer, T5ForConditionalGeneration

    T5ForConditionalGeneration.from_pretrained(OOV_G2P_MODEL)
    # ByT5's byte tokenizer needs no vocab files; resolving it here just warms
    # the config so the runtime (offline) load never touches the network.
    try:
        AutoTokenizer.from_pretrained(OOV_G2P_MODEL)
    except Exception:
        from transformers import ByT5Tokenizer

        ByT5Tokenizer()

# Never upload local secrets, recordings, databases, caches, or test artifacts.
# The model is copied in its own cached layer, so source-only changes don't
# re-upload the weight.
IMAGE_IGNORES = [
    ".git", ".git/**",
    ".env", ".env.*", "!.env.example",
    ".pytest_cache", ".pytest_cache/**",
    "**/__pycache__", "**/__pycache__/**", "**/*.pyc",
    "tests", "tests/**",
    "pronunciation_ai.db", "pronunciation_ai.db-*", "pronunciation_ai.db.*",
    "uploads/**",
    "model/**",
]

runtime_image = (
    # DeepFilterLib 0.5.6 provides binary wheels through CPython 3.11. Using
    # 3.11 avoids compiling its Rust extension during image creation.
    modal.Image.debian_slim(python_version="3.11")
    # DeepFilterNet's startup logger shells out to git for build metadata.
    # NeMo's TTS extra may need native build tooling for text-normalization
    # dependencies when a compatible wheel is unavailable.
    .apt_install("ffmpeg", "git", "build-essential", "cmake", "ninja-build")
    .pip_install(
        "torch==2.11.0",
        "torchaudio==2.11.0",
        index_url="https://download.pytorch.org/whl/cpu",
    )
    .pip_install_from_requirements(str(PROJECT_DIR / "requirements-deploy.txt"))
    .env(
        {
            "PRONUNCIATION_DB_PATH": "/data/pronunciation_ai.db",
            "PRONUNCIATION_UPLOAD_DIR": "/tmp/pronunciation_uploads",
            "AUDIO_CLEANING_ENABLED": "1",
            "AUDIO_CLEANING_USE_GPU": "0",
            "AUDIO_CLEANING_KEEP_INTERMEDIATE_FILES": "0",
            "RETAIN_AUDIO": "0",
            "G2P_REQUIRE_NEMO": "1",
            "PYTHONUNBUFFERED": "1",
            # Predictive OOV G2P: enabled, with weights served from the baked
            # HF cache below.
            "OOV_G2P_ENABLED": "1",
            "OOV_G2P_MODEL": OOV_G2P_MODEL,
            "HF_HOME": HF_CACHE_DIR,
            # The Xet transfer backend can stall on unauthenticated pulls; use
            # the standard resolver for the deterministic build-time download.
            "HF_HUB_DISABLE_XET": "1",
        }
    )
    # Bake the ByT5 weights into their own cached layer (needs network at build
    # time only), then pin the runtime offline so a request never fetches.
    .run_function(_bake_oov_g2p_model)
    .env({"HF_HUB_OFFLINE": "1", "TRANSFORMERS_OFFLINE": "1"})
    .add_local_dir(str(MODEL_DIR), remote_path=MODEL_REMOTE_DIR, copy=True)
    .add_local_dir(str(PROJECT_DIR), remote_path=APP_DIR, copy=True, ignore=IMAGE_IGNORES)
)

app = modal.App(APP_NAME)
data_volume = modal.Volume.from_name("pronunciation-ai-data", create_if_missing=True)


@app.function(
    image=runtime_image,
    secrets=[modal.Secret.from_name("pronunciation-ai-secrets")],
    volumes={"/data": data_volume},
    cpu=1.0,
    memory=4096,
    timeout=600,
    scaledown_window=60,
    max_containers=1,
)
@modal.concurrent(max_inputs=1)
@modal.asgi_app()
def web():
    """Expose the FastAPI app at a public Modal HTTPS URL."""
    os.chdir(APP_DIR)
    if APP_DIR not in sys.path:
        sys.path.insert(0, APP_DIR)

    # Bootstrap (schema + seed) runs in the app's lifespan; explicitly commit
    # the Volume afterward so the seeded database is durable.
    from api.main import app as fastapi_app

    return fastapi_app
