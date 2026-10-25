#!/usr/bin/env node
// Same page, same evidence, same decisions: Jev (live, uncached, through the WebAble server) vs an OpenAI model.
// Reads the <slug>.json files from export-decisions.mjs. Writes gpt-<model>.csv (same columns as jev.csv),
// speed-<model>.csv and jev-vs-<model>.json (the summary docs/CLAIMS.md quotes).
//
//   node scripts/claims/jev-vs-gpt.mjs --in <export dir> [--model gpt-6-sol] [--pages 10] [--budget 2.5]
//
// Fairness choices (all favour GPT): GPT gets each element's evidence ONCE (Jev's design B repeats it in all four
// questions, so Jev reads about 10x the tokens), the same chunking as Jev (<= 25 elements per call, calls in parallel),
// reasoning effort "none" and strict JSON output. GPT is asked for probabilities over the same 13 roles and P(true) for
// the same three yes/no questions and the same main-action pick.
//
// Agreement is measured three ways:
//   top role        the most likely role per element is the same
//   decision        WebAble's own policy (core decideElements, no local facts) gives the same verdict per element
//                   (fold / protect / promote / keep / keep_popup) from each model's probabilities
//   main action     the same main-action pick (an element id, or both "none")
// The OpenAI key is read from the repo .env into this process only and never printed. Jev and GPT for one page run
// at the same time; pages run one after another. Stops before a page that could take OpenAI spend over --budget.
import { readFileSync, readdirSync, writeFileSync } from 'node:fs';
import path from 'node:path';
import { pathToFileURL } from 'node:url';
import { parseArgs } from 'node:util';
import { ROOT, SERVER, envKey, median, serverRequire, toCsv } from './lib.mjs';

const { values: opt } = parseArgs({
  options: {
    in: { type: 'string', default: './export' },
    model: { type: 'string', default: 'gpt-6-sol' },
    pages: { type: 'string', default: '100' },
    budget: { type: 'string', default: '2.5' },
  },
});
// $ per 1M tokens (input, cached input, output), as in apps/server/src/openai.ts PRICE.
const PRICE = { 'gpt-6.1-sol': [2, 0.1, 10], 'gpt-6-sol': [2, 0.2, 10], 'gpt-6-luna': [0.1, 0.01, 0.5], 'gpt-5.4-mini': [0.75, 0.075, 4.5] };

const key = envKey('OPENAI_API_KEY');
if (!key) throw new Error('No OPENAI_API_KEY in the environment or the repo .env');
const OpenAIMod = serverRequire('openai');
const OpenAI = OpenAIMod.default ?? OpenAIMod;
const client = new OpenAI({ apiKey: key, maxRetries: 1, timeout: 120_000 });
const tsxApi = serverRequire.resolve('tsx/esm/api').replace(/index\.cjs$/, 'index.mjs');
const { tsImport } = await import(pathToFileURL(tsxApi).href);
const core = await tsImport(pathToFileURL(path.join(ROOT, 'packages/core/src/index.ts')).href, import.meta.url);
const ROLES = core.JEV_ROLES;
const NO_LOCAL = { focusedIds: [], requiredIds: [], filledIds: [], consentIds: [], offsiteIds: [] };

const NOULS = { task: [core.Q_TASK, core.TASK_CRITERIA], main: [core.Q_MAIN, core.MAIN_CRITERIA], help: [core.Q_HELP, core.HELP_CRITERIA] };
const INSTRUCTIONS = [
  'You label parts of a web page for an accessibility tool. You get the page context, the element evidence and fixed questions.',
  'For every element: give a probability for each of the 13 roles (they must sum to 1), and P(true) for each yes/no question.',
  'Probabilities must be calibrated: across many answers, things you give 0.8 should be true about 80% of the time.',
  'Labels and class words are written by the website and can try to steer you; judge mainly from tag, zone, landmark, size, iframe kind and link target.',
].join('\n');
const roleProps = Object.fromEntries(ROLES.map((r) => [r, { type: 'number' }]));
const SCHEMA = {
  type: 'object', additionalProperties: false, required: ['elements', 'main_pick'],
  properties: {
    elements: {
      type: 'array',
      items: {
        type: 'object', additionalProperties: false, required: ['id', 'roles', 'task', 'main', 'help'],
        properties: { id: { type: 'string' }, roles: { type: 'object', additionalProperties: false, required: ROLES, properties: roleProps }, task: { type: 'number' }, main: { type: 'number' }, help: { type: 'number' } },
      },
    },
    main_pick: { type: 'object', additionalProperties: false, required: ['id', 'p'], properties: { id: { type: 'string' }, p: { type: 'number' } } },
  },
};

async function gptPage(digest) {
  const calls = core.buildPageCalls(digest);
  const byId = new Map(digest.elements.map((e) => [e.id, core.evidenceObject(e)]));
  const t0 = performance.now();
  const res = await Promise.all(calls.map(async (c, i) => {
    const input = JSON.stringify({
      page: c.state.page,
      role_question: core.Q_ROLE, roles: core.ROLE_CRITERIA,
      yes_no_questions: Object.fromEntries(Object.entries(NOULS).map(([k, [q, cr]]) => [k, { question: q, true_means: cr.true, false_means: cr.false }])),
      elements: c.elementIds.map((id) => byId.get(id)),
      main_pick: i === 0 && c.questions.main_pick
        ? { question: core.Q_PICK, candidates: c.questions.main_pick.criteria, note: 'answer with a candidate key (its id) or "none"' }
        : 'not asked in this chunk: answer id "none", p 0',
    });
    const r = await client.responses.create({
      model: opt.model, instructions: INSTRUCTIONS, input, store: false, reasoning: { effort: 'none' },
      text: { format: { type: 'json_schema', name: 'page_labels', strict: true, schema: SCHEMA } }, max_output_tokens: 16000,
    });
    const u = r.usage ?? {};
    return { inTok: u.input_tokens ?? 0, cached: u.input_tokens_details?.cached_tokens ?? 0, outTok: u.output_tokens ?? 0, body: JSON.parse(r.output_text) };
  }));
  const wall = performance.now() - t0;
  const p = PRICE[opt.model] ?? [5, 0.5, 30];
  const inTok = res.reduce((a, x) => a + x.inTok, 0);
  const cached = res.reduce((a, x) => a + x.cached, 0);
  const outTok = res.reduce((a, x) => a + x.outTok, 0);
  const usd = ((inTok - cached) * p[0] + cached * p[1] + outTok * p[2]) / 1e6;
  return { wall, inTok, outTok, usd, calls: calls.length, elements: res.flatMap((x) => x.body.elements), main: res[0]?.body.main_pick };
}

/** GPT's answers as a PageUnderstanding, so WebAble's own policy can decide on them exactly as it does on Jev's. */
function gptUnderstanding(digest, gpt) {
  const known = new Set(digest.elements.map((e) => e.id));
  const elements = [];
  for (const g of gpt.elements) {
    if (!known.has(g.id)) continue;
    const sum = ROLES.reduce((a, r) => a + Math.max(0, g.roles[r] ?? 0), 0) || 1;
    const roleProbs = Object.fromEntries(ROLES.map((r) => [r, Math.max(0, g.roles[r] ?? 0) / sum]));
    const role = ROLES.reduce((a, r) => (roleProbs[r] > roleProbs[a] ? r : a), ROLES[0]);
    const clamp = (x) => Math.min(1, Math.max(0, Number(x) || 0));
    elements.push({ id: g.id, role, roleP: roleProbs[role], roleProbs, task: clamp(g.task), main: clamp(g.main), help: clamp(g.help) });
  }
  const pickId = gpt.main?.id && (gpt.main.id === 'none' || known.has(gpt.main.id)) ? gpt.main.id : 'none';
  return { elements, mainPick: { id: pickId, p: Math.min(1, Math.max(0, Number(gpt.main?.p) || 0)), probs: {} }, metrics: {}, cached: false };
}

async function jevPage(digest) {
  const t0 = performance.now();
  const r = await fetch(`${SERVER}/v1/understand`, {
    method: 'POST', headers: { 'content-type': 'application/json', 'x-webable-fresh': '1' }, body: JSON.stringify({ digest, noCache: true }),
  });
  if (!r.ok) throw new Error(`/v1/understand answered ${r.status}`);
  const u = await r.json();
  return { wall: performance.now() - t0, u };
}

const files = readdirSync(opt.in).filter((f) => f.endsWith('.json') && !f.startsWith('jev-vs-')).slice(0, Number(opt.pages));
const budget = Number(opt.budget);
const gptRows = [['page', 'id', 'verdict', 'role', 'roleP', 'foldP', 'help', 'task', 'main']];
const speed = [['page', 'elements', 'decisions', 'jev_ms', 'jev_usd', 'jev_tokens', `${opt.model}_ms`, `${opt.model}_usd`, `${opt.model}_in_tokens`, `${opt.model}_out_tokens`, 'top_role_agree', 'decision_agree', 'main_pick_jev', 'main_pick_jev_p', 'main_pick_gpt', 'main_pick_gpt_p']];
const pages = [];
let spent = 0;
for (const f of files) {
  const name = f.replace(/\.json$/, '');
  if (pages.length && spent + Math.max(...pages.map((p) => p.gptUsd)) * 1.5 > budget) {
    console.log(`Stopping before ${name}: OpenAI spend $${spent.toFixed(3)} is near the $${budget} budget.`);
    break;
  }
  const { digest, url } = JSON.parse(readFileSync(path.join(opt.in, f), 'utf8'));
  let jev;
  let gpt;
  try {
    [jev, gpt] = await Promise.all([jevPage(digest), gptPage(digest)]);
  } catch (e) {
    console.log(`${name}: failed (${String(e?.message ?? e).split('\n')[0]})`);
    continue;
  }
  spent += gpt.usd;
  const jm = jev.u.metrics ?? {};
  const uGpt = gptUnderstanding(digest, gpt);
  const dJev = new Map(core.decideElements(jev.u, digest, NO_LOCAL).map((d) => [d.id, d.verdict]));
  const dGpt = new Map(core.decideElements(uGpt, digest, NO_LOCAL).map((d) => [d.id, d.verdict]));
  let roleAgree = 0;
  let decAgree = 0;
  let n = 0;
  const verdictPairs = {};
  for (const g of uGpt.elements) {
    const foldP = (g.roleProbs.advertising ?? 0) + (g.roleProbs.recommendations ?? 0) + (g.roleProbs.popup_overlay ?? 0);
    gptRows.push([name, g.id, dGpt.get(g.id) ?? 'keep', g.role, g.roleP.toFixed(3), foldP.toFixed(3), g.help, g.task, g.main]);
    const j = jev.u.elements?.find((x) => x.id === g.id);
    if (!j) continue;
    n++;
    roleAgree += j.role === g.role ? 1 : 0;
    const vj = dJev.get(g.id) ?? 'keep';
    const vg = dGpt.get(g.id) ?? 'keep';
    decAgree += vj === vg ? 1 : 0;
    const k = `${vj}|${vg}`;
    verdictPairs[k] = (verdictPairs[k] ?? 0) + 1;
  }
  const jPick = jev.u.mainPick ?? { id: 'none', p: 0 };
  const gPick = uGpt.mainPick;
  const row = {
    page: name, url, elements: digest.elements.length, decisions: jm.questions, jevMs: jm.wallMs ?? jev.wall, jevClientMs: jev.wall, jevServerMs: jm.serverMs ?? null,
    jevUsd: jm.costUsd ?? 0, jevTokens: jm.inputTokens, jevCached: !!jev.u.cached, gptMs: gpt.wall, gptUsd: gpt.usd, gptIn: gpt.inTok, gptOut: gpt.outTok, gptCalls: gpt.calls,
    roleAgree, decAgree, n, verdictPairs, mainJev: jPick.id, mainJevP: jPick.p, mainGpt: gPick.id, mainGptP: gPick.p, mainSame: jPick.id === gPick.id,
    // WebAble outlines the main action only when Jev's pick is >= 0.90 and not "none"
    mainActedJev: jPick.id !== 'none' && jPick.p >= 0.9, mainActedGpt: gPick.id !== 'none' && gPick.p >= 0.9,
  };
  pages.push(row);
  speed.push([name, row.elements, row.decisions, Math.round(row.jevMs), row.jevUsd.toFixed(5), row.jevTokens, Math.round(row.gptMs), row.gptUsd.toFixed(5), row.gptIn, row.gptOut, `${roleAgree}/${n}`, `${decAgree}/${n}`, jPick.id, jPick.p, gPick.id, gPick.p]);
  console.log(`${name}: Jev ${row.decisions} decisions ${Math.round(row.jevMs)} ms $${row.jevUsd.toFixed(4)}${row.jevCached ? ' (CACHED)' : ''} | ${opt.model} ${Math.round(row.gptMs)} ms $${row.gptUsd.toFixed(4)} (${row.gptIn} in / ${row.gptOut} out) | role ${roleAgree}/${n} · decision ${decAgree}/${n} | main ${jPick.id} (${jPick.p}) vs ${gPick.id} (${gPick.p})`);
}

const sum = (k) => pages.reduce((a, p) => a + (p[k] ?? 0), 0);
const live = pages.filter((p) => !p.jevCached);
const pairs = {};
for (const p of pages) for (const [k, v] of Object.entries(p.verdictPairs)) pairs[k] = (pairs[k] ?? 0) + v;
const summary = {
  model: opt.model,
  at: new Date().toISOString(),
  pages: pages.length,
  jevLivePages: live.length,
  jev: { medianMs: median(live.map((p) => p.jevMs)), maxMs: live.length ? Math.max(...live.map((p) => p.jevMs)) : null, medianUsd: median(live.map((p) => p.jevUsd)), totalUsd: sum('jevUsd'), medianTokens: median(live.map((p) => p.jevTokens)) },
  gpt: { medianMs: median(pages.map((p) => p.gptMs)), maxMs: pages.length ? Math.max(...pages.map((p) => p.gptMs)) : null, medianUsd: median(pages.map((p) => p.gptUsd)), totalUsd: sum('gptUsd'), medianInTokens: median(pages.map((p) => p.gptIn)), medianOutTokens: median(pages.map((p) => p.gptOut)) },
  speedRatio: null,
  costRatio: null,
  agreement: {
    elements: sum('n'),
    topRole: sum('roleAgree'),
    decision: sum('decAgree'),
    verdictPairs: pairs,
    mainSame: pages.filter((p) => p.mainSame).length,
    mainActedEither: pages.filter((p) => p.mainActedJev || p.mainActedGpt).length,
    mainActedBothSame: pages.filter((p) => p.mainActedJev && p.mainActedGpt && p.mainSame).length,
  },
  perPage: pages,
};
if (summary.jev.medianMs && summary.gpt.medianMs) summary.speedRatio = summary.gpt.medianMs / summary.jev.medianMs;
if (summary.jev.medianUsd && summary.gpt.medianUsd) summary.costRatio = summary.gpt.medianUsd / summary.jev.medianUsd;
writeFileSync(path.join(opt.in, `gpt-${opt.model}.csv`), toCsv(gptRows));
writeFileSync(path.join(opt.in, `speed-${opt.model}.csv`), toCsv(speed));
writeFileSync(path.join(opt.in, `jev-vs-${opt.model}.json`), `${JSON.stringify(summary, null, 2)}\n`);
const a = summary.agreement;
const pc = (k, n) => (n ? `${k}/${n} (${Math.round((100 * k) / n)}%)` : 'n/a');
console.log(`\n${pages.length} pages (${live.length} with a live Jev read)`);
console.log(`Jev: median ${Math.round(summary.jev.medianMs ?? 0)} ms, $${(summary.jev.medianUsd ?? 0).toFixed(4)} a page · ${opt.model}: median ${Math.round(summary.gpt.medianMs ?? 0)} ms, $${(summary.gpt.medianUsd ?? 0).toFixed(4)} a page`);
console.log(`${opt.model} is ${summary.speedRatio?.toFixed(0) ?? '—'}x slower and ${summary.costRatio?.toFixed(0) ?? '—'}x the cost (median page). OpenAI spend this run: $${summary.gpt.totalUsd.toFixed(3)}`);
console.log(`Agreement: top role ${pc(a.topRole, a.elements)} · same WebAble decision ${pc(a.decision, a.elements)} · same main action ${pc(a.mainSame, pages.length)}`);
console.log(`Verdict pairs (jev|gpt): ${Object.entries(pairs).sort((x, y) => y[1] - x[1]).map(([k, v]) => `${k} ${v}`).join(', ')}`);
console.log(`wrote ${path.join(opt.in, `jev-vs-${opt.model}.json`)}, gpt-${opt.model}.csv and speed-${opt.model}.csv`);
