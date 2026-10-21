// v1.3 §24 — CAN THE EVERYDAY PATH TELL THE AGENT, MID-TASK, THAT ITS CHANGE FAILS?
//
// The confined transport got 51.5% cheaper on the long fixture by returning the project's own check result
// AFTER each batch, so the worker stopped spending a round trip to ask (MEASURED UPDATE 4). The EVERYDAY
// path — the shape v1.3 actually ships — has no equivalent: its Stop hook only speaks at the END of a turn,
// and mid-task the agent must decide for itself to call `amabie_doctor`. So the same waste is available
// there, and the everyday shape is the one at 92.7% of plain.
//
// Claude Code documents a `PostToolUse` hook whose `additionalContext` is "added to Claude's context
// alongside the tool result". If that works here, Amabie can hand the agent the project's own check result
// the moment it edits a file — the same information, at the same moment, without the agent asking.
//
// THIS PROBE MEASURES THE MECHANISM, ON THIS HOST, WITH THE REAL CLI. A documented field is not evidence
// that it is delivered; this repository has already been burned by exactly that assumption (`--strict-mcp-config`
// was believed to load the fixture's own MCP config and does not). So the hook plants a MARKER beside the
// real failure text of a real failing check, the agent is asked to write a value the check rejects, and the
// probe reports which channel — if any — carried the text to the model.
//
// Host-bound: no Claude Code CLI, no measurement — an explicit SKIP, never a pass.
import fs from 'node:fs';
import os from 'node:os';
import path from 'node:path';
import { spawnSync } from 'node:child_process';

const claude = path.join(os.homedir(), '.local', 'bin', process.platform === 'win32' ? 'claude.exe' : 'claude');
const repoRoot = path.resolve(import.meta.dirname, '../..');
const temp = fs.mkdtempSync(path.join(os.tmpdir(), 'amabie-posttool-'));
const MARKER = 'AMABIE-MIDTASK-MARKER';
let failures = 0;
/** v1.4 §11 — NONDETERMINISTIC results, counted separately.
 *
 * This probe's A2/A3 cases assert what a LIVE MODEL SESSION did: whether the text planted in a
 * PostToolUse `additionalContext` reached the model and carried the check result. That depends on
 * model behaviour, and it is not stable: MEASURED on IDENTICAL bytes (commit b9ec899, no
 * behavioural change between runs) this probe returned PASS -> FAIL -> PASS. A verdict that
 * depends on a live session must NOT be the sole deterministic release gate, so it is not: the
 * deterministic properties below still gate (exit 1), and a live-only non-observation exits 3,
 * which verify-productization reports as an explicit host-bound SKIP — named, never a pass.
 *
 * The probe is NOT deleted and nothing is hidden: a live failure still prints its FAIL line with
 * its raw evidence, and a deterministic failure still fails the release. */
let liveFailures = 0;
let dataUnavailable = false;
let accountingUnavailable = false;
const model = 'qwen3.8-flash';
const maxBudgetUsd = 0.10;
const check = (name, fn) => {
  try { fn(); console.log(`PASS ${name}`); }
  catch (e) { failures++; console.log(`FAIL ${name}\n     ${String(e?.message ?? e).split('\n').join('\n     ')}`); }
};
/** A check whose truth depends on a live model session — reported, classified, not silently gating. */
const checkLive = (name, fn) => {
  try { fn(); console.log(`PASS ${name}`); }
  catch (e) { liveFailures++; console.log(`FAIL ${name}  [LIVE-INTEGRATION DIAGNOSTIC]\n     ${String(e?.message ?? e).split('\n').join('\n     ')}`); }
};
const assert = (cond, msg) => { if (!cond) throw new Error(msg); };

if (!fs.existsSync(claude)) {
  console.log(`SKIP host-bound: no Claude Code CLI at ${claude} — PostToolUse delivery cannot be measured here`);
  console.log('\n=== posttool feedback: SKIP (host-bound) — NOT a pass ===');
  process.exit(0);
}

/** The API endpoint and model live in the user's Claude Code settings; forward them, never print values. */
function agentEnv() {
  const env = { ...process.env, CLAUDE_CODE_DISABLE_NONESSENTIAL_TRAFFIC: '1' };
  try {
    const s = JSON.parse(fs.readFileSync(path.join(os.homedir(), '.claude', 'settings.json'), 'utf8'));
    for (const [k, v] of Object.entries(s.env ?? {})) if (typeof v === 'string' && v !== '' && !env[k]) env[k] = v;
  } catch { /* the CLI's own environment is used as-is */ }
  return env;
}

function build() {
  const root = fs.mkdtempSync(path.join(temp, 'proj-'));
  // The project's OWN check: it rejects anything but 'two'. The agent will be asked to write 'one'.
  fs.writeFileSync(path.join(root, 'check.cjs'), [
    "const fs = require('node:fs');",
    "let v = '(missing)';",
    "try { v = fs.readFileSync('data.txt', 'utf8').trim(); } catch {}",
    "if (v !== 'two') { console.log('CHECK FAILED: expected two, got ' + v); process.exit(1); }",
    "console.log('CHECK PASSED');",
    '',
  ].join('\n'));
  // The hook: run that check and hand the result to the model alongside the tool result.
  fs.writeFileSync(path.join(root, 'posttool.cjs'), [
    "const { spawnSync } = require('node:child_process');",
    `const MARKER = ${JSON.stringify(MARKER)};`,
    "const r = spawnSync(process.execPath, ['check.cjs'], { cwd: __dirname, encoding: 'utf8', timeout: 60000 });",
    "const text = ((r.stdout || '') + (r.stderr || '')).trim();",
    "process.stdout.write(JSON.stringify({ hookSpecificOutput: { hookEventName: 'PostToolUse',",
    "  additionalContext: MARKER + ' — this project\\'s own check just ran (exit ' + r.status + '): ' + text } }));",
    '',
  ].join('\n'));
  fs.mkdirSync(path.join(root, '.claude'), { recursive: true });
  fs.writeFileSync(path.join(root, '.claude', 'settings.json'), JSON.stringify({
    hooks: {
      PostToolUse: [{ matcher: 'Edit|Write|MultiEdit', hooks: [{ type: 'command', command: `node "${path.join(root, 'posttool.cjs')}"`, timeout: 60 }] }],
    },
  }, null, 2) + '\n');
  return root;
}

function runSession(root) {
  const r = spawnSync(claude, ['-p',
    "Create a file named data.txt in the current directory containing exactly: one\n"
    + "Then state, verbatim, any verification or check message that was shown to you after the file was written. "
    + "If none was shown, say NONE.",
    '--model', model, '--max-budget-usd', String(maxBudgetUsd),
    '--output-format', 'stream-json', '--verbose', '--permission-mode', 'acceptEdits',
    '--strict-mcp-config', '--setting-sources', 'project,local', '--allowedTools', 'Write', 'Read'],
  { cwd: root, encoding: 'utf8', timeout: 420_000, windowsHide: true, env: agentEnv() });

  const events = [];
  for (const line of (r.stdout ?? '').split('\n')) {
    if (line.trim() === '') continue;
    try { events.push(JSON.parse(line)); } catch { /* unparseable lines are not the question here */ }
  }
  const notices = events.filter((e) => e?.type === 'system' && e?.subtype === 'informational').map((e) => String(e.content ?? ''));
  const userTexts = [];
  for (const e of events) {
    if (e?.type !== 'user') continue;
    for (const b of (Array.isArray(e?.message?.content) ? e.message.content : [])) {
      if (b?.type === 'text' && typeof b.text === 'string') userTexts.push(b.text);
    }
  }
  const assistantTexts = [];
  for (const e of events) {
    if (e?.type !== 'assistant') continue;
    for (const b of (Array.isArray(e?.message?.content) ? e.message.content : [])) {
      if (b?.type === 'text' && typeof b.text === 'string') assistantTexts.push(b.text);
    }
  }
  const result = events.find((e) => e?.type === 'result') ?? null;
  const carrier = notices.some((n) => n.includes(MARKER)) ? 'informational'
    : userTexts.some((t) => t.includes(MARKER)) ? 'user-message'
      : assistantTexts.some((t) => t.includes(MARKER)) ? 'assistant-text'
        : 'none';
  return { status: r.status, notices, userTexts, assistantTexts, result, carrier, delivered: carrier !== 'none',
    usage: result?.usage ?? null, stderr: (r.stderr ?? '').trim() };
}

try {
  const root = build();
  const run = runSession(root);
  const nativeCostUsd = Number.isFinite(run.result?.total_cost_usd) ? run.result.total_cost_usd : null;
  const tokens = run.usage ? (run.usage.input_tokens ?? 0) + (run.usage.output_tokens ?? 0)
    + (run.usage.cache_read_input_tokens ?? 0) + (run.usage.cache_creation_input_tokens ?? 0) : null;
  console.log(`INFO model/budget: ${model} / $${maxBudgetUsd.toFixed(2)}`);
  console.log(`INFO session: exit ${run.status}; result ${run.result?.subtype ?? 'MISSING'}; tokens ${tokens ?? 'n/a'}; provider cost ${nativeCostUsd === null ? 'MISSING' : `$${nativeCostUsd.toFixed(6)}`}`);
  accountingUnavailable = nativeCostUsd === null;
  if (nativeCostUsd !== null && nativeCostUsd > maxBudgetUsd) {
    failures++;
    console.log(`FAIL provider-native cost exceeded the enforced $${maxBudgetUsd.toFixed(2)} cap`);
  }
  console.log(`INFO marker delivered via: ${run.carrier}`);
  const said = run.assistantTexts.find((t) => /CHECK FAILED|expected two/i.test(t));
  if (said) console.log(`INFO the model repeated the check result: ${said.trim().slice(0, 200)}`);

  check('A1-the-hook-ran-and-the-project-check-failed-as-designed', () => {
    const wrote = fs.existsSync(path.join(root, 'data.txt'));
    assert(wrote, 'the agent never wrote data.txt, so no PostToolUse event fired and this probe measured nothing');
    const v = fs.readFileSync(path.join(root, 'data.txt'), 'utf8').trim();
    assert(v !== 'two', `the fixture is wrong: data.txt holds "${v}", which the check accepts, so there was no failure to report`);
  });

  checkLive('A2-PostToolUse-additionalContext-REACHES-THE-MODEL-on-this-host', () => {
    assert(run.delivered,
      'the marker planted in the hook\'s additionalContext never reached the session. The documented field is '
      + 'therefore NOT usable here, and the mid-task feedback design is closed on this harness version rather '
      + `than assumed to work. channels seen: notices=${run.notices.length} user=${run.userTexts.length} assistant=${run.assistantTexts.length}`);
  });

  checkLive('A3-the-delivered-text-carried-the-CHECK-RESULT-not-just-a-marker', () => {
    const haystack = [...run.notices, ...run.userTexts, ...run.assistantTexts].join('\n');
    assert(/expected two, got one/i.test(haystack),
      'the marker arrived but the check\'s own failure text did not, so the model was told "something happened" '
      + 'rather than what failed — which is the part that saves the round trip');
  });

  // ── D: how much is there to remove on the everyday path? (answered from records, free) ──
  // The mechanism working is not the same as the mechanism mattering. Before building an everyday feedback
  // hook, the recorded everyday trials say how much self-checking there is to remove: `stream.commands.checks`
  // is the number of check commands the MODEL ran itself. If that is small, the lever's ceiling is small.
  const evidence = path.join(repoRoot, 'tooling/benchmark/results/session-evidence');
  const guarded = fs.existsSync(evidence)
    ? fs.readdirSync(evidence).filter((n) => /^v12tok-guarded-.+-guarded-\d+\.json$/.test(n))
    : [];
  const rows = [];
  for (const n of guarded) {
    try {
      const d = JSON.parse(fs.readFileSync(path.join(evidence, n), 'utf8'));
      const turns = d.stream?.turns ?? d.agentResult?.numTurns ?? null;
      const checks = d.stream?.commands?.checks ?? null;
      const amabie = d.stream?.commands?.amabie ?? null;
      if (typeof turns === 'number' && typeof checks === 'number') rows.push({ n, turns, checks, amabie });
    } catch { /* a malformed record is not this probe's question */ }
  }
  console.log(`\nINFO everyday (guarded) records with a usable command ledger: ${rows.length}`);
  for (const r of rows) console.log(`INFO   ${r.n.replace(/^v12tok-guarded-|\.json$/g, '')}: turns=${r.turns} modelRunChecks=${r.checks} amabieCommands=${r.amabie}`);

  if (rows.length === 0) {
    dataUnavailable = true;
    console.log('SKIP D1/D2: no stored everyday guarded command-ledger records; this corpus cannot establish the ceiling or Amabie command count');
  } else {
  check('D1-the-everyday-path-has-little-self-checking-left-to-remove', () => {
    assert(rows.length > 0,
      'no guarded record carried stream.commands.checks, so the ceiling of the mid-task lever cannot be '
      + 'read from the corpus — report it rather than assuming the lever is small');
    const turns = rows.reduce((a, r) => a + r.turns, 0);
    const checks = rows.reduce((a, r) => a + r.checks, 0);
    const share = 100 * checks / turns;
    console.log(`INFO   ${checks} self-run checks over ${turns} turns = ${share.toFixed(1)}% of turns (the lever's CEILING)`);
    assert(share < 15,
      `the everyday agent now runs ${share.toFixed(1)}% of its turns as self-checks. If that has grown, the `
      + 'mid-task feedback lever has become worth building after all — MEASURED UPDATE 5 closed it at ~8%, '
      + 'and that conclusion must be re-derived rather than inherited');
    console.log('INFO   consistent with MEASURED UPDATE 5: mid-task feedback cannot close the gap on this shape');
  });

  check('D2-no-recorded-everyday-run-called-a-amabie-tool', () => {
    // Second, independent confirmation of the standing-context OPEN finding: the measured everyday arms had
    // NO MCP server (`--strict-mcp-config` with no `--mcp-config`), so the tool surface's token cost is
    // UNMEASURED rather than zero.
    const withLedger = rows.filter((r) => typeof r.amabie === 'number');
    assert(withLedger.length > 0, 'no record carried an amabie command count');
    const called = withLedger.filter((r) => r.amabie > 0);
    assert(called.length === 0,
      `${called.length} everyday record(s) now call Amabie tools (${called.map((c) => c.n).join(', ')}). That `
      + 'means the measured arms DO load an MCP server, the 92.7% figure now includes the tool surface, and '
      + 'both the standing-context OPEN finding and the audit must be re-derived');
    console.log(`INFO   amabie commands = 0 across all ${withLedger.length} everyday records — the tool surface is not in that figure`);
  });
  }

  // v1.4 §11 — the two verdicts are separated so a live-model flake cannot silently gate a release
  // and a real (deterministic) failure cannot hide behind a skip.
  if (failures > 0) {
    console.log(`\nFAIL v1.3 posttool feedback — a DETERMINISTIC property does not hold on this host (${failures} failure(s))`);
    process.exit(1);
  }
  if (liveFailures > 0 || dataUnavailable || accountingUnavailable) {
    if (liveFailures > 0) console.log(`SKIP live integration: ${liveFailures} live check(s) did not observe feedback; outcome is model-dependent`);
    if (accountingUnavailable) console.log('SKIP native cost accounting was absent; the bounded live-session result is not used as a cost measurement');
    if (dataUnavailable) console.log('SKIP everyday feedback ceiling remains unmeasured without stored guarded-run ledgers');
    console.log('\nSKIP v1.3 posttool feedback — required diagnostic evidence unavailable; no product claim inferred');
    process.exit(3);
  }
  console.log('\nPASS v1.3 posttool feedback — mid-task check delivery WORKS on this host (deterministic properties AND the live delivery)');
  process.exit(0);
} catch (e) {
  console.log(`FAIL v1.3 posttool feedback — ${String(e?.message ?? e)}`);
  process.exit(1);
} finally {
  try { fs.rmSync(temp, { recursive: true, force: true }); } catch { /* best effort */ }
}
