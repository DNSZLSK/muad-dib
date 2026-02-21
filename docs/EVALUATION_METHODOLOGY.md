# MUAD'DIB — Evaluation Methodology

## 1. Methodology

MUAD'DIB measures scanner effectiveness using a rigorous experimental protocol inspired by machine learning evaluation practices. Two distinct datasets are used:

### Training Set (Adversarial)

The **adversarial dataset** (`datasets/adversarial/`) contains malicious samples used during rule development. When a sample fails detection, rules are improved until it passes. This measures the scanner's **tuned performance** — the best-case scenario after iterative refinement.

- Samples are created before any rule changes
- Initial scores are recorded with rules frozen (pre-tuning baseline)
- Rules are then improved to close detection gaps
- Final scores represent post-tuning performance

### Holdout Set

The **holdout set** is a separate batch of samples created after rule tuning is complete. Rules are **frozen** — no modifications allowed. The raw scores measure the scanner's **generalization ability**: how well existing rules detect attack patterns they were never tuned for.

- Samples designed independently from current rules
- Scores reported as-is, no threshold adjustments
- Provides an honest assessment of detection gaps

Both metrics (ADR and Holdout) are published together. The gap between them reveals how much the scanner relies on sample-specific tuning vs. genuine pattern recognition.

---

## 2. Raw Scores Before Correction (Holdout History)

Each batch below was evaluated with **rules frozen** at the time of creation. These scores represent pre-tuning baselines — the scanner's genuine first-contact performance on unseen samples.

### Robustness Test (3 samples, rules frozen): 1/3 (33%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| dynamic-require | 28 | 40 | FAIL |
| iife-exfil | 58 | 40 | PASS |
| conditional-chain | 3 | 30 | FAIL |

### Vague 2 (5 samples, rules frozen): 0/5 (0%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| template-literal-obfuscation | 3 | 30 | FAIL |
| proxy-env-intercept | 28 | 40 | FAIL |
| nested-payload | 13 | 30 | FAIL |
| dynamic-import | 13 | 30 | FAIL |
| websocket-exfil | 13 | 30 | FAIL |

### Intermediate Batch (5 samples, rules frozen): 3/5 (60%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| bun-runtime-evasion | 48 | 30 | PASS |
| preinstall-exec | 13 | 35 | FAIL |
| remote-dynamic-dependency | 35 | 35 | PASS |
| github-exfil | 68 | 30 | PASS |
| detached-background | 13 | 35 | FAIL |

### Vague 3 (5 samples, rules frozen): 3/5 (60%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| ai-agent-weaponization | 13 | 35 | FAIL |
| ai-config-injection | 0 | 30 | FAIL |
| rdd-zero-deps | PASS | 35 | PASS |
| discord-webhook-exfil | PASS | 30 | PASS |
| preinstall-background-fork | PASS | 35 | PASS |

### Holdout v1 (10 samples, rules frozen): 3/10 (30%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| silent-error-swallow | 35 | 25 | PASS |
| double-base64-exfil | 13 | 30 | FAIL |
| crypto-wallet-harvest | 0 | 25 | FAIL |
| self-hosted-runner-backdoor | 3 | 20 | FAIL |
| dead-mans-switch | 68 | 30 | PASS |
| fake-captcha-fingerprint | 3 | 20 | FAIL |
| pyinstaller-dropper | 3 | 35 | FAIL |
| gh-cli-token-steal | 0 | 30 | FAIL |
| triple-base64-github-push | 38 | 30 | PASS |
| browser-api-hook | 0 | 20 | FAIL |

### Holdout v2 (10 samples, rules frozen): 4/10 (40%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| env-var-reconstruction | 3 | 25 | FAIL |
| homedir-ssh-key-steal | 35 | 30 | PASS |
| setTimeout-chain | 35 | 25 | PASS |
| wasm-loader | 25 | 20 | PASS |
| npm-lifecycle-preinstall-curl | 13 | 30 | FAIL |
| process-env-proxy-getter | 0 | 20 | FAIL |
| readable-stream-hijack | 0 | 20 | FAIL |
| github-workflow-inject | 0 | 25 | FAIL |
| npm-cache-poison | 0 | 20 | FAIL |
| conditional-os-payload | 35 | 25 | PASS |

### Holdout v3 (10 samples, rules frozen): 6/10 (60%)

| Sample | Score | Threshold | Result |
|--------|-------|-----------|--------|
| require-cache-poison | 0 | 20 | FAIL |
| symlink-escape | 35 | 25 | PASS |
| dns-txt-payload | 10 | 25 | FAIL |
| env-file-parse-exfil | 25 | 25 | PASS |
| git-credential-steal | 25 | 25 | PASS |
| electron-rce | 45 | 25 | PASS |
| postinstall-reverse-shell | 3 | 30 | FAIL |
| steganography-payload | 10 | 15 | FAIL |
| npm-hook-hijack | 38 | 20 | PASS |
| timezone-trigger | 45 | 20 | PASS |

### Holdout v4 (10 samples, rules frozen, deobfuscation test): 8/10 (80%)

This holdout specifically tests whether the new deobfuscation pre-processing (`src/scanner/deobfuscate.js`) improves detection of obfuscated malware. Samples use string concatenation, charcode reconstruction, base64 encoding, and hex arrays to hide malicious intent.

| Sample | Score | Threshold | Result | Deobfuscation Impact |
|--------|-------|-----------|--------|----------------------|
| base64-require | 25 | 20 | PASS | Resolves `Buffer.from('Y2hpbGRfcHJvY2Vzcw==','base64')` |
| charcode-fetch | 35 | 20 | PASS | Resolves `String.fromCharCode` URL |
| concat-env-steal | 13 | 20 | FAIL | Concat resolved but insufficient score |
| hex-array-exec | 25 | 20 | PASS | **0 → 25** (only detected with deobfuscation) |
| atob-eval | 11 | 20 | FAIL | `eval(atob(...))` not yet a distinct rule |
| nested-base64-concat | 10 | 20 | FAIL | Const propagation not yet implemented |
| charcode-spread-homedir | 45 | 20 | PASS | Resolves `String.fromCharCode(...[111,115])` |
| mixed-obfuscation-stealer | 45 | 25 | PASS | **10 → 45** (multi-layer resolved) |
| template-literal-hide | 60 | 15 | PASS | Template literals already detected |
| double-decode-exfil | 70 | 20 | PASS | Double base64 layers resolved |

**Note:** The raw pre-tuning score is **8/10 (80%)**. Two samples (atob-eval and nested-base64-concat) were later fixed with `staged_eval_decode` (MUADDIB-AST-021) and const propagation in the deobfuscator, bringing the post-correction score to 10/10. The 80% is the honest generalization metric.

**Key deobfuscation impact:** `hex-array-exec` went from score 0 (undetectable) to 25 purely thanks to deobfuscation resolving `[0x63,...].map(c=>String.fromCharCode(c)).join('')`. `mixed-obfuscation-stealer` went from 10 to 45 as multiple obfuscation layers were resolved, revealing hidden dangerous patterns.

### Holdout v5 (10 samples, rules frozen, inter-module dataflow test): 5/10 (50%)

This holdout is the first to specifically test **cross-file dataflow detection** (`src/scanner/module-graph.js`). Samples split credential theft across multiple files: one module reads sensitive data, another exfiltrates it over the network. Patterns include re-export chains, class method analysis, named export destructuring, function-wrapped taint propagation, and 3-hop chains with intermediate transforms.

| Sample | Score | Threshold | Result | Technique |
|--------|-------|-----------|--------|-----------|
| split-env-exfil | PASS | 20 | PASS | Cross-file `process.env.GITHUB_TOKEN` → `fetch()` |
| split-npmrc-steal | PASS | 20 | PASS | Cross-file `fs.readFileSync(.npmrc)` → `https.request` |
| reexport-chain | PASS | 20 | PASS | Double re-export chain (a → b → c) |
| three-hop-chain | PASS | 20 | PASS | Source → transform (base64) → sink, 3-hop propagation |
| named-export-steal | PASS | 20 | PASS | Named export destructuring `{ getCredentials }` → `fetch()` |
| class-method-exfil | FAIL | 20 | FAIL | Class instantiation + method call dataflow |
| mixed-inline-split | PASS | 20 | PASS | Dual: inline eval + cross-file credential flow |
| conditional-split | PASS | 20 | PASS | CI-gated exfiltration (only in `process.env.CI`) |
| event-emitter-flow | FAIL | 20 | FAIL | EventEmitter pub/sub dataflow across modules |
| callback-exfil | FAIL | 20 | FAIL | Callback parameter passing for credential exfiltration |

**Note:** The raw pre-tuning score is **5/10 (50%)**. The 50% drop from holdout v4 (80%) is expected — this is the first holdout testing an entirely new scanner (`module-graph.js`) rather than improvements to existing scanners. 3 samples use patterns outside the current scope: EventEmitter pub/sub flow, callback-based taint propagation, and class instantiation method calls. These are accepted as known limitations of the static AST approach. Post-correction score: 8/10, with 2 limitations accepted (EventEmitter, callback).

**Key inter-module capabilities validated:** re-export chains (a → b → c), 3-hop propagation with intermediate transforms, named export + destructuring, inline require re-export, function-wrapped taint propagation, and class method analysis (post-correction).

---

## 3. Progression

| Batch | Pre-Tuning Rate | Samples |
|-------|-----------------|---------|
| Robustness Test | 33% (1/3) | 3 |
| Vague 2 | 0% (0/5) | 5 |
| Intermediate | 60% (3/5) | 5 |
| Vague 3 | 60% (3/5) | 5 |
| Holdout v1 | 30% (3/10) | 10 |
| Holdout v2 | 40% (4/10) | 10 |
| Holdout v3 | 60% (6/10) | 10 |
| **Holdout v4** | **80% (8/10)** | 10 |
| **Holdout v5** | **50% (5/10)** | 10 |

**Key observations:**

- The 0% in Vague 2 exposed critical gaps (template literal handling, staged payloads, dynamic imports). Fixing these improved subsequent batches.
- The 60% in Intermediate/Vague 3 shows partial generalization — rules improved for earlier samples also caught new patterns.
- The **Holdout v1 30%** revealed 7 genuine blind spots: binary droppers, prototype hooking, credential CLI theft, workflow injection, crypto wallet harvesting, and more.
- The **Holdout v2 40%** shows marginal improvement in generalization (+10pp). 6 new blind spots identified: env var charcode reconstruction, lifecycle shell pipe, Object.defineProperty proxy, Node.js core prototype hijack, GitHub workflow injection via template literals, npm cache poisoning.
- The **Holdout v3 60%** shows significant improvement (+20pp over v2). 4 blind spots identified: require.cache poisoning, DNS TXT payload staging, JavaScript reverse shell (net.Socket + pipe), steganographic payload execution.
- The **Holdout v4 80%** shows the strongest generalization yet (+20pp over v3). This batch specifically tested deobfuscation — 2 samples only detectable thanks to the new deobfuscation pre-processing (`hex-array-exec` 0→25, `mixed-obfuscation-stealer` 10→45). 2 blind spots identified: eval+decode compound pattern, const propagation needed for split base64 variables.
- The **Holdout v5 50%** is the first holdout testing an entirely new scanner (`module-graph.js`) rather than improvements to existing ones. The drop from 80% to 50% reflects the challenge of a new detection domain (inter-module dataflow). 5 samples detected out of the box — re-export chains, 3-hop propagation, named exports, inline require, conditional splits. 3 samples failed: EventEmitter flows, callback-based taint, and class method calls (2 accepted as fundamental limitations of static analysis, 1 fixed post-holdout).
- **Progression trend: 30% → 40% → 60% → 80% → 50%** — the first four holdouts show consistent improvement on the same scanner. Holdout v5 tests a new scanner, resetting the baseline. The 50% on first contact with inter-module patterns is a strong starting point.
- After corrections, all 73 samples pass (ADR 100%, with 2 accepted limitations). But the pre-correction holdout scores (30%, 40%, 60%, 80%, 50%) are the true measures of generalization.

---

## 4. Improvement Cycle

MUAD'DIB follows a structured **tune-freeze-holdout-publish** cycle:

```
1. TUNE     Create adversarial samples with rules frozen
            Record pre-tuning scores (raw holdout data)
            Improve rules until all samples pass

2. FREEZE   Lock rules — no further modifications

3. HOLDOUT  Create new samples never seen during tuning
            Run scanner with frozen rules
            Record raw scores (no threshold changes)

4. PUBLISH  Report both metrics:
            - ADR (post-tuning): measures tuned performance
            - Holdout (pre-tuning): measures generalization

5. PROMOTE  Move FAIL samples to adversarial dataset
            Improve rules to close gaps
            Repeat from step 2 with new holdout batch
```

This cycle ensures:
- **Honesty**: pre-tuning scores are always published alongside post-tuning scores
- **No overfitting**: holdout samples test genuine generalization, not memorization
- **Continuous improvement**: each cycle identifies real blind spots and closes them
- **Reproducibility**: `muaddib evaluate` reproduces all metrics locally

---

## 5. Attack Technique Sources

All adversarial samples are based on real-world attack techniques documented by security researchers in 2025-2026:

| Source | Techniques | Reference |
|--------|-----------|-----------|
| **Snyk** | ToxicSkills (AI config injection in .cursorrules, CLAUDE.md), s1ngularity/Nx (AI agent weaponization with --dangerously-skip-permissions), Clinejection (prompt injection via copilot-instructions.md) | Snyk Blog 2025 |
| **Sonatype** | PhantomRaven (zero-deps variant with inline https.get + eval in postinstall), binary droppers via /tmp/ | Sonatype Blog 2025 |
| **Datadog Security Labs** | Shai-Hulud 2.0 (GitHub Actions workflow injection, self-hosted runner backdoor, discussion.yaml persistence) | Datadog Security Research 2025 |
| **Unit 42 (Palo Alto)** | Shai-Hulud v1 campaign analysis, credential exfiltration patterns, dead man's switch (rm -rf if no tokens) | Unit 42 Threat Research 2025 |
| **Check Point Research** | Shai-Hulud 2.0 credential harvesting, Discord webhook exfiltration, base64 multi-layer encoding | Check Point Research 2025 |
| **Zscaler ThreatLabz** | Shai-Hulud V2 evasion techniques, CI-gated payloads, DNS chunked exfiltration | Zscaler ThreatLabz 2025 |
| **StepSecurity** | s1ngularity campaign (Claude/Gemini/Q agent abuse, --yolo flag), postinstall fork + detached credential theft | StepSecurity Blog 2025 |
| **Socket.dev** | Mid-Year Supply Chain Report 2025, preinstall-exec patterns, staged fetch payloads, npm lifecycle hooks abuse | Socket.dev 2025 |
| **NVIDIA** | AI agent security guidance, prompt injection in AI config files, tool-use exploitation | NVIDIA AI Security 2025 |
| **Sygnia** | chalk/debug September 2025 compromise, prototype hooking (globalThis.fetch, XMLHttpRequest.prototype), native API interception | Sygnia Threat Intelligence 2025 |
| **Hive Pro** | Typosquatting credential theft, crypto wallet harvesting (.ethereum, .electrum, .config/solana), gh auth token CLI abuse | Hive Pro Research 2025 |
| **Koi Security** | PackageGate vulnerability, npm registry metadata manipulation, publish frequency anomalies | Koi Security 2025 |

---

## 6. FPR Methodology Correction (v2.2.7)

### Previous FPR was invalid (v2.2.0–v2.2.6)

The FPR metric reported in versions v2.2.0 through v2.2.6 (0% on 98 packages) was **invalid**. The `evaluateBenign()` function created empty temporary directories containing only a `package.json` with the package name, then ran the scanner against these empty directories. This only tested IOC name matching and typosquat detection — it did **not** scan the actual source code of the packages. The 13+ scanners (AST, dataflow, obfuscation, entropy, etc.) had nothing to analyze.

This was discovered when comparing the evaluation approach for benign packages vs. ground truth/adversarial: the latter scanned real JavaScript files, while benign packages never downloaded or examined any code.

### Fix: real source code scanning

In v2.2.7, `evaluateBenign()` was rewritten to:
1. Download real tarballs via `npm pack <pkg>` (executed with `cwd` to avoid Windows path issues)
2. Extract tarballs using native Node.js (`zlib.gunzipSync` + tar header parsing — no shell `tar` dependency)
3. Scan the extracted source code with all 14 scanners
4. Cache tarballs in `.muaddib-cache/benign-tarballs/` to avoid re-downloading
5. Support `--benign-limit N` to test a subset and `--refresh-benign` to force re-download

### Real FPR: 38% (19/50) — first honest measurement (v2.2.7)

Measured on 50 real npm packages (first 50 from the 529-package benign list). Threshold: score > 20.

**Top FP-causing threat types** (frequency across all 19 false positives):

| Threat Type | Count | Primary Offenders |
|-------------|-------|-------------------|
| `dynamic_require` | 127 | next (76), gatsby (20), strapi (7), sails (6) |
| `dangerous_call_function` | 90 | keystone (29), next (20), htmx.org (10), vue (7) |
| `prototype_hook` | 67 | restify (52), next (15) |
| `env_access` | 61 | next (33), keystone (17), moleculer (3) |
| `dynamic_import` | 56 | next (45), gatsby (7), nuxt (3) |
| `obfuscation_detected` | 44 | next (41), keystone (1), total.js (1) |
| `typosquat_detected` | 25 | chai↔chalk, pino↔sinon, ioredis↔redis, etc. |
| `suspicious_dataflow` | 26 | next (13), keystone (4), moleculer (4) |
| `dangerous_call_eval` | 21 | next (11), htmx.org (6), total.js (4) |
| `require_cache_poison` | 18 | gatsby (8), next (4), moleculer (2) |
| `staged_payload` | 10 | htmx.org (5), next (4), total.js (1) |

**Worst offenders** (score 100):

| Package | Score | Primary FP Causes |
|---------|-------|-------------------|
| next | 100 | Massive bundled output with dynamic requires/imports, obfuscated dist files, prototype extensions |
| gatsby | 100 | Plugin system with dynamic requires, require.cache for HMR |
| restify | 100 | `Request.prototype.*` / `Response.prototype.*` assignments (52 hits) |
| moleculer | 100 | Datadog metrics (os.hostname + fetch), require.cache for hot-reload |
| keystone | 100 | Bundled admin UI (minified JS), env access for config keys |
| total.js | 100 | eval-based template engine, dynamic env access, staged payload pattern |
| htmx.org | 100 | eval for dynamic CSS expressions + fetch in same file |

---

## 7. FP Reduction (v2.2.8)

### Approach: count-based severity downgrade

The key insight: **legitimate frameworks produce high volumes of certain threat types, while malware typically has 1-3 occurrences**. A package with 76 `dynamic_require` hits is almost certainly a plugin system (Next.js), not malware. A package with 52 `prototype_hook` hits is a framework extending its own classes (Restify), not a prototype poisoning attack.

MUAD'DIB v2.2.8 introduces **post-processing FP reductions** applied after deduplication but before scoring/enrichment. These downgrade severity (not remove findings) based on per-package threat counts, preserving detection signals while reducing score impact.

### 5 corrections

**Correction 1 — `dynamic_require` (>10 occurrences → LOW):**
- If a package has more than 10 `dynamic_require` findings, all HIGH occurrences are downgraded to LOW
- Rationale: Next.js has 76, Gatsby 20, Strapi 7. Malware never has >10 dynamic requires.
- Safety: adversarial `dynamic-require` sample has ~5-6 findings (well under threshold)

**Correction 2 — `dangerous_call_function` (>5 occurrences → LOW):**
- If a package has more than 5 `dangerous_call_function` findings, all MEDIUM occurrences are downgraded to LOW
- Rationale: Keystone has 29, Next.js 20, htmx 10. Template engines legitimately use many `Function()` calls.
- Safety: no adversarial sample has >5 Function() calls

**Correction 3 — `prototype_hook` (custom framework prototypes → MEDIUM):**
- `prototype_hook` findings targeting `Request.prototype.*`, `Response.prototype.*`, `App.prototype.*`, or `Router.prototype.*` are downgraded from HIGH to MEDIUM
- CRITICAL prototype hooks (Node.js core: `http.IncomingMessage`, `net.Socket`) are NOT touched
- Malicious hooks targeting `globalThis.fetch` or `XMLHttpRequest.prototype` remain HIGH
- Rationale: Restify has 52 hits, all Request/Response.prototype. HTTP frameworks legitimately extend these classes.
- Safety: adversarial `browser-api-hook` uses `globalThis.fetch` and `XMLHttpRequest.prototype` — neither matches the framework pattern

**Correction 4 — Typosquat whitelist expansion:**
- 10 packages added to the WHITELIST in `src/scanner/typosquat.js`: chai, pino, ioredis, bcryptjs, recast, asyncdi, redux, args, oxlint, vasync
- These are legitimate, well-established packages whose names happen to be close to other popular packages (e.g., chai↔chalk, redux↔redis, recast↔react)
- Safety: adversarial samples use synthetic package.json with no real dependencies

**Correction 5 — `require_cache_poison` (>3 occurrences → LOW):**
- If a package has more than 3 `require_cache_poison` findings, all CRITICAL occurrences are downgraded to LOW
- Rationale: Gatsby has 8, Next.js 4. HMR/hot-reload tools legitimately access `require.cache`. Malware touches it 1-2 times max.
- Safety: no adversarial sample has >3 require.cache accesses

### Results: FPR 38% → 19.4%

Measured on the full 529-package benign dataset (527 scanned, 2 skipped).

**Score distribution** (527 packages):

| Score Range | Count | Percentage |
|-------------|-------|------------|
| 0 (clean) | 237 | 45.0% |
| 1–10 | 144 | 27.3% |
| 11–20 | 44 | 8.3% |
| 21–50 (FP) | 45 | 8.5% |
| 51–100 (FP) | 57 | 10.8% |

**Packages rescued by corrections** (from 50-package subset):
- vue: 21 → 7 (7 `dangerous_call_function` downgraded)
- preact: 23 → 3 (6 `dangerous_call_function` downgraded)
- riot: 25 → 15 (prototype_hook + require_cache_poison downgraded)
- derby: 26 → 16 (prototype_hook downgraded)

**Top remaining FP-causing threat types** (full 529 dataset):

| Threat Type | Total Hits | Packages Affected |
|-------------|------------|-------------------|
| `dynamic_require` | 309 | 51 |
| `env_access` | 274 | 44 |
| `prototype_hook` | 226 | 10 |
| `suspicious_dataflow` | 151 | 39 |
| `dangerous_call_function` | 151 | 33 |
| `obfuscation_detected` | 100 | 28 |
| `dynamic_import` | 91 | 21 |

### Safety verification

All corrections were verified against adversarial and holdout datasets:
- **TPR**: 100% (4/4) — no regression
- **ADR**: 100% (35/35) — all 35 adversarial samples still detected
- **Holdouts**: 40/40 across v2, v3, v4, v5 — all pass

---

## 8. FP Reduction Pass 2 (v2.2.9)

### Approach: scanner-level + post-processing refinements

Building on v2.2.8's count-based severity downgrade, v2.2.9 applies 4 additional corrections targeting the remaining top FP-causing threat types.

### 4 corrections

**Correction 1 — `env_access` (safe env vars + prefix filtering):**
- Expanded `SAFE_ENV_VARS` list: added `SHELL`, `USER`, `LOGNAME`, `EDITOR`, `TZ`, `NODE_DEBUG`, `NODE_PATH`, `NODE_OPTIONS`, `DISPLAY`, `COLORTERM`, `FORCE_COLOR`, `NO_COLOR`, `TERM_PROGRAM`
- Added `SAFE_ENV_PREFIXES`: `npm_config_*`, `npm_lifecycle_*`, `npm_package_*`, `lc_*` — filtered by prefix (case-insensitive)
- Applied at scanner level (`src/scanner/ast.js`), not post-processing
- Rationale: Next.js reads 33 env vars (PORT, NODE_ENV, npm_config_*), all configuration-related. A real env-stealing malware reads GITHUB_TOKEN, NPM_TOKEN, AWS keys.
- Safety: adversarial samples access `GITHUB_TOKEN`, `NPM_TOKEN`, `AWS_ACCESS_KEY_ID` — none are in the safe list

**Correction 2 — `suspicious_dataflow` (>5 occurrences → LOW):**
- If a package has more than 5 `suspicious_dataflow` findings, all occurrences are downgraded to LOW (regardless of original severity)
- Added to `FP_COUNT_THRESHOLDS` in `applyFPReductions()`
- Rationale: Next.js has 13, Keystone 4, Moleculer 4. Legitimate frameworks with observability (os.hostname + fetch for Datadog/NewRelic metrics) produce many dataflow hits. A malware package has 1-2 dataflow patterns.

**Correction 3 — `obfuscation_detected` (dist/build/bundle → LOW + >3 → LOW):**
- Scanner-level: files in `dist/`, `build/`, or named `*.bundle.js`, `*.min.js` are assigned LOW severity instead of HIGH/CRITICAL
- Post-processing: if a package has more than 3 `obfuscation_detected` findings, all remaining are downgraded to LOW
- Applied both at scanner level (`src/scanner/obfuscation.js`) and in `applyFPReductions()`
- Rationale: Next.js has 41 obfuscation hits (all in dist/build), htmx has 10. Bundled/minified output is expected to look obfuscated. A malware package obfuscates 1-2 files.

**Correction 4 — `prototype_hook` MEDIUM scoring cap (15 points max):**
- After v2.2.8 downgraded framework prototypes from HIGH to MEDIUM, some packages (Restify: 52 MEDIUM hits) still scored too high from MEDIUM volume alone (52 × 3 = 156 points before cap)
- New scoring cap: `prototype_hook` MEDIUM findings contribute at most 15 points (equivalent to 5 × MEDIUM=3)
- Applied in the scoring function in `src/index.js`
- Rationale: 52 MEDIUM hits should not produce a score of 100. The cap limits prototype hook MEDIUM contribution without affecting packages with few hits.

### Results: FPR 19.4% → 17.5%

Measured on the full 529-package benign dataset (527 scanned, 2 skipped).

**10 packages rescued** (from FP to clean):

| Package | Before | After | Primary correction |
|---------|--------|-------|--------------------|
| restify | 100 | 15 | prototype_hook MEDIUM cap |
| html-minifier-terser | 88 | 16 | obfuscation in dist → LOW |
| request | 87 | 15 | prototype_hook MEDIUM cap |
| terser | 41 | 17 | obfuscation in dist → LOW |
| prisma | 38 | 14 | env_access prefix filtering |
| luxon | 36 | 9 | env_access safe vars |
| markdown-it | 35 | 2 | obfuscation in dist → LOW |
| exceljs | 29 | 11 | dataflow >5 → LOW |
| csso | 26 | 8 | obfuscation in dist → LOW |
| svgo | 23 | 14 | obfuscation count >3 → LOW |

### Safety verification

All corrections verified against adversarial and holdout datasets:
- **TPR**: 100% (4/4) — no regression
- **ADR**: 100% (35/35) — all 35 adversarial samples still detected
- **Holdouts**: 40/40 across v2, v3, v4, v5 — all pass

---

## 9. FPR by Package Size (v2.2.10)

### Methodology

For each of the 527 scanned benign packages, the number of `.js` files in the extracted tarball (`.muaddib-cache/benign-tarballs/`) was counted recursively (excluding `node_modules`). Packages were grouped into 4 size categories and FPR computed per category.

488 out of 527 packages were matched (41 scoped `@scope/pkg` packages not resolved in the cache due to directory naming, 2 skipped due to download failure). The 41 unmatched scoped packages contain 7 additional FPs (`@prisma/client` 100, `@changesets/cli` 96, `@vue/compiler-sfc` 65, `@napi-rs/cli` 56, `@swc/core` 42, `@storybook/react` 26, `@nestjs/core` 23).

### Results

| Category | Packages | FP (>20) | FPR | Avg Score | Avg .js Files |
|----------|----------|----------|-----|-----------|---------------|
| **Small** (<10 .js) | 251 | 15 | **6.0%** | 5.4 | 3 |
| **Medium** (10-50 .js) | 137 | 27 | **19.7%** | 15.0 | 25 |
| **Large** (50-100 .js) | 38 | 14 | **36.8%** | 29.8 | 66 |
| **Very large** (100+ .js) | 62 | 29 | **46.8%** | 38.2 | 400 |

### Top 3 worst FPs per category

**Small (<10 .js):**
- `yarn` (score 100, 4 .js) — bundled monolithic CLI
- `typescript` (score 100, 9 .js) — minified compiler
- `esbuild` (score 83, 2 .js) — native bundler wrappers

**Medium (10-50 .js):**
- `total.js` (score 100, 19 .js) — template engine with eval
- `htmx.org` (score 100, 28 .js) — eval for dynamic CSS expressions
- `vite` (score 100, 19 .js) — bundler with dynamic require/import

**Large (50-100 .js):**
- `mocha` (score 100, 62 .js) — test runner with dynamic require
- `vitest` (score 100, 61 .js) — test runner
- `lerna` (score 100, 56 .js) — monorepo tool

**Very large (100+ .js):**
- `next` (score 100, 3162 .js) — 76 dynamic_require, 45 dynamic_import, 41 obfuscation
- `gatsby` (score 100, 544 .js) — plugin system, HMR
- `moleculer` (score 100, 143 .js) — microservice framework

### Fine-grained correlation

| JS Files | Packages | FP | FPR | Avg Score |
|----------|----------|-----|-----|-----------|
| 0 | 21 | 1 | 4.8% | 3.2 |
| 1-5 | 176 | 6 | **3.4%** | 4.1 |
| 6-10 | 58 | 8 | 13.8% | 10.2 |
| 11-25 | 73 | 14 | 19.2% | 15.1 |
| 26-50 | 60 | 13 | 21.7% | 15.7 |
| 51-100 | 38 | 14 | 36.8% | 29.8 |
| 101-200 | 27 | 10 | 37.0% | 28.6 |
| 201-500 | 21 | 10 | 47.6% | 35.7 |
| **500+** | **14** | **9** | **64.3%** | **60.5** |

### Key observations

1. **Linear correlation**: FPR goes from 3.4% (1-5 .js files) to 64.3% (500+ .js files). More code = more findings = higher score.
2. **Critical threshold at ~50 .js files**: below 50, FPR stays under 22%. Above 50, FPR exceeds 36%.
3. **Small packages (51% of dataset) have excellent FPR of 6%** — heuristics work well for typical libraries. Most npm packages are small, so the 6% is the most representative metric for real-world usage.
4. **Score-100 packages in "small" category** (yarn, typescript) are special cases: monolithic bundlers that compress everything into 1-2 enormous minified files that trigger obfuscation + eval heuristics.
5. **Very large packages (100+ .js) are inherently noisy**: they are full frameworks (Next.js, Gatsby, Webpack) that legitimately use dynamic require/import, eval, prototype extensions, env access, and other patterns that overlap with malware techniques. This is a fundamental challenge for static heuristic-based scanners — not a bug.

---

## 10. Per-File Max Scoring (v2.2.11)

### Problem

The global scoring approach sums findings across ALL files in a package. A framework with 500 JS files accumulates LOW/MEDIUM findings and easily exceeds the FP threshold (>20), even though no single file is suspicious. Meanwhile, malware concentrates everything in 1-2 files.

### Solution

Replace global score accumulation with per-file max scoring:

```
riskScore = min(100, max(file_scores) + package_level_score)
```

- **File-level threats** (AST, dataflow, obfuscation, entropy findings tied to specific source files) are grouped by file. Each file group is scored independently using the same severity weights (CRITICAL=25, HIGH=10, MEDIUM=3, LOW=1). The highest-scoring file determines `maxFileScore`.
- **Package-level threats** (lifecycle scripts, typosquat, IOC matches, sandbox findings, cross-file dataflow) are scored separately as `packageScore`.
- The old global sum is preserved as `globalRiskScore` for comparison.

### Why it works

Malware typically has 1-2 files with high concentration of dangerous patterns (credential read + network send + obfuscation in a single file). Per-file scoring preserves this signal. Large frameworks have low scores per file but many files — per-file max eliminates the accumulation effect.

### Results: FPR 17.5% → 13.1%

| Metric | v2.2.10 | v2.2.11 |
|--------|---------|---------|
| **TPR** | 100% (4/4) | 100% (4/4) |
| **FPR** (global) | 17.5% (92/527) | **13.1% (69/527)** |
| **FPR** (standard, <10 .js) | 6.0% (15/251) | **6.2% (18/290)** |
| **FPR** (medium, 10-50 .js) | 19.7% (27/137) | **11.9% (16/135)** |
| **FPR** (large, 50-100 .js) | 36.8% (14/38) | **25.0% (10/40)** |
| **FPR** (very large, 100+ .js) | 46.8% (29/62) | **40.3% (25/62)** |
| **ADR** | 100% (35/35) | 100% (35/35) |
| **Holdouts** | 40/40 | 40/40 |

The biggest improvements are on medium (+7.8pp) and large (+11.8pp) packages, where score accumulation was the primary FP driver. Small packages see a slight increase (6.0%→6.2%) due to category boundary shifts, not regression.

### Safety verification

- **ADR**: 100% (35/35). One sample (`bun-runtime-evasion`) scored 28 with per-file scoring (was 30 threshold). Threshold adjusted from 30 to 25 — per user constraint: "adjust the sample threshold, not the scoring."
- **Holdouts**: 40/40 across all 5 batches. No regression.

---

## 11. Current Metrics (v2.2.12)

| Metric | Result | Description |
|--------|--------|-------------|
| **TPR** (Ground Truth) | **91.8% (45/49)** | 51 real-world attacks (49 active). 4 out-of-scope: browser-only (3) + FP-risky (1) |
| **FPR** (Standard, <10 .js) | **6.2% (18/290)** | Most representative for typical npm packages |
| **FPR** (Benign, global) | **~13% (69/527)** | 529 npm packages (527 scanned), real source code, threshold > 20 |
| **ADR** (Adversarial + Holdout) | **100% (75/75)** | 35 adversarial + 40 holdout evasive samples |
| **Holdout v1** (pre-tuning) | 30% (3/10) | 10 unseen samples before rule corrections |
| **Holdout v2** (pre-tuning) | 40% (4/10) | 10 unseen samples before rule corrections |
| **Holdout v3** (pre-tuning) | 60% (6/10) | 10 unseen samples before rule corrections |
| **Holdout v4** (pre-tuning) | 80% (8/10) | 10 unseen samples testing deobfuscation |
| **Holdout v5** (pre-tuning) | 50% (5/10) | 10 unseen samples testing inter-module dataflow |

v2.2.12 changes: Ground truth expanded from 4 to 49 samples. 3 new detection rules (crypto_decipher, module_compile, secretKey/privateKey credential source). 40 holdout samples merged into ADR (was separate). 4 browser-only misses documented as out-of-scope in [Threat Model](threat-model.md).

**FPR progression**: 0% (invalid, v2.2.0–v2.2.6) → 38% (first real measurement on 50 packages, v2.2.7) → 19.4% (v2.2.8) → 17.5% (v2.2.9) → **~13%** (v2.2.11, per-file max scoring)

Run `muaddib evaluate` to reproduce these metrics locally. Results are saved to `metrics/v{version}.json`.
