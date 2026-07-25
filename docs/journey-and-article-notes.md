# Journey & article source notes

**Purpose.** Raw narrative material for two planned write-ups:

1. **Article 1 — "Porting Squoosh to SvelteKit"** (the migration). Detailed source
   lives in [`history/`](history/); this doc summarises the arc + the best
   problem/solution beats and points at the deep docs.
2. **Article 2 — "Rebuilding seven WASM codecs from source, no Docker"** (the
   codec sweep, 2026-06-02). Documented here in full depth, because it happened in
   one push and the detail is freshest here.

Each section is structured the way an article wants it: **what we set out to do →
the problem we hit → how we actually solved it → the result / the lesson.** Keep
this honest — the dead ends and the misdiagnoses are the most interesting parts.

Cross-references for facts: [the project brief](project/brief.md) (live state),
[codec-build-notes.md](codec-build-notes.md) (per-codec build engineering),
[codec-provenance.md](codec-provenance.md) (exact versions),
[threading-enablement.md](threading-enablement.md) (the threading subsystem).

---

## Article 1 — The SvelteKit migration (summary + pointers)

> Full detail: [`history/MIGRATION-PLAN.md`](history/MIGRATION-PLAN.md),
> [`history/sveltekit-migration-seams-exit-audit.md`](history/sveltekit-migration-seams-exit-audit.md),
> [`history/sveltekit-codec-asset-strategy.md`](history/sveltekit-codec-asset-strategy.md),
> [`history/dashboard.html`](history/dashboard.html). This section is a skeleton to
> flesh out from those.

**The arc.** Squoosh is a Preact app; the goal was a SvelteKit static app at the
repo root, preserving every codec + the bulk-processing engine, then flipping the
SvelteKit app to be *the* app (it now lives at the repo root; the Preact original
is on the `preact` branch).

**Problem/solution beats worth telling (pull specifics from `history/`):**
- **The codec asset seam.** Squoosh resolves codec `.wasm`/worker URLs in ways a
  Vite/SvelteKit static build doesn't do for free. Solution at the time: a data-driven asset
  manifest (logical keys → physical assets → precache), plus a wrapper-patch step
  so Vite did not emit duplicate WASM. The manifest and worker modules are now
  committed source; only wrapper patching remains generated.
- **One pipeline for single-image and bulk.** Both go through
  `imagePipeline.compressImage` via the shared worker bridge, so there's no
  per-format branching. (`src/lib/compress.ts`, `history/bulk-image-architecture`.)
- **Cross-origin isolation got dropped in the root move.** Commit `b6abdea0`
  ("Promote SvelteKit app to root") deleted `serve.json`, silently disabling
  `SharedArrayBuffer` (and therefore all WASM threading). This became the seed of
  the threading thread in Article 2.
- **Dead weight removed:** WebP2 (`codecs/wp2/`) and dead codec dirs
  (`codecs/png/`, `codecs/visdif/`) — see
  [codec-surface-cleanup.md](history/codec-surface-cleanup.md).
- **A narrowed conditional, found a month later (2026-06-28).** Porting Squoosh's
  `getOutputPreviewImageState` to Svelte, the two-up output box was pinned to the
  source dims only for the `contain` fit method — but the original pinned it
  *unconditionally* and used the flag only to toggle `object-fit`. So every default
  (`stretch`) downscale silently broke the before/after alignment — latent until a
  user actually resized, months later. Traced with `git log -S` straight back to
  the "alignment" commit. The tell that it was an accident, not a decision: the same
  `pickFiles` reset kept the encoder but wiped the processors — half-and-half is the
  fingerprint of a convenience default. Reinforces the lesson below: a faithful
  port's bugs hide in *narrowed* conditionals — `always` quietly becomes
  `if (specialCase)`.

**The lesson angle:** a faithful framework migration is mostly about finding the
*implicit* contracts (asset URLs, headers, worker spawning) the old framework
satisfied for free, and making them explicit + tested.

---

## Article 2 — Rebuilding seven WASM codecs from source (no Docker)

### The setup: why, and the constraint that shaped everything

**Why.** A codec version audit found the vendored WASM codecs were years stale and
several carried real CVEs (libwebp's CVE-2023-4863 "BLASTPASS"; libaom's
CVE-2024-5171, CVSS 9.8; multiple libjxl CVEs; mozjpeg's libjpeg-turbo base had 9).
"Just bump a few versions" isn't enough when there's a CVSS-9.8 in the tree.

**The constraint.** The original codecs were built via Docker with a pinned old
Emscripten (`emsdk:2.0.34`). The decision: **build everything natively — no Docker,
no sudo.** That one constraint generated most of the war stories below, because the
modern toolchain (Emscripten 5.x / 3.1.0, cmake 4.x, nightly Rust) disagrees with
2021-era codec build files in a dozen small ways.

**The toolchains that ended up mattering:**
- `emsdk 5.0.7` (latest) — fine for *simple* single-library codecs (imagequant, webp).
- `emsdk 3.1.0` (arm64-native, era-matched to 2.0.34) — used for every *complex*
  multi-library C/C++ codec (avif, jxl, mozjpeg).
- `rustup nightly` + `wasm-pack` — for the Rust codecs (oxipng, resize).

> The single most important meta-lesson: **a build that "succeeds" can still produce
> a broken codec.** Three different codecs compiled + linked cleanly and produced
> WASM that was silently wrong (AVIF with no AV1 support, JXL that threw on output,
> a resize that could've returned garbage). The e2e + benchmark harness below is
> what caught them. Never trust the build exit code.

### The harness we built first (so nothing could break silently)

Before touching a codec we built the safety net — this is its own good article beat:
- **Playwright e2e suite** that drives the *real* production static build: per-codec
  magic-byte encode checks, alpha round-trips (decode the output, assert
  transparency survived), a 12 MP smoke test, quantize + resize functional tests,
  and a cross-origin-isolation boot check.
- **A benchmark harness** (`benchmarks/`) that encodes a fixed fixture set through
  every codec and records exact output size + encode time, with a `compare.mjs`
  that fails on regression (size exact, time noisy → 0.5%/12% tolerances).
- Later: a **multi-image fixture corpus** (expanded 4 → 9), and a **WebKit
  (Safari engine) project** so codecs are verified cross-engine, not just Chromium.

### The codecs, in order — task / problem / solution / result

**imagequant 2.12.1 → 2.18.0** (commit `f5f2b922`). The easy one, done first to
prove the native pipeline. Simple C library, byte-identical output. The one general
fix that unlocked everything else: the sync script's WASM-URL wrapper patch had to
be made **toolchain-agnostic** (older Emscripten emits `.toString()`, newer `.href`)
or modern rebuilds fail `npm run check`.

**libwebp (pre-1.2.0 commit) → v1.6.0** — CVE-2023-4863 (commit `c32fc2db`).
Byte-identical output (pure security win). Two real gotchas: (1) since v1.3.0
`libsharpyuv` is a **separate archive** — the Makefile had to link `libsharpyuv.a`
after `libwebp.a`; (2) the SIMD variant **silently lost its SIMD** (it built to the
non-SIMD baseline — caught because `webp_enc_simd.wasm` came out the same size as
`webp_enc.wasm`) until `-msimd128` was added.

**libavif 1.0.1 → 1.4.2 + libaom 3.7.0 → 3.12.1** — CVE-2024-5171 (commit
`d0655976`). **The best misdiagnosis story of the project.** The encoder linked to
a **21 KB** `.wasm` (vs ~2.8 MB) with no AV1 support. The first ~2-hour diagnosis
blamed an "Emscripten 5.x linker DCE change" that strips the inner library — and
that was **wrong**. Both emcc 3.1.0 and 5.x failed identically. The real cause:
**libavif v1.4 changed `AVIF_CODEC_AOM` from a boolean to a string enum
(`OFF`/`SYSTEM`/`LOCAL`)**, so the old `-DAVIF_CODEC_AOM=1` silently meant "no codec
source" → libavif built *without* the AOM codec → nothing referenced libaom → the
linker **correctly** dropped it. The 21 KB binary was the toolchain doing exactly
the right thing with a misconfigured input. Fix: `-DAVIF_CODEC_AOM=SYSTEM` (+
`-DAVIF_LIBYUV=OFF`, which v1.4 newly requires). **Lesson for the article:** when a
sub-library "vanishes," prove whether it's *referenced at all* (inspect the glue
object in the inner archive — `emar t libavif.a | grep codec_aom`) before blaming
the linker. Result: zero size regression, **6–13% faster** encode.

**libjxl (pre-0.7 commit) → v0.8.5** — 3 CVEs (commit `1063d1b9`). **The most
expensive bug, and the most generalizable.** Path A (v0.8.5) was chosen because the
encoder wrapper uses libjxl's *internal* C++ API, removed at v0.9+. After porting
the wrapper (the `quality_pair` field was removed; `ConvertFromExternal` got a new
signature), the encoder **compiled, linked, and produced a valid 56 KB JXL** —
`EncodeFile ok=1` — but the app showed *no output* and the e2e failed with "no
download." The cause was nowhere near the codec: the wrapper cached the JS
`Uint8Array` constructor in a **namespace-scope `thread_local`**
(`val::global("Uint8Array")`), and in a *large* module on emcc 3.1.0 that static
initializer runs **before the JS runtime is ready**, yielding an invalid emval
handle that throws `TypeError: Cannot read properties of undefined (reading 'value')`
*only when marshalling the result*. avif and webp use the identical pattern and
survive it (smaller static-init chains) — which is exactly why it looked
codec-specific. Fix: resolve `val::global(...)` at *call time*. Finding it required
realizing `compress.ts` decodes the output for preview *before* creating the
download URL (so an encoder OR decoder failure both look like "no download"), then
`EM_ASM` console probes captured via Playwright's `worker.on('console')`, plus a
fast manual relink loop (reuse the built `libjxl.a`, ~30 s vs a 20-min `make`).
Also five separate macOS/modern-toolchain build gotchas (nproc, cmake-policy,
llvm-ar PATH, `JPEGXL_BUNDLE_SKCMS=0`, submodule population). Result: **3–6% smaller
+ 2–9% faster**.

**oxipng 9.0.0 → 10.1.1** (Rust, commit `1051dc69`). Byte-identical output;
security/maintenance + fast-mode/ICC fixes. The Rust-codec gotchas (which the
article should treat as "the no-Docker Rust path"): (1) oxipng 10 pulls
**libdeflate-sys (C)**, and the `cc` crate's default Apple clang has **no
WebAssembly backend** — you must point it at emsdk's clang + libc headers; (2)
wasm-bindgen 0.2.73 is too old for nightly 1.98 — bump it *and delete `Cargo.lock`*
(the lock pinned the old one and "0.2" still satisfied it); (3) `~/.cargo/bin` must
be first on PATH so the rustup shim wins over a Homebrew cargo. Plus the sync
script's wasm-bindgen wrapper patch broke (the loader var was renamed `input` →
`module_or_path`) — fixed to be variable-name-agnostic, which then unblocked resize
too.

**mozjpeg v3.3.1 → v4.1.5** — 9 CVEs (commit `2b6f54f6`). Byte-identical output
(the byte-identical *is* the proof the migration is wired right). The real work was
**autotools → CMake** (v4 deleted `configure.ac`). The blocker beat:
`check_type_size(size_t)` is **broken on emsdk 3.1.0 under `-flto`** — Emscripten's
CheckTypeSize greps an `INFO:size[N]` sentinel out of the compiled object, but
`-flto` makes that object LLVM bitcode (sentinel unreadable), so `SIZEOF_SIZE_T`
came out **9** (or **1** with the node emulator), and jchuff.c `#error`'d "Cannot
determine word size." Fix: pre-seed `-DSIZE_T=4 -DHAVE_SIZE_T=1` to skip the broken
probe (wasm32 is ILP32). Also had to compile `rdswitch.o` ourselves (the wrapper
calls `set_quality_ratings`, a cjpeg helper not in `libjpeg.a`).

**resize 0.5.5 → 0.8.9** (Rust, commit `4d817ada`). No CVE — but we are **ahead of
both Squoosh and jSquash** (both pin 0.5.5), so there's no reference build; we
verified it directly. The 0.8 API resizes **typed pixel slices** (`rgb::RGBA<u8>`),
not raw `&[u8]`; the crate is **edition 2015** so a new dep needs `extern crate`,
and an `extern crate` inside a module is referenced via `self::` in a `use`. Since
there was no upstream to match, verification was two-pronged: a UI-driven e2e
(resize had zero coverage before) **and** a direct nodejs-target harness exercising
both the RGBA8 and the RGBAF32 premultiply/linear paths.

### The benchmark corpus expansion (a good standalone beat)

The original 4 fixtures clustered. We added 5 deterministic, generated fixtures
(seeded PRNG + an embedded bitmap font, no downloads) targeting the axes that
differentiate codecs: gradient/dithered-gradient (banding), hard-edges (DCT
ringing — oxiPNG **5 KB** vs JXL **63 KB** on the same image), noise-synthetic
(QOI *bloats past the input*, a great regression canary), and a synthetic
screenshot (JXL-modular/WebP-lossless win, MozJPEG worst on text). The point:
diverse inputs reveal 10×+ spreads that averaged numbers hide — directly usable as
article data.

### The threading thread (the cliffhanger / sequel hook)

This connects back to the migration (cross-origin isolation got dropped). The app
*already ships* multithreaded codec variants; they were deliberately disabled
because the make-or-break unknown was "Safari can't do nested workers" (the codecs
run inside a worker, and wasm-bindgen-rayon / Emscripten pthreads spawn a
worker-in-worker). Two findings, both committed/documented:
1. **The Safari unknown is resolved.** Using Playwright's WebKit (Safari's exact
   engine), `tests/e2e/threads-support.spec.ts` proves modern Safari supports
   nested workers + SharedArrayBuffer + Atomics. The reason for the deferral is
   gone.
2. **The full oxipng threaded wiring was built** (Vite bundles the nested rayon
   worker; the generator emits the threaded assets) but was blocked on one thing:
   the threaded `pkg-parallel` wasm shipped a **non-shared** `WebAssembly.Memory`,
   so rayon's `postMessage(memory)` threw `DataCloneError` and it fell back to
   single-thread. **Resolved 2026-06-03** — see below.

### The threading resolution — "the recipe rotted out from under the docs"

> **What we set out to do.** Ship the already-built threaded oxipng so it uses
> all cores. **The problem.** The threaded wasm's memory was non-shared
> (`flags=0x0`); rayon couldn't `postMessage` it. The previous session had tried
> the *canonical* wasm-bindgen-rayon recipe (`-C target-feature=+atomics,+bulk-memory,+mutable-globals`
> + `-Z build-std`) and it *still* came out non-shared — and forcing
> `--shared-memory --max-memory` made **wasm-bindgen** error `failed to prepare
> module for threading`. A genuine dead-end on the surface.

**How we actually solved it.** Two sub-agents researched in parallel: one read
**jSquash's** working oxipng-parallel build, the other read the **current**
wasm-bindgen-rayon README + issue tracker. The two sources *disagreed*, and the
disagreement WAS the answer:

- jSquash (wasm-bindgen-rayon **1.2.1**, wasm-bindgen **0.2.92**) gets shared
  memory from bare `+atomics,+bulk-memory` — on that toolchain `+atomics`
  auto-emitted a shared+imported memory at link.
- The current README (tested on a late-2025 nightly, even older than our
  2026-06 nightly) now documents the **full explicit linker set** — because that
  implicit behavior was removed. `+atomics` alone now emits a *non-shared*
  memory.

So the recipe hadn't been *wrong*, it had **rotted**: the toolchain quietly
dropped the auto-shared-memory behavior the canonical recipe leaned on. The fix
was to pass everything explicitly: `--shared-memory` + `--max-memory` (a shared
memory must declare a max) + `--import-memory` + the TLS exports
(`__wasm_init_tls`, `__tls_{size,align,base}`) **and** `__heap_base`. The earlier
dead-end was *incomplete*, not wrong — wasm-bindgen's threading pass needs those
exported symbols to rewrite, and it tells you which one is missing
(`failed to prepare module for threading` → no TLS exports; `failed to find
__heap_base` → add `__heap_base`). Each error named the next flag to add.

**The result / the lesson.** oxipng now threads multi-core — **11 rayon workers
in Chromium, an 8-thread pool in WebKit/Safari** — verified by an e2e test that
asserts threading *engages* (worker-helper fetch + no single-thread-fallback
warning), single-thread fallback intact. **The lesson:** a "known-good recipe"
has an implicit dependency on the toolchain version that produced it; when it
fails on a newer toolchain, diff a *recent* working build against the *canonical*
docs — the delta is the behavior the new toolchain stopped doing for free. (And
trust the compiler's error messages: each missing-export error pointed straight
at the next flag.) Full technical record:
[threading-enablement.md](threading-enablement.md),
[codec-build-notes.md](codec-build-notes.md).

### AVIF + JXL threading — "a deadlock that had been latent for years"

> **What we set out to do.** Extend threading to AVIF and JXL. Unlike oxipng
> (Rust/rayon) these are **Emscripten pthreads**, and their `_mt` / `_mt_simd`
> builds *already existed* — so this looked like pure JS wiring. **The problem.**
> After wiring, every AVIF/JXL encode **hung forever** — not a crash, not a
> fallback, a silent hang.

**The wiring itself was the easy part** (and it works): the threaded glue is
served from a hashed `?url`, so the pthread workers it self-spawns can't use the
relative `./<codec>_mt.js` import Emscripten defaults to — you hand them the glue's
URL as `Module.mainScriptUrlOrBlob`. (Plus a Vite gotcha: the ~2 kB `.worker.js`
was being **inlined as a `data:` URI** under the 4 kB limit, which breaks a Worker
under COEP — pin `assetsInlineLimit` to keep it a real file.)

**The hang was the hard part, and the diagnosis is the whole story.** The pthread
workers are *classic nested* workers, which Playwright doesn't surface — so there
was no console, no error, nothing. We narrowed it by **moving the code to where we
could see it**: loaded the glue in the page itself → `init` resolved fine, but
`encode()` threw `Atomics.wait cannot be called in this context` (the encode is
*meant* to run on a worker thread, not the main thread). Then ran it in a
*nested* worker with step-by-step `postMessage` progress → it printed
"factory resolved" then "encoding" then **stopped**. That pinned it: not init, the
encode.

**The root cause was in the codec build, not our code** — and it had been latent
*because the threaded builds had never actually been run* (threading was disabled
since the migration). The `_mt` Makefiles compile with `-pthread` but set **no
`PTHREAD_POOL_SIZE`**, so Emscripten creates pthreads **on-demand** mid-encode. But
the encode runs synchronously in the codec worker and **blocks on `Atomics.wait`**
waiting for the pool — so it can never process the new worker's "I'm loaded"
message, and the thread it's waiting for can never start. Classic deadlock. **The
fix:** rebuild the `_mt` wrappers with
`-sPTHREAD_POOL_SIZE=navigator.hardwareConcurrency` so the pool is spawned + ready
*before* the blocking encode. It's a link-only flag (relink against the cached
`.a`s in seconds), with one trap: keep the original `-O3 -flto` +
`ALLOW_MEMORY_GROWTH` env flags or you silently ship a 16 MB-capped, unoptimised
binary.

**The result / the lesson.** AVIF + JXL now spawn the full pthread pool (11 workers
on an 11-core machine) and encode without falling back, Chromium + WebKit. **The
lesson:** *code that is never executed accumulates latent bugs that look like
config but are real.* The `_mt` builds had shipped for years with a fatal
threading deadlock that nobody hit because nobody turned threading on. And when the
runtime gives you nothing — classic nested workers are invisible — **relocate the
failing code to a context you can observe** (page → nested worker, with progress
pings) and the silent hang names itself.

### Cross-cutting lessons (the article's takeaways)

- **The build harness is the product.** Three codecs compiled fine and were silently
  broken; the e2e/benchmark caught all three. Build first, then verify behaviour.
- **"It vanished" usually means "it was never referenced."** (AVIF.) Inspect the
  archive before blaming the toolchain.
- **A bug can be entirely outside the thing you changed.** (JXL: a codec port
  surfaced an emscripten static-init bug in the result marshalling.)
- **Old build files vs new toolchains is a genre of bug**: nproc (Linux-only),
  cmake-4-vs-2019-CMakeLists, `check_type_size` + `-flto`, Apple-clang-has-no-wasm,
  edition-2015 `extern crate`. Each is small; together they're the whole story of
  "no Docker."
- **Byte-identical is a feature, not a disappointment** — for a security rebuild it's
  the proof you changed nothing but the version.
- **Keep the fix, not the band-aid.** Several first attempts (ERROR_ON_UNDEFINED=0
  masking, `--whole-archive` force-include, the emcc-version theory) were reverted
  once the real cause was found and written down so we'd never retry them.

## Bonus beats — the performance pass (2026-06-10)

Not a planned article, but several beats here are strong sidebar material for
either write-up. Task: make the app faster, smoother, leaner.

### The service worker was shipping both halves of every either/or

**The task.** First-visit payload audit: the SW precached 14.27 MB.
**The problem.** `$service-worker`'s `build` array lists *every* Vite-emitted
asset, and the SW blanket-`addAll`'d it — so every visitor downloaded the
multi-thread AND single-thread AVIF encoders (2.8 + 2.7 MB), three JXL encoder
variants of which any given browser runs exactly one, SIMD and baseline WebP,
and WASM decoders for formats their browser decodes natively.
**The solution.** Feature-detect *in the service worker at install time*
(threads + SIMD via `wasm-feature-detect`; native AVIF/WebP decode by feeding
tiny probe images to `createImageBitmap`) and precache only the selected
variants; everything else stays reachable via cache-first-with-runtime-fill,
so a misdetection costs one online fetch, never a broken codec.
**The result.** 6.82 MB precache in Chromium (−52%), offline promise intact,
asserted by the e2e suite. **The lesson:** a "cache everything" install step
silently doubles as a download-everything tax; the variant structure was
already in the data model (`threaded-only` tags) — nobody had wired it to the
SW.

### Two gotchas inside SvelteKit's service-worker build

1. The SW is built by a *separate* Vite config (kit's own): the app's
   `assetsInlineLimit` doesn't apply, so sub-4 kB assets imported into the SW
   graph (rotate WASM, pthread worker stubs) inline as `data:` URLs — and
   `cache.addAll` rejects `data:` schemes. Fix: a curated generated records
   module that simply never imports the tiny files (they ride the app shell,
   whose URLs come as strings from `build`).
2. `?worker&url` imports in the SW graph make that separate build re-emit the
   whole worker chunk under its own hash — 270 kB of dead duplicates that got
   precached while the page fetched the real ones. The audit script now
   asserts the SW build emits zero own worker chunks.

### svelte-check crashing with `forEachResolvedModule is not a function`

A heisenbug worth its own sidebar: svelte-check 4.3.4 + TypeScript 6 only
crashed when *some* diagnostic existed whose code-fix path consults the
symlink cache (volar's wrapper calls the TS-internal
`program.forEachResolvedModule`, removed in TS 6). A clean tree checked fine;
one bad named import anywhere crashed the whole run with no stack trace. Cost
a long bisect (file-by-file, then content-by-content, then a deliberate
bad-import experiment on a clean tree proved it environmental). Fix:
svelte-check 4.6.0.

### Small leans with outsized ratios

- `logo.webp`: 512 px / 56 kB for an 88-CSS-px slot → 176 px / 7 kB (cwebp
  q90). The largest first-load asset of an image-compression app was an
  unoptimized image.
- The landing blob animation did 2× `getBoundingClientRect` +
  `getComputedStyle` + a full canvas backing-store reallocation
  (`canvas.width =`) *per rAF frame* — geometry now lives in a
  ResizeObserver-refreshed snapshot and the loop just
  `setTransform`+`clearRect`s.
- The codec worker idle-terminated after 10 s (upstream Squoosh's number);
  with threaded codecs a respawn now re-instantiates WASM and a pthread pool,
  so a slider tweak after a pause paid a visible cold start. 60 s.
- Verification gotcha: `vite preview` (sirv) snapshots the served file list at
  boot — after a rebuild the new hashed filenames 404 until the preview server
  restarts. Looks exactly like a broken build.
