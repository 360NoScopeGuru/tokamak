/* This Source Code Form is subject to the terms of the Mozilla Public
 * License, v. 2.0. If a copy of the MPL was not distributed with this
 * file, You can obtain one at https://mozilla.org/MPL/2.0/. */

import { useEffect, useRef, useState } from "react";
import { invoke } from "@tauri-apps/api/core";
import { listen } from "@tauri-apps/api/event";
import { open } from "@tauri-apps/plugin-dialog";
import { getCurrentWindow } from "@tauri-apps/api/window";
import { getCurrentWebview } from "@tauri-apps/api/webview";
import { Library } from "./Library";
import { Rail, Ghost } from "./Rail";
import { Dock } from "./Dock";
import { Console, ConsoleHandle, StagedIgnite } from "./Console";
import { Sessions } from "./Sessions";
import { Downloads } from "./Downloads";
import { FluxSample } from "./Flux";
import {
  BatchEstimate,
  BenchResult,
  InferenceMetrics,
  LlamaBinary,
  ModelEntry,
  ScanPhase,
  ScanProgress,
  ScanRoot,
  ServerStatus,
  DraftCandidate,
  SessionMeta,
  Settings,
  SpecProgress,
  SuiteRow,
  TelemetrySnapshot,
  VramEstimate,
  baseName,
  ctxLabel,
  gb,
  modelLabel,
} from "./types";
import "./styles.css";

const PORT = 8137;
const FLUX_WINDOW = 60;

interface RuntimeBuild {
  id: string;
  label: string;
  note: string;
  assets: string[];
  total_bytes: number;
  recommended: boolean;
}

type KvType = "f16" | "q8_0" | "q4_0";
/// Quantizing the KV cache trades a little cache precision for a lot of
/// context. Effective sizes include llama.cpp's per-block scales, so q8_0 is
/// 8.5 bpw rather than a clean half of f16's 16.
const KV_TYPES: { id: KvType; label: string; hint: string }[] = [
  { id: "f16", label: "f16", hint: "full precision — llama.cpp default" },
  { id: "q8_0", label: "q8_0", hint: "~half the KV memory, ~2x context, negligible quality cost" },
  { id: "q4_0", label: "q4_0", hint: "~quarter the KV memory, ~4x context, measurable quality cost" },
];

export default function App() {
  const [models, setModels] = useState<ModelEntry[]>([]);
  const [roots, setRoots] = useState<ScanRoot[]>([]);
  // Startup has two stages worth naming separately; see `ScanPhase`. The
  // library derives its own "busy" flag from this rather than a bare boolean,
  // so the panel can say which stage it is in.
  const [phase, setPhase] = useState<ScanPhase>({ kind: "idle" });
  const [error, setError] = useState<string | null>(null);
  const [telemetry, setTelemetry] = useState<TelemetrySnapshot | null>(null);
  const [metrics, setMetrics] = useState<InferenceMetrics | null>(null);
  const [server, setServer] = useState<ServerStatus | null>(null);
  const [estimates, setEstimates] = useState<Map<string, VramEstimate>>(new Map());
  const [hoverPath, setHoverPath] = useState<string | null>(null);
  // Saved sessions live in the left rail beneath the model list. The console
  // owns the transcripts; the rail only lists them and asks it to open one.
  const [sessions, setSessions] = useState<SessionMeta[] | null>(null);
  const [consoleState, setConsoleState] = useState<{ openIds: string[]; busy: boolean }>({
    openIds: [],
    busy: false,
  });
  const consoleRef = useRef<ConsoleHandle>(null);
  const [selectedPath, setSelectedPath] = useState<string | null>(null);
  const [launching, setLaunching] = useState(false);
  const [liveCfg, setLiveCfg] = useState<{ ngl: number; ctx: number; draft: string | null } | null>(
    null
  );
  // Live speculative-decoding counters, pushed by the chat backend. Held here
  // rather than in the console because the readout lives in the telemetry rail.
  const [spec, setSpec] = useState<SpecProgress | null>(null);
  const [history, setHistory] = useState<FluxSample[]>([]);
  const [bench, setBench] = useState<{
    path: string;
    name: string;
    expected: number;
    results: BenchResult[];
  } | null>(null);
  const [benching, setBenching] = useState(false);
  const [suite, setSuite] = useState<{
    running: boolean;
    current: string | null;
    total: number;
    rows: SuiteRow[];
    exportPath: string | null;
  } | null>(null);
  const [binaries, setBinaries] = useState<LlamaBinary[]>([]);
  const [settings, setSettings] = useState<Settings | null>(null);
  const [scale, setScale] = useState(1);
  // KV cache element type. Quantizing it is the cheapest context you can buy:
  // the cache is the only VRAM term that scales with context length.
  const [kvType, setKvType] = useState<KvType>("f16");
  const [getOpen, setGetOpen] = useState(false);
  // Speculative decoding: which local models could draft for the staged one,
  // and which the user picked. Keyed by nothing — the list is refetched when
  // the staged model changes, since candidacy is relative to the target.
  const [drafts, setDrafts] = useState<DraftCandidate[] | null>(null);
  const [draftPath, setDraftPath] = useState<string | null>(null);
  // Managed llama.cpp runtime: offered when no binary can be found, so nobody
  // has to install LM Studio just to get an inference backend.
  const [rtBuilds, setRtBuilds] = useState<RuntimeBuild[] | null>(null);
  const [rtBusy, setRtBusy] = useState<string | null>(null);
  const [rtProgress, setRtProgress] = useState<{ stage: string; received: number; total: number } | null>(null);

  const estimatesRef = useRef(estimates);
  estimatesRef.current = estimates;

  // ---- scanning + estimates ----

  async function rescan() {
    setPhase({ kind: "scanning", root: "", rootIndex: 0, totalRoots: 0, found: 0 });
    try {
      const [rootList, modelList] = await Promise.all([
        invoke<ScanRoot[]>("scan_roots"),
        invoke<ModelEntry[]>("scan_models", { extraDirs: [] }),
      ]);
      setRoots(rootList);
      setModels(modelList);

      // Prime fit verdicts for every primary model. One call for the whole
      // library, not one per model: priming them separately meant an IPC round
      // trip, an NVML snapshot, a read of settings.json and a second parse of
      // an already-parsed GGUF header *each*, which was the second of the two
      // startup freezes. Verdicts still arrive one at a time, pushed by
      // `estimate-progress`.
      const want = modelList.filter(
        (m) =>
          !m.is_shard_continuation &&
          !m.is_mmproj &&
          !m.parse_error &&
          !m.load_blocker &&
          !estimatesRef.current.has(m.path)
      );
      if (want.length === 0) return;
      setPhase({ kind: "estimating", done: 0, total: want.length });
      // Swallowed deliberately, and separately from the scan above. This call
      // fails outright on a machine with no NVML GPU, which is every AMD, Intel
      // and Apple one — the per-model version each had its own ignored catch,
      // so failing here used to mean no fit verdicts, not an error banner on
      // every scan. Finding models still has to work without a GPU.
      await invoke<BatchEstimate[]>("estimate_configs", {
        modelPaths: want.map((m) => m.path),
      }).catch(() => {});
    } catch (e) {
      setError(String(e));
    } finally {
      setPhase({ kind: "idle" });
    }
  }

  // Both startup stages report what they are doing. The guards matter: a late
  // event must not resurrect the strip once the scan has finished, which is
  // easy to hit because the last few arrive while the batch call is resolving.
  useEffect(() => {
    const uns: Array<() => void> = [];
    let disposed = false;
    const keep = (un: () => void) => (disposed ? un() : uns.push(un));

    listen<ScanProgress>("scan-progress", (e) => {
      const p = e.payload;
      setPhase((cur) =>
        cur.kind === "scanning"
          ? {
              kind: "scanning",
              root: p.root,
              rootIndex: p.root_index,
              totalRoots: p.total_roots,
              found: p.found,
            }
          : cur
      );
    })
      .then(keep)
      .catch(() => {});

    listen<{ done: number; total: number; entry: BatchEstimate }>("estimate-progress", (e) => {
      const { done, total, entry } = e.payload;
      setPhase((cur) => (cur.kind === "estimating" ? { kind: "estimating", done, total } : cur));
      const est = entry.estimate;
      if (est) setEstimates((prev) => new Map(prev).set(entry.path, est));
    })
      .then(keep)
      .catch(() => {});

    return () => {
      disposed = true;
      for (const un of uns) un();
    };
  }, []);

  useEffect(() => {
    rescan();
    invoke<LlamaBinary[]>("llama_binaries").then(setBinaries).catch(() => {});
    invoke<Settings>("get_settings")
      .then((s) => {
        setSettings(s);
        if (s.ui_scale && s.ui_scale >= 0.5 && s.ui_scale <= 2.5) setScale(s.ui_scale);
        setKvType(s.kv_cache_type === "q8_0" || s.kv_cache_type === "q4_0" ? s.kv_cache_type : "f16");
      })
      .catch(() => {});
  }, []);

  useEffect(() => {
    let disposed = false;
    let un: (() => void) | undefined;
    listen<{ stage: string; received: number; total: number; done: boolean; error: string | null }>(
      "runtime-progress",
      (e) => {
        const p = e.payload;
        setRtProgress({ stage: p.stage, received: p.received, total: p.total });
        if (p.done) {
          setRtBusy(null);
          setRtProgress(null);
          if (p.error) setError(p.error);
          else {
            // A new binary changes what can be launched — refresh both.
            invoke<LlamaBinary[]>("llama_binaries").then(setBinaries).catch(() => {});
            setRtBuilds(null);
          }
        }
      }
    ).then((u) => (disposed ? u() : (un = u)));
    return () => {
      disposed = true;
      un?.();
    };
  }, []);

  useEffect(() => {
    let disposed = false;
    let un: (() => void) | undefined;
    listen<SpecProgress>("spec-progress", (e) => setSpec(e.payload)).then((u) =>
      disposed ? u() : (un = u)
    );
    return () => {
      disposed = true;
      un?.();
    };
  }, []);

  async function loadRuntimeOptions() {
    setError(null);
    try {
      setRtBuilds(await invoke<RuntimeBuild[]>("runtime_options"));
    } catch (e) {
      setError(String(e));
    }
  }

  async function installRuntime(b: RuntimeBuild) {
    setRtBusy(b.id);
    setRtProgress({ stage: "starting", received: 0, total: b.total_bytes });
    try {
      await invoke("runtime_install", { build: b });
    } catch (e) {
      setError(String(e));
      setRtBusy(null);
      setRtProgress(null);
    }
  }

  /// Changing the KV type changes how much context fits, so every cached
  /// estimate is stale — drop them and let the library re-estimate under the
  /// new setting rather than showing a ladder the server won't honour.
  async function pickKvType(kind: KvType) {
    if (kind === kvType) return;
    setKvType(kind);
    try {
      setSettings(await invoke<Settings>("set_kv_cache_type", { kind }));
    } catch (e) {
      setError(String(e));
      return;
    }
    setEstimates(new Map());
  }

  // ---- UI scaling (independent of the DPI corrector below: this is user
  // preference, applied as CSS zoom; the corrector fixes webview DPI bugs) ----

  const scaleSaveTimer = useRef<number | undefined>(undefined);
  useEffect(() => {
    (document.documentElement.style as CSSStyleDeclaration & { zoom: string }).zoom =
      String(scale);
    window.clearTimeout(scaleSaveTimer.current);
    scaleSaveTimer.current = window.setTimeout(() => {
      invoke("set_ui_scale", { scale }).catch(() => {});
    }, 600);
  }, [scale]);

  const bumpScale = (d: number) =>
    setScale((s) => Math.min(2, Math.max(0.7, Math.round((s + d) * 20) / 20)));

  useEffect(() => {
    const onKey = (e: KeyboardEvent) => {
      if (!e.ctrlKey) return;
      if (e.key === "=" || e.key === "+") {
        e.preventDefault();
        bumpScale(0.1);
      } else if (e.key === "-") {
        e.preventDefault();
        bumpScale(-0.1);
      } else if (e.key === "0") {
        e.preventDefault();
        setScale(1);
      }
    };
    const onWheel = (e: WheelEvent) => {
      if (!e.ctrlKey) return;
      e.preventDefault();
      bumpScale(e.deltaY < 0 ? 0.05 : -0.05);
    };
    window.addEventListener("keydown", onKey);
    window.addEventListener("wheel", onWheel, { passive: false });
    return () => {
      window.removeEventListener("keydown", onKey);
      window.removeEventListener("wheel", onWheel);
    };
  }, []);

  // WebView2 on Windows can lay the page out at physical-pixel width while
  // still rendering at the display's DPI scale, painting wider/taller than the
  // window and clipping the right/bottom of the UI. Self-correct by zooming so
  // rendered size == real client size (no-op on healthy setups; re-checked on
  // every resize).
  const zoomRef = useRef(1);
  useEffect(() => {
    let disposed = false;
    const correct = async () => {
      try {
        // Ground truth from Win32 GetClientRect — tao/WebView2 can agree on a
        // DPI belief that the real window contradicts.
        const truth = await invoke<[number, number] | null>("true_client_size");
        if (!truth) return;
        const ratio = truth[0] / (window.innerWidth * window.devicePixelRatio);
        if (!disposed && isFinite(ratio) && ratio > 0.3 && Math.abs(1 - ratio) > 0.02) {
          zoomRef.current *= ratio;
          await getCurrentWebview().setZoom(zoomRef.current);
        }
      } catch {
        /* not fatal */
      }
    };
    // The webview's DPI belief can settle (or flip) some time after load with
    // no resize event, so re-check on a short cadence at first, then keep a
    // cheap 5s no-op comparison running.
    correct();
    let ticks = 0;
    const iv = setInterval(() => {
      ticks += 1;
      correct();
      if (ticks > 6) {
        clearInterval(iv);
      }
    }, 1200);
    const slowIv = setInterval(correct, 5000);
    let unlisten: (() => void) | undefined;
    getCurrentWindow()
      .onResized(() => correct())
      .then((u) => (unlisten = u));
    return () => {
      disposed = true;
      clearInterval(iv);
      clearInterval(slowIv);
      unlisten?.();
    };
  }, []);

  // ---- polling (telemetry + inference at 1 Hz feeds the flux trace) ----

  useEffect(() => {
    let alive = true;
    const fast = setInterval(async () => {
      try {
        const [t, m] = await Promise.all([
          invoke<TelemetrySnapshot>("gpu_telemetry"),
          invoke<InferenceMetrics | null>("inference_metrics"),
        ]);
        if (alive) {
          setTelemetry(t);
          setMetrics(m);
          const g = t.gpus[0];
          setHistory((prev) => [
            ...prev.slice(-(FLUX_WINDOW - 1)),
            {
              decode: m?.predicted_tokens_per_sec ?? 0,
              util: g?.gpu_util_pct ?? 0,
              temp: g?.temperature_c ?? 0,
              kv: m?.kv_cache_usage_ratio ?? 0,
            },
          ]);
        }
      } catch {
        /* transient */
      }
    }, 1000);
    const slow = setInterval(async () => {
      try {
        const s = await invoke<ServerStatus>("llama_status");
        if (alive) setServer(s);
      } catch {
        /* transient */
      }
    }, 1500);
    return () => {
      alive = false;
      clearInterval(fast);
      clearInterval(slow);
    };
  }, []);

  // ---- launch / stop ----

  async function refreshSessions() {
    try {
      setSessions(await invoke<SessionMeta[]>("history_list"));
    } catch {
      setSessions([]);
    }
  }

  useEffect(() => {
    refreshSessions();
  }, []);

  async function ignite(m: ModelEntry, ngl?: number, ctx?: number, draft?: string | null) {
    setLaunching(true);
    setError(null);
    try {
      let est = estimates.get(m.path);
      if (!est && ngl === undefined) {
        est = await invoke<VramEstimate>("estimate_config", { modelPath: m.path });
        setEstimates((prev) => new Map(prev).set(m.path, est!));
      }
      const cfg = {
        model_path: m.path,
        n_gpu_layers: ngl ?? est?.n_gpu_layers ?? 999,
        ctx_size: ctx ?? est?.ctx_size ?? 4096,
        port: PORT,
        // llama.cpp ships context shift OFF, so a chat that fills the window
        // just stops answering. Sliding the oldest turns out degrades far more
        // gracefully than refusing to generate.
        context_shift: true,
        // Must match what the estimator assumed, or the context it promised
        // will not actually fit. f16 is passed as null so the server keeps its
        // own default rather than being handed a redundant flag.
        cache_type_k: kvType === "f16" ? null : kvType,
        cache_type_v: kvType === "f16" ? null : kvType,
        // Speculative decoding. The draft has to be fully offloaded: one
        // running on the CPU is slower than the model it drafts for, which
        // defeats the point.
        draft_model_path: draft ?? null,
        draft_n_gpu_layers: draft ? 999 : null,
      };
      const status = await invoke<ServerStatus>("llama_start", { config: cfg });
      setLiveCfg({ ngl: cfg.n_gpu_layers, ctx: cfg.ctx_size, draft: cfg.draft_model_path });
      setSpec(null);
      setServer(status);
    } catch (e) {
      setError(String(e));
    } finally {
      setLaunching(false);
    }
  }

  async function stop() {
    try {
      await invoke("llama_stop");
    } catch {
      /* ignore */
    }
    setLiveCfg(null);
    setSpec(null);
    setServer(await invoke<ServerStatus>("llama_status"));
  }

  // ---- benchmark ----

  async function runBench(m: ModelEntry) {
    setBenching(true);
    setError(null);
    const name = modelLabel(m);
    try {
      let est = estimates.get(m.path);
      if (!est) {
        est = await invoke<VramEstimate>("estimate_config", { modelPath: m.path });
      }
      const reduced = Math.max(1, Math.floor(est.n_gpu_layers / 3));
      const configs = [
        { n_gpu_layers: est.n_gpu_layers, ctx_size: est.ctx_size },
        { n_gpu_layers: reduced, ctx_size: est.ctx_size },
      ];
      setBench({ path: m.path, name, expected: configs.length, results: [] });
      const unlisten = await listen<BenchResult>("benchmark-progress", (e) => {
        setBench((prev) =>
          prev && prev.path === m.path
            ? { ...prev, results: [...prev.results, e.payload] }
            : prev
        );
      });
      try {
        const final = await invoke<BenchResult[]>("benchmark_model", {
          modelPath: m.path,
          configs,
        });
        setBench((prev) => (prev && prev.path === m.path ? { ...prev, results: final } : prev));
      } finally {
        unlisten();
      }
    } catch (e) {
      setError(String(e));
      setBench(null);
    } finally {
      setBenching(false);
      setLiveCfg(null);
      setServer(await invoke<ServerStatus>("llama_status"));
    }
  }

  // ---- benchmark suite (all models, recommended config each) ----

  async function runSuite() {
    const eligible = primary.filter((m) => !m.parse_error && !m.load_blocker);
    if (eligible.length === 0) return;
    setBenching(true);
    setBench(null);
    setSuite({ running: true, current: null, total: eligible.length, rows: [], exportPath: null });
    try {
      for (const m of eligible) {
        const name = modelLabel(m);
        setSuite((prev) => (prev ? { ...prev, current: name } : prev));
        let est = estimates.get(m.path);
        if (!est) {
          try {
            est = await invoke<VramEstimate>("estimate_config", { modelPath: m.path });
            setEstimates((prev) => new Map(prev).set(m.path, est!));
          } catch {
            /* fall through to skip */
          }
        }
        const push = (row: SuiteRow) =>
          setSuite((prev) => (prev ? { ...prev, rows: [...prev.rows, row] } : prev));
        if (!est || !est.fits) {
          push({
            model: name,
            quant: m.metadata?.quant_label ?? null,
            n_gpu_layers: 0,
            ctx_size: 0,
            load_ms: 0,
            prefill_tok_s: 0,
            decode_tok_s: 0,
            peak_vram_bytes: 0,
            skipped: est ? "won't fit on GPU" : "no estimate",
          });
          continue;
        }
        try {
          const res = await invoke<BenchResult[]>("benchmark_model", {
            modelPath: m.path,
            configs: [{ n_gpu_layers: est.n_gpu_layers, ctx_size: est.ctx_size }],
          });
          const r = res[0];
          push({
            model: name,
            quant: m.metadata?.quant_label ?? null,
            n_gpu_layers: r?.n_gpu_layers ?? est.n_gpu_layers,
            ctx_size: r?.ctx_size ?? est.ctx_size,
            load_ms: r?.load_ms ?? 0,
            prefill_tok_s: r?.prefill_tok_s ?? 0,
            decode_tok_s: r?.decode_tok_s ?? 0,
            peak_vram_bytes: r?.peak_vram_bytes ?? 0,
            skipped: r?.loaded ? null : r?.error ?? "failed",
          });
        } catch (e) {
          push({
            model: name,
            quant: m.metadata?.quant_label ?? null,
            n_gpu_layers: 0,
            ctx_size: 0,
            load_ms: 0,
            prefill_tok_s: 0,
            decode_tok_s: 0,
            peak_vram_bytes: 0,
            skipped: String(e),
          });
        }
      }
    } finally {
      setSuite((prev) => (prev ? { ...prev, running: false, current: null } : prev));
      setBenching(false);
      setLiveCfg(null);
      setServer(await invoke<ServerStatus>("llama_status"));
    }
  }

  async function exportSuite() {
    if (!suite) return;
    try {
      const rows = suite.rows
        .filter((r) => !r.skipped)
        .map(({ skipped, ...rest }) => rest);
      const path = await invoke<string>("export_bench_report", { rows });
      setSuite((prev) => (prev ? { ...prev, exportPath: path } : prev));
    } catch (e) {
      setError(String(e));
    }
  }

  // ---- folders / binary ----

  async function addFolder() {
    try {
      const dir = await open({ directory: true, title: "Add a model folder" });
      if (typeof dir !== "string" || !dir) return;
      await invoke("add_model_dir", { dir });
      await rescan();
    } catch (e) {
      setError(String(e));
    }
  }

  async function removeFolder(dir: string) {
    try {
      await invoke("remove_model_dir", { dir });
      await rescan();
    } catch (e) {
      setError(String(e));
    }
  }

  async function pickWorkspace() {
    try {
      const dir = await open({ directory: true, title: "Grant the agent a workspace folder" });
      if (typeof dir !== "string" || !dir) return;
      const s = await invoke<Settings>("set_agent_workspace", { dir });
      setSettings(s);
    } catch (e) {
      setError(String(e));
    }
  }

  async function pickBinary(path: string) {
    try {
      const s = await invoke<Settings>("set_preferred_binary", {
        path: path === "" ? null : path,
      });
      setSettings(s);
    } catch (e) {
      setError(String(e));
    }
  }

  // ---- derived ----

  const primary = models.filter((m) => !m.is_shard_continuation && !m.is_mmproj);
  const visionDirs = new Set(models.filter((m) => m.is_mmproj).map((m) => dirOf(m.path)));
  const busy = launching || benching;
  const runningPath = server?.running ? server.model_path : null;
  const selected = primary.find((m) => m.path === selectedPath) ?? null;

  // Draft candidates for whatever is staged. Scoped to the staged model rather
  // than fetched per selection because it walks the whole library: candidacy
  // is relative to a target, so there is nothing to cache across models.
  useEffect(() => {
    const target = selected?.path;
    if (!target || server?.running) {
      setDrafts(null);
      setDraftPath(null);
      return;
    }
    let stale = false;
    setDraftPath(null);
    invoke<DraftCandidate[]>("draft_candidates", {
      targetPath: target,
      extraDirs: [],
      ctxSize: estimates.get(target)?.ctx_size ?? null,
    })
      .then((list) => {
        if (!stale) setDrafts(list);
      })
      .catch(() => {
        if (!stale) setDrafts(null);
      });
    return () => {
      stale = true;
    };
  }, [selected?.path, server?.running, estimates]);
  const selectedEst = selected ? estimates.get(selected.path) ?? null : null;
  const runningModel = primary.find((m) => m.path === runningPath) ?? null;
  const liveEst = runningPath ? estimates.get(runningPath) ?? null : null;
  const gpu = telemetry?.gpus[0] ?? null;
  const health = server?.running ? server.health : "stopped";
  const ready = !!server?.running && health === "ok";
  const igniting = !!server?.running && (health === "starting" || health === "loading");
  const generating = ready && (metrics?.requests_processing ?? 0) > 0;
  const kvAlert = ready && (metrics?.kv_cache_usage_ratio ?? 0) >= 0.9;

  const hoverModel =
    hoverPath && hoverPath !== runningPath ? primary.find((m) => m.path === hoverPath) : null;
  const hoverEst = hoverModel ? estimates.get(hoverModel.path) : null;
  const ghost: Ghost | null =
    hoverModel && hoverEst
      ? {
          name: modelLabel(hoverModel),
          bytes:
            hoverEst.est_weights_bytes + hoverEst.est_kv_bytes + hoverEst.est_overhead_bytes,
          fits: hoverEst.fits,
          layers: hoverModel.metadata?.block_count
            ? `${hoverEst.n_gpu_layers}/${hoverModel.metadata.block_count}`
            : null,
        }
      : null;

  const liveName = runningModel
    ? modelLabel(runningModel)
    : server?.model_path
      ? baseName(server.model_path)
      : null;

  const staged: StagedIgnite | null =
    !server?.running &&
    !benching &&
    selected &&
    !selected.load_blocker &&
    selectedEst &&
    selectedEst.fits
      ? {
          name: modelLabel(selected),
          ngl: selectedEst.n_gpu_layers,
          layers: selected.metadata?.block_count ?? null,
          ctx: selectedEst.ctx_size,
          busy,
          drafts,
          draftPath,
          onPickDraft: setDraftPath,
          onIgnite: () =>
            ignite(selected, selectedEst.n_gpu_layers, selectedEst.ctx_size, draftPath),
        }
      : null;

  // Header state line.
  let stateText: string;
  let stateCls = "";
  let lampCls = "";
  if (kvAlert) {
    stateText = `GENERATING · CONTAINMENT ${Math.round((metrics?.kv_cache_usage_ratio ?? 0) * 100)}%`;
    stateCls = "alert";
    lampCls = "alert";
  } else if (server?.running && health === "error") {
    stateText = "FAULT";
    stateCls = "fault";
    lampCls = "alert";
  } else if (igniting || launching) {
    stateText = liveName ? `IGNITING · ${liveName}` : "IGNITING";
    stateCls = "live";
    lampCls = "igniting";
  } else if (generating) {
    stateText = `GENERATING · ${liveName ?? ""}`;
    stateCls = "live";
    lampCls = "live";
  } else if (ready) {
    stateText = `REACTOR LIVE · ${liveName ?? ""}`;
    stateCls = "live";
    lampCls = "live";
  } else if (benching) {
    stateText = suite ? "COLD · SUITE RUNNING" : "COLD · BENCH RUNNING";
    lampCls = "igniting";
  } else if (selected) {
    stateText = "COLD · FUEL SELECTED";
  } else {
    stateText = "COLD · NO REACTOR LIT";
  }

  const board = getOpen ? (
    <Downloads
      vramTotal={telemetry?.gpus?.[0]?.vram_total_bytes ?? null}
      onClose={() => setGetOpen(false)}
      onDownloaded={rescan}
    />
  ) : suite ? (
    <SuiteBoard
      suite={suite}
      onClose={() => setSuite(null)}
      onExport={exportSuite}
    />
  ) : null;

  return (
    <div className="shell">
      <header className="hdr">
        <span className="wordmark">TOKAMAK</span>
        <span className={`hdr-state ${stateCls}`}>
          <span className={`lamp ${lampCls}`} />
          {stateText}
        </span>
        <span className="spacer" />
        {gpu && (
          <span className="gpu-chip">
            {gpu.name} · {gb(gpu.vram_total_bytes, 0)} GB
          </span>
        )}
        {server?.running && (
          <button className="danger" onClick={stop}>
            Shutdown
          </button>
        )}
      </header>

      {binaries.length === 0 && (
        <div className="runtime-bar">
          <span className="rt-title">No inference runtime found</span>
          <span className="rt-sub">
            Tokamak can fetch the right llama.cpp build for your GPU and manage it
            itself &mdash; nothing else to install.
          </span>
          <span className="spacer" />
          {rtProgress ? (
            <span className="rt-prog">
              {rtProgress.stage}
              {rtProgress.total > 0 &&
                ` · ${gb(rtProgress.received, 1)} / ${gb(rtProgress.total, 1)} GB`}
            </span>
          ) : rtBuilds ? (
            rtBuilds.map((b) => (
              <button
                key={b.id}
                className={b.recommended ? "primary" : ""}
                disabled={!!rtBusy}
                title={b.note}
                onClick={() => installRuntime(b)}
              >
                {b.label} · {gb(b.total_bytes, b.total_bytes > 1e9 ? 1 : 2)} GB
              </button>
            ))
          ) : (
            <button className="primary" onClick={loadRuntimeOptions}>
              Find builds
            </button>
          )}
        </div>
      )}

      <div className="deck">
        <div className="rail-left">
        <Library
          models={primary}
          visionDirs={visionDirs}
          roots={roots}
          scan={phase}
          estimates={estimates}
          runningPath={runningPath ?? null}
          busy={busy}
          selectedPath={selectedPath}
          hoverPath={hoverPath}
          onHover={setHoverPath}
          onSelect={(path) => setSelectedPath(path === selectedPath ? null : path)}
          onIgnite={(m) => ignite(m)}
          onBench={runBench}
          onSuite={runSuite}
          onRescan={rescan}
          onGet={() => setGetOpen(true)}
          onAddFolder={addFolder}
          onRemoveFolder={removeFolder}
        />
          <Sessions
            sessions={sessions}
            openIds={consoleState.openIds}
            busy={consoleState.busy}
            onOpen={(id) => consoleRef.current?.loadSession(id)}
            onDelete={(id) => consoleRef.current?.deleteSession(id)}
          />
        </div>

        <div className="center">
          <Console
            ref={consoleRef}
            onSessionsChanged={refreshSessions}
            onStateChanged={setConsoleState}
            server={server}
            metrics={metrics}
            liveCfg={liveCfg}
            modelName={liveName}
            cfgText={
              liveCfg
                ? `${liveCfg.ngl}${
                    runningModel?.metadata?.block_count
                      ? `/${runningModel.metadata.block_count}`
                      : ""
                  } layers · ${ctxLabel(liveCfg.ctx)} ctx`
                : null
            }
            staged={staged}
            board={board}
            kvAlert={kvAlert}
            workspace={settings?.agent_workspace ?? null}
            onPickWorkspace={pickWorkspace}
          />
          <Dock
            selected={selected}
            selectedEst={selectedEst}
            liveModel={runningModel}
            liveEst={liveEst}
            liveCfg={liveCfg}
            metrics={metrics}
            uptimeMs={server?.uptime_ms ?? null}
            benchDetail={
              bench
                ? {
                    name: bench.name,
                    expected: bench.expected,
                    results: bench.results,
                    running: benching && !suite,
                  }
                : null
            }
            onCloseBench={() => setBench(null)}
          />
        </div>

        <Rail
          telemetry={telemetry}
          metrics={metrics}
          server={server}
          liveEst={liveEst}
          ghost={ghost}
          ctxSize={liveCfg?.ctx ?? null}
          history={history}
          kvAlert={kvAlert}
          spec={spec}
          draftActive={!!liveCfg?.draft}
        />
      </div>

      <footer className="statusbar">
        <select
          value={settings?.preferred_binary ?? ""}
          onChange={(e) => pickBinary(e.target.value)}
          title="llama-server binary (applies to the next ignition)"
        >
          <option value="">auto · {binaries[0]?.label ?? "no binary found"}</option>
          {binaries.map((b) => (
            <option key={b.path} value={b.path}>
              {b.label}
            </option>
          ))}
        </select>
        <span className="kv-ctl" title="KV cache precision — applies to the next ignition">
          KV
          {KV_TYPES.map((k) => (
            <button
              key={k.id}
              className={kvType === k.id ? "on" : ""}
              onClick={() => pickKvType(k.id)}
              title={k.hint}
            >
              {k.label}
            </button>
          ))}
          {kvType !== "f16" && server?.running && (
            <span className="kv-pending">next ignition</span>
          )}
        </span>
        <span className="scale-ctl">
          UI {Math.round(scale * 100)}%
          <button onClick={() => bumpScale(-0.1)} title="Ctrl+- / Ctrl+wheel">
            −
          </button>
          <button onClick={() => bumpScale(0.1)} title="Ctrl+= / Ctrl+wheel">
            +
          </button>
        </span>
        <span>poll 1 Hz</span>
        {server?.base_url && <span className="api">api {server.base_url} · /v1</span>}
        <span className="spacer" />
        <span>{roots.length} scan dirs</span>
        {server?.uptime_ms != null && server.running && (
          <span>session {fmtUptime(server.uptime_ms)}</span>
        )}
      </footer>

      {error && (
        <div className="toast-error">
          <button onClick={() => setError(null)}>✕</button>
          {error}
        </div>
      )}
    </div>
  );
}

function SuiteBoard({
  suite,
  onClose,
  onExport,
}: {
  suite: {
    running: boolean;
    current: string | null;
    total: number;
    rows: SuiteRow[];
    exportPath: string | null;
  };
  onClose: () => void;
  onExport: () => void;
}) {
  const done = suite.rows.filter((r) => !r.skipped);
  const skipped = suite.rows.filter((r) => r.skipped);
  const ranked = [...done].sort((a, b) => b.decode_tok_s - a.decode_tok_s);
  const best = ranked[0]?.decode_tok_s ?? 0;
  return (
    <div className="board">
      <div className="board-head">
        <span className="lbl">Bench Board</span>
        <span style={{ font: "10.5px var(--mono)", color: "var(--faint)" }}>
          ranked by decode tok/s · recommended config per model
        </span>
        <span className="spacer" />
        {!suite.running && done.length > 0 && <button onClick={onExport}>Export Report ⇣</button>}
        {!suite.running && <button onClick={onClose}>✕</button>}
      </div>
      <div className="board-cols">
        <span className="c-rank">#</span>
        <span className="c-name">Model · Config</span>
        <span className="c-bar">Decode tok/s</span>
        <span className="c-num">Prefill</span>
        <span className="c-num small">Load</span>
        <span className="c-num">Peak VRAM</span>
      </div>
      {ranked.map((r, i) => {
        const ratio = best > 0 ? r.decode_tok_s / best : 0;
        const isBest = i === 0 && r.decode_tok_s > 0;
        const fillCls = isBest ? "best" : ratio >= 0.5 ? "" : ratio >= 0.1 ? "slow" : "bad";
        return (
          <div key={r.model} className="board-row">
            <span className="c-rank" style={{ color: isBest ? "var(--plasma)" : "var(--low)" }}>
              {String(i + 1).padStart(2, "0")}
            </span>
            <span className="c-name" title={r.model}>
              {r.model}{" "}
              <span className="sub">
                {r.quant ?? ""} · {r.n_gpu_layers}L · {ctxLabel(r.ctx_size)}
              </span>
            </span>
            <span className="c-bar">
              <span className="track">
                <span className={`fill ${fillCls}`} style={{ width: `${Math.max(2, ratio * 100)}%` }} />
              </span>
              <span className={`c-val ${isBest ? "best" : ""}`}>{r.decode_tok_s.toFixed(1)}</span>
            </span>
            <span className="c-num">{Math.round(r.prefill_tok_s).toLocaleString()}</span>
            <span className="c-num small">{(r.load_ms / 1000).toFixed(1)}s</span>
            <span className="c-num">{gb(r.peak_vram_bytes, 1)} GB</span>
          </div>
        );
      })}
      {skipped.map((r) => (
        <div key={r.model} className="board-row skipped" title={r.skipped ?? undefined}>
          <span className="c-rank">—</span>
          <span className="c-name">{r.model}</span>
          <span className="c-bar" style={{ color: "var(--low)", font: "11px var(--mono)" }}>
            skipped · {r.skipped}
          </span>
        </div>
      ))}
      {suite.running && (
        <div className="board-row pending">
          measuring {suite.current ?? "…"} — loading + generating on the bench port…{" "}
          {suite.rows.length}/{suite.total}
        </div>
      )}
      <div className="board-foot">
        {suite.exportPath
          ? `report saved: ${suite.exportPath}`
          : !suite.running && done.length > 0
            ? "measured on your GPU — real generation, not estimated"
            : ""}
      </div>
    </div>
  );
}

function fmtUptime(ms: number): string {
  const s = Math.floor(ms / 1000);
  const h = Math.floor(s / 3600);
  const m = Math.floor((s % 3600) / 60);
  return `${String(h).padStart(2, "0")}:${String(m).padStart(2, "0")}:${String(s % 60).padStart(2, "0")}`;
}

function dirOf(path: string): string {
  return path.slice(0, Math.max(path.lastIndexOf("\\"), path.lastIndexOf("/")));
}
