#!/usr/bin/env node
// codeweb effectiveness study — Cluster C6 (auxiliary checks).
//
// Quantifies every remaining shipped feature as a study result. One standalone harness:
//   node bench/experiments/auxiliary.mjs
// prints one PASS/FAIL line per check, writes bench/results/auxiliary.json, and exits non-zero
// if ANY check fails (so bench/run-all.mjs can gate on it).
//
// RIGOR (per PRE-REGISTRATION.md §0 + the cluster's non-negotiables):
//   - Deterministic & seeded: every random draw uses a committed integer seed (mulberry32), so a
//     re-run reproduces byte-for-byte. Seeds are the SEEDS constants below.
//   - INDEPENDENT oracle: ground truth is computed by code here that does NOT import codeweb's
//     implementation of the thing under test. For A-LANG the expected node/edge sets are written by
//     hand per fixture; for A-PLACE/A-FIT/A-RISK/A-HOT the expected answer is recomputed inline from
//     the graph (re-deriving the *definition*, never importing the feature's compute). DISCLOSURE:
//     A-MCP compares the MCP server's output to the matching CLI on the same input — both are codeweb
//     surfaces, so A-MCP is a cross-INTERFACE consistency + protocol-conformance check, not an
//     external-oracle correctness check (the underlying correctness is covered by C1-C5). This is
//     stated honestly in the results JSON.
//   - Able to fail: every check carries a `canFail` probe — a deliberately wrong input the same
//     assertion logic must reject — proving the check is not vacuous. If a probe does NOT trip, the
//     check is reported failed (a check that cannot fail is worthless).
//   - Forced deterministic extraction: every extract-symbols run passes --no-ctags (as the tests do).
//   - Scratch corpora live in os.tmpdir() (mkdtemp), seeded, never committed; cleaned up after.
//
// Reuse: shares the mulberry32 PRNG + random-graph/op generators with tests/_proptest.mjs (imported),
// the stats lib for any bounds, and the SAME fixtures/approach as the named existing suites
// (extract-*, treemap-bisect, ci-gate, trend, placement, fitness, risk, hotspots, suppression, mcp).

import { spawnSync } from 'node:child_process';
import {
  mkdtempSync, mkdirSync, writeFileSync, readFileSync, rmSync, existsSync,
} from 'node:fs';
import { tmpdir } from 'node:os';
import { fileURLToPath } from 'node:url';
import { dirname, join, resolve } from 'node:path';

import { prng, int, pick, randomGraph, randomOp, naiveApply } from '../../tests/_proptest.mjs';
import { ruleOfThree, round } from '../lib/stats.mjs';

// ---------------------------------------------------------------------------------------------
// Paths + small process/fixture helpers (mirrors tests/helpers.mjs, kept local so paper/ is
// self-contained and runnable standalone).
// ---------------------------------------------------------------------------------------------
const HERE = dirname(fileURLToPath(import.meta.url));
const ROOT = resolve(HERE, '..', '..');               // codeweb repo root
const SCRIPTS = join(ROOT, 'scripts');
const CORPUS = join(ROOT, 'bench', 'corpus');
const RESULTS = join(ROOT, 'bench', 'results', 'auxiliary.json');
const script = (name) => join(SCRIPTS, name);
const NODE = process.execPath;

function runNode(scriptPath, args = [], { env = {}, input = undefined } = {}) {
  const r = spawnSync(NODE, [scriptPath, ...args], {
    cwd: ROOT, env: { ...process.env, ...env }, encoding: 'utf8', maxBuffer: 1 << 28, input,
  });
  return { status: r.status, stdout: r.stdout || '', stderr: r.stderr || '', error: r.error };
}
const tmp = (prefix) => mkdtempSync(join(tmpdir(), prefix));
const rmrf = (d) => { try { rmSync(d, { recursive: true, force: true }); } catch { /* best-effort */ } };
function writeTree(rootDir, files) {
  for (const [rel, content] of Object.entries(files)) {
    const abs = join(rootDir, rel);
    mkdirSync(dirname(abs), { recursive: true });
    writeFileSync(abs, content);
  }
  return rootDir;
}
const readJSON = (p) => JSON.parse(readFileSync(p, 'utf8'));
const edgeKey = (e) => `${e.from} ${e.to} ${e.kind}`;
const sortedKeys = (edges) => edges.map(edgeKey).sort();
const setEq = (a, b) => { const A = [...a].sort(), B = [...b].sort(); return A.length === B.length && A.every((x, i) => x === B[i]); };

// Committed seeds (one per randomized check). Changing these changes the trials, not the criterion.
const SEEDS = {
  place: 0x9CA11, fit: 0xF17, fitLayer: 0x1A4E, risk: 0x215C, hot: 0x70751,
  mcpGraph: 0x3C9, treemap: 0x77EE,
};

// Collects per-check outcomes for the results JSON + the gate.
const checks = []; // { id, metric, value, ci, passed, criterion, notes }
function record(id, { metric, value, ci = null, passed, criterion, notes = '' }) {
  checks.push({ id, metric, value, ci, passed, criterion, notes });
  const line = `${passed ? 'PASS' : 'FAIL'}  ${id.padEnd(16)} ${metric} = ${typeof value === 'object' ? JSON.stringify(value) : value}` +
    `  [criterion: ${criterion}]${notes ? `  — ${notes}` : ''}`;
  console.log(line);
}

// ============================================================================================
// A-LANG — per-language extraction soundness (JS, TS, Py, Rust, Go).
// Independent oracle: each fixture below pairs source with a HAND-WRITTEN expected node-id set and
// expected call-edge set. "No missed defs" = expectedNodes ⊆ extracted; "no fabricated edges" =
// extracted call edges ⊆ expectedEdges (every wired call traces to a real call in the source). The
// expected sets are authored here from reading the source, not from running codeweb — an independent
// ground truth. We assert node-set EQUALITY (over the functions/classes we planted) and call-edge
// SUBSET-of-expected (the extractor may legitimately resolve fewer under ambiguity, but must never
// invent an edge that is not a real call). Mirrors tests/extract-{symbols,rust,go}.test.mjs.
// ============================================================================================
const LANG_FIXTURES = {
  javascript: {
    files: {
      'a.js': 'export function add(a, b) {\n  return a + b;\n}\nexport function useAdd() {\n  return add(1, 2);\n}\n',
      'b.js': 'export function lonely() {\n  return 0;\n}\n',
    },
    // every function we wrote, by id
    expectNodes: ['a.js:add', 'a.js:useAdd', 'b.js:lonely'],
    // the ONLY real call in the source: useAdd -> add (same file)
    expectCalls: ['a.js:useAdd a.js:add call'],
  },
  typescript: {
    files: {
      'm.ts': 'export function square(x: number): number {\n  return x * x;\n}\nexport function quad(x: number): number {\n  return square(square(x));\n}\n',
    },
    expectNodes: ['m.ts:square', 'm.ts:quad'],
    expectCalls: ['m.ts:quad m.ts:square call'],
  },
  python: {
    files: {
      'mod.py': 'def helper(x):\n    return x + 1\n\n\ndef run():\n    return helper(41)\n',
    },
    expectNodes: ['mod.py:helper', 'mod.py:run'],
    expectCalls: ['mod.py:run mod.py:helper call'],
  },
  rust: {
    files: {
      'math.rs': 'pub fn add(a: i32, b: i32) -> i32 {\n    a + b\n}\n\nfn helper() -> i32 {\n    add(1, 2)\n}\n',
    },
    expectNodes: ['math.rs:add', 'math.rs:helper'],
    expectCalls: ['math.rs:helper math.rs:add call'],
  },
  go: {
    files: {
      'math.go': 'package math\n\nfunc Add(a int, b int) int {\n\treturn a + b\n}\n\nfunc helper() int {\n\treturn Add(1, 2)\n}\n',
    },
    expectNodes: ['math.go:Add', 'math.go:helper'],
    expectCalls: ['math.go:helper math.go:Add call'],
  },
};

function extractFixture(files, lang) {
  const dir = tmp(`cw-aux-lang-${lang}-`);
  try {
    writeTree(dir, files);
    const out = join(dir, 'fragment.json');
    const r = runNode(script('extract-symbols.mjs'), [dir, '--no-ctags', '--target', lang, '--out', out]);
    if (r.status !== 0) return { ok: false, err: r.stderr };
    return { ok: true, frag: readJSON(out) };
  } finally { rmrf(dir); }
}

function checkALang() {
  const perLang = {};
  let allPass = true;
  for (const [lang, fx] of Object.entries(LANG_FIXTURES)) {
    const res = extractFixture(fx.files, lang);
    if (!res.ok) { perLang[lang] = { extracted: false, err: res.err }; allPass = false; continue; }
    const ids = new Set(res.frag.nodes.map((n) => n.id));
    const calls = res.frag.edges.filter((e) => e.kind === 'call');
    const callKeys = new Set(sortedKeys(calls));
    const expectNodes = new Set(fx.expectNodes);
    const expectCalls = new Set(fx.expectCalls);
    // no missed defs: every expected node present
    const missedDefs = fx.expectNodes.filter((id) => !ids.has(id));
    // no fabricated edges: every extracted call edge is in the expected (real) set
    const fabricated = [...callKeys].filter((k) => !expectCalls.has(k));
    // also confirm the language was recognized
    const langOk = (res.frag.meta.languages || []).includes(lang);
    const pass = missedDefs.length === 0 && fabricated.length === 0 && langOk &&
      setEq(ids, new Set([...ids].filter((id) => expectNodes.has(id) || true))) /* ids superset of expected, no spurious checked below */;
    // spurious nodes: any extracted node we did not plant (functions/classes only)
    const spurious = [...ids].filter((id) => !expectNodes.has(id));
    const ok = missedDefs.length === 0 && fabricated.length === 0 && spurious.length === 0 && langOk;
    perLang[lang] = { extracted: true, nodes: res.frag.nodes.length, callEdges: calls.length, missedDefs, fabricated, spurious, langOk, ok };
    if (!ok) allPass = false;
  }

  // ---- ABLE-TO-FAIL probe: a fixture with a deliberately wrong expected set MUST be rejected.
  // We assert that the SAME comparison logic (subset/superset) flags a planted mismatch: claim a
  // node exists that the source never defines -> missedDefs must be non-empty.
  const probe = extractFixture(LANG_FIXTURES.javascript.files, 'javascript');
  let canFail = false;
  if (probe.ok) {
    const ids = new Set(probe.frag.nodes.map((n) => n.id));
    const bogusExpect = ['a.js:add', 'a.js:DOES_NOT_EXIST']; // a fabricated expectation
    const missed = bogusExpect.filter((id) => !ids.has(id));
    canFail = missed.length > 0; // the logic correctly detects the missing (bogus) def
    // also: a fabricated edge expectation is caught — pretend the extractor wired a non-call
    const calls = new Set(sortedKeys(probe.frag.edges.filter((e) => e.kind === 'call')));
    const fabricatedDetect = calls.has('b.js:lonely a.js:add call') === false; // that edge is NOT real and is absent
    canFail = canFail && fabricatedDetect;
  }
  record('A-LANG', {
    metric: 'languages with exact node-set & no-fabricated-edge extraction',
    value: `${Object.values(perLang).filter((v) => v.ok).length}/${Object.keys(LANG_FIXTURES).length}`,
    passed: allPass && canFail,
    criterion: 'all 5 langs: expected nodes == extracted (no missed/spurious defs), call edges ⊆ real calls; probe trips',
    notes: canFail ? '' : 'ABLE-TO-FAIL probe did not trip — check is vacuous',
  });
  return { perLang, canFail };
}

// ============================================================================================
// A-SELFCONTAINED — report.html FETCHES nothing from the network when opened.
// Independent oracle: a from-scratch regex scan over the SHIPPED report.html (built from a real
// corpus graph AND a synthetic graph). Mirrors the spirit of build-report.test.mjs (which proves no
// local-path leak); this proves no NET leak.
//
// SCOPE — the claim is "the report renders offline", i.e. the browser issues no network request to
// display it. That is a property of FETCHING constructs: src/href on script/link/img/iframe (and
// friends), CSS @import, and the url() references a stylesheet resolves. It is NOT a property of
// hyperlinks: an <a href="https://github.com/..."> is inert until a human clicks it, and the report
// footer legitimately links the project, the gate docs, and sponsors. The earlier detector flagged
// ANY absolute URL anywhere in the document, so it counted those footer links as "external refs"
// and reported 6 offenders on a report that fetches nothing — measuring hyperlink presence while
// claiming to measure network self-containment.
// ============================================================================================
function buildReportFrom(graphObj) {
  const dir = tmp('cw-aux-report-');
  const gp = join(dir, 'graph.json');
  writeFileSync(gp, JSON.stringify(graphObj));
  const r = runNode(script('build-report.mjs'), [gp, '--no-md']);
  const htmlPath = join(dir, 'report.html');
  return { dir, gp, htmlPath, ok: r.status === 0 && existsSync(htmlPath), r };
}
// Independent network-FETCH detector. Returns the list of offending constructs — each one a thing
// the browser would request on load. A remote URL that is only a hyperlink target is not one.
const REMOTE = String.raw`(?:https?:)?\/\/[^"'\s>]+`;
// Elements whose src/href the browser resolves without any user action. `href` fetches for <link>
// (stylesheets, fonts, preloads) but NOT for <a>, so the two are matched separately.
const FETCHING_SRC_TAGS = 'script|img|iframe|frame|embed|source|track|audio|video|input';
function externalRefs(html) {
  const offenders = [];
  const push = (v) => { if (v) offenders.push(v.trim()); };
  // 1) src= on any element the browser fetches automatically
  for (const m of html.matchAll(new RegExp(String.raw`<(?:${FETCHING_SRC_TAGS})\b[^>]*?\bsrc\s*=\s*["'](${REMOTE})["']`, 'gi'))) push(m[1]);
  // 2) <link href> — stylesheets, fonts, icons, preload/prefetch: all fetched on load
  for (const m of html.matchAll(new RegExp(String.raw`<link\b[^>]*?\bhref\s*=\s*["'](${REMOTE})["']`, 'gi'))) push(m[1]);
  // 3) srcset / data-src / poster / xlink:href — the same fetch by another attribute name
  for (const m of html.matchAll(new RegExp(String.raw`\b(?:srcset|data-src|poster|xlink:href)\s*=\s*["']\s*(${REMOTE})`, 'gi'))) push(m[1]);
  // 4) CSS @import and url() — a stylesheet resolving a remote asset
  for (const m of html.matchAll(new RegExp(String.raw`@import\s+(?:url\(\s*)?["']?(${REMOTE})`, 'gi'))) push(m[1]);
  for (const m of html.matchAll(new RegExp(String.raw`url\(\s*["']?(${REMOTE})`, 'gi'))) push(m[1]);
  // 5) script-initiated network calls — fetch()/XHR/EventSource/WebSocket/importScripts to a remote
  for (const m of html.matchAll(new RegExp(String.raw`(?:fetch|importScripts)\s*\(\s*["'\`](${REMOTE})`, 'gi'))) push(m[1]);
  for (const m of html.matchAll(new RegExp(String.raw`\.open\s*\(\s*["'][A-Z]+["']\s*,\s*["'\`](${REMOTE})`, 'gi'))) push(m[1]);
  for (const m of html.matchAll(new RegExp(String.raw`new\s+(?:WebSocket|EventSource|Worker)\s*\(\s*["'\`]((?:wss?:|https?:)?\/\/[^"'\`\s]+)`, 'gi'))) push(m[1]);
  return [...new Set(offenders)];
}

function checkASelfContained(realGraph) {
  const synth = {
    meta: { target: 'synthetic', engine: 'regex', languages: ['javascript'], symbols: 2 },
    nodes: [
      { id: 'a.js:f', label: 'f', kind: 'function', file: 'a.js', line: 1, loc: 3, domain: 'core' },
      { id: 'b.js:g', label: 'g', kind: 'function', file: 'b.js', line: 1, loc: 3, domain: 'lib' },
    ],
    edges: [{ from: 'a.js:f', to: 'b.js:g', kind: 'call' }],
    domains: [], overlaps: [],
  };
  const cases = { synthetic: synth };
  if (realGraph) cases.real = realGraph;

  const perCase = {};
  let allClean = true;
  for (const [name, g] of Object.entries(cases)) {
    const built = buildReportFrom(g);
    try {
      if (!built.ok) { perCase[name] = { built: false, err: built.r.stderr }; allClean = false; continue; }
      const html = readFileSync(built.htmlPath, 'utf8');
      const offenders = externalRefs(html);
      perCase[name] = { built: true, bytes: html.length, offenders };
      if (offenders.length) allClean = false;
    } finally { rmrf(built.dir); }
  }

  // ABLE-TO-FAIL probe: a doctored page carrying every fetch shape must trip the detector...
  const dirty = '<html><head><script src="https://cdn.jsdelivr.net/npm/chart.js"></script>' +
    '<link rel="stylesheet" href="//fonts.googleapis.com/css?family=Inter">' +
    '<style>@import url("https://unpkg.com/x.css"); body { background: url(//cdn.example.com/bg.png); }</style>' +
    '</head><body><img src="https://cdnjs.cloudflare.com/a.png">' +
    '<script>fetch("https://api.example.com/x"); new WebSocket("wss://example.com/s");</script></body></html>';
  const detected = externalRefs(dirty);
  const FETCH_SHAPES = 7; // script src, link href, @import, css url(), img src, fetch(), WebSocket
  const catchesFetches = detected.length >= FETCH_SHAPES;

  // ...and a page whose ONLY remote URLs are hyperlinks must NOT trip it. Without this half the
  // detector could pass by flagging everything, which is the defect being repaired: the report
  // footer's project/docs/sponsor links are inert until clicked and are not network references.
  const linksOnly = '<html><body><p>See <a href="https://github.com/GhostlyGawd/codeweb">codeweb</a> ' +
    'and <a href="https://example.com/docs" target="_blank">the gate docs</a>. ' +
    'Plain text mentioning https://example.org/ too.</p></body></html>';
  const linkOffenders = externalRefs(linksOnly);
  const ignoresHyperlinks = linkOffenders.length === 0;
  const canFail = catchesFetches && ignoresHyperlinks;

  record('A-SELFCONTAINED', {
    metric: 'network-fetching references in shipped report.html',
    value: Object.values(perCase).reduce((s, v) => s + (v.offenders ? v.offenders.length : 0), 0),
    passed: allClean && canFail,
    criterion: 'zero fetching refs (src/href on fetching elements, @import/url(), script-initiated requests) on synthetic+real reports; detector trips on a doctored page AND ignores plain hyperlinks',
    notes: canFail ? '' : `ABLE-TO-FAIL probe did not trip — detector is ${catchesFetches ? 'over-broad (flagged a hyperlink-only page)' : 'vacuous (missed a planted fetch)'}`,
  });
  return { perCase, canFail, probe: { catchesFetches, detectedOnDoctored: detected.length, ignoresHyperlinks, hyperlinkOffenders: linkOffenders } };
}

// ============================================================================================
// A-TREEMAP — the shipped treemap tiler terminates + tiles exactly on adversarial inputs.
// We extract the REAL `bisect` from scripts/report-template.html (the function that ships, inlined
// in the browser), exactly like tests/treemap-bisect.test.mjs, and exercise it on: a dominant final
// item, all-zero values, and a large-uniform set. Independent oracle: geometry invariants computed
// here (rect count == item count; every rect finite, non-negative, inside the parent box; covered
// area == box area within tolerance). No import of codeweb logic — pure geometry assertions.
// ============================================================================================
function extractFn(name, source) {
  const start = source.indexOf('function ' + name + '(');
  if (start < 0) return null;
  const open = source.indexOf('{', start);
  let depth = 0, i = open;
  for (; i < source.length; i++) {
    if (source[i] === '{') depth++;
    else if (source[i] === '}' && --depth === 0) { i++; break; }
  }
  const src = source.slice(start, i);
  // eslint-disable-next-line no-new-func — pure geometry helper, no closure/DOM deps.
  return new Function('return (' + src + ')')();
}

function checkATreemap() {
  const W = 800, H = 600, EPS = 1e-3;
  const template = readFileSync(join(SCRIPTS, 'report-template.html'), 'utf8');
  let bisect;
  try { bisect = extractFn('bisect', template); } catch { bisect = null; }
  if (typeof bisect !== 'function') {
    record('A-TREEMAP', { metric: 'treemap layout', value: 'bisect() not found', passed: false, criterion: 'terminates+tiles on adversarial inputs', notes: 'template no longer defines bisect()' });
    return { canFail: false };
  }
  const tile = (vals) => { const out = []; bisect(vals.map((v, i) => ({ value: v, id: i })), 0, 0, W, H, out); return out; };
  const rng = prng(SEEDS.treemap);
  const inBounds = (r) => ['x', 'y', 'w', 'h'].every((k) => Number.isFinite(r[k])) &&
    r.w >= -EPS && r.h >= -EPS && r.x >= -EPS && r.y >= -EPS && r.x + r.w <= W + EPS && r.y + r.h <= H + EPS;
  const exact = (rects) => Math.abs(rects.reduce((s, r) => s + r.w * r.h, 0) - W * H) < 1; // covers the whole box

  const cases = {
    dominantFinal: [1, 1, 1, 1, 1, 1, 1, 1, 1, 1000],
    allZero: [0, 0, 0, 0, 0],
    largeUniform: Array(500).fill(1),
    randomLarge: Array.from({ length: int(rng, 200, 600) }, () => int(rng, 0, 50)),
  };
  const per = {};
  let allOk = true;
  for (const [name, vals] of Object.entries(cases)) {
    let rects, terminated = true, threw = null;
    try { rects = tile(vals); } catch (e) { terminated = false; threw = String(e && e.message || e); }
    if (!terminated) { per[name] = { terminated, threw }; allOk = false; continue; }
    const countOk = rects.length === vals.length;
    const boundsOk = rects.every(inBounds);
    const exactOk = exact(rects);
    const ok = countOk && boundsOk && exactOk;
    per[name] = { terminated, count: rects.length, expectCount: vals.length, boundsOk, exactOk, ok };
    if (!ok) allOk = false;
  }

  // ABLE-TO-FAIL probe: confirm the invariant set rejects a KNOWN-bad tiling (a rect outside the box,
  // and a wrong rect count). If our assertions accepted these, the check would be vacuous.
  const badRects = [{ x: 0, y: 0, w: W + 50, h: H, value: 1, id: 0 }]; // overflows the box
  const probeRejectsBounds = !badRects.every(inBounds);
  const probeRejectsCount = !(badRects.length === 3);
  const canFail = probeRejectsBounds && probeRejectsCount;

  record('A-TREEMAP', {
    metric: 'adversarial treemap cases terminating + tiling exactly',
    value: `${Object.values(per).filter((v) => v.ok).length}/${Object.keys(cases).length}`,
    passed: allOk && canFail,
    criterion: 'dominant/all-zero/large-uniform/random all terminate, rect-count==item-count, in-bounds, area exact; probe trips',
    notes: canFail ? '' : 'ABLE-TO-FAIL probe did not trip',
  });
  return { per, canFail };
}

// ============================================================================================
// A-CIGATE — ci-gate exits 1 on an injected regression, 0 on a clean diff, 0 on a pure removal.
// Drives the SHIPPED scripts/ci-gate.mjs against real git repos built in os.tmpdir() (mirrors
// tests/ci-gate.test.mjs). Independent oracle: the git ground truth we construct by hand — we KNOW
// which working-tree state is a regression (a byte-identical duplicate body) vs clean vs removal.
// ============================================================================================
const hasGit = spawnSync('git', ['--version'], { encoding: 'utf8' }).status === 0;
const COMPUTE = `export function compute(x) {
  let total = 0;
  for (let i = 0; i < x; i++) {
    if (i % 2 === 0) total += i * 3;
    else total -= i;
  }
  const scaled = total * 2 + 7;
  return scaled > 100 ? scaled - 100 : scaled;
}
`;
const SECOND = `export function tally(n) {
  let s = 0;
  for (let i = 1; i <= n; i++) s += i;
  return s;
}
`;
function gitRepo(files) {
  const repo = tmp('cw-aux-gate-');
  const gitC = (...args) => {
    const r = spawnSync('git', ['-C', repo, ...args], { encoding: 'utf8' });
    if (r.status !== 0) throw new Error(`git ${args.join(' ')}: ${r.stderr}`);
    return r;
  };
  gitC('init', '-q');
  gitC('config', 'user.email', 't@example.com');
  gitC('config', 'user.name', 'Test');
  gitC('config', 'commit.gpgsign', 'false');
  writeTree(repo, files);
  gitC('add', '-A'); gitC('commit', '-q', '-m', 'base');
  const base = gitC('rev-parse', 'HEAD').stdout.trim();
  return { repo, base, gitC };
}

function checkACiGate() {
  if (!hasGit) {
    record('A-CIGATE', { metric: 'ci-gate exit codes', value: 'git unavailable', passed: false, criterion: 'exit 1 on regression, 0 on clean, 0 on removal', notes: 'git not on PATH — cannot run' });
    return { canFail: false };
  }
  const results = {};
  // (1) injected regression: add a byte-identical duplicate of compute -> body-confirmed duplication.
  {
    const { repo, base } = gitRepo({ 'src/a.js': COMPUTE, 'src/b.js': SECOND });
    try {
      writeTree(repo, { 'src/c.js': COMPUTE }); // duplicate of a.js's compute
      const r = runNode(script('ci-gate.mjs'), ['--base', base, '--repo', repo, '--target', 'src']);
      results.regression = { status: r.status, reports: /regress|duplicat/i.test(r.stdout + r.stderr) };
    } finally { rmrf(repo); }
  }
  // (2) clean: working tree matches base exactly.
  {
    const { repo, base } = gitRepo({ 'src/a.js': COMPUTE, 'src/b.js': SECOND });
    try {
      const r = runNode(script('ci-gate.mjs'), ['--base', base, '--repo', repo, '--target', 'src']);
      results.clean = { status: r.status };
    } finally { rmrf(repo); }
  }
  // (3) pure removal: delete a file (no new code, no new dup) -> not a regression.
  {
    const { repo, base } = gitRepo({ 'src/a.js': COMPUTE, 'src/b.js': SECOND });
    try {
      rmSync(join(repo, 'src', 'b.js'), { force: true });
      const r = runNode(script('ci-gate.mjs'), ['--base', base, '--repo', repo, '--target', 'src']);
      results.removal = { status: r.status };
    } finally { rmrf(repo); }
  }
  const regOk = results.regression?.status === 1 && results.regression?.reports === true;
  const cleanOk = results.clean?.status === 0;
  const removalOk = results.removal?.status === 0;
  // ABLE-TO-FAIL: the regression case is itself the falsifier — if the gate could not fail it would
  // return 0 on the planted duplicate. We additionally assert the *clean* run is NOT exit 1 (so a
  // gate that always-fails would be caught by cleanOk). The two opposite-direction cases together
  // make the check non-vacuous.
  const canFail = (results.regression?.status === 1) && (results.clean?.status === 0);
  record('A-CIGATE', {
    metric: 'exit codes [regression, clean, removal]',
    value: [results.regression?.status, results.clean?.status, results.removal?.status],
    passed: regOk && cleanOk && removalOk && canFail,
    criterion: 'regression->1 (names why), clean->0, pure-removal->0; opposite-direction cases both observed',
    notes: canFail ? '' : 'gate did not show both a 1 (regression) and a 0 (clean) — vacuous',
  });
  return { results, canFail };
}

// ============================================================================================
// A-TREND — across a synthetic commit series with MONOTONICALLY RISING planted duplication, the
// reported `confirmed` (body-confirmed duplicate-logic) metric is monotone non-decreasing.
// We drive the SHIPPED scripts/trend.mjs on a sequence of pre-built graph snapshots (the documented
// graph-list mode), where snapshot k has k body-confirmed duplicate-logic overlaps planted.
// Independent oracle: WE plant the overlaps, so the true confirmed sequence is [0,1,2,3,4]; we assert
// the tool's per-snapshot confirmed equals it AND is monotone non-decreasing. (Mirrors trend.test.)
// ============================================================================================
function checkATrend() {
  const dir = tmp('cw-aux-trend-');
  try {
    const N = 5;
    const paths = [];
    for (let k = 0; k < N; k++) {
      const overlaps = Array.from({ length: k }, (_, i) => ({ kind: 'duplicate-logic', confidence: 'high', title: `dup${i}`, nodes: [] }));
      const g = { meta: { target: `snap${k}` }, nodes: [{ id: 'a', domain: 'A' }, { id: 'b', domain: 'B' }], edges: [{ from: 'a', to: 'b', kind: 'call', weight: 1 }], domains: [], overlaps };
      const p = join(dir, `g${k}.json`); writeFileSync(p, JSON.stringify(g)); paths.push(p);
    }
    const r = runNode(script('trend.mjs'), [...paths, '--json']);
    if (r.status !== 0) {
      record('A-TREND', { metric: 'confirmed-duplication sequence', value: `exit ${r.status}`, passed: false, criterion: 'monotone non-decreasing, == planted [0..4]', notes: r.stderr.trim() });
      return { canFail: false };
    }
    const out = JSON.parse(r.stdout);
    const seq = out.snapshots.map((s) => s.confirmed);
    const expected = Array.from({ length: N }, (_, k) => k);
    const matchesPlanted = seq.length === N && seq.every((v, i) => v === expected[i]);
    const monotone = seq.every((v, i) => i === 0 || v >= seq[i - 1]);

    // ABLE-TO-FAIL probe: the SAME monotonicity test must reject a known non-monotone series.
    const bad = [0, 2, 1, 3];
    const canFail = !bad.every((v, i) => i === 0 || v >= bad[i - 1]);

    record('A-TREND', {
      metric: 'confirmed-duplication sequence (oldest->newest)',
      value: seq.join(','),
      passed: matchesPlanted && monotone && canFail,
      criterion: 'tool sequence == planted [0,1,2,3,4] AND monotone non-decreasing; probe rejects a non-monotone series',
      notes: canFail ? '' : 'monotonicity probe did not trip',
    });
    return { seq, expected, canFail };
  } finally { rmrf(dir); }
}

// ============================================================================================
// A-PLACE — placement suggests the domain holding the PLURALITY of a new symbol's callees.
// Drives the SHIPPED scripts/placement.mjs over random graphs (mirrors tests/placement PL-GRAVITY).
// Independent oracle: pluralityDomain() recomputed INLINE here from the graph + the chosen callee
// ids (tie -> lexicographically smallest domain) — a recomputable consequence of the graph, NOT a
// call into placement's own logic. Pass criterion: 100% agreement over the trials.
// ============================================================================================
const PLACE_DOMAINS = ['auth', 'billing', 'api', 'core'];
function pluralityDomainOracle(nodes, ids) {
  const byId = new Map(nodes.map((n) => [n.id, n]));
  const counts = new Map();
  for (const id of ids) { const d = byId.get(id)?.domain; if (d) counts.set(d, (counts.get(d) || 0) + 1); }
  if (!counts.size) return null;
  return [...counts.entries()].sort((a, b) => b[1] - a[1] || (a[0] < b[0] ? -1 : a[0] > b[0] ? 1 : 0))[0][0];
}
function checkAPlace(T = 200) {
  const rng = prng(SEEDS.place);
  let agree = 0, total = 0;
  const disagreements = [];
  for (let c = 0; c < T; c++) {
    const n = int(rng, 4, 12);
    const nodes = Array.from({ length: n }, (_, i) => ({ id: `f${i}.js:s${i}`, label: `s${i}`, kind: 'function', file: `f${i}.js`, line: 1, loc: 1, exports: false, domain: pick(rng, PLACE_DOMAINS) }));
    const graph = { meta: { target: 'fx' }, nodes, edges: [], domains: [], overlaps: [] };
    const ids = nodes.map((x) => x.id);
    const callIds = ids.filter(() => rng() < 0.5);
    if (!callIds.length) callIds.push(pick(rng, ids));
    const dir = tmp('cw-aux-place-');
    try {
      const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(graph));
      const r = runNode(script('placement.mjs'), [gp, '--calls', callIds.join(','), '--json']);
      total++;
      if (r.status !== 0) { disagreements.push({ c, status: r.status }); continue; }
      const out = JSON.parse(r.stdout);
      const expected = pluralityDomainOracle(nodes, callIds);
      if (out.domain === expected) agree++;
      else disagreements.push({ c, got: out.domain, expected, callIds });
    } finally { rmrf(dir); }
  }

  // ABLE-TO-FAIL probe: a graph where the plurality domain is KNOWN ('core' x3 vs 'auth' x1). If we
  // assert the WRONG expected ('auth'), the agreement test must reject it -> the comparison can fail.
  let canFail = false;
  {
    const nodes = [
      { id: 'a.js:p', label: 'p', kind: 'function', file: 'a.js', line: 1, loc: 1, exports: false, domain: 'core' },
      { id: 'b.js:q', label: 'q', kind: 'function', file: 'b.js', line: 1, loc: 1, exports: false, domain: 'core' },
      { id: 'c.js:r', label: 'r', kind: 'function', file: 'c.js', line: 1, loc: 1, exports: false, domain: 'core' },
      { id: 'd.js:s', label: 's', kind: 'function', file: 'd.js', line: 1, loc: 1, exports: false, domain: 'auth' },
    ];
    const graph = { meta: {}, nodes, edges: [], domains: [], overlaps: [] };
    const dir = tmp('cw-aux-place-probe-');
    try {
      const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(graph));
      const out = JSON.parse(runNode(script('placement.mjs'), [gp, '--calls', 'a.js:p,b.js:q,c.js:r,d.js:s', '--json']).stdout);
      canFail = out.domain === 'core' && out.domain !== 'auth'; // tool says core; a wrong 'auth' claim would be rejected
    } finally { rmrf(dir); }
  }

  const passed = agree === total && total === T && canFail;
  record('A-PLACE', {
    metric: 'placement domain == inline plurality oracle',
    value: `${agree}/${total}`,
    passed,
    criterion: `100% agreement over T=${T} random graphs; probe confirms a wrong claim would be caught`,
    notes: disagreements.length ? `disagreements: ${JSON.stringify(disagreements.slice(0, 3))}` : (canFail ? '' : 'probe did not trip'),
  });
  return { agree, total, disagreements, canFail };
}

// ============================================================================================
// A-FIT — fitness flags EVERY injected rule violation and flags NONE on a clean graph.
// Drives the SHIPPED scripts/fitness.mjs (mirrors tests/fitness). Independent oracle: the violating
// edge/node set recomputed INLINE with a plain edge/degree filter (no shared lib) per rule type.
// Pass criterion: recall 1.0 on the injected-violation graphs AND 0 false flags on the clean graph.
// We exercise the documented rule types: forbidden-dependency, layer, no-cycles, max-fan-in,
// max-symbol-loc.
// ============================================================================================
const FIT_DOMAINS = ['ui', 'api', 'db', 'core'];
function fitGraph(rng, n) {
  const nodes = Array.from({ length: n }, (_, i) => ({ id: `f${i}.js:s${i}`, label: `s${i}`, kind: 'function', file: `f${i}.js`, line: 1, loc: int(rng, 1, 30), exports: false, domain: pick(rng, FIT_DOMAINS) }));
  const ids = nodes.map((x) => x.id); const edges = [];
  for (let i = 0; i < n; i++) for (let j = 0; j < n; j++) if (i !== j && rng() < 0.18) edges.push({ from: ids[i], to: ids[j], kind: 'call' });
  return { meta: {}, nodes, edges, domains: [], overlaps: [] };
}
function runFitness(graph, rules) {
  const dir = tmp('cw-aux-fit-');
  try {
    const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(graph));
    const rp = join(dir, 'rules.json'); writeFileSync(rp, JSON.stringify({ rules }));
    const r = runNode(script('fitness.mjs'), [gp, '--rules', rp, '--json']);
    return r.status === 2 ? { err: r.stderr, status: 2 } : { out: JSON.parse(r.stdout), status: r.status };
  } finally { rmrf(dir); }
}
function checkAFit(T = 60) {
  const rng = prng(SEEDS.fit);
  const domOf = (g) => { const m = new Map(g.nodes.map((n) => [n.id, n.domain])); return (id) => m.get(id) || 'unassigned'; };
  let injectedTotal = 0, injectedRecalled = 0;          // recall on graphs that DO violate
  let cleanRuns = 0, cleanFalseFlags = 0;               // false flags on graphs that DON'T violate

  for (let c = 0; c < T; c++) {
    const g = fitGraph(rng, int(rng, 5, 12));
    const d = domOf(g);

    // --- forbidden-dependency ui->db ---
    {
      const oracle = g.edges.filter((e) => d(e.from) === 'ui' && d(e.to) === 'db').map((e) => `${e.from} -> ${e.to}`).sort();
      const { out } = runFitness(g, [{ id: 'no-ui-db', type: 'forbidden-dependency', from: 'ui', to: 'db', severity: 'error' }]);
      const v = out.violations.find((x) => x.ruleId === 'no-ui-db');
      if (oracle.length) { injectedTotal++; if (v && setEq(v.subjects, oracle)) injectedRecalled++; }
      else { cleanRuns++; if (v) cleanFalseFlags++; }
    }
    // --- max-fan-in limit 2 ---
    {
      const callIn = new Map();
      for (const e of g.edges) if (e.kind === 'call') callIn.set(e.to, (callIn.get(e.to) || 0) + 1);
      const oracle = g.nodes.filter((n) => (callIn.get(n.id) || 0) > 2).map((n) => n.id).sort();
      const { out } = runFitness(g, [{ id: 'godcap', type: 'max-fan-in', limit: 2, severity: 'error' }]);
      const v = out.violations.find((x) => x.ruleId === 'godcap');
      const got = (v ? v.subjects.map((s) => s.split(' ')[0]) : []).sort();
      if (oracle.length) { injectedTotal++; if (setEq(got, oracle)) injectedRecalled++; }
      else { cleanRuns++; if (v) cleanFalseFlags++; }
    }
    // --- max-symbol-loc limit 25 ---
    {
      const oracle = g.nodes.filter((n) => (n.loc || 0) > 25).map((n) => n.id).sort();
      const { out } = runFitness(g, [{ id: 'loc', type: 'max-symbol-loc', limit: 25, severity: 'error' }]);
      const v = out.violations.find((x) => x.ruleId === 'loc');
      const got = (v ? v.subjects.map((s) => s.split(' ')[0]) : []).sort();
      if (oracle.length) { injectedTotal++; if (setEq(got, oracle)) injectedRecalled++; }
      else { cleanRuns++; if (v) cleanFalseFlags++; }
    }
  }

  // layer rule, on its own seed (independent upward-edge oracle)
  {
    const rng2 = prng(SEEDS.fitLayer);
    const order = ['ui', 'api', 'db'];
    const rank = new Map(order.map((dm, i) => [dm, i]));
    for (let c = 0; c < 30; c++) {
      const g = fitGraph(rng2, int(rng2, 6, 12));
      const d = domOf(g);
      const oracle = g.edges.filter((e) => { const rf = rank.get(d(e.from)), rt = rank.get(d(e.to)); return rf != null && rt != null && rt < rf; }).map((e) => `${e.from} -> ${e.to}`).sort();
      const { out } = runFitness(g, [{ id: 'layers', type: 'layer', order, severity: 'error' }]);
      const v = out.violations.find((x) => x.ruleId === 'layers');
      if (oracle.length) { injectedTotal++; if (v && setEq(v.subjects, oracle)) injectedRecalled++; }
      else { cleanRuns++; if (v) cleanFalseFlags++; }
    }
  }

  // a deliberately clean graph (acyclic, no forbidden edges) vs no-cycles + forbidden rule -> 0 flags
  let cleanGraphOk = true;
  {
    const clean = {
      meta: {}, domains: [], overlaps: [],
      nodes: [
        { id: 'a.js:x', label: 'x', kind: 'function', file: 'a.js', line: 1, loc: 5, exports: true, domain: 'ui' },
        { id: 'b.js:y', label: 'y', kind: 'function', file: 'b.js', line: 1, loc: 5, exports: true, domain: 'api' },
      ],
      edges: [{ from: 'a.js:x', to: 'b.js:y', kind: 'call' }], // ui->api, allowed; acyclic
    };
    const { out } = runFitness(clean, [
      { id: 'acyclic', type: 'no-cycles', severity: 'error' },
      { id: 'no-ui-db', type: 'forbidden-dependency', from: 'ui', to: 'db', severity: 'error' },
    ]);
    cleanGraphOk = out.violations.length === 0;
    cleanRuns++; if (!cleanGraphOk) cleanFalseFlags++;
  }

  // no-cycles positive: a real 2-file cycle MUST be flagged (injected violation).
  let cycleFlagged = false;
  {
    const cyclic = {
      meta: {}, domains: [], overlaps: [],
      nodes: [{ id: 'a.js:x', label: 'x', kind: 'function', file: 'a.js', line: 1, loc: 1, exports: true, domain: 'd' }, { id: 'b.js:y', label: 'y', kind: 'function', file: 'b.js', line: 1, loc: 1, exports: true, domain: 'd' }],
      edges: [{ from: 'a.js:x', to: 'b.js:y', kind: 'call' }, { from: 'b.js:y', to: 'a.js:x', kind: 'call' }],
    };
    const { out } = runFitness(cyclic, [{ id: 'acyclic', type: 'no-cycles', severity: 'error' }]);
    const v = out.violations.find((x) => x.ruleId === 'acyclic');
    cycleFlagged = !!v && v.subjects.some((s) => s.includes('a.js') && s.includes('b.js'));
    injectedTotal++; if (cycleFlagged) injectedRecalled++;
  }

  const recall = injectedTotal ? injectedRecalled / injectedTotal : 1;
  // ABLE-TO-FAIL: cycleFlagged is the positive falsifier (a clean run would not flag it); cleanGraphOk
  // is the negative falsifier (a flag-everything impl would trip it). Both observed -> non-vacuous.
  const canFail = cycleFlagged && cleanGraphOk;
  const passed = recall === 1 && cleanFalseFlags === 0 && canFail;
  record('A-FIT', {
    metric: 'recall on injected violations / false flags on clean',
    value: `recall=${round(recall, 4)} (${injectedRecalled}/${injectedTotal}); falseFlags=${cleanFalseFlags}/${cleanRuns}`,
    passed,
    criterion: 'recall == 1.0 on injected (forbidden/layer/cycle/fanin/loc); 0 false flags on clean; both directions observed',
    notes: canFail ? '' : 'positive+negative falsifiers not both observed — vacuous',
  });
  return { recall, injectedTotal, injectedRecalled, cleanFalseFlags, cleanRuns, canFail };
}

// ============================================================================================
// A-RISK — risk score is monotone non-decreasing in EACH documented input (fanIn, fanOut, loc,
// blast, churn) holding the others fixed.
// Independent oracle: re-implement the risk formula HERE (weighted, graph-max-normalized blend) with
// our OWN copy of the weights — NOT importing scripts/lib/risk.mjs — and assert that bumping any one
// component never decreases the recomputed score. Then confirm the SHIPPED scripts/risk.mjs ranking
// is consistent with that formula on a sample (so the proof covers the real artifact, not just our
// re-derivation). Mirrors tests/risk RK-MONOTONE + RK-COMPONENTS.
// ============================================================================================
// Independent re-derivation of the documented weights (from risk.mjs's header/docstring + README).
const RISK_WEIGHTS_INDEP = { fanIn: 0.30, fanOut: 0.15, loc: 0.15, blast: 0.30, churn: 0.10 };
function riskScoreIndep(c, maxes) {
  let s = 0;
  for (const k of Object.keys(RISK_WEIGHTS_INDEP)) {
    const m = maxes[k] || 0;
    s += RISK_WEIGHTS_INDEP[k] * (m > 0 ? (c[k] || 0) / m : 0);
  }
  return s;
}
function checkARisk(T = 2000) {
  const rng = prng(SEEDS.risk);
  const comps = Object.keys(RISK_WEIGHTS_INDEP);
  const maxes = { fanIn: 20, fanOut: 20, loc: 100, blast: 30, churn: 25 };
  const perComp = Object.fromEntries(comps.map((k) => [k, { violations: 0 }]));
  let total = 0;
  for (let i = 0; i < T; i++) {
    const base = { fanIn: int(rng, 0, 20), fanOut: int(rng, 0, 20), loc: int(rng, 0, 100), blast: int(rng, 0, 30), churn: int(rng, 0, 25) };
    const r0 = riskScoreIndep(base, maxes);
    for (const k of comps) {
      total++;
      const bumped = { ...base, [k]: base[k] + int(rng, 1, 5) };
      if (riskScoreIndep(bumped, maxes) < r0 - 1e-12) perComp[k].violations++;
    }
  }
  const monoViolations = Object.values(perComp).reduce((s, v) => s + v.violations, 0);

  // Cross-check the SHIPPED CLI agrees with the independent formula's RANKING on one random graph.
  let cliConsistent = null;
  {
    const files = ['a.js', 'b.js', 'c.js', 'd.js'];
    const n = 10;
    const nodes = Array.from({ length: n }, (_, idx) => ({ id: `${pick(rng, files)}#${idx}:s${idx}`, label: `s${idx}`, kind: 'function', file: pick(rng, files), line: 1, loc: int(rng, 1, 50), exports: false, domain: 'd' }));
    const ids = nodes.map((x) => x.id); const edges = [];
    for (let i = 0; i < n; i++) for (let j = 0; j < n; j++) if (i !== j && rng() < 0.14) edges.push({ from: ids[i], to: ids[j], kind: 'call' });
    const g = { meta: {}, nodes, edges, domains: [], overlaps: [] };
    const churn = {}; for (const f of new Set(nodes.map((nn) => nn.file))) churn[f] = int(rng, 0, 20);
    // independent components: fanIn/fanOut from call edges, blast = reverse-call closure size, loc/churn given
    const callIn = new Map(), callOut = new Map();
    for (const e of edges) { if (e.kind !== 'call') continue; (callIn.get(e.to) || callIn.set(e.to, new Set()).get(e.to)).add(e.from); (callOut.get(e.from) || callOut.set(e.from, new Set()).get(e.from)).add(e.to); }
    const blastOf = (id) => { const seen = new Set([id]); const q = [id]; while (q.length) { const cur = q.shift(); for (const p of (callIn.get(cur) || [])) if (!seen.has(p)) { seen.add(p); q.push(p); } } seen.delete(id); return seen.size; };
    const comp = nodes.map((nn) => ({ id: nn.id, fanIn: callIn.get(nn.id)?.size || 0, fanOut: callOut.get(nn.id)?.size || 0, loc: nn.loc || 0, blast: blastOf(nn.id), churn: churn[nn.file] || 0 }));
    const mx = { fanIn: 0, fanOut: 0, loc: 0, blast: 0, churn: 0 };
    for (const c of comp) for (const k of Object.keys(mx)) mx[k] = Math.max(mx[k], c[k]);
    const expectRanked = comp.map((c) => ({ id: c.id, risk: riskScoreIndep(c, mx) })).sort((a, b) => b.risk - a.risk || (a.id < b.id ? -1 : a.id > b.id ? 1 : 0)).map((x) => x.id);
    const dir = tmp('cw-aux-risk-');
    try {
      const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(g));
      const cp = join(dir, 'churn.json'); writeFileSync(cp, JSON.stringify(churn));
      const out = JSON.parse(runNode(script('risk.mjs'), [gp, '--churn', cp, '--json']).stdout);
      cliConsistent = setEq(out.ranked.map((r) => r.id), expectRanked) && out.ranked.map((r) => r.id).join('|') === expectRanked.join('|');
    } finally { rmrf(dir); }
  }

  // ABLE-TO-FAIL probe: a knowingly NON-monotone scoring fn (negate one weight) MUST produce a
  // monotonicity violation under the same test — proving the test detects non-monotonicity.
  let canFail = false;
  {
    const badWeights = { ...RISK_WEIGHTS_INDEP, churn: -0.10 };
    const badScore = (c, m) => Object.keys(badWeights).reduce((s, k) => s + badWeights[k] * ((m[k] || 0) > 0 ? (c[k] || 0) / m[k] : 0), 0);
    const base = { fanIn: 5, fanOut: 5, loc: 50, blast: 10, churn: 5 };
    const r0 = badScore(base, maxes);
    const bumped = { ...base, churn: base.churn + 5 };
    canFail = badScore(bumped, maxes) < r0 - 1e-12; // bumping churn LOWERS the bad score -> detected
  }

  const passed = monoViolations === 0 && cliConsistent === true && canFail;
  record('A-RISK', {
    metric: 'monotonicity violations across all 5 components',
    value: `${monoViolations}/${total} bumps; perComp=${JSON.stringify(Object.fromEntries(comps.map((k) => [k, perComp[k].violations])))}`,
    ci: ruleOfThree(total) === 1 ? null : `RuleOfThree 95% upper bound on violation rate <= ${round(ruleOfThree(total), 6)}`,
    passed,
    criterion: `0 monotonicity violations over T=${T} vectors (all 5 inputs); shipped CLI ranking == independent formula; probe trips`,
    notes: cliConsistent ? (canFail ? '' : 'non-monotone probe did not trip') : 'shipped risk.mjs ranking diverged from the independent formula',
  });
  return { monoViolations, total, perComp, cliConsistent, canFail };
}

// ============================================================================================
// A-HOT — hotspots score == documented 0.5*complexity + 0.3*fanIn + 0.2*churn (graph-max-normalized),
// recomputed INDEPENDENTLY within fp tolerance.
// Independent oracle: re-implement the normalized weighted blend HERE with our OWN copy of the
// documented weights (NOT importing lib/hotspots.mjs), compute components ourselves (complexity from
// the node, fanIn from call-in edges, churn from the map), normalize by our own graph maxes, and
// compare to the SHIPPED scripts/hotspots.mjs --json `score` per symbol. Mirrors tests/hotspots.
// ============================================================================================
const HOT_WEIGHTS_INDEP = { complexity: 0.5, fanIn: 0.3, churn: 0.2 };
function hotScoreIndep(c, maxes) {
  let s = 0;
  for (const k of Object.keys(HOT_WEIGHTS_INDEP)) {
    const m = maxes[k] || 0;
    s += HOT_WEIGHTS_INDEP[k] * (m > 0 ? (c[k] || 0) / m : 0);
  }
  return s;
}
function checkAHot(T = 60) {
  const rng = prng(SEEDS.hot);
  const files = ['a.js', 'b.js', 'c.js', 'd.js', 'e.js'];
  let total = 0, mismatches = 0;
  let maxAbsErr = 0;
  const samples = [];
  for (let c = 0; c < T; c++) {
    const n = int(rng, 3, 12);
    const nodes = Array.from({ length: n }, (_, i) => ({ id: `f${i}.js:s${i}`, label: `s${i}`, kind: 'function', file: pick(rng, files), line: 1, loc: int(rng, 1, 50), complexity: int(rng, 0, 15), maxDepth: int(rng, 0, 5), exports: false, domain: 'd' }));
    const ids = nodes.map((x) => x.id); const edges = [];
    for (let i = 0; i < n; i++) for (let j = 0; j < n; j++) if (i !== j && rng() < 0.16) edges.push({ from: ids[i], to: ids[j], kind: 'call' });
    const g = { meta: { target: 'fx' }, nodes, edges, domains: [], overlaps: [] };
    const churn = {}; for (const f of new Set(nodes.map((nn) => nn.file))) churn[f] = int(rng, 0, 25);
    // independent components + maxes
    const callIn = new Map();
    for (const e of edges) if (e.kind === 'call') callIn.set(e.to, (callIn.get(e.to) || 0) + 1);
    const comp = nodes.map((nn) => ({ id: nn.id, complexity: nn.complexity || 0, fanIn: callIn.get(nn.id) || 0, churn: churn[nn.file] || 0 }));
    const mx = { complexity: 0, fanIn: 0, churn: 0 };
    for (const cc of comp) for (const k of Object.keys(mx)) mx[k] = Math.max(mx[k], cc[k]);
    const expect = new Map(comp.map((cc) => [cc.id, hotScoreIndep(cc, mx)]));
    const dir = tmp('cw-aux-hot-');
    try {
      const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(g));
      const cp = join(dir, 'churn.json'); writeFileSync(cp, JSON.stringify(churn));
      const out = JSON.parse(runNode(script('hotspots.mjs'), [gp, '--churn', cp, '--json']).stdout);
      for (const r of out.ranked) {
        total++;
        const e = expect.get(r.id);
        const err = Math.abs((r.score ?? NaN) - e);
        if (!(err < 1e-9)) { mismatches++; if (samples.length < 3) samples.push({ id: r.id, got: r.score, expect: e }); }
        maxAbsErr = Math.max(maxAbsErr, Number.isFinite(err) ? err : Infinity);
      }
    } finally { rmrf(dir); }
  }

  // ABLE-TO-FAIL probe: compare against a WRONG formula (swap complexity/churn weights). The same
  // tolerance check MUST flag a mismatch on a non-degenerate input.
  let canFail = false;
  {
    const wrong = { complexity: 0.2, fanIn: 0.3, churn: 0.5 };
    const c = { complexity: 10, fanIn: 0, churn: 0 }, mx = { complexity: 10, fanIn: 5, churn: 4 };
    const right = hotScoreIndep(c, mx);                       // 0.5
    const wrongScore = Object.keys(wrong).reduce((s, k) => s + wrong[k] * ((mx[k] || 0) > 0 ? (c[k] || 0) / mx[k] : 0), 0); // 0.2
    canFail = Math.abs(right - wrongScore) >= 1e-9;            // tolerance check separates them
  }

  const passed = mismatches === 0 && total > 0 && canFail;
  record('A-HOT', {
    metric: 'symbols whose shipped score != independent 0.5cx+0.3fanIn+0.2churn',
    value: `${mismatches}/${total} (maxAbsErr=${round(maxAbsErr, 12)})`,
    passed,
    criterion: `0 mismatches within 1e-9 over T=${T} random graphs; probe separates a wrong formula`,
    notes: mismatches ? `samples: ${JSON.stringify(samples)}` : (canFail ? '' : 'wrong-formula probe did not trip'),
  });
  return { mismatches, total, maxAbsErr, canFail };
}

// ============================================================================================
// A-SUPP — annotate hides a finding by identity; a mutated fingerprint resurfaces it.
// Drives the SHIPPED scripts/deadcode.mjs + scripts/annotate.mjs end-to-end (mirrors
// tests/suppression). Independent oracle: WE control the graph + which symbol is the orphan, so the
// expected behavior (hidden when suppressed, counted; resurfaced when the id changes) is known
// ground truth, asserted against the tools' JSON.
// ============================================================================================
const SUPP_GRAPH = {
  meta: { target: 'supp' }, domains: [], overlaps: [],
  nodes: [
    { id: 'a.js:used', label: 'used', kind: 'function', file: 'a.js', exports: true, loc: 3 },
    { id: 'b.js:dead', label: 'dead', kind: 'function', file: 'b.js', exports: false, loc: 4 },
  ],
  edges: [],
};
function checkASupp() {
  if (!existsSync(script('annotate.mjs')) || !existsSync(script('deadcode.mjs'))) {
    record('A-SUPP', { metric: 'suppress/resurface', value: 'tool missing', passed: false, criterion: 'hide by identity; resurface on mutated fingerprint', notes: 'annotate.mjs or deadcode.mjs missing' });
    return { canFail: false };
  }
  const dir = tmp('cw-aux-supp-');
  try {
    const gp = join(dir, 'graph.json'); writeFileSync(gp, JSON.stringify(SUPP_GRAPH));
    // 1. baseline: dead is reported safe with a fingerprint, 0 suppressed
    const before = JSON.parse(runNode(script('deadcode.mjs'), [gp, '--annotations', dir, '--json']).stdout);
    const dead = before.safe.find((o) => o.id === 'b.js:dead');
    const baselineOk = !!(dead && dead.fingerprint) && before.totals.suppressed === 0;
    // 2. annotate it as a false positive
    const ann = runNode(script('annotate.mjs'), ['--suppress', dead.fingerprint, '--dir', dir, '--note', 'entrypoint', '--json']);
    // 3. now hidden + counted
    const after = JSON.parse(runNode(script('deadcode.mjs'), [gp, '--annotations', dir, '--json']).stdout);
    const hidden = !after.safe.some((o) => o.id === 'b.js:dead') && after.totals.suppressed === 1 && after.suppressed.some((o) => o.id === 'b.js:dead');
    // 4. --show-suppressed reveals it again
    const shown = JSON.parse(runNode(script('deadcode.mjs'), [gp, '--annotations', dir, '--show-suppressed', '--json']).stdout);
    const revealed = shown.safe.some((o) => o.id === 'b.js:dead');
    // 5. mutate the id (rename) -> fingerprint changes -> resurfaces, suppression no longer applies
    const g2 = { ...SUPP_GRAPH, nodes: SUPP_GRAPH.nodes.map((n) => (n.id === 'b.js:dead' ? { ...n, id: 'b.js:deadRenamed', label: 'deadRenamed' } : n)) };
    writeFileSync(gp, JSON.stringify(g2));
    const renamed = JSON.parse(runNode(script('deadcode.mjs'), [gp, '--annotations', dir, '--json']).stdout);
    const resurfaced = renamed.safe.some((o) => o.id === 'b.js:deadRenamed') && renamed.totals.suppressed === 0;

    // ABLE-TO-FAIL: 'hidden' (suppression actually removed it) and 'resurfaced' (mutation defeats the
    // suppression) are opposite-direction observations. A no-op annotate would fail 'hidden'; a
    // fingerprint-blind suppression would fail 'resurfaced'. Both observed -> non-vacuous.
    const canFail = hidden && resurfaced;
    const passed = baselineOk && ann.status === 0 && hidden && revealed && resurfaced;
    record('A-SUPP', {
      metric: 'suppress-by-identity + resurface-on-mutation',
      value: `baseline=${baselineOk} hidden=${hidden} revealed=${revealed} resurfaced=${resurfaced}`,
      passed: passed && canFail,
      criterion: 'suppressed finding hidden+counted; --show-suppressed reveals; renamed id resurfaces (suppressed->0)',
      notes: canFail ? '' : 'opposite-direction observations not both present — vacuous',
    });
    return { baselineOk, hidden, revealed, resurfaced, canFail };
  } finally { rmrf(dir); }
}

// ============================================================================================
// A-MCP — each of the 20 MCP tools' JSON result == its CLI equivalent on the same input; plus
// JSON-RPC initialize / tools.list / tools.call conformance + error codes.
// We spawn scripts/mcp-server.mjs over stdio (newline-delimited JSON-RPC), and for every tool we
// compare the server's content[0].text to the SHIPPED CLI invocation on the same graph+args.
// DISCLOSURE: both sides are codeweb surfaces, so this is a cross-INTERFACE parity + protocol check,
// not an external-oracle correctness check. Mirrors tests/mcp.test.mjs (which pins the parity for a
// subset); here we cover EVERY shipped tool. The mapping (tool -> CLI argv) is re-derived
// INDEPENDENTLY below from each tool's documented contract — we do NOT import mcp-server's TOOLS
// table, because a table copied from the thing under test cannot detect that thing drifting.
//
// The cost of that independence is that the table is HAND-MAINTAINED and goes stale when a tool
// ships: `toolsListMatches` compares the server's tools/list against this table plus NON_PARITY_
// TOOLS, so a missing entry reads as a conformance failure. `conf.toolsListMissing` /
// `toolsListUnexpected` below name the difference so the next reader sees "the table is short one
// tool", not a bare false. (This is exactly how the 27-vs-28 gap presented after codeweb_dependents
// shipped.)
// ============================================================================================
function rpc(messages) {
  const input = messages.map((m) => JSON.stringify(m)).join('\n') + '\n';
  const r = runNode(script('mcp-server.mjs'), [], { input });
  const responses = (r.stdout || '').split('\n').filter(Boolean).map((l) => { try { return JSON.parse(l); } catch { return { __unparseable: l }; } });
  return { status: r.status, stderr: r.stderr, responses, byId: new Map(responses.map((x) => [x.id, x])), junk: responses.filter((x) => x.__unparseable) };
}
const INIT = { jsonrpc: '2.0', id: 1, method: 'initialize', params: { protocolVersion: '2025-06-18', capabilities: {}, clientInfo: { name: 'aux', version: '0' } } };
const callTool = (id, name, args) => ({ jsonrpc: '2.0', id, method: 'tools/call', params: { name, arguments: args } });

// Independent re-derivation of each tool's equivalent CLI: [binFile, argvBuilder]. Authored from the
// tools' documented contracts (query flags vs dedicated scripts), NOT copied from mcp-server.mjs.
function cliEquivalents() {
  return {
    codeweb_callers: ['query.mjs', (a) => [a.graph, '--callers', a.symbol]],
    codeweb_dependents: ['query.mjs', (a) => [a.graph, '--dependents', a.symbol, ...(a.limit ? ['--limit', String(a.limit)] : [])]],
    codeweb_callees: ['query.mjs', (a) => [a.graph, '--callees', a.symbol]],
    codeweb_impact: ['query.mjs', (a) => [a.graph, '--impact', a.symbol]],
    codeweb_cycles: ['query.mjs', (a) => [a.graph, '--cycles']],
    codeweb_orphans: ['query.mjs', (a) => [a.graph, '--orphans']],
    codeweb_tests: ['query.mjs', (a) => [a.graph, '--tests', a.symbol]],
    codeweb_diff: ['diff.mjs', (a) => [a.before, a.after]],
    codeweb_find_similar: ['find-similar.mjs', (a) => [a.graph, '--signature', a.signature]],
    codeweb_placement: ['placement.mjs', (a) => [a.graph, '--calls', a.calls]],
    codeweb_review: ['review.mjs', (a) => [a.graph, '--changed', a.changed]],
    codeweb_fitness: ['fitness.mjs', (a) => [a.graph, '--rules', a.rules]],
    codeweb_risk: ['risk.mjs', (a) => [a.graph]],
    codeweb_break_cycles: ['break-cycles.mjs', (a) => [a.graph]],
    codeweb_deadcode: ['deadcode.mjs', (a) => [a.graph]],
    codeweb_codemod: ['codemod.mjs', (a) => [a.graph, '--merge', a.merge, '--into', a.into]],
    codeweb_context: ['context-pack.mjs', (a) => [a.graph, a.symbol]],
    codeweb_refresh: ['refresh.mjs', (a) => [a.graph]],
    codeweb_hotspots: ['hotspots.mjs', (a) => [a.graph]],
    codeweb_campaign: ['campaign.mjs', (a) => [a.graph]],
    codeweb_reading_order: ['reading-order.mjs', (a) => [a.graph, ...(a.budget ? ['--budget', String(a.budget)] : [])]],
    codeweb_brief: ['brief.mjs', (a) => [a.graph]],
    codeweb_explain: ['explain.mjs', (a) => [a.graph, a.symbol]],
    codeweb_find: ['find.mjs', (a) => [a.graph, a.query]],
    codeweb_simulate: ['simulate-edit.mjs', (a) => [a.graph, '--delete', a.delete]],
    codeweb_annotate: ['annotate.mjs', (a) => ['--dir', dirname(a.graph), '--list']],
    codeweb_stats: ['stats.mjs', (a) => [a.graph]],
  };
}

// Tools with no --json CLI twin to diff against (codeweb_map wraps the whole pipeline into a
// workspace; its contract is covered by tests/mcp.test.mjs, not text parity).
const NON_PARITY_TOOLS = ['codeweb_map'];

function checkAMcp(realGraphForRefresh) {
  process.env.CODEWEB_NO_STATS = '1'; // parity must not depend on which surface bumped the ledger first
  // --- Build a stable on-disk fixture with a meta.root pointing at REAL source (find_similar,
  //     context, refresh need bodies on disk). ---
  const ws = tmp('cw-aux-mcp-');
  const srcRoot = join(ws, 'src');
  writeTree(srcRoot, {
    'main.js': 'import { helper } from "./util.js";\nexport function main() {\n  return helper(2);\n}\n',
    'util.js': 'export function helper(x) {\n  if (x > 0) return x * 2;\n  return 0;\n}\n',
  });
  const G = {
    meta: { root: srcRoot.replace(/\\/g, '/'), target: 'mcp-aux' }, domains: [], overlaps: [],
    nodes: [
      { id: 'main.js:main', label: 'main', kind: 'function', file: 'main.js', line: 2, loc: 2, exports: true, domain: 'app', complexity: 1, maxDepth: 0 },
      { id: 'util.js:helper', label: 'helper', kind: 'function', file: 'util.js', line: 1, loc: 4, exports: true, domain: 'lib', complexity: 2, maxDepth: 1 },
    ],
    edges: [{ from: 'main.js:main', to: 'util.js:helper', kind: 'call' }],
  };
  const GP = join(ws, 'graph.json'); writeFileSync(GP, JSON.stringify(G));
  // diff snapshots (before == after-clean -> ok:true)
  const BEFORE = { meta: { target: 'before' }, domains: [], overlaps: [], nodes: [{ id: 'a.js:fa', label: 'fa', file: 'a.js', domain: 'app', exports: true }, { id: 'b.js:fb', label: 'fb', file: 'b.js', domain: 'core', exports: false }], edges: [{ from: 'a.js:fa', to: 'b.js:fb', kind: 'call' }] };
  const BP = join(ws, 'before.json'); writeFileSync(BP, JSON.stringify(BEFORE));
  // rules file for fitness
  const RULES = { rules: [{ id: 'cap', type: 'max-fan-in', limit: 0, severity: 'warning' }] };
  const RP = join(ws, 'rules.json'); writeFileSync(RP, JSON.stringify(RULES));

  // Per-tool args used IDENTICALLY on both surfaces. Each refresh/codemod gets its OWN graph copy so
  // a mutating tool (refresh rewrites graph.json) doesn't poison another tool's input.
  const copyGraph = (tag) => { const p = join(ws, `g-${tag}.json`); writeFileSync(p, JSON.stringify(G)); return p; };
  const argsFor = {
    codeweb_callers: { graph: GP, symbol: 'util.js:helper' },
    // explicit on BOTH surfaces: MCP injects limit 20, and under a budget `dependents` deliberately
    // collapses byKind to counts, so an unbudgeted CLI call would compare two different shapes
    codeweb_dependents: { graph: GP, symbol: 'util.js:helper', limit: 20 },
    codeweb_callees: { graph: GP, symbol: 'main.js:main' },
    codeweb_impact: { graph: GP, symbol: 'util.js:helper' },
    codeweb_cycles: { graph: GP },
    codeweb_orphans: { graph: GP },
    codeweb_tests: { graph: GP, symbol: 'util.js:helper' },
    codeweb_diff: { before: BP, after: BP },
    codeweb_find_similar: { graph: GP, signature: 'function helper(x) { if (x > 0) return x * 2; return 0; }' },
    codeweb_placement: { graph: GP, calls: 'util.js:helper' },
    codeweb_review: { graph: GP, changed: 'util.js' },
    codeweb_fitness: { graph: GP, rules: RP },
    codeweb_risk: { graph: GP },
    codeweb_break_cycles: { graph: GP },
    codeweb_deadcode: { graph: GP },
    codeweb_codemod: { graph: GP, merge: 'main.js:main,util.js:helper', into: 'util.js:helper' },
    codeweb_context: { graph: GP, symbol: 'util.js:helper' },
    codeweb_refresh: { graph: copyGraph('refresh-mcp') },     // overridden per-surface below
    codeweb_hotspots: { graph: GP },
    codeweb_campaign: { graph: GP },
    codeweb_reading_order: { graph: GP, budget: 20 }, // explicit on BOTH surfaces (MCP injects 20 by default; the bare CLI defaults to 40)
    codeweb_brief: { graph: GP },
    codeweb_explain: { graph: GP, symbol: 'util.js:helper' },
    codeweb_find: { graph: GP, query: 'helper util' },
    codeweb_simulate: { graph: GP, delete: 'main.js:main' },
    codeweb_annotate: { graph: GP, list: true },
    codeweb_stats: { graph: GP },
  };

  try {
    const equivalents = cliEquivalents();
    const toolNames = Object.keys(equivalents);

    // ---- protocol conformance ----
    const conf = {};
    {
      const init = rpc([INIT]);
      conf.pureStdout = init.junk.length === 0;
      const initRes = init.byId.get(1)?.result;
      conf.initialize = !!(initRes && initRes.protocolVersion && typeof initRes.capabilities?.tools === 'object' && initRes.serverInfo?.name === 'codeweb');
      conf.exitsClean = init.status === 0;

      const list = rpc([INIT, { jsonrpc: '2.0', id: 2, method: 'tools/list' }]).byId.get(2)?.result?.tools || [];
      const listed = list.map((t) => t.name).sort();
      conf.toolsListCount = listed.length;
      const expectedTools = [...toolNames, ...NON_PARITY_TOOLS];
      conf.toolsListMatches = setEq(listed, expectedTools) && listed.length === expectedTools.length;
      // Name the difference, so a stale hand-maintained table is legible as a table problem rather
      // than an unexplained conformance failure.
      conf.toolsListMissing = listed.filter((n) => !expectedTools.includes(n));      // shipped, absent from the table
      conf.toolsListUnexpected = expectedTools.filter((n) => !listed.includes(n));   // in the table, no longer shipped
      conf.allHaveObjectSchema = list.every((t) => t.inputSchema?.type === 'object' && t.description);

      // error codes: unknown tool -> -32602; unknown method -> -32601; bad JSON -> -32700; missing arg -> isError
      const e1 = rpc([INIT, callTool(5, 'codeweb_nope', { graph: GP })]).byId.get(5);
      conf.unknownTool = e1?.error?.code === -32602;
      const e2 = rpc([INIT, { jsonrpc: '2.0', id: 8, method: 'foo/bar' }]).byId.get(8);
      conf.unknownMethod = e2?.error?.code === -32601;
      // malformed JSON line followed by a valid request: parse error -32700, then recovery.
      const rawIn = 'this is not json\n' + JSON.stringify({ jsonrpc: '2.0', id: 11, method: 'tools/list' }) + '\n';
      const e3b = runNode(script('mcp-server.mjs'), [], { input: rawIn });
      const e3lines = (e3b.stdout || '').split('\n').filter(Boolean).map((l) => { try { return JSON.parse(l); } catch { return null; } });
      conf.parseError = e3lines.some((l) => l && l.error && l.error.code === -32700) && e3lines.some((l) => l && l.id === 11);
      const e4 = rpc([INIT, callTool(10, 'codeweb_callers', { graph: GP })]).byId.get(10); // missing symbol
      conf.missingArgIsError = !e4?.error && e4?.result?.isError === true;
      // notification (no id) gets no reply; later request still answered
      const note = rpc([INIT, { jsonrpc: '2.0', method: 'notifications/initialized' }, { jsonrpc: '2.0', id: 9, method: 'tools/list' }]);
      conf.notificationNoReply = !!note.byId.get(9) && note.responses.length === 2 && note.responses.every((r) => r.id !== undefined && r.id !== null);
    }
    // Every recorded conformance value must be affirmative: booleans true, counts numeric, and the
    // two drift-diagnostic lists empty.
    const confOk = Object.values(conf).every((v) => (Array.isArray(v) ? v.length === 0 : v === true || typeof v === 'number'));
    const confAllTrue = ['pureStdout', 'initialize', 'exitsClean', 'toolsListMatches', 'allHaveObjectSchema', 'unknownTool', 'unknownMethod', 'parseError', 'missingArgIsError', 'notificationNoReply'].every((k) => conf[k] === true);

    // ---- per-tool parity ----
    let parityOk = 0; const parityFail = [];
    for (let i = 0; i < toolNames.length; i++) {
      const name = toolNames[i];
      const [binFile, argv] = equivalents[name];
      const baseArgs = argsFor[name];
      // refresh mutates graph.json -> isolate copies for each surface so they don't fight
      let mcpArgs = baseArgs, cliArgs = baseArgs;
      if (name === 'codeweb_refresh') {
        const mcpG = copyGraph('refresh-mcp'); const cliG = copyGraph('refresh-cli');
        mcpArgs = { graph: mcpG }; cliArgs = { graph: cliG };
      }
      // MCP side
      const res = rpc([INIT, callTool(100 + i, name, mcpArgs)]).byId.get(100 + i)?.result;
      const mcpText = (res?.content?.[0]?.text ?? '').trim();
      // CLI side (always --json appended, matching the server)
      const cli = runNode(script(binFile), [...argv(cliArgs), '--json']);
      const cliText = (cli.stdout || '').trim();

      let ok;
      if (name === 'codeweb_refresh') {
        // refresh prints a per-run summary with surface-specific paths; the SHIPPED contract (and
        // mcp.test.mjs) is that the REFRESHED graph.json is identical. Compare the on-disk graphs.
        const a = readJSON(mcpArgs.graph), b = readJSON(cliArgs.graph);
        ok = setEq(a.nodes.map((n) => n.id), b.nodes.map((n) => n.id)) &&
          setEq(a.edges.map(edgeKey), b.edges.map(edgeKey));
      } else {
        ok = mcpText.length > 0 && mcpText === cliText;
      }
      if (ok) parityOk++;
      else parityFail.push({ name, mcpHead: mcpText.slice(0, 80), cliHead: cliText.slice(0, 80), mcpErr: res?.isError || false });
    }

    // ABLE-TO-FAIL probe: comparing a tool's MCP output to the WRONG CLI (callees vs callers on an
    // asymmetric edge main->helper) MUST differ -> the parity equality can fail.
    let canFail = false;
    {
      const callers = rpc([INIT, callTool(900, 'codeweb_callers', { graph: GP, symbol: 'util.js:helper' })]).byId.get(900)?.result?.content?.[0]?.text?.trim();
      const wrongCli = runNode(script('query.mjs'), [GP, '--callees', 'util.js:helper', '--json']).stdout.trim();
      canFail = callers && wrongCli && callers !== wrongCli; // a mismatched pairing is detected
    }

    const passed = parityOk === toolNames.length && confAllTrue && canFail && confOk;
    record('A-MCP', {
      metric: 'tools at CLI parity / protocol conformance',
      value: `${parityOk}/${toolNames.length} parity; conformance=${confAllTrue}; toolsList=${conf.toolsListCount}`,
      passed,
      criterion: `all ${toolNames.length} parity tools == CLI on same input (codeweb_map covered by mcp.test.mjs); initialize/tools.list/tools.call + error codes (-32602/-32601/-32700, isError) conform; probe trips`,
      notes: parityFail.length ? `parity fails: ${JSON.stringify(parityFail.slice(0, 4))}` : (canFail ? '' : 'mismatch probe did not trip'),
    });
    return { parityOk, totalTools: toolNames.length, parityFail, conf, confAllTrue, canFail };
  } finally { rmrf(ws); }
}

// ============================================================================================
// Real-corpus support: build ONE real graph (smallest repo: gorilla-mux) for A-SELFCONTAINED(real)
// and to confirm the extraction fast path on real code. Deterministic (--no-ctags). If the corpus
// is absent we degrade gracefully (synthetic-only) and disclose it — we do NOT silently skip.
// ============================================================================================
function buildRealGraph() {
  const repoDir = join(CORPUS, 'gorilla-mux');
  if (!existsSync(repoDir)) return { available: false, reason: 'corpus/gorilla-mux not present' };
  const dir = tmp('cw-aux-real-');
  try {
    const out = join(dir, 'fragment.json');
    const ex = runNode(script('extract-symbols.mjs'), [repoDir, '--target', 'gorilla-mux', '--no-ctags', '--out', out]);
    if (ex.status !== 0) return { available: false, reason: `extract failed: ${ex.stderr.trim().slice(0, 200)}` };
    // cluster to produce graph.json with domains (CODEWEB_WS = dir)
    const cl = runNode(script('cluster3.mjs'), [], { env: { CODEWEB_WS: dir } });
    const gp = join(dir, 'graph.json');
    if (cl.status !== 0 || !existsSync(gp)) return { available: false, reason: `cluster failed: ${cl.stderr.trim().slice(0, 200)}` };
    const graph = readJSON(gp);
    return { available: true, graph, nodes: graph.nodes.length, edges: graph.edges.length, dir };
  } catch (e) {
    return { available: false, reason: String(e && e.message || e) };
  } finally { rmrf(dir); }
}

// ============================================================================================
// MAIN
// ============================================================================================
console.log('# codeweb effectiveness study — C6 auxiliary checks\n');

const t0 = Date.now();
const real = buildRealGraph();
if (!real.available) console.log(`(note) real corpus graph unavailable (${real.reason}); A-SELFCONTAINED runs synthetic-only.\n`);
else console.log(`(real graph) gorilla-mux: ${real.nodes} nodes, ${real.edges} edges (fast path, --no-ctags)\n`);

const details = {};
details.aLang = checkALang();
details.aSelfContained = checkASelfContained(real.available ? real.graph : null);
details.aTreemap = checkATreemap();
details.aCiGate = checkACiGate();
details.aTrend = checkATrend();
details.aPlace = checkAPlace();
details.aFit = checkAFit();
details.aRisk = checkARisk();
details.aHot = checkAHot();
details.aSupp = checkASupp();
details.aMcp = checkAMcp(real.available ? real.graph : null);

const elapsedMs = Date.now() - t0;
const allPassed = checks.every((c) => c.passed);

// ---- write results JSON (machine-readable; the schema the cluster spec requires) ----
const resultsObj = {
  cluster: 'C6-auxiliary',
  generatedAt: new Date().toISOString(),
  elapsedMs,
  seeds: SEEDS,
  node: process.version,
  realCorpus: real.available ? { repo: 'gorilla-mux', nodes: real.nodes, edges: real.edges } : { available: false, reason: real.reason },
  hasGit,
  // disclosure of oracle independence per check (honesty contract)
  oracleNotes: {
    'A-LANG': 'independent: expected node/edge sets authored by hand per fixture',
    'A-SELFCONTAINED': 'independent: from-scratch regex network-ref scan over shipped report.html',
    'A-TREEMAP': 'independent: pure geometry invariants over the shipped bisect() extracted from the template',
    'A-CIGATE': 'independent: git ground truth we construct (known regression/clean/removal states)',
    'A-TREND': 'independent: we plant the duplicate-logic overlaps; true confirmed sequence known',
    'A-PLACE': 'independent: plurality-domain recomputed inline from graph (not placement.mjs)',
    'A-FIT': 'independent: per-rule violating set recomputed inline with plain edge/degree filters',
    'A-RISK': 'independent: risk formula re-implemented here with own weights; CLI ranking cross-checked',
    'A-HOT': 'independent: 0.5cx+0.3fanIn+0.2churn re-implemented here with own weights vs shipped score',
    'A-SUPP': 'independent: we control the orphan + identity; expected hide/resurface is known',
    'A-MCP': 'cross-INTERFACE parity (MCP vs CLI, same input) + protocol conformance — NOT an external oracle; underlying correctness covered by C1-C5',
  },
  perHypothesis: checks.map((c) => ({
    id: c.id, metric: c.metric, value: c.value, ci: c.ci, passed: c.passed, criterion: c.criterion, notes: c.notes,
  })),
  details,
  summary: { total: checks.length, passed: checks.filter((c) => c.passed).length, failed: checks.filter((c) => !c.passed).length, allPassed },
};
mkdirSync(dirname(RESULTS), { recursive: true });
writeFileSync(RESULTS, JSON.stringify(resultsObj, null, 2));

console.log(`\n${allPassed ? 'ALL PASS' : 'SOME FAILED'} — ${resultsObj.summary.passed}/${resultsObj.summary.total} checks passed in ${elapsedMs}ms`);
console.log(`results -> ${RESULTS}`);

process.exit(allPassed ? 0 : 1);
