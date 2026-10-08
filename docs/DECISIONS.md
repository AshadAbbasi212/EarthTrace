# Architectural Decisions & Deviations Log (docs/DECISIONS.md)

This document records all deviations from `PROJECT_BRIEF.md`, architectural decisions, and hardware/environmental constraints verified on the deployment system.

---

## 1. Python Runtime Selection: Python 3.11.9
- **Brief Specification:** Section 6 specifies Python 3.11 or 3.12.
- **Observed Reality:** The system default PATH had Python 3.14.6 installed, which has no stable binary PyTorch/torchvision/transformers wheels on Windows. A native Python 3.11.9 installation was discovered at `C:\Users\David\AppData\Local\Python\pythoncore-3.11-64\python.exe`.
- **Decision:** Dedicated `.venv` created strictly with Python 3.11.9 to ensure full binary wheel compatibility with PyTorch, CUDA, and ML dependencies.

---

## 2. Host GPU Hardware: NVIDIA Quadro M1200 (4 GB VRAM)
- **Brief Specification:** Section 2 and Section 7 target Windows + 8 GB VRAM.
- **Observed Reality:** `nvidia-smi` identifies the GPU as an NVIDIA Quadro M1200 (GM107/Maxwell architecture, Compute Capability 5.0) with **4,096 MiB (4 GB) VRAM**, running driver 582.53 and CUDA 13.0 driver support.
- **Implications & Decision:**
  - 4 GB VRAM is tighter than the 8 GB target in the brief.
  - The sequential single-model execution strategy (`ModelManager` with aggressive CUDA cache clearing and unloading) is essential.
  - VLM models will be configured with lightweight 4-bit / quantized checkpoints (e.g. Qwen2.5-VL-3B or 7B with CPU offload/4-bit quantization, or SmolVLM-Instruct) to prevent OOM.
  - Image long edges will be scaled conservatively (default 768px - 1024px) during VLM inference.
  - If PyTorch CUDA cannot run sm_50 kernels on newer PyTorch builds, CPU fallback will be seamlessly handled without crashing the pipeline worker.

---

## 3. Disabling Reverse Image Search (`revimg.py` in `intake.py`)
- **Brief Specification:** Section 4 states: *"Reverse image search in intake.py probably depends on an external service. If it needs a key or scraping, disable it and document that."* Section 2a: *"Sending photos or any user data to any third-party service: Not permitted."*
- **Observed Reality:** `revimg.py` uploads user photos or edge crops to Baidu and Yandex web search engines via Playwright browser automation.
- **Decision:** Reverse image search is completely disabled. `intake.py` runs with `--no-rev`. No user photos are ever sent to external search engines.

---

## 4. Street-Level Imagery Providers (`gsv.py`, `baidu_pano.py`, KartaView)
- **Brief Specification:** Section 2a: *"Google Street View, Mapillary and Baidu need keys or tokens, so they are not used (leave the vendored gsv.py and baidu_pano.py untouched and unused; do not add key slots for them). Keyless street-level coverage (e.g. KartaView, Wikimedia Commons geotagged photos; verify) is sparse... report 'not available' when no coverage."*
- **Observed Reality:**
  - `gsv.py` and `baidu_pano.py` remain untouched and unused.
  - `api.openstreetcam.org` (KartaView) was tested with live queries and returns HTTP 400 with `"Restricted access!"`, confirming anonymous public access is restricted.
  - Direct connection to `commons.wikimedia.org` is reset by local network, but Wikipedia Geosearch via `en.wikipedia.org/w/api.php` and thumbnail retrieval from `thumb.wikimedia.org` work 100% keyless and return geocoded photos.
- **Decision:**
  - KartaView is disabled due to restricted API access.
  - Street-level / ground photo provider uses Wikipedia/Wikimedia Geosearch (`en.wikipedia.org/w/api.php` + `thumb.wikimedia.org`).
  - Where no ground-level photos exist, the report honestly outputs `"not available"` and relies on DEM skyline horizon profiles and satellite tile verification.

---

## 5. Overpass API Endpoint Redundancy
- **Observed Reality:** Probing `https://overpass-api.de/api/status` succeeded with HTTP 200 (0.61s). Mirror `https://overpass.kumi.systems/api/status` returned HTTP 500.
- **Decision:** The OSM Overpass provider will use prioritized mirrors (`overpass-api.de`, `overpass.private.coffee`, `maps.mail.ru`) with fallback, local query-hash disk caching in `.geo-cache/osm/`, and exponential backoff.
