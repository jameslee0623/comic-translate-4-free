// Offscreen ML host: owns ALL onnxruntime-web sessions (detector,
// Baberu OCR, LaMa inpainter). The service worker orchestrates; this document only runs
// inference. Models are read from the shared IndexedDB ('ct-db'/'models').
// Verified: ort 1.30 threaded WASM runs here with numThreads=1 and no COOP/COEP
// (chrome-extension: pages get SharedArrayBuffer without crossOriginIsolated).
import { MSG, openDb, idbGet } from '../shared/contracts.js';
import { ALL_FILES, downloadFileToIdb, readChunked, ocrEngineForLang, BABERU_VOCAB_ASSET } from '../shared/model-specs.js';
import { Detector } from './ml/detector.js';
import { BaberuOCR } from './ml/baberu.js';
import { meanBrightness } from '../shared/image-ops.js';
import { Inpainter } from './ml/inpaint.js';
import { tileOrigins, TILE_MAX, balanceOcrCrops } from '../shared/textblock.js';
import { pixelPut, pixelPeek } from '../shared/pixel-bus.js';

// Worker-safe: a Firefox inpaint worker imports this module, and a worker
// may not have chrome.runtime. Fall back to a path relative to this script:
// both offscreen.html and background/ml-worker.js sit one level under
// src/, so ../offscreen/vendor/ resolves to the same dir in both.
try {
  ort.env.wasm.wasmPaths = chrome.runtime.getURL('src/offscreen/vendor/');
} catch {
  ort.env.wasm.wasmPaths = new URL('../offscreen/vendor/', self.location.href).href;
}
// WASM threads ON, all detected cores, no cap (Chrome 2.0.3).
// Correction to the 1.2.10 note: 1.2.8 (threads on, full-res inpaint)
// works — threads are proven safe. 1.2.9 stalled because of half-res
// inpaint, not threads, so threads are back and half-res is removed
// (see inpaint.js). Set before any session is created (ensureModel
// below). Other users may have more cores than this Mac's 10, so the
// old 10 cap is removed: a 16-core machine uses 16 threads, a 4-core
// machine uses 4. Firefox is unaffected in practice:
// SharedArrayBuffer is off there, so ORT still runs single-threaded
// (thread-info numThreads 1) regardless of core count.
ort.env.wasm.numThreads = Math.max(1, (typeof navigator !== 'undefined' && navigator.hardwareConcurrency) || 4);

// Chrome 2.0.13: measured thread count (ML_BENCH_THREADS). The benchmark
// runs once, in the background, after a successful run, and saves the
// fastest count for this machine (measuredThreads). Later runs use it
// instead of the raw core count. numThreads only takes effect before a
// session is created, so threadsReady() re-reads storage on every call
// (inside ensureModel, at the start of a run before any session is
// used): when a stored count differs from the one already applied, it
// sets numThreads and drops the cached WASM sessions, so the next
// ensureModel recreates them with the new pool. That is what makes the
// measured count real on the next run — the old code read storage once
// at doc load and cached it, so a bench result saved after load never
// applied until a reload. Never throws: any failure keeps the current
// count. The GPU worker is a separate realm and is not affected.
// The big/small-core split is why this measurement matters at all: the
// browser only reports the total core count, so the best count (usually
// near the big-core count) has to be measured, not assumed.
// (2.0.16: re-read + reset; was read-once at load.)
// (2.0.18: the measurement is permanent — saved to storage.local AND
// storage.sync, read from local with sync as fallback. A cache clear
// that wipes local storage must not lose it or re-trigger the bench:
// sync lives in a separate store a local clear does not touch. Chrome
// close and reboot already keep both stores. It runs once, the first
// time the models exist (after the first successful run — at install
// the models are not downloaded yet, so there is nothing to measure),
// and then never again.)
async function readMeasuredThreads() {
  try {
    const local = (typeof chrome !== 'undefined' && chrome.storage && chrome.storage.local) ? chrome.storage.local : null;
    if (local) {
      const saved = await local.get('measuredThreads');
      if (saved && saved.measuredThreads) return saved.measuredThreads;
    }
  } catch {}
  try {
    const sync = (typeof chrome !== 'undefined' && chrome.storage && chrome.storage.sync) ? chrome.storage.sync : null;
    if (sync) {
      const saved = await sync.get('measuredThreads');
      if (saved && saved.measuredThreads) {
        // Restore the local copy so later reads are fast and the result
        // survives even if sync is unavailable later.
        try { await chrome.storage.local.set({ measuredThreads: saved.measuredThreads }); } catch {}
        return saved.measuredThreads;
      }
    }
  } catch {}
  return null;
}
async function saveMeasuredThreads(value) {
  try { await chrome.storage.local.set({ measuredThreads: value }); } catch {}
  try { await chrome.storage.sync.set({ measuredThreads: value }); } catch {}
}
let threadsApplied = Math.max(1, (typeof navigator !== 'undefined' && navigator.hardwareConcurrency) || 4);
let threadsApplying = null;
async function threadsReady() {
  if (threadsApplying) { try { await threadsApplying; } catch {} return; }
  threadsApplying = (async () => {
    try {
      const m = await readMeasuredThreads();
      if (m && Number.isInteger(m.threads) && m.threads >= 1 && m.threads !== threadsApplied) {
        threadsApplied = m.threads;
        ort.env.wasm.numThreads = m.threads;
        // The old pool is fixed at first session creation — drop the
        // cached sessions so they are recreated with the new count.
        await resetGroup('*');
      }
    } catch {}
  })();
  try { await threadsApplying; } catch {} finally { threadsApplying = null; }
}
threadsReady();

// Chrome 2.0.13: one benchmark line to the panel log (via the SW, which
// owns diagPush) plus the offscreen doc console. Fire-and-forget.
// 2.1.14: persist the bench's state to storage so the next run can report
// it even if the SW restarts (benchLog lines are lost on SW restart, so a
// missing bench line never proved the bench did not run). The pool's done
// line carries it, so one run shows whether the bench ran, which counts it
// measured, and why it stopped.
async function saveBenchStatus(state, extra = {}) {
  try {
    await chrome.storage.local.set({ benchStatus: { state, ...extra, updatedAt: new Date().toISOString() } });
  } catch {}
}
async function readBenchStatus() {
  try {
    const saved = await chrome.storage.local.get('benchStatus');
    return (saved && saved.benchStatus) || null;
  } catch { return null; }
}

function benchLog(line) {
  try { console.log('[ct-threads] ' + line); } catch {}
  try {
    const p = chrome.runtime.sendMessage({ type: MSG.ML_BENCH_RESULT, line });
    if (p && p.catch) p.catch(() => {});
  } catch {}
}

// 2.0.21: the benchmark is idle-time work. A new run interrupts it:
// benchCancel() stops the in-flight count and the loop, saves nothing,
// and the extension keeps the raw core count until a later bench
// finishes and overwrites it. The SW re-triggers the bench after the
// next successful run, so an interrupted bench simply retries later.
let benchCancelled = false;
let benchCancelResolve = null;
function benchCancel() {
  if (!benchRunning) return;
  benchCancelled = true;
  if (benchCancelResolve) { const r = benchCancelResolve; benchCancelResolve = null; try { r(); } catch {} }
}

// Time one thread count in a fresh worker (a fresh realm, because the
// pool size is fixed at first session creation). Resolves the full
// chain result {visionMs, prefillMs, stepMs, totalMs} or null on any
// failure, timeout or cancel — a failed count is skipped, never fatal. Timeout
// 120s (a bound, not a target): the worker loads three models
// (~122MB) and creates three sessions, so it needs more room than the
// old step-only worker's 60s.
function benchOneCount(threads) {
  return new Promise((resolve) => {
    let worker;
    let timer;
    let settled = false;
    const done = (v) => { if (settled) return; settled = true; benchCancelResolve = null; clearTimeout(timer); try { worker.terminate(); } catch {} resolve(v); };
    try { worker = new Worker(chrome.runtime.getURL('src/background/ml-bench-worker.js')); } catch { resolve(null); return; }
    timer = setTimeout(() => done(null), 120000);
    benchCancelResolve = () => done(null);
    worker.onmessage = (e) => {
      const d = e && e.data;
      if (!d || d.type !== 'bench-result' || d.threads !== threads) return;
      // Pass a worker-reported error through (truncated by the logger)
      // so a failed count is diagnosable from the panel log instead of
      // just 'failed' — the 2.0.20 all-failed run gave no reason.
      done(d.ok && typeof d.totalMs === 'number' ? { visionMs: d.visionMs, prefillMs: d.prefillMs, stepMs: d.stepMs, totalMs: d.totalMs } : { error: d.error || 'unknown error' });
    };
    worker.onerror = () => done(null);
    try { worker.postMessage({ type: 'bench', threads, steps: 20, warmup: 2 }); }
    catch { done(null); }
  });
}

// 2.0.24: bench keepalive — held ONLY while the benchmark measures.
// The bench runs in a background offscreen doc the browser can
// freeze/throttle when idle (James: >10 min, still no result). An open
// runtime Port to a DIFFERENT context, with heartbeat messages across
// it, is the documented activity that keeps an event page / worker
// alive; a silent self-connect is not (see the FIX3 comment in
// service-worker.js — the SW accepts this Port name). The doc opens the
// Port when the bench starts measuring and disconnects it when the
// bench ends or is cancelled, so the hold exists only for the
// measurement — never always-on. Best-effort: if the Port cannot open,
// the bench still runs (and still resumes, 2.0.23).
let benchKeepAlivePort = null;
let benchKeepAliveTimer = null;
function benchKeepAliveStart() {
  try {
    if (typeof chrome === 'undefined' || !chrome.runtime || !chrome.runtime.connect) return;
    const port = chrome.runtime.connect({ name: 'ct-bench-keepalive' });
    benchKeepAlivePort = port;
    try { port.onDisconnect.addListener(() => { if (benchKeepAlivePort === port) benchKeepAlivePort = null; }); } catch {}
    try {
      benchKeepAliveTimer = setInterval(() => {
        try { if (benchKeepAlivePort) benchKeepAlivePort.postMessage({ beat: Date.now() }); } catch {}
      }, 20000);
    } catch {}
  } catch {}
}
function benchKeepAliveStop() {
  try { if (benchKeepAliveTimer) { clearInterval(benchKeepAliveTimer); benchKeepAliveTimer = null; } } catch {}
  try { if (benchKeepAlivePort) { benchKeepAlivePort.disconnect(); benchKeepAlivePort = null; } } catch {}
}

// Chrome 2.0.13: measure the best WASM thread count once, in the
// background. Counts tried (2.0.26): start from max(3, ceil(cores/4)),
// then 4, 5, 6, then +2 (even only) up to the total — 10 cores ->
// 3,4,5,6,8,10; 32 cores -> 8,10,12,... Stop early when a count is
// >10% slower than the best so far (2.0.26); after a stop, the total
// is not tested. The old doubling spread (1,2,4,8,10) missed the
// commonest big-core counts (6, 12). See the 2.0.26 comment below
// for why each part of the set exists.
// Each count times the FULL Baberu chain in its own worker (median
// vision + median prefill + 20 steps, per representative crop; 2.0.20
// — the old step-only timing could not prove the overall winner, since
// the steps are only ~20% of OCR time and vision may scale the other
// way). The winner is the smallest count within 5% of the lowest
// total — same speed for less CPU. Saved to storage (measuredThreads,
// with the core count it was measured on); the next run uses it via
// threadsReady.
// Skips on Firefox (no SharedArrayBuffer: every count would be 1 thread),
// while a benchmark is already running, and when a result for this core
// count already exists.
let benchRunning = false;
let benchStartedAt = 0;
// 2.1.17: a bench that never finishes wedges benchRunning forever, so
// every later trigger is a no-op and the status stays 'none'. A bench
// measures at most [3,4,5] then early-stops (~30-90s on the M4), so a
// bench running longer than 3 minutes is stuck (a hung storage call or
// a throttled doc) — treat it as stale, reset, and start fresh. The
// next trigger after a run retries, so a wedged bench gets a fresh
// attempt on every run instead of blocking the bench forever.
const BENCH_STALE_MS = 3 * 60 * 1000;
async function runThreadBenchmark() {
  if (benchRunning) {
    if (Date.now() - benchStartedAt > BENCH_STALE_MS) {
      benchLog('threads bench stale (running >3m) — resetting and starting fresh');
      benchRunning = false;
      benchCancelled = false;
    } else {
      return;
    }
  }
  if (typeof document === 'undefined') return; // offscreen-document realm only
  if (typeof SharedArrayBuffer === 'undefined') { benchLog('threads bench skipped: no SharedArrayBuffer'); return; }
  benchRunning = true;
  benchStartedAt = Date.now();
  benchCancelled = false;
  // 2.1.14: hold the doc awake from the very start of the bench, before
  // any await. The keepalive was opened only once measuring began, so a
  // doc discarded in the gap (read storage, then measure) killed the
  // bench silently and nothing was ever saved. benchKeepAliveStop in the
  // finally still releases it.
  benchKeepAliveStart();
  try {
    const cores = (typeof navigator !== 'undefined' && navigator.hardwareConcurrency) || 4;
    // 2.0.26: new bench spread (James's design, from CPU research
    // 2021-2026 — big-core counts cluster at 4, 6, 8, 10, 12, with
    // 3 and 5 on binned Apple chips; big cores are at least 1/3 of
    // total, so cores/4 is always below the big-core count; no odd
    // big-core count above 6 exists).
    // - 1 core: no test, use 1 thread.
    // - 2 cores: test 1 and 2 (could be 1 big + 1 small).
    // - 3+ cores: start from max(3, ceil(cores/4)), then 4, 5, 6,
    //   then +2 (even only) up to the total. The total itself is
    //   included when the run reaches it (it can be odd, e.g. 11).
    // - Early stop (below): when a count is >10% slower than the
    //   best so far, stop — the total is not tested after a stop.
    //   Noise is 6-11% on the M4, so 10% avoids false stops; the
    //   true gap from the best to the next count is 8-12%.
    if (cores <= 1) {
      benchLog('threads bench skipped: single core, using 1 thread');
      try { await saveMeasuredThreads({ threads: 1, method: 'full-chain', timings: {}, hardwareConcurrency: cores, measuredAt: new Date().toISOString() }); } catch {}
      return;
    }
    const benchCounts = (c) => {
      if (c === 2) return [1, 2];
      const start = Math.max(3, Math.ceil(c / 4));
      const list = [];
      let n = start;
      while (n <= 6 && n <= c) { list.push(n); n++; }
      if (n % 2 === 1) n++;
      while (n <= c) { list.push(n); n += 2; }
      if (list.length && list[list.length - 1] !== c) list.push(c);
      return list;
    };
    const counts = benchCounts(cores);
    // 2.0.23: RESUMABLE. The bench runs in a background offscreen doc
    // that the browser can freeze/throttle when idle, and a new run can
    // cancel it — and until now it saved NOTHING until every count was
    // done, so each attempt restarted from count 1 and never finished
    // (James: >10 min, still no result). Now each count's timings are
    // saved the moment that count finishes (partial: true, no winner
    // yet, so threadsReady ignores it), and the next trigger resumes
    // from the counts still missing instead of starting over. A cancel
    // or freeze loses at most the in-flight count. A complete save
    // (integer threads winner) still skips the bench entirely, and a
    // partial from a different core count is discarded. A count that
    // fails is retried on the next trigger (its slot stays empty).
    // method 'full-chain' (2.0.20): an older step-only result has no
    // method, so it is re-measured once with the full chain instead
    // of being kept — the old number answered a different question.
    const timings = {};
    try {
      const m = await readMeasuredThreads();
      if (m && m.method === 'full-chain' && m.hardwareConcurrency === cores && Number.isInteger(m.threads)) {
        benchLog('threads bench skipped: already measured ' + m.threads + ' threads');
        return;
      }
      // 2.0.25: diagnostic — the bench re-measured after every run in
      // 2.0.24 even though a complete save existed. Log what was read so
      // the next run proves whether the skip sees the save.
      benchLog('threads bench read storage: ' + (m ? 'method=' + (m.method || 'none') + ' threads=' + (m.threads === undefined ? 'none' : m.threads) + ' timings=' + (m.timings ? Object.keys(m.timings).length : 0) : 'nothing saved'));
      if (m && m.method === 'full-chain' && m.hardwareConcurrency === cores && m.timings && typeof m.timings === 'object') {
        for (const n of counts) {
          const t = m.timings[n];
          if (t && typeof t.total === 'number' && typeof t.vision === 'number' && typeof t.prefill === 'number' && typeof t.step === 'number') {
            timings[n] = { vision: t.vision, prefill: t.prefill, step: t.step, total: t.total };
          }
        }
      }
    } catch {}
    const results = [];
    for (const n of counts) {
      const t = timings[n];
      if (t) results.push({ threads: n, visionMs: t.vision, prefillMs: t.prefill, stepMs: t.step, totalMs: t.total });
    }
    const remaining = counts.filter((n) => !timings[n]);
    if (remaining.length) {
      benchLog('threads bench started, testing ' + remaining.join(', ') + ' threads' + (results.length ? ' (resuming, ' + results.length + ' already measured)' : ''));
      try { await saveBenchStatus('running', { testing: remaining, measured: results.map((r) => r.threads) }); } catch {}
    } else {
      benchLog('threads bench resuming, all counts already measured — picking the winner');
    }
    // 2.0.26: early stop. When a count is >10% slower than the best
    // so far, the curve has turned — further counts only add slower
    // efficiency cores, and the total will not recover (on the M4 the
    // total was 17% slower than the best). Stop here and do not test
    // the total. The 10% line is above the 6-11% measurement noise,
    // so a noisy count does not stop the bench by itself.
    let stoppedEarly = false;
    for (const n of remaining) {
      if (benchCancelled) break;
      const r = await benchOneCount(n);
      if (benchCancelled) break;
      if (r != null && !r.error && typeof r.totalMs === 'number') {
        results.push({ threads: n, ...r });
        timings[n] = { vision: Math.round(r.visionMs * 10) / 10, prefill: Math.round(r.prefillMs * 10) / 10, step: Math.round(r.stepMs * 10) / 10, total: Math.round(r.totalMs * 10) / 10 };
        benchLog('threads bench ' + n + ' threads: vision ' + Math.round(r.visionMs) + 'ms prefill ' + Math.round(r.prefillMs) + 'ms step ' + Math.round(r.stepMs * 10) / 10 + 'ms/step total ' + Math.round(r.totalMs) + 'ms/crop');
        // Save after EVERY count — a cancel/freeze loses at most the
        // in-flight count, never the ones already measured.
        // 2.0.25: preserve the saved winner. A partial must never
        // overwrite a complete result and destroy its threads — that
        // left storage with no winner, so the next run could not apply
        // the measured count and the next bench could not skip.
        try {
          const prev = await readMeasuredThreads().catch(() => null);
          const keep = (prev && Number.isInteger(prev.threads)) ? { threads: prev.threads } : {};
          await saveMeasuredThreads({ ...keep, method: 'full-chain', timings, hardwareConcurrency: cores, measuredAt: new Date().toISOString(), partial: true });
          await saveBenchStatus('running', { measured: results.map((x) => x.threads) });
        } catch {}
        // 2.0.26: stop when this count is >10% slower than the best
        // measured so far (the best includes this count, so a new
        // best never triggers a stop — only a real decline does).
        if (results.length > 1) {
          const bestSoFar = Math.min(...results.map((x) => x.totalMs));
          if (r.totalMs > bestSoFar * 1.10) {
            stoppedEarly = true;
            benchLog('threads bench ' + n + ' threads: ' + Math.round((r.totalMs / bestSoFar - 1) * 100) + '% slower than best — stopping early, total not tested');
            break;
          }
        }
      } else if (r && r.error) {
        benchLog('threads bench ' + n + ' threads: failed: ' + String(r.error).slice(0, 120));
      } else {
        benchLog('threads bench ' + n + ' threads: failed');
      }
    }
    if (benchCancelled) { benchLog('threads bench cancelled: interrupted by a new run, keeping ' + cores + ' threads — progress saved, resumes next run'); try { await saveBenchStatus('cancelled', { measured: results.map((x) => x.threads) }); } catch {} return; }
    if (!results.length) { benchLog('threads bench: no count succeeded, keeping ' + cores + ' threads'); try { await saveBenchStatus('failed', { measured: [] }); } catch {} return; }
    const missing = counts.filter((n) => !timings[n]);
    // 2.0.26: an early stop is a decision, not a failure — the
    // untested counts were skipped on purpose, so pick the winner
    // from the counts actually measured and save it complete. The
    // bench will not resume the skipped counts on the next trigger.
    if (!stoppedEarly && missing.length) {
      benchLog('threads bench: ' + missing.join(', ') + ' threads not measured yet — will retry next run');
      try { await saveBenchStatus('incomplete', { measured: results.map((x) => x.threads), missing }); } catch {}
      return;
    }
    const minTotal = Math.min(...results.map((r) => r.totalMs));
    const best = results.filter((r) => r.totalMs <= minTotal * 1.05).sort((a, b) => a.threads - b.threads)[0];
    try {
      await saveMeasuredThreads({ threads: best.threads, method: 'full-chain', timings, hardwareConcurrency: cores, measuredAt: new Date().toISOString() });
      await saveBenchStatus('done', { best: best.threads, measured: results.map((x) => x.threads) });
    } catch {}
    benchLog('threads bench best ' + best.threads + ' threads (was ' + cores + '), total ' + Math.round(best.totalMs) + 'ms/crop — used from the next run');
  } finally {
    benchKeepAliveStop(); // 2.0.24: release the measurement-only hold (also on cancel)
    benchRunning = false;
    benchStartedAt = 0;
    benchCancelled = false;
  }
}

const detector = new Detector();
const baberu = new BaberuOCR();
const inpainter = new Inpainter();

// Drop loaded ORT sessions so the next inference re-reads model files from
// IndexedDB. group: 'detector' | 'ocr-baberu' | 'inpaint' | '*'.
async function resetGroup(group) {
  if (group === 'detector' || group === '*') await detector.reset();
  if (group === 'ocr-baberu' || group === '*') await baberu.reset();
  if (group === 'inpaint' || group === '*') await inpainter.reset();
}

// WASM OOM signatures from ORT/Emscripten. Matches ml-bridge.js's OOM_RE.
const OOM_RE = /out of memory|no available backend|aborted\s*\(/i;
const isOom = e => OOM_RE.test(String((e && e.message) || e || ''));

let db = null;
async function getDb() {
  if (!db) db = await openDb();
  return db;
}

async function modelBuffer(id) {
  const db = await getDb();
  const rec = await idbGet(db, id);
  if (!rec) throw new Error(`model "${id}" not in local cache — download it from the popup first`);
  const spec = ALL_FILES.find(f => f.id === id);
  if (spec && spec.bytes && rec.bytes !== spec.bytes) {
    throw new Error(
      `cached model "${id}" is ${rec.bytes} bytes but should be ${spec.bytes} — ` +
      `it is the wrong file or a truncated download. Delete it in the popup and download it again.`);
  }
  if (rec.data) return rec.data; // single-record format (older builds)
  if (rec.chunks) return readChunked(db, id, rec); // chunked format
  throw new Error(`cached model "${id}" is corrupt — delete it in the popup and download it again`);
}

async function assetText(path) {
  return (await (await fetch(chrome.runtime.getURL(path))).text());
}

// WebGPU PARKED (1.3.7) — all models WASM. It failed every way:
// detector OOM (1.3.0/1.3.1), Baberu hang at OCR 38% (1.3.4), LaMa
// buffer error (1.3.5), LaMa stall at inpaint 71% (1.3.6). A hang
// throws no error, so no error-only fallback can catch it — only a
// hang watchdog (per-run timeout + downgrade + retry) could, and no
// watchdog can be verified here (no GPU in this VM), so no more GPU
// guesses. 1.3.7 shipped no GPU code at all.
// GPU1 RETURN (LaMa only, dedicated GPU worker realm only): the
// missing pieces from 1.3.6 are now built — a background-side hang
// watchdog (ml-bridge.js runGpuInpaint, 60s no-progress), a separate
// GPU worker realm (ml-gpu-worker.js, terminated to reclaim GPU
// buffers), FIX1 recovery, keep-alives, and the panel log, so a GPU
// failure is observed in full and fails cleanly instead of freezing.
// Detector stays WASM-only (it hardcodes ['wasm'] below), Baberu
// stays WASM-only ('ocr-baberu' is never in this set). Only LaMa
// inpaint ever touches GPU, and only in the GPU worker realm: the
// flag below is set by ml-gpu-worker.js before importing this module,
// and unset everywhere else (shared worker, background page,
// offscreen document), where this set stays empty and all models
// stay WASM. Chrome GPU1: the offscreen document spawns the GPU worker
// (ML_GPU_INPAINT handler) but never sets the flag itself, so its own
// sessions stay WASM — only the spawned worker realm runs GPU. A WebGPU session still runs inside a WASM instance and
// shares its realm's heap (1.3.4 finding) — that is why GPU LaMa
// must never share a realm with WASM sessions.
const WEBGPU_KINDS = (typeof globalThis !== 'undefined' && globalThis.__ctGpuInpaintWorker) ? new Set(['inpaint']) : new Set([]);
const HAS_WEBGPU = typeof navigator !== 'undefined' && !!navigator.gpu;
const webgpuDowngraded = new Set(); // kinds that fell back to WASM
function providersFor(kind) {
  if (!WEBGPU_KINDS.has(kind) || !HAS_WEBGPU || webgpuDowngraded.has(kind)) return ['wasm'];
  return ['webgpu'];
}
const loading = {};
async function loadBaberu(providers) {
  // Fetch + attach one graph at a time so the three buffers (121MB)
  // are never all resident at once. All three share providers, so
  // vision→prefill tensors never cross providers.
  await baberu.loadVis(await modelBuffer('ocr-baberu-vision-v12'), providers);
  await baberu.loadPre(await modelBuffer('ocr-baberu-prefill-v12'), providers);
  await baberu.loadStep(await modelBuffer('ocr-baberu-step-v12'), providers);
}
async function loadWithWebgpuFallback(kind, loadFn) {
  // 1.4.0 (m2): NO in-worker WASM fallback. Try WebGPU alone; on
  // creation failure, reset the group once (dispose any half-loaded
  // WebGPU sessions, or they leak GPU resources) and THROW the original
  // error, so the service worker downgrades to shared WASM and logs it
  // truthfully as "gpu failed". The old in-worker fallback made the
  // service worker log "gpu done" while WASM actually ran inside the
  // GPU worker — and stacked WASM attempts on OOM (in-worker retry,
  // then the service-worker retry). This branch only ever runs in the
  // GPU worker realm (WEBGPU_KINDS is empty elsewhere), and the
  // service-worker downgrade path already handles GPU failure cleanly.
  const providers = providersFor(kind);
  try {
    await loadFn(providers);
  } catch (e) {
    if (providers[0] !== 'webgpu') throw e;
    await resetGroup(kind);
    throw e;
  }
}
async function ensureModel(kind) {
  // Await any in-flight load so inference never runs on a null session.
  if (loading[kind]) { await loading[kind]; return; }
  const p = (async () => {
    // 2.0.13: apply a measured thread count before creating any session.
    await threadsReady();
    if (kind === 'detector' && !detector.loaded) {
      await detector.load(await modelBuffer('detector'), ['wasm']);
    } else if (kind === 'ocr-baberu' && !baberu.loaded) {
      const vocabJson = await assetText(BABERU_VOCAB_ASSET);
      try {
        await loadWithWebgpuFallback(kind, loadBaberu);
      } catch (e) { await baberu.reset(); throw e; }
      baberu.setVocab(vocabJson);
    } else if (kind === 'inpaint' && !inpainter.loaded) {
      await loadWithWebgpuFallback(kind, async (providers) => {
        await inpainter.load(await modelBuffer('inpaint'), providers);
      });
    }
  })();
  loading[kind] = p;
  try { await p; } finally { delete loading[kind]; }
}

// (pixel payloads now travel via the IDB pixel bus — see pixel-bus.js)

// Run ids whose ML work must stop ASAP (see ML_CANCEL). Checked between
// units of work. An entry is dropped when a handler finishes for a run that
// was NOT cancelled; a cancelled run keeps its flag so the NEXT ML stage of
// the same run aborts immediately instead of silently running to completion.
const cancelledRuns = new Set();
function throwIfCancelled(runId) {
  if (runId && cancelledRuns.has(runId)) throw new Error('cancelled');
}
function releaseRun(runId) {
  if (runId && !cancelledRuns.has(runId)) cancelledRuns.delete(runId);
}

// Chrome GPU1 (2.0.6): ONE shared dedicated GPU worker per offscreen
// document, kept alive across runs so the LaMa WebGPU session (206MB
// model + session creation, ~6.3s on the first run) loads once. Later
// runs find inpainter.loaded true in the worker and pay ~0ms load.
// Replies are routed by callId, so concurrent runs share the worker.
// The worker dies only on GPU failure/hang (untrustworthy session),
// on worker error, or after 10 idle minutes — never after a
// successful reply, and never on user cancel (cancel stops the run's
// loop but keeps the session). Results are IDB keys, so keeping the
// worker loses nothing. Document realm only — the document spawns the
// worker; the service worker cannot spawn workers. All of this stays
// empty in worker realms (workers never run ML_GPU_INPAINT), so the
// cancel/kill helpers below are no-ops there.
let chromeGpuWorker = null;
let chromeGpuWorkerReady = null; // promise resolved at ml-ready
let chromeGpuSeq = 0;
const chromeGpuPending = new Map(); // callId -> {resolve, reject, runId}
let chromeGpuIdleTimer = null;
const CHROME_GPU_IDLE_MS = 10 * 60 * 1000;

function armChromeGpuIdleTimer() {
  try { if (chromeGpuIdleTimer) clearTimeout(chromeGpuIdleTimer); } catch {}
  chromeGpuIdleTimer = setTimeout(() => {
    // Only when idle: a pending job re-arms on completion, so this
    // never fires mid-run. The next run recreates the worker and pays
    // the model load again.
    if (chromeGpuPending.size === 0) terminateChromeGpuWorker(null);
  }, CHROME_GPU_IDLE_MS);
}

function terminateChromeGpuWorker(err) {
  const worker = chromeGpuWorker;
  chromeGpuWorker = null;
  chromeGpuWorkerReady = null;
  try { if (chromeGpuIdleTimer) { clearTimeout(chromeGpuIdleTimer); chromeGpuIdleTimer = null; } } catch {}
  if (worker) { try { worker.terminate(); } catch {} }
  if (err) {
    for (const [, p] of chromeGpuPending) { try { p.reject(err); } catch {} }
    chromeGpuPending.clear();
  }
}

// Cancel one run's GPU job without killing the shared worker: reject
// its pending replies and tell the worker to stop its inpaint loop
// (the worker's ML_CANCEL handler marks the run; the loop throws
// between tiles). The loaded LaMa session stays for the next run.
function cancelChromeGpuJob(runId, err) {
  let hadPending = false;
  for (const [callId, p] of chromeGpuPending) {
    if (p.runId === runId) {
      chromeGpuPending.delete(callId);
      hadPending = true;
      try { p.reject(err || Object.assign(new Error('cancelled'), { cancelled: true })); } catch {}
    }
  }
  if (chromeGpuWorker) {
    try { chromeGpuWorker.postMessage({ type: MSG.ML_CANCEL, runId }); } catch {}
  }
  return hadPending;
}

// Get the shared GPU worker, creating it (and awaiting ml-ready) on
// the first run only. Concurrent callers during creation share the
// one creation promise instead of spawning a second worker.
async function getChromeGpuWorker() {
  if (chromeGpuWorkerReady) {
    await chromeGpuWorkerReady;
    if (!chromeGpuWorker) throw new Error('GPU_SKIPPED: GPU worker failed to start');
    return { worker: chromeGpuWorker, readyMs: 0 };
  }
  let worker;
  try {
    worker = new Worker(chrome.runtime.getURL('src/background/ml-gpu-worker.js'));
  } catch (e) {
    throw new Error('GPU_SKIPPED: GPU worker creation failed: ' + String((e && e.message) || e));
  }
  chromeGpuWorker = worker;
  const readyT0 = performance.now();
  chromeGpuWorkerReady = new Promise((resolve, reject) => {
    const to = setTimeout(() => {
      // Creation timed out: drop the worker so the next run retries.
      if (chromeGpuWorker === worker) { chromeGpuWorker = null; chromeGpuWorkerReady = null; try { worker.terminate(); } catch {} }
      reject(new Error('GPU_SKIPPED: GPU worker did not become ready after 15s'));
    }, 15000);
    worker.onmessage = (e) => {
      const d = e && e.data;
      if (!d) return;
      if (d.type === 'ml-ready') {
        clearTimeout(to);
        worker.onmessage = (ev) => {
          const m = ev && ev.data;
          if (!m) return;
          if (m.type === 'inpaint-progress') {
            try { if (globalThis.__ctInpaintProgress) globalThis.__ctInpaintProgress(m.runId, m.frac); } catch {}
            return;
          }
          if (m.callId == null) return;
          const p = chromeGpuPending.get(m.callId);
          if (!p) return;
          chromeGpuPending.delete(m.callId);
          if (m.ok) p.resolve(m.res);
          else {
            // An error reply means the GPU session may be broken —
            // drop the worker so the next run starts fresh (and pays
            // the load again). The SW downgrades this run to WASM.
            const err = new Error(m.error || 'GPU worker failed');
            terminateChromeGpuWorker(err);
            try { p.reject(err); } catch {}
          }
        };
        worker.onerror = (ev) => {
          terminateChromeGpuWorker(new Error('GPU worker failed: ' + String((ev && ev.message) || ev || '')));
        };
        resolve();
      }
    };
    worker.onerror = (ev) => {
      clearTimeout(to);
      if (chromeGpuWorker === worker) { chromeGpuWorker = null; chromeGpuWorkerReady = null; }
      reject(new Error('GPU worker failed to start: ' + String((ev && ev.message) || ev || '')));
    };
  });
  await chromeGpuWorkerReady;
  return { worker: chromeGpuWorker, readyMs: Math.round(performance.now() - readyT0) };
}

// ---------------------------------------------------------------- OCR pool
// Chrome OCR pool test (2.1.10): two dedicated workers, each with its
// own Baberu session, splitting the crops. Mirrors the GPU worker
// lifecycle on purpose (kept alive across runs, 10-min idle timeout,
// terminate on error, cancel keeps the worker): the pool is a fair
// test only if the sessions stay loaded — a fresh load per run would
// eat the parallel gain. The workers are plain ml-worker.js (WASM-
// only, same handlers as the doc); the doc owns them because the SW
// cannot spawn workers. Each worker gets the measured thread count
// (see ML_OCR `threads`), so both run 4 threads on this machine.
// K=2 only: a third worker would need its own split and its own
// measurement, and the question this test answers is whether a second
// worker helps at all.
const poolOcrWorkers = [null, null];
const poolOcrReady = [null, null]; // per-slot creation promises
let poolOcrSeq = 0;
const poolOcrPending = new Map(); // callId -> {resolve, reject, runId, slot}
let poolOcrIdleTimer = null;
const POOL_OCR_IDLE_MS = 10 * 60 * 1000;

function armPoolOcrIdleTimer() {
  try { if (poolOcrIdleTimer) clearTimeout(poolOcrIdleTimer); } catch {}
  poolOcrIdleTimer = setTimeout(() => {
    if (poolOcrPending.size === 0) {
      terminatePoolOcrWorker(0, null);
      terminatePoolOcrWorker(1, null);
    }
  }, POOL_OCR_IDLE_MS);
}

function terminatePoolOcrWorker(slot, err) {
  const worker = poolOcrWorkers[slot];
  poolOcrWorkers[slot] = null;
  poolOcrReady[slot] = null;
  if (worker) { try { worker.terminate(); } catch {} }
  if (err) {
    for (const [callId, p] of poolOcrPending) {
      if (p.slot === slot) {
        poolOcrPending.delete(callId);
        try { p.reject(err); } catch {}
      }
    }
  }
}

// Cancel one run's pool jobs without killing the workers: reject its
// pending replies and tell both workers to stop their OCR loops (each
// worker's ML_CANCEL handler marks the run; the decode loop throws
// between crops). The loaded Baberu sessions stay for the next run.
function cancelPoolOcrJob(runId, err) {
  let hadPending = false;
  for (const [callId, p] of poolOcrPending) {
    if (p.runId === runId) {
      poolOcrPending.delete(callId);
      hadPending = true;
      try { p.reject(err || Object.assign(new Error('cancelled'), { cancelled: true })); } catch {}
    }
  }
  for (const w of poolOcrWorkers) {
    if (w) { try { w.postMessage({ type: MSG.ML_CANCEL, runId }); } catch {} }
  }
  return hadPending;
}

// Get one pool worker, creating it (and awaiting ml-ready) on the first
// run only. Concurrent callers during creation share the one creation
// promise instead of spawning a second worker for the slot.
async function getPoolOcrWorker(slot) {
  if (poolOcrReady[slot]) {
    await poolOcrReady[slot];
    if (!poolOcrWorkers[slot]) throw new Error('OCR pool worker failed to start');
    return poolOcrWorkers[slot];
  }
  let worker;
  try {
    worker = new Worker(chrome.runtime.getURL('src/background/ml-worker.js'));
  } catch (e) {
    throw new Error('OCR pool worker creation failed: ' + String((e && e.message) || e));
  }
  poolOcrWorkers[slot] = worker;
  poolOcrReady[slot] = new Promise((resolve, reject) => {
    const to = setTimeout(() => {
      if (poolOcrWorkers[slot] === worker) { poolOcrWorkers[slot] = null; poolOcrReady[slot] = null; try { worker.terminate(); } catch {} }
      reject(new Error('OCR pool worker did not become ready after 15s'));
    }, 15000);
    worker.onmessage = (e) => {
      const d = e && e.data;
      if (!d) return;
      if (d.type === 'ml-ready') {
        clearTimeout(to);
        worker.onmessage = (ev) => {
          const m = ev && ev.data;
          if (!m || m.callId == null) return;
          const p = poolOcrPending.get(m.callId);
          if (!p) return;
          poolOcrPending.delete(m.callId);
          if (m.ok) p.resolve(m.res);
          else {
            // An error reply means this worker's session may be broken —
            // drop the worker so the next run starts fresh (and pays the
            // load again). The SW falls back to single for this run.
            const err = new Error(m.error || 'OCR pool worker failed');
            terminatePoolOcrWorker(slot, err);
            try { p.reject(err); } catch {}
          }
        };
        worker.onerror = (ev) => {
          terminatePoolOcrWorker(slot, new Error('OCR pool worker failed: ' + String((ev && ev.message) || ev || '')));
        };
        resolve();
      }
    };
    worker.onerror = (ev) => {
      clearTimeout(to);
      if (poolOcrWorkers[slot] === worker) { poolOcrWorkers[slot] = null; poolOcrReady[slot] = null; }
      reject(new Error('OCR pool worker failed to start: ' + String((ev && ev.message) || ev || '')));
    };
  });
  await poolOcrReady[slot];
  return worker;
}

// Fast-path inpaint for uniform backgrounds: if the unmasked pixels have low
// variance, fill masked pixels with the median background color instead of
// running LaMa. Returns Uint8ClampedArray RGBA, or null if background is not
// uniform (caller falls back to LaMa).
function uniformBackgroundFill(rgba, mask, w, h) {
  // Sample unmasked pixels (stride to keep it fast)
  const rs = [], gs = [], bs = [];
  const stride = Math.max(1, Math.floor(Math.sqrt((w * h) / 2000)));
  let maskedCount = 0;
  for (let y = 0; y < h; y += stride) {
    for (let x = 0; x < w; x += stride) {
      const i = y * w + x;
      if (mask[i]) { maskedCount++; continue; }
      const o = i * 4;
      rs.push(rgba[o]); gs.push(rgba[o + 1]); bs.push(rgba[o + 2]);
    }
  }
  if (rs.length < 10) return null;
  if (maskedCount === 0) return rgba; // nothing to inpaint — skip LaMa entirely
  // Median (robust to outliers)
  const med = a => { const s = [...a].sort((x, y) => x - y); return s[s.length >> 1]; };
  const mr = med(rs), mg = med(gs), mb = med(bs);
  // Std dev; uniform if low
  let vr = 0, vg = 0, vb = 0;
  for (let i = 0; i < rs.length; i++) {
    vr += (rs[i] - mr) ** 2; vg += (gs[i] - mg) ** 2; vb += (bs[i] - mb) ** 2;
  }
  const sr = Math.sqrt(vr / rs.length), sg = Math.sqrt(vg / rs.length), sb = Math.sqrt(vb / rs.length);
  if (sr > 12 || sg > 12 || sb > 12) return null; // not uniform
  // Fill masked pixels with median background color
  const out = new Uint8ClampedArray(rgba);
  for (let i = 0; i < w * h; i++) {
    if (mask[i]) {
      const o = i * 4;
      out[o] = mr; out[o + 1] = mg; out[o + 2] = mb; out[o + 3] = 255;
    }
  }
  return out;
}

const handlers = {
  [MSG.ML_PING]() {
    return { ok: true, loaded: { detector: detector.loaded, baberu: baberu.loaded, inpaint: inpainter.loaded } };
  },

  async [MSG.ML_ENSURE]({ model }) {
    await ensureModel(model);
    return { ok: true };
  },

  // Downloads run here (not the SW) so a long 197MB fetch can't be killed
  // mid-stream by service-worker shutdown.
  async [MSG.ML_DOWNLOAD]({ fileId }) {
    const spec = ALL_FILES.find(f => f.id === fileId);
    if (!spec) throw new Error('unknown model file ' + fileId);
    // Broadcast completion one-way: the SW's request/response channel does
    // not survive a service worker restart during a multi-minute download,
    // so the UI must not depend on this handler's return value.
    const announce = payload => chrome.runtime.sendMessage(
      { type: MSG.MODEL_PROGRESS, fileId, ...payload }).catch(() => {});
    try {
      const total = await downloadFileToIdb(spec.id, spec.url, (loaded, totalBytes) => {
        chrome.runtime.sendMessage({
          type: MSG.MODEL_PROGRESS, id: spec.group, fileId: spec.id,
          loaded, total: totalBytes,
        }).catch(() => {});
      });
      // Drop any session built from the old bytes so the fresh file is used.
      await resetGroup(spec.group);
      announce({ done: true });
      return { ok: true, bytes: total };
    } catch (e) {
      console.error('[ct-dl] download failed for', fileId + ':',
        String((e && e.message) || e).slice(0, 200));
      announce({ error: String((e && e.message) || e) });
      throw e;
    }
  },

  // ML_RESET {group} — drop loaded sessions for a model group (used after
  // model delete / download so stale bytes are never reused).
  async [MSG.ML_RESET]({ group }) {
    await resetGroup(group || '*');
    return { ok: true };
  },

  // ML_CANCEL {runId} — mark a run's in-flight ML work for abortion. The
  // detect/ocr/inpaint handlers check this flag between units of work and
  // throw, so a cancelled run stops burning CPU instead of finishing a page
  // the user already left.
  [MSG.ML_CANCEL]({ runId }) {
    if (runId) {
      cancelledRuns.add(runId);
      // Bound the set: a run cancelled between ML stages keeps its flag (so
      // the next stage aborts) and would otherwise never be released. Sets
      // iterate in insertion order, so this drops the oldest entries first.
      while (cancelledRuns.size > 64) cancelledRuns.delete(cancelledRuns.values().next().value);
      // Chrome GPU1 (2.0.6): cancel this run's GPU job WITHOUT killing
      // the shared worker — its loaded LaMa session stays for the next
      // run. No-op in worker realms (their registry is always empty).
      cancelChromeGpuJob(runId, Object.assign(new Error('cancelled'), { cancelled: true }));
      // OCR pool (2.1.10): same — stop this run's pool jobs without
      // killing the pool workers; their loaded Baberu sessions stay.
      cancelPoolOcrJob(runId, Object.assign(new Error('cancelled'), { cancelled: true }));
    }
    return { ok: true };
  },

  // ML_GPU_CANCEL {runId} — Chrome GPU1: the SW watchdog sends this on
  // a hang (no progress or reply). A hung GPU session is untrustworthy,
  // so the shared worker dies with all its pending jobs. The SW
  // downgrades this run to WASM; the next run creates a fresh worker
  // and pays the model load again. User cancel does NOT use this path
  // (it sends ML_CANCEL, which keeps the worker alive).
  [MSG.ML_GPU_CANCEL]({ runId }) {
    if (runId) terminateChromeGpuWorker(Object.assign(new Error('cancelled'), { cancelled: true }));
    return { ok: true };
  },

  // ML_GPU_WARMUP {runId} — Chrome GPU1 (2.0.7): warm the shared GPU
  // worker at pipeline start (see service-worker.js). Creates the
  // worker if needed, then posts ML_ENSURE for inpaint so the LaMa
  // model loads now, overlapping detect/OCR/translate. The reply is
  // ignored (no pending entry) and this handler never throws — a
  // warmup failure changes nothing: the normal GPU path still loads
  // on demand and falls back to WASM on failure.
  async [MSG.ML_GPU_WARMUP]({ runId }) {
    try {
      const { worker } = await getChromeGpuWorker();
      try { worker.postMessage({ type: MSG.ML_ENSURE, model: 'inpaint', runId, callId: ++chromeGpuSeq }); } catch {}
    } catch {}
    return { ok: true };
  },

  // ML_BENCH_THREADS — Chrome 2.0.13: the SW sends this once after a
  // successful run. Fire-and-forget: returns at once; the benchmark runs
  // on its own (runThreadBenchmark) and saves the winner. A failure
  // changes nothing: the next run keeps the raw core count.
  // 2.1.16: record that the doc received the trigger (storage survives
  // a service-worker restart, so the next run's pool line can show
  // whether the trigger reached the doc even if the bench never saved).
  [MSG.ML_BENCH_THREADS]() {
    try { chrome.storage.local.set({ benchTriggerReceived: { at: new Date().toISOString() } }); } catch {}
    try { runThreadBenchmark().catch(() => {}); } catch {}
    return { ok: true };
  },

  // ML_GPU_INPAINT {patches, runId} — Chrome GPU1: offscreen-document
  // only. The SW cannot spawn workers, so the document owns the
  // dedicated GPU worker (ml-gpu-worker.js, __ctGpuInpaintWorker flag set
  // there, WEBGPU_KINDS ['inpaint'] in that realm only), forwards this
  // run's ML_INPAINT to it, forwards its progress through
  // __ctInpaintProgress (offscreen-progress.js throttles to 500ms, plus
  // the final 1.0). 2.0.6: the worker is SHARED across runs, not
  // spawned per run — the LaMa WebGPU session loads once and later runs
  // pay ~0ms load (readyMs 0, loadMs ~0 in the split line). The worker
  // dies only on GPU failure/hang, worker error, or 10 idle minutes.
  // The document realm itself never runs a GPU session: its own
  // WEBGPU_KINDS stays empty, so its WASM sessions are untouched.
  // Results are pixel keys in IDB, not worker memory, so keeping the
  // worker loses nothing. Errors are prefixed GPU_SKIPPED when the
  // failure is absence (no navigator.gpu, worker creation/ready
  // failure) rather than a GPU run failure — the SW logs those as
  // "skipped", not "failed", and falls back to the single WASM path
  // either way. Any other error is a GPU run failure and the SW
  // downgrades (once) to WASM.
  async [MSG.ML_GPU_INPAINT]({ patches, runId }) {
    // DIAG (2.1.9): doc-side time for the inpaint timing diagnostic —
    // the SW's call time minus hostMs, docMs, worker ms and loadMs is
    // the SW<->doc message transit both ways.
    const docT0 = performance.now();
    if (typeof document === 'undefined') throw new Error('GPU_SKIPPED: ml/gpu-inpaint is offscreen-document-only');
    if (typeof navigator === 'undefined' || !navigator.gpu) throw new Error('GPU_SKIPPED: no navigator.gpu in the offscreen document realm, using WASM path');
    if (!patches || !patches.length) return { ok: true, results: [], ms: 0, totalTiles: 0, docMs: Math.round(performance.now() - docT0) };
    throwIfCancelled(runId);
    const { worker, readyMs } = await getChromeGpuWorker();
    throwIfCancelled(runId);
    const callId = ++chromeGpuSeq;
    const res = await new Promise((resolve, reject) => {
      chromeGpuPending.set(callId, { resolve, reject, runId });
      try {
        worker.postMessage({ type: MSG.ML_INPAINT, runId, callId, patches });
      } catch (e) {
        chromeGpuPending.delete(callId);
        reject(e);
      }
    });
    armChromeGpuIdleTimer();
    return { ok: true, results: (res && res.results) || [], ms: (res && res.ms) || 0, totalTiles: (res && res.totalTiles) || 0, readyMs, loadMs: (res && res.loadMs) || 0, patchStats: (res && res.patchStats) || [], tileMax: (res && res.tileMax) || 0, docMs: Math.round(performance.now() - docT0) };
  },

  // ML_POOL_OCR {crops, sourceLang, runId} — Chrome OCR pool test (2.1.10):
  // split the crops across two dedicated workers, each with its own
  // Baberu session, and merge the results in crop order. Returns the
  // ML_OCR result shape, so the SW's OCR merge code is unchanged.
  // Groups are balanced by area (balanceOcrCrops). Each worker gets the
  // measured thread count so both run 4 threads even if chrome.storage
  // is unreadable in a worker realm. A worker failure (error, timeout,
  // never ready) rejects the pool call and the SW falls back to single
  // OCR for the run; the faulty worker is terminated, the healthy one
  // stays. Cancel rejects as cancelled and never falls back.
  async [MSG.ML_POOL_OCR]({ crops, runId, sourceLang }) {
    if (typeof document === 'undefined') throw new Error('OCR pool is offscreen-document-only');
    if (!crops || crops.length < 2) throw new Error('OCR pool needs at least 2 crops');
    throwIfCancelled(runId);
    const t0 = performance.now();
    const [w0, w1] = await Promise.all([getPoolOcrWorker(0), getPoolOcrWorker(1)]);
    throwIfCancelled(runId);
    let threads = null;
    let threadsSource = '';
    try {
      const m = await readMeasuredThreads();
      if (m && Number.isInteger(m.threads) && m.threads >= 1) { threads = m.threads; threadsSource = 'measured:' + m.threads; }
    } catch {}
    if (threads == null) {
      // No measured count yet — the bench has not finished/saved. Do NOT
      // fall back to the raw core count (10+10 was slower than single in
      // 2.1.11). Use the bench's own starting point instead:
      // max(3, ceil(cores/4)) per worker — the smallest plausible
      // big-core count — capped at floor(cores/2) so the two workers
      // together never exceed the core count and cannot oversubscribe.
      // This is a hardware-derived fallback, not the measured best —
      // the pool switches to measured:N once the bench saves.
      const cores = (typeof navigator !== 'undefined' && navigator.hardwareConcurrency) || 4;
      threads = Math.min(Math.floor(cores / 2), Math.max(3, Math.ceil(cores / 4)));
      if (!Number.isInteger(threads) || threads < 1) threads = 1;
      threadsSource = 'fallback:' + threads;
    }
    // 2.1.14: carry the bench's persisted status so the SW log shows
    // whether the bench ran and why it stopped (benchLog lines are lost
    // on SW restart, so this is the durable signal).
    let benchStatusText = 'none';
    try {
      const b = await readBenchStatus();
      if (b && b.state) {
        benchStatusText = b.state
          + (b.best != null ? ' best ' + b.best : '')
          + (b.measured && b.measured.length ? ' measured ' + b.measured.join(',') : '')
          + (b.missing && b.missing.length ? ' missing ' + b.missing.join(',') : '');
      }
    } catch {}
    const groups = balanceOcrCrops(crops);
    const GROUP_TIMEOUT_MS = 120 * 1000;
    const runGroup = (slot, group) => {
      if (!group.length) return Promise.resolve({ results: [], ms: 0, loadMs: 0, engine: '' });
      return new Promise((resolve, reject) => {
        const callId = ++poolOcrSeq;
        const to = setTimeout(() => {
          if (!poolOcrPending.has(callId)) return;
          poolOcrPending.delete(callId);
          terminatePoolOcrWorker(slot, new Error('OCR pool worker timed out after 120s'));
          reject(new Error('OCR pool worker timed out after 120s'));
        }, GROUP_TIMEOUT_MS);
        poolOcrPending.set(callId, {
          resolve: (res) => { clearTimeout(to); resolve(res); },
          reject: (err) => { clearTimeout(to); reject(err); },
          runId, slot,
        });
        try {
          (slot === 0 ? w0 : w1).postMessage({ type: MSG.ML_OCR, runId, callId, crops: group, sourceLang, threads });
        } catch (e) {
          clearTimeout(to);
          poolOcrPending.delete(callId);
          reject(e);
        }
      });
    };
    let groupResults;
    try {
      groupResults = await Promise.all([runGroup(0, groups[0]), runGroup(1, groups[1])]);
    } catch (e) {
      // A failed group must not leave the other worker running crops
      // nobody waits for: stop both loops (sessions stay loaded).
      for (const w of [w0, w1]) { try { w.postMessage({ type: MSG.ML_CANCEL, runId }); } catch {} }
      throw e;
    }
    // Guard against late completion after timeout/cancel: don't deliver
    // stale results if the run was cancelled while we were working.
    throwIfCancelled(runId);
    const results = [...groupResults[0].results, ...groupResults[1].results].sort((a, b) => a.id - b.id);
    armPoolOcrIdleTimer();
    return {
      ok: true, results,
      ms: Math.round(performance.now() - t0),
      engine: groupResults[0].engine || groupResults[1].engine || '',
      loadMs: Math.max(groupResults[0].loadMs || 0, groupResults[1].loadMs || 0),
      groups: [groups[0].length, groups[1].length],
      threads: [(groupResults[0].threads || 0), (groupResults[1].threads || 0)],
      groupMs: [(groupResults[0].ms || 0), (groupResults[1].ms || 0)],
      threadsSource,
      bench: benchStatusText,
    };
  },

  async [MSG.ML_DETECT]({ key, width, height, threshold, runId, noStrip }) {
    throwIfCancelled(runId);
    const t0 = performance.now();
    // Pixel bytes arrive via the IDB pixel bus (see pixel-bus.js) — they do
    // not survive chrome.runtime messaging from the service worker.
    const raw = await pixelPeek(key);
    const buf = new Uint8ClampedArray(raw);
    let boxes;
    const runDetect = async () => {
      await ensureModel('detector');
      throwIfCancelled(runId);
      return detector.detect(buf, width, height, threshold, {
        shouldAbort: () => cancelledRuns.has(runId),
        noStrip: !!noStrip,
      });
    };
    try {
      boxes = await runDetect();
    } catch (e) {
      // OOM recovery: on Firefox all models share one WASM heap. If a previous
      // run left Baberu/LaMa loaded (~330MB), the detector can OOM even on a
      // small image — during model load or inference. Drop the heavy models
      // we don't need for detection and retry once; they reload on demand.
      if (!isOom(e)) throw e;
      await resetGroup('ocr-baberu');
      await resetGroup('inpaint');
      boxes = await runDetect();
    } finally {
      releaseRun(runId);
    }
    throwIfCancelled(runId);
    return { ok: true, boxes, ms: Math.round(performance.now() - t0), inputMean: +meanBrightness(buf).toFixed(4) };
  },

  async [MSG.ML_OCR]({ crops, runId, sourceLang, threads }) {
    throwIfCancelled(runId);
    // OCR engine follows the source language — all languages use Baberu.
    const engine = ocrEngineForLang(sourceLang || 'ja');
    // OCR pool (2.1.10): the doc passes the measured thread count so a
    // pool worker uses it even if chrome.storage is unreadable in its
    // realm. Applied before ensureModel (which re-reads storage and
    // agrees — both are the measured count). Single-path calls pass no
    // threads, so this is a no-op for them. The reset drops this realm's
    // sessions so the new count takes effect on the next load.
    if (Number.isInteger(threads) && threads >= 1) {
      try {
        if (typeof ort !== 'undefined' && ort.env && ort.env.wasm && ort.env.wasm.numThreads !== threads) {
          ort.env.wasm.numThreads = threads;
          await resetGroup('*');
        }
      } catch {}
    }
    // DIAG (2.0.9): time the model load separately — it runs before t0
    // and is invisible in r.ms, so the SW split can tell load from run
    // (same as inpaint loadMs in 2.0.5).
    const loadT0 = performance.now();
    await ensureModel(engine);
    const loadMs = Math.round(performance.now() - loadT0);
    throwIfCancelled(runId);
    const t0 = performance.now();
    // Stddev of a crop's grayscale pixels, sampled every 4th pixel. A
    // near-uniform crop (detector false positive on flat background) scores
    // ~1-2 from JPEG noise alone; real text — even faint — scores 30+ from
    // stroke contrast, so 3.0 is far below any readable text.
    const cropStddev = (u8) => {
      let n = 0, mean = 0, m2 = 0;
      for (let i = 0; i < u8.length; i += 16) {
        const g = (u8[i] + u8[i + 1] + u8[i + 2]) / 3;
        n++;
        const d = g - mean;
        mean += d / n;
        m2 += d * (g - mean);
      }
      return n > 1 ? Math.sqrt(m2 / (n - 1)) : 0;
    };
    // 2.0.10 tried 2 crops at a time and it did NOT help: total 7,535ms
    // -> 7,268ms (noise — OCR varies by seconds run to run) while each
    // crop got ~2x slower (1,124ms max -> 2,334ms max), so one crop
    // already fills the 10 WASM threads and two just share them.
    // Reverted to sequential in 2.0.11; do not re-add concurrency here
    // without a new measurement.
    const results = [];
    try {
      for (const c of crops) {
        throwIfCancelled(runId);
        // DIAG (2.0.9): per-crop ms — Baberu is autoregressive, so time
        // grows with output tokens; one long crop can dominate the stage.
        const cT0 = performance.now();
        const raw = await pixelPeek(c.key);
        const u8 = new Uint8ClampedArray(raw);
        // Skip the model on blank crops: ~1ms variance check vs ~1s of
        // vision+prefill+autoregressive steps. Empty text flows downstream
        // exactly as if OCR had returned ''.
        if (cropStddev(u8) < 3.0) {
          results.push({ id: c.id, text: '', chars: 0, chunks: 0, hitCeiling: false, stopped: 'eos', skipped: true, ms: Math.round(performance.now() - cT0) });
          continue;
        }
        // Baberu v1.1 reads up to ~256 chars; the chunked path is a rare
        // fallback for over-long crops, re-OCR'd in overlapping pieces.
        let r;
        try {
          r = await baberu.ocrChunked(u8, c.width, c.height, {
            lang: sourceLang || 'ja',
            shouldAbort: () => cancelledRuns.has(runId),
          });
        } catch (e) {
          // OOM recovery: drop the inpainter (206MB, not needed for OCR)
          // first to free memory, then retry this crop once. Baberu is
          // WASM-only (GPU OCR was tried in 2.1.6 and reverted in 2.1.8:
          // it finished but ran ~2x slower than WASM — the
          // autoregressive step loop is latency-bound, not throughput-
          // bound — so there is no GPU downgrade path here).
          if (!isOom(e) || c._oomRetried) {
            // Debug (2.1.7, kept through the 2.1.8 revert): name the
            // crop that broke, so a failing run shows which crop it was
            // stuck on. Cancellations pass through untagged — the SW
            // detects them from the run's cancelled flag, not the message.
            if (e && e.cancelled) throw e;
            throw new Error('ocr crop ' + c.id + ' (' + c.width + 'x' + c.height + '): ' + String((e && e.message) || e));
          }
          await resetGroup('inpaint');
          c._oomRetried = true;
          r = await baberu.ocrChunked(u8, c.width, c.height, {
            lang: sourceLang || 'ja',
            shouldAbort: () => cancelledRuns.has(runId),
          });
        }
        results.push({ id: c.id, text: r.text, chars: r.text.length, chunks: r.chunks, hitCeiling: r.hitCeiling, stopped: r.stopped, ms: Math.round(performance.now() - cT0) });
      }
    } finally {
      releaseRun(runId);
    }
    // Guard against late completion after timeout/cancel: don't deliver
    // stale results if the run was cancelled while we were working.
    throwIfCancelled(runId);
    // DIAG (2.1.11): report the thread count this realm actually used,
    // so the pool's done line can show whether each worker really ran
    // the measured count (the pool run was ~3x slower per crop, and the
    // first suspect is a worker running 1 thread, not 4).
    const threadsUsed = (typeof ort !== 'undefined' && ort.env && ort.env.wasm && typeof ort.env.wasm.numThreads === 'number') ? ort.env.wasm.numThreads : null;
    return { ok: true, results, ms: Math.round(performance.now() - t0), engine, loadMs, threads: threadsUsed };
  },

  // MEASURE1 diagnostic: report the WASM thread facts of the realm
  // actually running ML (Firefox classic worker or Chrome offscreen
  // document — same module, both hosts). No model load, no session use,
  // so it cannot disturb a run. SharedArrayBuffer is what ORT needs for
  // threads; without it ORT silently runs 1 thread. `context` tells
  // which realm answered: 'worker' (no document) vs 'document'.
  [MSG.ML_DIAG]() {
    let numThreads = null;
    try { numThreads = (typeof ort !== 'undefined' && ort.env && ort.env.wasm) ? ort.env.wasm.numThreads : null; } catch { numThreads = null; }
    let sharedArrayBuffer = false;
    try { sharedArrayBuffer = typeof SharedArrayBuffer !== 'undefined'; } catch { sharedArrayBuffer = false; }
    let crossOriginIsolated = null;
    try { crossOriginIsolated = (typeof globalThis !== 'undefined' && 'crossOriginIsolated' in globalThis) ? globalThis.crossOriginIsolated : null; } catch { crossOriginIsolated = null; }
    let hardwareConcurrency = null;
    try { hardwareConcurrency = (typeof navigator !== 'undefined' && navigator.hardwareConcurrency) || null; } catch { hardwareConcurrency = null; }
    const context = (typeof document !== 'undefined') ? 'document' : 'worker';
    return { ok: true, sharedArrayBuffer, crossOriginIsolated, hardwareConcurrency, numThreads, context };
  },

  async [MSG.ML_INPAINT]({ patches, runId, attempt }) {
    // `attempt` (from ml-bridge.js): if this is a retry after a timed-out
    // call, namespace the `:out` result keys (`key:out#a2`) so a late
    // completion of the timed-out attempt can't clobber this retry's output.
    // The SW reads resKey from the response, so this is transparent to it.
    const outSuffix = attempt > 1 ? `#a${attempt}` : '';
    throwIfCancelled(runId);
    // DIAG (2.0.5): time the model load separately — it runs before t0
    // and is invisible in r.ms, so the SW split can tell load from run.
    const loadT0 = performance.now();
    await ensureModel('inpaint');
    const loadMs = Math.round(performance.now() - loadT0);
    // DIAG-EXP (2.0.10): GPU tiles are 1024, WASM tiles stay 512. The 512
    // cap exists because a WASM run blocks its thread (on Firefox, the
    // main thread) — a 1024 WASM tile would stall progress and the
    // watchdog. A WebGPU run is async, so the cap does not apply there,
    // and 1024 halves the overlap waste (8 tiles -> 2 for a 686x1623
    // patch) and the per-run overhead. The size follows the provider
    // actually running, so the WASM fallback keeps 512 automatically.
    const tileMax = providersFor('inpaint')[0] === 'webgpu' ? 1024 : TILE_MAX;
    throwIfCancelled(runId);
    const t0 = performance.now();
    const results = [];
    // MEASURE1: total LaMa tiles across all patches, by the same
    // tileOrigins math inpaintPatch uses (a patch fitting tileMax is
    // 1 tile, otherwise xs * ys). Fast-path patches still count: this
    // is the tiling shape of the page, not a LaMa-run counter.
    let totalTiles = 0;
    try {
      for (const p of patches) totalTiles += tileOrigins(p.width, tileMax).length * tileOrigins(p.height, tileMax).length;
    } catch { totalTiles = 0; }
    // DIAGNOSTIC (temporary): total work, so the log shows how many
    // patches the run had (not a guessed count).
    console.error('[ct-diag] inpaint start run ' + runId + ' patches ' + patches.length);
    // Long inpaints report progress: the Firefox background page sets
    // globalThis.__ctInpaintProgress (same module scope there — see
    // background-ff.js/service-worker.js). The Chrome offscreen document sets
    // it via offscreen-progress.js (forwarded to the service worker). Without
    // it a multi-minute tiled inpaint looks exactly like a stall.
    // Progress across parallel patches: each patch reports its own
    // 0..1 fraction; the bar shows the mean, so it moves forward
    // steadily no matter which patch finishes first.
    const patchFrac = new Array(patches.length).fill(0);
    let maxInpaintFrac = 0;
    const reportInpaint = (pi, frac) => {
      if (pi != null) patchFrac[pi] = Math.max(patchFrac[pi] || 0, frac);
      let sum = 0;
      for (const f of patchFrac) sum += f;
      const overall = patches.length ? sum / patches.length : 1;
      if (overall <= maxInpaintFrac) return;
      maxInpaintFrac = overall;
      try { if (globalThis.__ctInpaintProgress) globalThis.__ctInpaintProgress(runId, overall); } catch { /* never break inpaint */ }
    };
    // DIAG (2.0.8): per-patch time, so one Mac run shows whether the
    // GPU tile time is one big patch, even per-tile cost, or fast-path
    // hits — the fix depends on which it is.
    const patchStats = [];
    // 2.0.11 ran patches in parallel on WebGPU (up to 4) and it HUNG:
    // the GPU worker made no progress for 120s, the watchdog fired,
    // and the run fell back to WASM (total 148,870ms). Concurrent
    // session.run calls on one ORT WebGPU session deadlock — the
    // session is not reentrant. So patches run one after another (1),
    // and 1 is the number the algorithm gives: one session, one run
    // at a time. Real parallelism would need one session per patch,
    // which is a different design (and each session holds its own
    // GPU buffers), not a number to tune. Reverted in 2.0.12.
    try {
      for (const [pi, p] of patches.entries()) {
        throwIfCancelled(runId);
        const pT0 = performance.now();
        const rgbaRaw = await pixelPeek(p.key);
        const maskRaw = await pixelPeek(p.maskKey);
        const rgba = new Uint8ClampedArray(rgbaRaw);
        const mask = new Uint8Array(maskRaw);
        // Fast path: if the unmasked background is uniform, fill masked pixels
        // with the background color instead of running LaMa. Faster and
        // cleaner for white/paper backgrounds (common in manga bubbles).
        // Falls back to LaMa for textured/variegated backgrounds.
        const bgFill = uniformBackgroundFill(rgba, mask, p.width, p.height);
        let out;
        if (bgFill) {
          out = bgFill;
        } else {
          try {
            out = await inpainter.inpaintPatch(
              rgba, mask, p.width, p.height,
              () => cancelledRuns.has(runId),
              (done, total) => reportInpaint(pi, done / total),
              tileMax);
          } catch (e) {
            // WebGPU run failure recovery: if LaMa is on WebGPU, ANY
            // run failure downgrades it to WASM, reloads, and retries
            // once — not just OOM. WebGPU can fail other ways too
            // (e.g. buffer_manager.cc WGPUBuffer errors, shader or
            // device errors), and those must also fall back instead
            // of failing the page. The downgrade sticks for this
            // session. Cancelled runs are never retried. If LaMa is
            // already on WASM, only an OOM gets the drop-others +
            // retry (as before). _oomRetried guards the single retry.
            if (p._oomRetried) throw e;
            const msg = String((e && e.message) || e || '');
            if (/cancel/i.test(msg)) throw e;
            // GPU1: in the dedicated GPU worker realm, do NOT retry
            // inside the worker on a GPU run failure. The background
            // terminates this worker (reclaiming GPU buffers) and
            // retries once on the preloaded shared WASM worker, which
            // is faster than loading WASM here and avoids a second
            // retry (handler retry + background retry would be two).
            // WASM OOM logic below is untouched: it only runs when
            // the provider is already WASM (shared worker, offscreen
            // document, or a GPU worker without navigator.gpu).
            if (providersFor('inpaint')[0] === 'webgpu' && globalThis.__ctGpuInpaintWorker) throw e;
            const onWebgpu = providersFor('inpaint')[0] === 'webgpu';
            if (!onWebgpu && !isOom(e)) throw e;
            await resetGroup('detector');
            await resetGroup('ocr-baberu');
            if (onWebgpu) {
              webgpuDowngraded.add('inpaint');
              await inpainter.reset();
              await ensureModel('inpaint');
            }
            p._oomRetried = true;
            out = await inpainter.inpaintPatch(
              rgba, mask, p.width, p.height,
              () => cancelledRuns.has(runId),
              (done, total) => reportInpaint(pi, done / total),
              tileMax);
          }
        }
        const resKey = p.key + ':out' + outSuffix;
        await pixelPut(resKey, out.buffer);
        results.push({ id: p.id, key: resKey, width: p.width, height: p.height });
        let pTiles = 0;
        try { pTiles = tileOrigins(p.width, tileMax).length * tileOrigins(p.height, tileMax).length; } catch { pTiles = 0; }
        patchStats.push({ id: p.id, w: p.width, h: p.height, tiles: pTiles, fast: !!bgFill, ms: Math.round(performance.now() - pT0) });
        reportInpaint(pi, 1);
      }
    } finally {
      releaseRun(runId);
    }
    return { ok: true, results, ms: Math.round(performance.now() - t0), totalTiles, loadMs, patchStats, tileMax };
  },
};

// Exported for the Firefox background page, which hosts the ML sessions
// in-process instead of in an offscreen document (see background-ff.js and
// ml-bridge.js). Chrome keeps using the message listener below.
export const mlHandlers = handlers;

// Guarded: a worker importing this module may not have chrome.runtime.
// Document realm only (Chrome offscreen doc, Firefox background page —
// both have a document, so their listeners register exactly as before).
// The document guard is load-bearing for Chrome GPU1: a Dedicated Worker
// in Chrome may expose chrome.runtime.onMessage, and without it the GPU
// worker realm would ALSO receive the SW's runtime messages (ML_INPAINT,
// ML_CANCEL, ...) and run them a second time in the GPU realm —
// shadowing the document's reply and clobbering pixel outputs. Workers
// never used this listener anyway (they use self.onmessage), so
// excluding them changes nothing for Firefox.
if (typeof document !== 'undefined' && typeof chrome !== 'undefined' && chrome.runtime?.onMessage?.addListener) {
chrome.runtime.onMessage.addListener((msg, _sender, sendResponse) => {
  const fn = handlers[msg && msg.type];
  if (!fn) return false; // not ours
  // 2.0.21: a new run interrupts the idle-time benchmark — the bench
  // yields the CPU to real work and retries after the next run. Any
  // message here except the bench trigger itself means real work.
  if (msg.type !== MSG.ML_BENCH_THREADS) benchCancel();
  (async () => {
    try {
      sendResponse(await fn(msg));
    } catch (e) {
      console.error('[offscreen]', e);
      sendResponse({ ok: false, error: String((e && e.message) || e) });
    }
  })();
  return true; // async response
});
}
