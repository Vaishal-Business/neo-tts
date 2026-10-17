#!/usr/bin/env python3
"""
neo-tts v2 deploy script. Runs as __main__ (python or %run).

How audio stays gap-free on 2 vCPUs (the core idea of v2)
---------------------------------------------------------
TTS here runs slower than real time (wall seconds per audio second, "w", is
about 1.3-1.6 for PocketTTS). Any "start playing, hope the buffer holds"
strategy underruns. But underrun is predictable. After the LLM finishes, the
full text is known, so the server can estimate how long every remaining
sentence will take to synthesise (wall) and how much audio it will produce.
Playback may start the moment, for EVERY remaining sentence j:

    audio_buffered + sum(audio of sentences before j)  >=  safety * sum(wall of sentences up to j) + lead

That is the earliest start that is still provably gap-free under the
estimate. With w=1.43 this starts audio after ~30% of the synthesis instead
of 100% (pure smooth mode), and with a fast backend (Kokoro, w<1) it starts
after the first sentence. The safety factor self-tunes: the client reports
late chunks (underruns) and the server raises safety; clean turns lower it.
smooth mode (one AudioBuffer, zero risk) remains available per request.
"""
import os, sys, re, io, json, time, glob, base64, shutil, threading, subprocess, queue, collections, concurrent.futures
import importlib.util, urllib.request, urllib.error
from pathlib import Path

# Learned the hard way: progress bars leave Jupyter cells in "partial line" state.
os.environ.setdefault("HF_HUB_DISABLE_PROGRESS_BARS", "1")
os.environ.setdefault("TQDM_DISABLE", "1")
os.environ.setdefault("TOKENIZERS_PARALLELISM", "false")
# Match the 2 physical vCPUs; more threads = context switching.
for _k in ("OMP_NUM_THREADS", "OPENBLAS_NUM_THREADS", "MKL_NUM_THREADS"):
    os.environ.setdefault(_k, "2")

def _env(n, d):
    return os.environ.get(n, d)

# ----- config (model is config, not a constant) -----
PORT = int(_env("NEO_PORT", "8000"))
MODEL_REPO = _env("NEO_MODEL_REPO", "unsloth/Llama-3.2-1B-Instruct-GGUF")
MODEL_FILE = _env("NEO_MODEL_FILE", "Llama-3.2-1B-Instruct-Q4_K_M.gguf")
# Size gate: a truncated GGUF (interrupted copy / Drive sync) makes the model
# emit immediate EOS = "0 tok/s". For Qwen2.5-0.5B Q4_K_M (~400 MB) set NEO_MODEL_MIN_MB=350.
MODEL_MIN_BYTES = int(float(_env("NEO_MODEL_MIN_MB", "700")) * 1e6)
AUDIO_MODE = _env("NEO_AUDIO_MODE", "adaptive").lower()
TTS_BACKEND = _env("NEO_TTS_BACKEND", "pocket").lower()   # pocket (your voice, auto-tuned) | auto | kokoro
KOKORO_VOICE = _env("NEO_KOKORO_VOICE", "af_heart")
MAX_TURNS = 10            # rolling window of user/assistant pairs
MAX_TOKENS = int(_env("NEO_MAX_TOKENS", "90"))
PAD_S = 0.10              # silence between sentences
LEAD_S = float(_env("NEO_LEAD_S", "0.8"))   # extra cushion for tunnel jitter
SAFETY0, SAFETY_MIN, SAFETY_MAX = 1.3, 1.15, 2.5
MAX_SENT_CHARS = 220

SYSTEM_PROMPT = (
    "You are Neo, a voice assistant. Your replies are spoken aloud. "
    "Reply in one or two short sentences, under thirty words in total, unless the person explicitly asks for more. "
    "Use plain spoken English only. Never use markdown, lists, headings, asterisks, emojis, code, or URLs. "
    "Write numbers and symbols as words."
)

_T0 = time.time()
def log(msg):
    print(f"[{time.time() - _T0:6.1f}s] {msg}", flush=True)

try:
    HERE = Path(__file__).resolve().parent
except NameError:
    HERE = Path.cwd()

# ===== PATHS / DRIVE =====
def resolve_state_dir():
    if not os.path.isdir("/content/drive/MyDrive"):
        try:
            from google.colab import drive  # guarded: same script must run in a local venv
            drive.mount("/content/drive")
        except ImportError:
            log("not on Colab; using local cache dir instead of Drive")
        except Exception as e:
            log(f"Drive mount failed: {e!r}; using local cache dir")
    base = Path("/content/drive/MyDrive") if os.path.isdir("/content/drive/MyDrive") else Path.home() / ".neo_tts_drive"
    d = base / "neo-tts"
    d.mkdir(parents=True, exist_ok=True)
    return d

STATE_DIR = resolve_state_dir()
MODELS_DRIVE = STATE_DIR / "models"
WHEELS_DRIVE = STATE_DIR / "wheels"
LOCAL_MODELS = Path("/content/neo_tts_models") if os.path.isdir("/content") else Path("/tmp/neo_tts_models")
URL_FILE = Path("/content/.neo_tts_url.txt") if os.path.isdir("/content") else Path("/tmp/.neo_tts_url.txt")
for _d in (MODELS_DRIVE, WHEELS_DRIVE, LOCAL_MODELS):
    _d.mkdir(parents=True, exist_ok=True)

def atomic_copy(src, dst):
    """Copy to .part, verify size, then rename. Root-cause fix for truncated GGUFs."""
    dst = Path(dst)
    dst.parent.mkdir(parents=True, exist_ok=True)
    tmp = dst.with_name(dst.name + ".part")
    shutil.copyfile(src, tmp)
    if os.path.getsize(tmp) != os.path.getsize(src):
        raise IOError(f"short copy {src} -> {dst}")
    os.replace(tmp, dst)

def download(url, dst, min_bytes=0):
    dst = Path(dst)
    tmp = dst.with_name(dst.name + ".part")
    with urllib.request.urlopen(url, timeout=60) as r, open(tmp, "wb") as f:
        total = int(r.headers.get("Content-Length") or 0)
        got = 0
        while True:
            b = r.read(4 << 20)
            if not b:
                break
            f.write(b)
            got += len(b)
    if (total and got != total) or got < min_bytes:
        raise IOError(f"incomplete download {url}: {got}/{total} bytes")
    os.replace(tmp, dst)

def pip(*args):
    return subprocess.run([sys.executable, "-m", "pip", "install", "-q", "--disable-pip-version-check", *args],
                          check=False, capture_output=True, text=True)

def run_with_heartbeat(cmd, env, label, every=30):
    lp = Path("/tmp") / (label.replace(" ", "_") + ".log")
    with open(lp, "w") as lf:
        p = subprocess.Popen(cmd, env=env, stdout=lf, stderr=subprocess.STDOUT)
        t = time.time()
        while p.poll() is None:
            time.sleep(2)
            if time.time() - t >= every:
                log(f"{label}: still running ({int(time.time() - _T0)}s elapsed)")
                t = time.time()
    return p.returncode, lp.read_text(errors="ignore")[-1500:]

# ===== LLAMA-CPP (cached wheel first, source build fallback) =====
def llama_ok():
    # Subprocess check: an illegal-instruction crash must not kill the kernel.
    r = subprocess.run([sys.executable, "-c", "import llama_cpp"], check=False, capture_output=True, text=True)
    return r.returncode == 0

def ensure_llama():
    if llama_ok():
        log("llama_cpp already importable")
        return
    for d in (WHEELS_DRIVE, HERE / "wheels"):
        if d.is_dir() and glob.glob(str(d / "llama_cpp_python-*.whl")):
            r = pip("--no-index", "--no-deps", "--find-links", str(d), "llama-cpp-python")
            pip("diskcache", "jinja2", "numpy", "typing-extensions")
            if r.returncode == 0 and llama_ok():
                log(f"installed llama_cpp from cached wheel in {d}")
                return
            log(f"cached wheel in {d} unusable: {r.stderr[-300:]}")
    log("no usable cached wheel; building from source (5-10 min, first boot only)")
    subprocess.run(["apt-get", "install", "-y", "-qq", "libopenblas-dev", "pkg-config"],
                   check=False, capture_output=True)
    # DEVIATION from the old design: GGML_NATIVE=OFF + explicit AVX2/FMA/F16C.
    # Colab hands out different CPU models; a -march=native wheel cached on Drive
    # can SIGILL on a different host. Explicit flags give the same AVX2 kernels
    # (no SSE fallback) and the wheel stays portable. Both GGML_* and legacy
    # LLAMA_* BLAS names are passed because llama.cpp renamed them.
    cmake = ("-DGGML_BLAS=ON -DGGML_BLAS_VENDOR=OpenBLAS -DLLAMA_BLAS=ON -DLLAMA_BLAS_VENDOR=OpenBLAS "
             "-DGGML_NATIVE=OFF -DGGML_AVX=ON -DGGML_AVX2=ON -DGGML_FMA=ON -DGGML_F16C=ON")
    env = dict(os.environ, CMAKE_ARGS=cmake, FORCE_CMAKE="1", CMAKE_BUILD_PARALLEL_LEVEL="2")
    wh = Path("/tmp/neo_wheelhouse")
    shutil.rmtree(wh, ignore_errors=True)
    wh.mkdir(parents=True)
    rc, tail = run_with_heartbeat([sys.executable, "-m", "pip", "wheel", "--no-cache-dir", "--no-deps",
                                   "-w", str(wh), "llama-cpp-python"], env, "llama build")
    wheels = glob.glob(str(wh / "llama_cpp_python-*.whl"))
    if rc != 0 or not wheels:
        raise RuntimeError(f"llama-cpp-python build failed:\n{tail}")
    pip("--no-index", "--no-deps", "--find-links", str(wh), "llama-cpp-python")
    pip("diskcache", "jinja2", "numpy", "typing-extensions")
    if not llama_ok():
        raise RuntimeError("llama_cpp built but not importable")
    for w in wheels:
        shutil.copy2(w, WHEELS_DRIVE / Path(w).name)
        if os.path.getsize(w) < 95e6:  # GitHub hard limit is 100 MB per file
            try:
                (HERE / "wheels").mkdir(exist_ok=True)
                shutil.copy2(w, HERE / "wheels" / Path(w).name)
            except OSError as e:
                log(f"could not copy wheel into repo dir: {e!r}")
        else:
            log("wheel >95 MB: cached on Drive only (too big for plain git)")
    log("wheel cached to Drive (next boot installs in ~10 s)")

def ensure_py_deps():
    need = []
    for mod, pkg in (("fastapi", "fastapi"), ("uvicorn", "uvicorn"), ("numpy", "numpy"), ("pocket_tts", "pocket-tts")):
        if importlib.util.find_spec(mod) is None:
            need.append(pkg)
    if TTS_BACKEND in ("kokoro", "auto") and importlib.util.find_spec("kokoro_onnx") is None:
        need.append("kokoro-onnx")
    if need:
        log(f"pip installing: {' '.join(need)}")
        r = pip(*need)
        if r.returncode != 0:
            raise RuntimeError(f"pip failed: {r.stderr[-500:]}")

def ensure_cloudflared():
    cf = shutil.which("cloudflared")
    if cf:
        return cf
    cached = STATE_DIR / "bin" / "cloudflared"
    dst = Path("/usr/local/bin/cloudflared")
    try:
        if not cached.exists():
            cached.parent.mkdir(parents=True, exist_ok=True)
            download("https://github.com/cloudflare/cloudflared/releases/latest/download/cloudflared-linux-amd64",
                     cached, 10_000_000)
        shutil.copyfile(cached, dst)
        os.chmod(dst, 0o755)
        return str(dst)
    except Exception as e:
        raise RuntimeError(f"cloudflared unavailable: {e!r}")

# ===== GGUF RESOLUTION (priority order matters) =====
def good(p):
    return p.is_file() and p.stat().st_size >= MODEL_MIN_BYTES

def resolve_gguf():
    local = LOCAL_MODELS / MODEL_FILE
    # Exact filename only: a stale GGUF of a different model must never be picked up.
    for p in (local, HERE / "models" / MODEL_FILE):          # 1. session-local / LFS clone
        if good(p):
            log(f"GGUF: session-local {p}")
            return p
        if p.is_file():
            log(f"GGUF {p} is too small ({p.stat().st_size} B): truncated, ignoring")
    d = MODELS_DRIVE / MODEL_FILE                              # 2. Drive cache (fast path)
    if good(d):
        log("GGUF: copying from Drive cache")
        atomic_copy(d, local)
        return local
    log("GGUF: downloading from HuggingFace")                 # 3. HF, then cache to Drive
    download(f"https://huggingface.co/{MODEL_REPO}/resolve/main/{MODEL_FILE}", local, MODEL_MIN_BYTES)
    if not good(local):
        raise RuntimeError("downloaded GGUF failed size check")
    try:
        atomic_copy(local, d)
        log("GGUF cached to Drive")
    except Exception as e:
        log(f"could not cache GGUF to Drive: {e!r}")
    return local

# ===== TTS BACKENDS (pluggable) =====
import numpy as np

class TTSBackend:
    name = "base"
    sample_rate = 24000
    parallel = 1            # how many sentences can be synthesised at once
    @property
    def executor(self):
        if not hasattr(self, "_ex"):
            self._ex = concurrent.futures.ThreadPoolExecutor(max_workers=self.parallel)
        return self._ex
    def load(self): raise NotImplementedError
    def synth(self, text):  # -> float32 mono ndarray
        raise NotImplementedError
    def close(self): pass

def find_voice():
    for p in (HERE / "voice.safetensors", Path("/content/neo-tts/voice.safetensors"), STATE_DIR / "voice.safetensors"):
        if p.is_file() and p.stat().st_size > 1000:
            return p
    return None

def _to_np(a):
    return np.asarray(a.detach().cpu().numpy() if hasattr(a, "detach") else a, dtype=np.float32).reshape(-1)

class PocketBackend(TTSBackend):
    """One in-process model. quant=int8 or fp32, threads=torch intra-op threads."""
    def __init__(self, quant=True, threads=2):
        self.quant, self.threads = quant, threads
        self.name = f"pocket-tts ({'int8' if quant else 'fp32'}, {threads} threads)"
    def load(self):
        import torch
        torch.set_num_threads(self.threads)
        from pocket_tts import TTSModel
        if self.quant:
            try:
                self.model = TTSModel.load_model(quantize=True)
            except TypeError as e:
                log(f"load_model(quantize=True) unsupported ({e}); loading fp32")
                self.model = TTSModel.load_model()
        else:
            self.model = TTSModel.load_model()
        vp = find_voice()
        if vp is None:
            log("WARNING: voice.safetensors not found; using the built-in default voice")
            self.voice = self.model.get_state_for_audio_prompt("alba")
        else:
            self.voice = self.model.get_state_for_audio_prompt(str(vp))
        self.sample_rate = int(self.model.sample_rate)
    def synth(self, text):
        import torch
        torch.set_num_threads(self.threads)
        return _to_np(self.model.generate_audio(self.voice, text))
    def close(self):
        self.model = None

# Worker for PocketPoolBackend. Separate PROCESSES, not threads: one autoregressive stream scales
# poorly past 1 thread (tiny matrices, sync overhead), so two single-thread processes working on
# two sentences give close to 2x aggregate throughput on 2 vCPUs. A subprocess (not multiprocessing)
# is used because spawn cannot import functions defined in a notebook's __main__.
_POCKET_WORKER_SRC = r"""
import sys, json
proto = sys.stdout.buffer
sys.stdout = sys.stderr          # library prints must never corrupt the binary protocol
import numpy as np, torch
torch.set_num_threads(1)
voice, quant = sys.argv[1], sys.argv[2] == "1"
from pocket_tts import TTSModel
try:
    model = TTSModel.load_model(quantize=True) if quant else TTSModel.load_model()
except TypeError:
    model = TTSModel.load_model()
state = model.get_state_for_audio_prompt(voice)
proto.write((json.dumps({"ready": True, "sr": int(model.sample_rate)}) + "\n").encode()); proto.flush()
for line in sys.stdin:
    try:
        a = model.generate_audio(state, json.loads(line)["text"])
        a = np.asarray(a.detach().cpu().numpy() if hasattr(a, "detach") else a, dtype=np.float32).reshape(-1)
        proto.write((json.dumps({"n": int(a.size)}) + "\n").encode()); proto.write(a.tobytes())
    except Exception as e:
        proto.write((json.dumps({"error": repr(e)}) + "\n").encode())
    proto.flush()
"""

class PocketPoolBackend(TTSBackend):
    def __init__(self, n=2, quant=True):
        self.n, self.quant, self.parallel = n, quant, n
        self.name = f"pocket-tts ({'int8' if quant else 'fp32'}, {n} procs x 1 thread)"
    def load(self):
        wp = Path("/tmp/neo_pocket_worker.py")
        wp.write_text(_POCKET_WORKER_SRC)
        vp = find_voice()
        if vp is None:
            log("WARNING: voice.safetensors not found; using the built-in default voice")
        env = dict(os.environ, OMP_NUM_THREADS="1", MKL_NUM_THREADS="1", OPENBLAS_NUM_THREADS="1")
        self.procs, self.free = [], queue.Queue()
        for k in range(self.n):   # start all first so the models load in parallel
            err = open(f"/tmp/neo_pocket_worker_{k}.log", "w")
            p = subprocess.Popen([sys.executable, str(wp), str(vp) if vp else "alba", "1" if self.quant else "0"],
                                 stdin=subprocess.PIPE, stdout=subprocess.PIPE, stderr=err, env=env)
            self.procs.append(p)
        for k, p in enumerate(self.procs):
            line = p.stdout.readline()
            if not line:
                tail = Path(f"/tmp/neo_pocket_worker_{k}.log").read_text(errors="ignore")[-600:]
                raise RuntimeError(f"pocket worker {k} died on startup: {tail}")
            self.sample_rate = int(json.loads(line)["sr"])
            self.free.put(p)
    def synth(self, text):
        p = self.free.get()
        try:
            p.stdin.write((json.dumps({"text": text}) + "\n").encode()); p.stdin.flush()
            hdr = p.stdout.readline()
            if not hdr:
                raise RuntimeError("pocket worker died mid-synthesis")
            h = json.loads(hdr)
            if "error" in h:
                raise RuntimeError(h["error"])
            need = h["n"] * 4
            buf = p.stdout.read(need)
            if len(buf) != need:
                raise RuntimeError("short read from pocket worker")
            return np.frombuffer(buf, dtype=np.float32).copy()
        finally:
            self.free.put(p)
    def close(self):
        for p in getattr(self, "procs", []):
            try:
                p.kill()
            except OSError as e:
                log(f"worker kill: {e!r}")

class KokoroBackend(TTSBackend):
    name = "kokoro-82m-int8"
    def load(self):
        from kokoro_onnx import Kokoro
        base = "https://github.com/thewh1teagle/kokoro-onnx/releases/download/model-files-v1.0/"
        files = {"kokoro-v1.0.int8.onnx": 60_000_000, "voices-v1.0.bin": 10_000_000}
        for fn, mn in files.items():
            p = MODELS_DRIVE / fn
            if not (p.is_file() and p.stat().st_size >= mn):
                log(f"downloading {fn}")
                download(base + fn, p, mn)
        self.k = Kokoro(str(MODELS_DRIVE / "kokoro-v1.0.int8.onnx"), str(MODELS_DRIVE / "voices-v1.0.bin"))
        self.sample_rate = 24000
    def synth(self, text):
        s, sr = self.k.create(text, voice=KOKORO_VOICE, speed=1.0, lang="en-us")
        self.sample_rate = int(sr)
        return np.asarray(s, dtype=np.float32).reshape(-1)

def make_backend():
    if TTS_BACKEND == "kokoro":
        try:
            b = KokoroBackend(); b.load(); return b
        except Exception as e:
            log(f"kokoro failed ({e!r}); falling back to pocket-tts")
    b = PocketBackend(); b.load(); return b

# ===== TEXT HELPERS =====
_SPLIT = re.compile(r"(?<=[.!?])\s+|\n+")
_EMOJI = re.compile("[\U0001F000-\U0001FFFF\u2600-\u27BF\uFE0F]")

def clean_for_tts(t):
    t = re.sub(r"```.*?```", " ", t, flags=re.S)
    t = re.sub(r"https?://\S+", "link", t)
    t = _EMOJI.sub("", t)
    t = re.sub(r"[*_#`>~|]", " ", t)
    return re.sub(r"\s+", " ", t).strip()

def split_sentences(t):
    out, carry = [], ""
    for s in _SPLIT.split(t):
        s = (carry + " " + s).strip() if carry else s.strip()
        carry = ""
        while len(s) > MAX_SENT_CHARS:
            cut = max(s.rfind(", ", 0, MAX_SENT_CHARS), s.rfind(" ", 0, MAX_SENT_CHARS))
            if cut < 40:
                cut = MAX_SENT_CHARS
            out.append(s[:cut + 1].strip())
            s = s[cut + 1:].strip()
        if not s:
            continue
        # tiny fragments ("Ok.") cost a full synth call and sound choppy: merge into a neighbour
        if len(s) < 14:
            if out:
                out[-1] += " " + s
            else:
                carry = s
        else:
            out.append(s)
    if carry:
        out.append(carry)
    return [s for s in out if re.search(r"[A-Za-z0-9]", s)]

def pcm_b64(x):
    x = np.clip(np.nan_to_num(x), -1.0, 1.0)
    return base64.b64encode((x * 32767).astype("<i2").tobytes()).decode()

# ===== PACE ESTIMATOR (the gap-free start gate) =====
class Pace:
    def __init__(self):
        self.spc = 0.065      # audio seconds per character
        self.wpc = 0.09       # wall seconds of synthesis per character (measured under real contention)
        self.lcps = 18.0      # characters per second the LLM writes
        self.reply = 120.0    # typical reply length in characters (EMA)
        self.safety = SAFETY0
        self.lock = threading.Lock()
    def seed(self, chars, audio_s, wall_s):
        with self.lock:
            self.spc = min(max(audio_s / chars, 0.03), 0.12)
            self.wpc = min(max(wall_s / chars, 0.005), 0.4)
    def gate(self, buffered, rem_chars, speech_done, chars_done, wall_done, future_chars=0):
        """True if starting playback now cannot underrun, under the estimate.
        rem_chars: sentences already written but not yet synthesised.
        future_chars: text the LLM has not written yet, modelled as 90-char chunks that arrive at LLM speed."""
        with self.lock:
            spc, wpc, sf, lcps = self.spc, self.wpc, self.safety, max(self.lcps, 5.0)
        if chars_done > 0:
            lam = min(1.0, chars_done / 60.0) * 0.8   # trust this turn's own measurements more as they accrue
            spc = (1 - lam) * spc + lam * (speech_done / chars_done)
            wpc = (1 - lam) * wpc + lam * (wall_done / chars_done)
        t, avail = 0.0, buffered
        for c in rem_chars:
            t += sf * wpc * c            # wall time until this sentence's audio arrives
            if avail < t + LEAD_S:       # playback would have run dry before it arrives
                return False
            avail += spc * c + PAD_S
        text_t, left = 0.0, future_chars
        while left > 0:
            c = min(left, 90); left -= c
            text_t += sf * c / lcps      # LLM has to write the chunk first
            t = max(t, text_t) + sf * wpc * c
            if avail < t + LEAD_S:
                return False
            avail += spc * c + PAD_S
        return avail >= LEAD_S
    def update(self, chars, speech, wall):
        if chars < 20 or speech <= 0:
            return
        with self.lock:
            self.spc = 0.6 * self.spc + 0.4 * (speech / chars)
            self.wpc = 0.6 * self.wpc + 0.4 * (wall / chars)
    def update_llm(self, chars, secs):
        if chars < 20 or secs <= 0:
            return
        with self.lock:
            self.lcps = 0.6 * self.lcps + 0.4 * (chars / secs)
    def feedback(self, late):
        with self.lock:
            if late > 0:
                self.safety = min(SAFETY_MAX, self.safety + 0.2)
            else:
                self.safety = max(SAFETY_MIN, self.safety - 0.03)
            return self.safety

# ===== GLOBAL STATE =====
LLM = None
TTS = None
HISTORY = [{"role": "system", "content": SYSTEM_PROMPT}]
PACE = Pace()
TURN_LOCK = threading.Lock()   # LLM and TTS share 2 vCPUs: never run them concurrently
CANCEL = threading.Event()
SERVER = None
_FRESH = False
TTS_SERIAL = False
FILLERS = []

def reset_history():
    HISTORY[:] = [{"role": "system", "content": SYSTEM_PROMPT}]

def load_llm(path):
    from llama_cpp import Llama
    kw = dict(model_path=str(path), n_ctx=4096, n_threads=2, n_threads_batch=2,
              n_batch=256, n_ubatch=128, flash_attn=False,   # flash_attn is a GPU/Metal flag; never enable on CPU
              use_mmap=True, use_mlock=True, verbose=False)
    try:
        return Llama(**kw)
    except Exception as e:
        log(f"Llama() failed with mlock ({e!r}); retrying without use_mlock")
        kw["use_mlock"] = False
        return Llama(**kw)

def boot_models():
    global LLM, TTS
    # pip work is serialised in one thread (concurrent pip corrupts site-packages);
    # GGUF + cloudflared fetch run in parallel with it to hit the 60 s target.
    res = {}
    def t_pip():
        try:
            ensure_llama(); ensure_py_deps(); res["pip"] = True
        except Exception as e:
            res["pip"] = e
    def t_assets():
        try:
            res["gguf"] = resolve_gguf(); res["cf"] = ensure_cloudflared()
        except Exception as e:
            res["assets"] = e
    th = [threading.Thread(target=t_pip), threading.Thread(target=t_assets)]
    for t in th: t.start()
    for t in th: t.join()
    for k in ("pip", "assets"):
        if isinstance(res.get(k), Exception):
            raise res[k]
    log("loading LLM")
    LLM = load_llm(res["gguf"])
    # prewarm LLM: 1-token completion, then reset history (first real TTFT drops 3-4 s)
    LLM.create_chat_completion(messages=[HISTORY[0], {"role": "user", "content": "hi"}], max_tokens=1)
    reset_history()
    log("selecting TTS backend")
    TTS, ratio = select_tts()
    finalize_tts(ratio)
    try:
        FILLERS[:] = build_fillers()
    except Exception as e:
        log(f"fillers unavailable: {e!r}")

def _measure(b):
    """Returns (chars, audio_seconds, wall_seconds_per_stream). With P parallel workers, wall is divided by P:
    it is the aggregate throughput that decides whether playback can keep up."""
    probe = "This is a short test of the voice engine."
    P = max(1, b.parallel)
    for f in [b.executor.submit(b.synth, "Hello.") for _ in range(P)]:   # first call pays one-off graph cost
        f.result()
    t = time.perf_counter()
    outs = [f.result() for f in [b.executor.submit(b.synth, probe) for _ in range(P)]]
    wall = (time.perf_counter() - t) / P
    return len(probe), len(outs[0]) / b.sample_rate, wall

def _cpu_key():
    try:
        for l in open("/proc/cpuinfo"):
            if l.startswith("model name"):
                return l.split(":", 1)[1].strip()
    except OSError as e:
        log(f"cpuinfo unreadable: {e!r}")
    return "unknown"

def tune_pocket():
    """Find the fastest way to run YOUR voice on THIS CPU. Candidates differ in int8 vs fp32 (int8 can be
    slower at batch 1) and in-process threads vs two single-thread worker processes. First boot tries them
    (about a minute); the winner is cached on Drive per CPU model, later boots load only the winner."""
    cands = {"pool2_int8": lambda: PocketPoolBackend(2, True), "inproc_int8": lambda: PocketBackend(True, 2),
             "pool2_fp32": lambda: PocketPoolBackend(2, False), "inproc_fp32": lambda: PocketBackend(False, 2)}
    tf, key, cached = STATE_DIR / "pocket_tuning.json", _cpu_key(), None
    try:
        cached = json.loads(tf.read_text())
    except FileNotFoundError:
        pass
    except ValueError as e:
        log(f"tuning cache unreadable: {e!r}")
    if cached and cached.get("cpu") == key and cached.get("best") in cands:
        b = cands[cached["best"]](); b.load()
        log(f"pocket-tts variant from cache: {b.name}")
        return b, _measure(b)
    log("first boot on this CPU: benchmarking pocket-tts variants (cached afterwards)")
    best, results = None, {}
    for name, mk in cands.items():
        try:
            b = mk(); b.load(); m = _measure(b)
        except Exception as e:
            log(f"variant {name} failed: {e!r}")
            continue
        ratio = m[2] / m[1]; results[name] = round(ratio, 2)
        log(f"  {b.name}: wall/audio = {ratio:.2f}")
        if best is None or ratio < best[0]:
            if best: best[2].close()
            best = (ratio, name, b, m)
        else:
            b.close()
        if ratio <= 0.5:
            break
    if best is None:
        raise RuntimeError("no pocket-tts variant could be loaded")
    try:
        tf.write_text(json.dumps({"cpu": key, "best": best[1], "ratios": results}))
    except OSError as e:
        log(f"could not write tuning cache: {e!r}")
    return best[2], best[3]

def finalize_tts(ratio):
    """Adapt the whole pipeline to how fast the voice really is."""
    global TTS_SERIAL, SYSTEM_PROMPT, MAX_TOKENS
    # Default: speak WHILE the LLM streams (overlap). The adaptive gate decides when it is safe to start;
    # Live mode starts at the first chunk. NEO_SERIAL=1 forces the old "wait for the full text first"
    # behaviour, which is exact but silent until the LLM finishes.
    TTS_SERIAL = os.environ.get("NEO_SERIAL", "0") == "1" and ratio > 0.55
    if ratio > 1.0:
        # Slower than real time: audio length is the cost, so keep replies to one short sentence.
        SYSTEM_PROMPT = SYSTEM_PROMPT.replace("one or two short sentences, under thirty words in total",
                                              "one short sentence, under fifteen words")
        MAX_TOKENS = min(MAX_TOKENS, 48)
        reset_history()
    log(f"pipeline: serial={TTS_SERIAL}, max_tokens={MAX_TOKENS}, parallel voice workers={TTS.parallel}")

FILLER_TEXTS = ["Okay.", "Sure thing.", "Let me see."]

def build_fillers():
    """Short acknowledgements in YOUR voice, rendered once and cached on Drive. The browser plays one the
    instant you send, so sound starts at 0 ms even though the real answer takes seconds to prepare."""
    import hashlib
    vp = find_voice()
    h = hashlib.sha1(vp.read_bytes() if vp else b"default"); h.update(TTS.name.encode())
    cache = STATE_DIR / f"fillers_{h.hexdigest()[:12]}.json"
    try:
        return json.loads(cache.read_text())
    except FileNotFoundError:
        pass
    except ValueError as e:
        log(f"filler cache unreadable: {e!r}")
    outl = []
    for f in [TTS.executor.submit(TTS.synth, t) for t in FILLER_TEXTS]:
        pcm = f.result()
        outl.append({"sr": TTS.sample_rate, "dur": len(pcm) / TTS.sample_rate, "pcm": pcm_b64(pcm)})
    try:
        cache.write_text(json.dumps(outl))
    except OSError as e:
        log(f"could not cache fillers: {e!r}")
    return outl

def select_tts():
    """pocket (default): your custom voice, auto-tuned for speed. kokoro: forced Kokoro.
    auto: pocket, but fall back to Kokoro if even the tuned pocket is slower than ~0.9x real time."""
    if TTS_BACKEND == "kokoro":
        b = make_backend()
        c, a, w = _measure(b); PACE.seed(c, a, w)
        log(f"TTS {b.name}: wall/audio = {w/a:.2f}")
        return b, w / a
    b, (c, a, w) = tune_pocket()
    ratio = w / a
    log(f"TTS {b.name}: aggregate wall/audio = {ratio:.2f} (<1.0 = faster than real time)")
    if TTS_BACKEND == "auto" and ratio > 0.9:
        log("pocket-tts still too slow to stream gap-free next to the LLM; trying Kokoro")
        try:
            k = KokoroBackend(); k.load()
            kc, ka, kw = _measure(k)
            if kw / ka < ratio:
                log(f"USING {k.name} ({kw/ka:.2f}); voice is Kokoro '{KOKORO_VOICE}', not your custom voice")
                b.close(); PACE.seed(kc, ka, kw)
                return k, kw / ka
            log("Kokoro was not faster; keeping pocket-tts")
        except Exception as e:
            log(f"Kokoro unavailable ({e!r}); keeping pocket-tts")
    PACE.seed(c, a, w)
    return b, ratio

# ===== THE TURN PIPELINE (LLM -> sentences -> TTS -> client, all overlapped) =====
_BOUND = re.compile(r"[.!?][\"')\]]*\s")

def _emit_ready(buf, sq, st):
    """Move completed sentences out of the streaming text buffer into the TTS queue.
    The FIRST chunk of a turn may be cut at a comma (28+ chars) so speech can start while the LLM is still writing."""
    def put(txt):
        for s in split_sentences(clean_for_tts(txt)):
            sq.put(s); st["sent"] += 1
    pos = 0
    while True:
        m = _BOUND.search(buf, pos)
        if not m:
            break
        if len(buf[:m.end()].strip()) >= 14:    # too-short fragments ("Ok.") wait for the next boundary
            put(buf[:m.end()]); buf = buf[m.end():]; pos = 0
        else:
            pos = m.end()
    if st["sent"] == 0 and len(buf) >= 28:
        cut = buf.rfind(", ")
        if cut >= 20:
            put(buf[:cut + 1]); buf = buf[cut + 1:]
    if len(buf) > 160:                          # long run without punctuation: cut at a comma
        cut = buf.rfind(", ", 0, 160)
        if cut > 40:
            put(buf[:cut + 1]); buf = buf[cut + 1:]
    return buf

def turn_events(user_text, mode, tts_on, max_tokens):
    """Three cooperating threads per turn: LLM producer -> TTS worker -> this generator (to the client).
    Sentences are synthesised while the LLM is still writing. Playback is released by PACE.gate, which
    accounts for text the LLM has not written yet. Everything funnels through one queue so the NDJSON
    stream stays ordered."""
    t_req = time.perf_counter()
    with TURN_LOCK:
        CANCEL.clear()
        while len(HISTORY) - 1 >= MAX_TURNS * 2:   # rolling window; system prompt stays at index 0
            del HISTORY[1:3]
        HISTORY.append({"role": "user", "content": user_text})
        out, sq = queue.Queue(), queue.Queue()
        parts = []
        st = {"committed": False, "clean_end": False, "llm_done": False, "chars": 0, "ntok": 0,
              "t_first": None, "t_llm_end": None, "tts_wall": 0.0, "speech": 0.0, "chars_done": 0,
              "go_s": None, "stream": None, "sent": 0}

        def llm_worker():
            buf = ""
            try:
                # Full growing history: llama.cpp reuses the KV prefix, past turns are never re-tokenised.
                st["stream"] = LLM.create_chat_completion(messages=HISTORY, stream=True, max_tokens=max_tokens,
                                                          temperature=0.6, top_p=0.9, repeat_penalty=1.1)
                for ch in st["stream"]:
                    if CANCEL.is_set():
                        break
                    d = ch["choices"][0]["delta"].get("content")
                    if not d:
                        continue
                    if st["t_first"] is None:
                        st["t_first"] = time.perf_counter()
                    parts.append(d); st["ntok"] += 1; st["chars"] += len(d)
                    out.put({"type": "text", "delta": d})
                    if tts_on:
                        buf = _emit_ready(buf + d, sq, st)
                st["t_llm_end"] = time.perf_counter()
                text = "".join(parts).strip()
                if text:
                    HISTORY.append({"role": "assistant", "content": text}); st["committed"] = True
                if tts_on and not CANCEL.is_set():
                    for s in split_sentences(clean_for_tts(buf)):
                        sq.put(s)
            except Exception as e:
                print(f"[llm] failed: {e!r}", flush=True)
                out.put({"type": "error", "message": f"llm failed: {e!r}"})
            finally:
                st["llm_done"] = True        # set AFTER the tail flush so the gate never misses queued text
                sq.put(None)
                if not tts_on:
                    out.put(("_end",))

        def tts_worker():
            pcms, buffered, went, sr, last_k = [], 0.0, False, TTS.sample_rate, -1
            P = max(1, TTS.parallel)
            inflight, eof, idx = collections.deque(), False, 0
            def timed(text):
                t = time.perf_counter(); p = TTS.synth(text); return p, time.perf_counter() - t
            try:
                while not CANCEL.is_set():
                    if TTS_SERIAL and not st["llm_done"]:
                        time.sleep(0.05)       # slow voice: let the LLM have both cores; text is then fully known
                        continue
                    while not eof and len(inflight) < P:     # keep every voice worker busy
                        try:
                            item = sq.get(timeout=0.05) if not inflight else sq.get_nowait()
                        except queue.Empty:
                            break
                        if item is None:
                            eof = True
                            break
                        inflight.append((idx, item, TTS.executor.submit(timed, item))); idx += 1
                    if not inflight:
                        if eof:
                            break
                        continue
                    k, text, fut = inflight.popleft()
                    out.put({"type": "status", "stage": "synth", "i": k})   # also keeps the tunnel warm
                    try:
                        pcm, dt = fut.result()
                    except Exception as e:
                        print(f"[tts] sentence {k} failed: {e!r}", flush=True)
                        out.put({"type": "error", "message": f"tts failed on sentence {k}: {e!r}"})
                        continue
                    sr = TTS.sample_rate
                    # dt/P: with P workers busy at once, aggregate wall per audio second is dt/P
                    st["tts_wall"] += dt / P; st["speech"] += len(pcm) / sr; st["chars_done"] += len(text)
                    pcm = np.concatenate([pcm, np.zeros(int(PAD_S * sr), np.float32)])
                    last_k = k
                    if mode == "smooth":
                        pcms.append(pcm)
                        continue
                    buffered += len(pcm) / sr
                    out.put({"type": "sentence_audio", "i": k, "sr": sr, "pcm": pcm_b64(pcm)})
                    if not went:
                        if mode == "stream":
                            ok = True
                        else:
                            with sq.mutex:
                                pending = [len(t) for _, t, _ in inflight] + [len(x) for x in list(sq.queue) if x]
                            # text the LLM has not written yet: expect a typical reply length, at least one more sentence
                            fut_chars = 0 if st["llm_done"] else max(50, int(PACE.reply * 1.25) - st["chars"])
                            ok = PACE.gate(buffered, pending, st["speech"], st["chars_done"], st["tts_wall"], fut_chars)
                        if ok:
                            went = True
                            st["go_s"] = time.perf_counter() - t_req
                            out.put({"type": "go", "after_sentence": k, "buffered_s": round(buffered, 2)})
                if mode == "smooth" and pcms and not CANCEL.is_set():
                    full = np.concatenate(pcms)
                    st["go_s"] = time.perf_counter() - t_req
                    out.put({"type": "audio_full", "sr": sr, "dur": len(full) / sr, "pcm": pcm_b64(full)})
                elif mode != "smooth" and not went and buffered > 0:
                    st["go_s"] = time.perf_counter() - t_req
                    out.put({"type": "go", "after_sentence": last_k, "buffered_s": round(buffered, 2)})
            except Exception as e:
                print(f"[tts] worker failed: {e!r}", flush=True)
                out.put({"type": "error", "message": f"tts worker failed: {e!r}"})
            finally:
                out.put(("_end",))

        threads = [threading.Thread(target=llm_worker, daemon=True, name="neo-llm")]
        if tts_on:
            threads.append(threading.Thread(target=tts_worker, daemon=True, name="neo-tts"))
        try:
            yield {"type": "meta", "sample_rate": TTS.sample_rate, "audio_mode": mode, "backend": TTS.name,
                   "pid": os.getpid()}
            for th in threads:
                th.start()
            while True:
                try:
                    ev = out.get(timeout=0.25)
                except queue.Empty:
                    if not any(th.is_alive() for th in threads) and out.empty():
                        break
                    continue
                if isinstance(ev, tuple):       # ("_end",)
                    break
                yield ev
            text = "".join(parts).strip()
            if not text:
                # Empty generation: the finally block pops the user message. Keeping an
                # assistant "" pair makes Llama's template emit instant EOS forever ("0 tok/s" bug).
                yield {"type": "error", "message": "empty generation (rolled back, try again)"}
                return
            st["clean_end"] = True
            t_end = time.perf_counter()
            if st["chars_done"]:
                PACE.update(st["chars_done"], st["speech"], st["tts_wall"])
            if st["t_first"] and st["t_llm_end"] and st["t_llm_end"] > st["t_first"]:
                PACE.update_llm(st["chars"], st["t_llm_end"] - st["t_first"])
            PACE.reply = 0.6 * PACE.reply + 0.4 * st["chars"]
            tf, te = st["t_first"], st["t_llm_end"]
            yield {"type": "metrics",
                   "ttft_s": round(tf - t_req, 2) if tf else None,
                   "tok_s": round(st["ntok"] / max(te - tf, 1e-6), 1) if tf and te else None,
                   "tokens": st["ntok"], "llm_s": round((te - t_req), 2) if te else None,
                   "tts_s": round(st["tts_wall"], 2), "audio_s": round(st["speech"], 2),
                   "tts_wall_per_audio": round(st["tts_wall"] / st["speech"], 2) if st["speech"] else None,
                   "audio_start_s": round(st["go_s"], 2) if st["go_s"] else None,
                   "total_s": round(t_end - t_req, 2), "mode": mode, "backend": TTS.name,
                   "safety": round(PACE.safety, 2), "history_len": len(HISTORY)}
            yield {"type": "done"}
        finally:
            if not st["clean_end"]:
                CANCEL.set()                    # client left or error: stop both workers before releasing the lock
            for th in threads:
                if th.is_alive():
                    th.join(timeout=40)
            s = st["stream"]
            if s is not None and hasattr(s, "close"):
                try: s.close()
                except Exception as e: print(f"[llm] stream close: {e!r}", flush=True)
            if not st["committed"]:
                partial = "".join(parts).strip()
                if partial:
                    HISTORY.append({"role": "assistant", "content": partial})
                elif HISTORY and HISTORY[-1]["role"] == "user":
                    HISTORY.pop()

# ===== WEB APP =====
_UI_B64 = "<!doctype html>
<html lang="en"><head><meta charset="utf-8">
<meta name="viewport" content="width=device-width,initial-scale=1,viewport-fit=cover">
<title>neo-tts</title>
<style>
:root{--bg:#12151a;--panel:#1a1e25;--fg:#e9ebf0;--mut:#8e97a8;--line:#2a303b;--acc:#7fd6c2;--me:#232a36}
@media (prefers-color-scheme:light){:root{--bg:#f4f5f7;--panel:#fff;--fg:#161a21;--mut:#5f6879;--line:#dde1e9;--acc:#0f7f6a;--me:#e8ecf3}}
*{box-sizing:border-box}
html,body{height:100%;margin:0}
body{background:var(--bg);color:var(--fg);font:16px/1.5 system-ui,-apple-system,"Segoe UI",sans-serif;display:flex;flex-direction:column;max-width:760px;margin:0 auto;padding:env(safe-area-inset-top) 12px env(safe-area-inset-bottom)}
header{display:flex;align-items:center;gap:10px;padding:14px 4px;border-bottom:1px solid var(--line)}
h1{font-size:17px;margin:0;font-weight:600;letter-spacing:.2px}
#chip{color:var(--mut);font-size:13px;flex:1}
select,button,input{font:inherit;color:var(--fg)}
label.chk{font-size:13px;color:var(--mut);display:flex;gap:4px;align-items:center}
select{background:var(--panel);border:1px solid var(--line);border-radius:8px;padding:6px 8px}
#log{flex:1;overflow-y:auto;padding:16px 2px;display:flex;flex-direction:column;gap:12px}
.m{max-width:88%;padding:10px 14px;border-radius:14px;white-space:pre-wrap;word-wrap:break-word}
.u{align-self:flex-end;background:var(--me)}
.a{align-self:flex-start;background:var(--panel);border:1px solid var(--line)}
.meta{font-size:12px;color:var(--mut);margin-top:6px}
#status{min-height:20px;font-size:13px;color:var(--acc);padding:0 4px}
form{display:flex;gap:8px;padding:10px 0 14px}
input{flex:1;background:var(--panel);border:1px solid var(--line);border-radius:12px;padding:12px 14px}
input:focus-visible,button:focus-visible,select:focus-visible{outline:2px solid var(--acc);outline-offset:2px}
button{background:var(--acc);color:#0b1210;border:0;border-radius:12px;padding:0 18px;font-weight:600;cursor:pointer}
button.ghost{background:transparent;color:var(--fg);border:1px solid var(--line)}
button:disabled{opacity:.5;cursor:default}
</style></head>
<body>
<header><h1>neo-tts</h1><span id="chip">connecting</span>
<select id="mode" title="Audio mode"><option value="adaptive">Adaptive (safe start)</option><option value="stream">Live (speak at once)</option><option value="smooth">Smooth (after full reply)</option></select>
<label class="chk"><input type="checkbox" id="fill" checked> Quick ack</label><button class="ghost" id="reset" type="button">New chat</button></header>
<div id="log" aria-live="polite"></div>
<div id="status"></div>
<form id="f"><input id="q" autocomplete="off" placeholder="Type a message" aria-label="Message"><button id="send">Send</button><button class="ghost" id="stop" type="button" disabled>Stop</button></form>
<script>
"use strict";
const $ = s => document.querySelector(s);
const A = {ctx: null, sr: 24000, head: 0, started: false, queue: [], late: 0, sources: []};
let ctrl = null, fillers = [], fi = 0;
fetch("/fillers").then(r => r.json()).then(f => { fillers = f; }).catch(e => console.warn("fillers", e));
function playFiller() {
  if (!$("#fill").checked || !fillers.length) return;
  const f = fillers[fi++ % fillers.length];
  if (f.sr !== A.sr) return;
  A.head = A.ctx.currentTime + 0.03;    // plays at once, before the server has produced anything
  schedule(fade(pcmToF32(f.pcm), 3, 10));
}

function ensureCtx(sr) {
  if (A.ctx && A.ctx.sampleRate === sr) return;
  if (A.ctx) A.ctx.close();
  A.sr = sr;
  // Fixed 24 kHz context: the default 48 kHz context resamples our buffers and crackles.
  A.ctx = new (window.AudioContext || window.webkitAudioContext)({sampleRate: sr, latencyHint: "playback"});
}
function resetAudio() {
  for (const s of A.sources) { try { s.stop(); } catch (e) { console.warn("stop", e); } }
  A.sources = []; A.head = 0; A.started = false; A.queue = []; A.late = 0;
}
function pcmToF32(b64) {
  const bin = atob(b64), n = bin.length >> 1, out = new Float32Array(n);
  for (let i = 0; i < n; i++) {
    let v = bin.charCodeAt(2 * i) | (bin.charCodeAt(2 * i + 1) << 8);
    if (v & 0x8000) v -= 0x10000;
    out[i] = v / 32768;
  }
  return out;
}
function fade(f, inMs, outMs) {
  const ni = Math.min(f.length >> 1, Math.round(A.sr * inMs / 1000)), no = Math.min(f.length >> 1, Math.round(A.sr * outMs / 1000));
  for (let i = 0; i < ni; i++) f[i] *= i / ni;
  for (let i = 0; i < no; i++) f[f.length - 1 - i] *= i / no;
  return f;
}
function schedule(f) {
  const buf = A.ctx.createBuffer(1, f.length, A.sr);
  buf.copyToChannel(f, 0);
  const src = A.ctx.createBufferSource();
  src.buffer = buf; src.connect(A.ctx.destination);
  const now = A.ctx.currentTime;
  if (A.head < now + 0.01) {            // chunk arrived after the queue ran dry: an audible gap
    if (A.started && A.head > 0) A.late++;
    A.head = now + 0.06;
  }
  src.start(A.head);                    // sample-accurate: head advances by exact buffer duration
  A.head += buf.duration;
  A.sources.push(src);
}
function go() {
  if (A.started) return;
  A.started = true; A.head = Math.max(A.head, A.ctx.currentTime + 0.08);
  for (const f of A.queue) schedule(f);
  A.queue = [];
}

function bubble(cls, text) {
  const d = document.createElement("div"); d.className = "m " + cls; d.textContent = text;
  $("#log").appendChild(d); $("#log").scrollTop = 1e9; return d;
}

async function send(text) {
  ensureCtx(A.sr); await A.ctx.resume(); resetAudio(); playFiller();
  bubble("u", text);
  const out = bubble("a", ""); const meta = document.createElement("div"); meta.className = "meta"; out.appendChild(meta);
  const body = document.createTextNode(""); out.insertBefore(body, meta);
  ctrl = new AbortController();
  $("#send").disabled = true; $("#stop").disabled = false;
  try {
    const res = await fetch("/chat", {method: "POST", headers: {"Content-Type": "application/json"},
      body: JSON.stringify({message: text, mode: $("#mode").value}), signal: ctrl.signal});
    const rd = res.body.getReader(), dec = new TextDecoder(); let buf = "";
    for (;;) {
      const {value, done} = await rd.read(); if (done) break;
      buf += dec.decode(value, {stream: true});
      let i;
      while ((i = buf.indexOf("\n")) >= 0) {
        const line = buf.slice(0, i); buf = buf.slice(i + 1);
        if (line.trim()) handle(JSON.parse(line), body, meta);
      }
    }
  } catch (e) {
    if (e.name !== "AbortError") { meta.textContent = "Connection problem: " + e.message; console.error(e); }
  }
  if (!A.started && A.queue.length) go();   // fallback: never leave audio unplayed
  fetch("/feedback", {method: "POST", headers: {"Content-Type": "application/json"}, body: JSON.stringify({late: A.late})})
    .catch(e => console.warn("feedback", e));
  $("#status").textContent = ""; $("#send").disabled = false; $("#stop").disabled = true; $("#q").focus();
}

function handle(ev, body, meta) {
  switch (ev.type) {
    case "meta":
      if (ev.sample_rate !== A.sr) { ensureCtx(ev.sample_rate); A.ctx.resume(); }
      $("#chip").textContent = ev.backend; break;
    case "text": body.nodeValue += ev.delta; $("#log").scrollTop = 1e9; break;
    case "status": $("#status").textContent = "Preparing voice, sentence " + (ev.i + 1); break;
    case "sentence_audio": {
      const f = fade(pcmToF32(ev.pcm), 3, 3);
      if (A.started) schedule(f); else A.queue.push(f);
      break; }
    case "go": go(); $("#status").textContent = "Speaking"; break;
    case "audio_full": {
      const f = fade(pcmToF32(ev.pcm), 5, 15);
      A.queue.push(f); go(); $("#status").textContent = "Speaking"; break; }
    case "error": meta.textContent = ev.message; break;
    case "metrics": {
      const m = ev;
      meta.textContent = (m.tok_s ?? "?") + " tok/s, first text " + (m.ttft_s ?? "?") + " s, voice starts " + (m.audio_start_s ?? "n/a") + " s, voice built at " + (m.tts_wall_per_audio ?? "n/a") + "x audio length, " + m.mode;
      break; }
    case "done": break;
  }
}

$("#f").addEventListener("submit", e => { e.preventDefault(); const t = $("#q").value.trim(); if (!t) return; $("#q").value = ""; send(t); });
$("#stop").addEventListener("click", () => { fetch("/cancel", {method: "POST"}); if (ctrl) ctrl.abort(); resetAudio(); });
$("#reset").addEventListener("click", async () => { await fetch("/reset", {method: "POST"}); $("#log").innerHTML = ""; resetAudio(); });
fetch("/config").then(r => r.json()).then(c => { A.sr = c.sample_rate; $("#mode").value = c.audio_mode; $("#chip").textContent = c.backend + " / " + c.model; })
  .catch(e => { $("#chip").textContent = "server not reachable"; console.error(e); });
</script></body></html>
"
def load_ui():
    try:
        return (HERE / "_ui.html").read_text(encoding="utf-8")
    except FileNotFoundError:   # fresh clone missing the file / not pushed
        return base64.b64decode(_UI_B64).decode("utf-8")

LOG_CONFIG = {"version": 1, "disable_existing_loggers": False,
              "handlers": {"null": {"class": "logging.NullHandler"}},
              "loggers": {n: {"handlers": ["null"], "level": "CRITICAL", "propagate": False}
                          for n in ("uvicorn", "uvicorn.error", "uvicorn.access")}}

def build_app():
    from fastapi import FastAPI, Request
    from fastapi.responses import HTMLResponse, StreamingResponse, JSONResponse
    app = FastAPI()

    @app.get("/", response_class=HTMLResponse)
    def index():
        return load_ui()

    @app.get("/health")
    def health():
        return {"ok": LLM is not None and TTS is not None, "backend": TTS.name if TTS else None}

    @app.get("/version")
    def version():
        return {"pid": os.getpid(), "history_len": len(HISTORY), "history_roles": [m["role"] for m in HISTORY]}

    @app.get("/config")
    def config():
        return {"audio_mode": AUDIO_MODE, "sample_rate": TTS.sample_rate, "backend": TTS.name,
                "model": MODEL_FILE, "safety": PACE.safety}

    @app.get("/fillers")
    def fillers():
        return FILLERS

    @app.post("/chat")
    async def chat(req: Request):
        b = await req.json()
        msg = (b.get("message") or "").strip()
        if not msg:
            return JSONResponse({"error": "empty message"}, status_code=400)
        mode = b.get("mode") if b.get("mode") in ("adaptive", "smooth", "stream") else AUDIO_MODE
        mt = int(b.get("max_tokens") or MAX_TOKENS)
        def gen():
            for ev in turn_events(msg, mode, bool(b.get("tts", True)), mt):
                yield json.dumps(ev, separators=(",", ":")) + "\n"
        return StreamingResponse(gen(), media_type="application/x-ndjson",
                                 headers={"Cache-Control": "no-cache", "X-Accel-Buffering": "no"})

    @app.post("/cancel")
    def cancel():
        CANCEL.set(); return {"ok": True}

    @app.post("/reset")
    def reset():
        reset_history(); return {"ok": True, "history_len": len(HISTORY)}

    @app.post("/feedback")
    async def feedback(req: Request):
        b = await req.json()
        return {"safety": PACE.feedback(int(b.get("late", 0)))}

    return app

# ===== TUNNEL / LIFECYCLE =====
def http_json(path, timeout=3):
    with urllib.request.urlopen(f"http://127.0.0.1:{PORT}{path}", timeout=timeout) as r:
        return json.loads(r.read().decode())

def alive():
    try:
        return bool(http_json("/health").get("ok"))
    except Exception:
        return False

def start_tunnel(cf):
    pat = re.compile(r"https://[a-z0-9-]+\.trycloudflare\.com")
    lp = Path("/tmp/cloudflared.log")
    for attempt in (1, 2):
        subprocess.run(["pkill", "-f", "cloudflared"], check=False)   # orphans from prior sessions
        time.sleep(0.5)
        lf = open(lp, "w")
        proc = subprocess.Popen([cf, "tunnel", "--url", f"http://127.0.0.1:{PORT}", "--no-autoupdate",
                                 "--protocol", "http2"], stdout=lf, stderr=subprocess.STDOUT,
                                start_new_session=True)   # detaches: survives the cell returning
        end = time.time() + 60
        while time.time() < end:
            m = pat.search(lp.read_text(errors="ignore"))
            if m:
                return m.group(0)
            if proc.poll() is not None:
                break
            time.sleep(0.5)
        log(f"tunnel attempt {attempt} failed: {lp.read_text(errors='ignore')[-300:]}")
    return None

def start_server():
    """Idempotent. Returns after printing the URL; server (daemon thread) and tunnel (detached) keep running."""
    global SERVER, _FRESH
    if alive():
        if URL_FILE.exists():
            url = URL_FILE.read_text().strip()
            log(f"server already running: {url}")
            return url
        url = start_tunnel(ensure_cloudflared())
        if url: URL_FILE.write_text(url)
        return url
    _FRESH = True
    boot_models()
    import uvicorn, socket
    global PORT
    # A previous run in this same kernel may still hold the port (its daemon thread
    # survives re-runs and %run gives each run fresh globals). Never fight for it.
    for cand in range(PORT, PORT + 10):
        sk = socket.socket()
        try:
            sk.bind(("127.0.0.1", cand)); free = True
        except OSError:
            free = False
        finally:
            sk.close()
        if free:
            if cand != PORT:
                log(f"port {PORT} is busy (stale server from an earlier run); using {cand}")
            PORT = cand
            break
    else:
        raise RuntimeError("no free port in range; restart the runtime")
    cfg = uvicorn.Config(build_app(), host="127.0.0.1", port=PORT, log_config=LOG_CONFIG,
                         access_log=False, log_level="critical")
    SERVER = uvicorn.Server(cfg)
    errs = []
    def _run():
        try:
            SERVER.run()
        except BaseException as e:   # SystemExit on bind failure is otherwise invisible (loggers are silenced)
            errs.append(repr(e)); print(f"[uvicorn] crashed: {e!r}", flush=True)
    th = threading.Thread(target=_run, daemon=True, name="neo-uvicorn")
    th.start()
    for _ in range(150):
        if alive(): break
        if not th.is_alive():
            raise RuntimeError(f"uvicorn thread exited before serving: {errs or 'no exception (port bind failed?)'}")
        time.sleep(0.2)
    else:
        raise RuntimeError("server not healthy after 30 s")
    log("server healthy; opening tunnel")
    url = start_tunnel(ensure_cloudflared())
    if not url:
        raise RuntimeError("cloudflared did not produce a URL (see /tmp/cloudflared.log)")
    URL_FILE.write_text(url)
    return url

def stop_server():
    global SERVER
    if SERVER is not None:
        SERVER.should_exit = True
    subprocess.run(["pkill", "-f", "cloudflared"], check=False)
    try: URL_FILE.unlink()
    except FileNotFoundError: pass
    log("server stopping; port frees in a moment")

# ===== SELF TEST =====
def post_chat(msg, **kw):
    body = json.dumps(dict(message=msg, **kw)).encode()
    rq = urllib.request.Request(f"http://127.0.0.1:{PORT}/chat", data=body, headers={"Content-Type": "application/json"})
    evs = []
    with urllib.request.urlopen(rq, timeout=240) as r:
        for line in r:
            if line.strip():
                evs.append(json.loads(line))
    return evs

def selftest():
    try:
        for q in ("Say hello in five words.", "Name one color.", "What is two plus two?"):
            post_chat(q, tts=False, max_tokens=16, mode="smooth")
        v = http_json("/version")
        print(f"history_len after 3 turns: {v['history_len']} (expected 7) -> {'PASS' if v['history_len'] == 7 else 'FAIL'}", flush=True)
        print("/health:", http_json("/health"), flush=True)
        ev = post_chat("Say good morning.", tts=True, max_tokens=24, mode="smooth")
        ty = [e["type"] for e in ev]
        print(f"smooth round trip: text={ty.count('text')} audio_full={ty.count('audio_full')} -> "
              f"{'PASS' if 'text' in ty and 'audio_full' in ty else 'FAIL'}", flush=True)
        ev = post_chat("Count to three.", tts=True, max_tokens=24, mode="adaptive")
        ty = [e["type"] for e in ev]
        m = [e for e in ev if e["type"] == "metrics"]
        print(f"adaptive round trip: sentence_audio={ty.count('sentence_audio')} go={ty.count('go')} -> "
              f"{'PASS' if 'go' in ty and 'sentence_audio' in ty else 'FAIL'}", flush=True)
        if m: print("sample metrics:", m[0], flush=True)
    except Exception as e:
        print(f"SELFTEST ERROR: {e!r}", flush=True)
    finally:
        try:
            urllib.request.urlopen(urllib.request.Request(f"http://127.0.0.1:{PORT}/reset", data=b"{}", method="POST"), timeout=5)
        except Exception as e:
            print(f"reset after selftest failed: {e!r}", flush=True)

if __name__ == "__main__":
    try:
        url = start_server()
        print("\n" + "=" * 64 + f"\n  neo-tts is live: {url}\n  audio mode: {AUDIO_MODE}   tts backend: {TTS.name if TTS else TTS_BACKEND}"
              "\n  stop with stop_server()\n" + "=" * 64, flush=True)
        if _FRESH and os.environ.get("NEO_SELFTEST", "1") == "1":
            selftest()
        print("SCRIPT COMPLETE", flush=True)
    finally:
        sys.stdout.flush()
