// Tests for the evidence checker. Most drive its seam, `run({ body, outputs }, { client })`, with a
// fake client returning canned Jev answers; the CLI tests run it as a subprocess, as an agent would,
// against a fake Jev server on localhost and with a `gh` stub first on PATH. Nothing reaches Jev or
// needs a key.

import { spawn } from 'node:child_process';
import { test } from 'node:test';
import assert from 'node:assert/strict';
import { chmod, mkdtemp, readFile, rm, writeFile } from 'node:fs/promises';
import { existsSync } from 'node:fs';
import { tmpdir } from 'node:os';
import path from 'node:path';
import { fileURLToPath } from 'node:url';
import { createClient } from './client.mjs';
import { fakeJev } from './fake-jev.mjs';
import { parseEvidence, run } from './evidence.mjs';

const HERE = path.dirname(fileURLToPath(import.meta.url));

// A PR body in the format docs/agents/issue-tracker.md § Evidence defines.
const BODY = `## Summary

Adds a thing.

## Evidence

- **The tests pass**
  \`scripts/verify.sh\` → \`ℹ fail 0\`
- **The vendored \`pr\` skill is unchanged**
  \`git diff --stat origin/main -- .agents/skills/pr/\` → prints nothing
- **The page renders**
  \`node render.mjs\` → it looks right
  **Before** old. **After** new.

## Notes

- **Not evidence** \`x\` → \`y\`

Closes #12
`;

const OUTPUTS = {
  'scripts/verify.sh': '✔ a test\nℹ pass 3\nℹ fail 0\n',
  'git diff --stat origin/main -- .agents/skills/pr/': '',
  'node render.mjs': 'rendered\n',
};

// A client that answers each question with `answer(id, question)`, and records every request.
function fakeClient(answer) {
  const calls = [];
  return {
    calls,
    async available() {
      return { status: 'ok' };
    },
    async ask(request) {
      calls.push(request);
      const answers = {};
      for (const [id, question] of Object.entries(request.questions)) answers[id] = answer(id, question);
      return { status: 'ok', answers };
    },
  };
}

const choice = (pick, confidence) => () => ({ type: 'choice', choice: pick, probabilities: {}, confidence });

test('parses each claim of the ## Evidence section: criterion, command and the quoted result', () => {
  assert.deepEqual(parseEvidence(BODY), [
    { id: 'E1', criterion: 'The tests pass', command: 'scripts/verify.sh', expect: { quote: 'ℹ fail 0' } },
    {
      id: 'E2',
      criterion: 'The vendored `pr` skill is unchanged',
      command: 'git diff --stat origin/main -- .agents/skills/pr/',
      expect: { nothing: true },
    },
    { id: 'E3', criterion: 'The page renders', command: 'node render.mjs', expect: null },
  ]);
});

test('a quote with backticks in it, in a double-backtick span, and a second claim in one entry', () => {
  const body = '## Evidence\n\n- **Both**\n  `a` → `` say `hi` ``\n  `b` -> "done"\n- **No claim at all**\n';
  assert.deepEqual(parseEvidence(body), [
    { id: 'E1', criterion: 'Both', command: 'a', expect: { quote: 'say `hi`' } },
    { id: 'E2', criterion: 'Both', command: 'b', expect: { quote: 'done' } },
    { id: 'E3', criterion: 'No claim at all', command: null, expect: null },
  ]);
});

test('a missing quote is flagged without a call, and so is a missing command', async () => {
  const client = fakeClient(choice('supports', 0.99));
  const body = '## Evidence\n\n- **Unquoted**\n  `node render.mjs` → it looks right\n- **No claim at all**\n';
  const result = await run({ body, outputs: OUTPUTS }, { client });
  assert.equal(result.status, 'ok');
  assert.deepEqual(
    result.claims.map((c) => [c.id, c.decision, c.reason]),
    [
      ['E1', 'flag', 'no-quote'],
      ['E2', 'flag', 'no-quote'],
    ],
  );
  assert.equal(client.calls.length, 0);
});

test('a quote that is not in the output, or a command with no output given, is flagged without a call', async () => {
  const client = fakeClient(choice('supports', 0.99));
  const body = '## Evidence\n\n- **Wrong**\n  `scripts/verify.sh` → `ℹ fail 1`\n- **Not run**\n  `make check` → `ok`\n';
  const result = await run({ body, outputs: OUTPUTS }, { client });
  assert.deepEqual(
    result.claims.map((c) => [c.decision, c.reason]),
    [
      ['flag', 'not-in-output'],
      ['flag', 'no-output'],
    ],
  );
  assert.equal(client.calls.length, 0);
});

test('a matched quote is asked as one Choice per claim, contradicts first, with the output in it', async () => {
  const client = fakeClient(choice('supports', 0.95));
  const result = await run({ body: BODY, outputs: OUTPUTS }, { client });
  assert.equal(client.calls.length, 1);
  const { questions } = client.calls[0];
  assert.deepEqual(Object.keys(questions), ['E1', 'E2']);
  assert.equal(questions.E1.type, 'choice');
  assert.deepEqual(Object.keys(questions.E1.criteria), ['contradicts', 'silent', 'supports']);
  assert.match(questions.E1.instructions, /ℹ pass 3/);
  assert.match(questions.E1.instructions, /The tests pass/);
  assert.deepEqual(
    result.claims.map((c) => [c.id, c.decision, c.reason]),
    [
      ['E1', 'note', 'supports'],
      ['E2', 'note', 'supports'],
      ['E3', 'flag', 'no-quote'],
    ],
  );
});

test('colour codes and CRLF line ends in the output do not defeat the exact match', async () => {
  const client = fakeClient(choice('supports', 0.9));
  const body = '## Evidence\n\n- **Clean**\n  `scan` → `no leaks found`\n';
  const outputs = { scan: '\u001b[32mINF\u001b[0m \u001b[1mno leaks found\u001b[0m\r\n' };
  const result = await run({ body, outputs }, { client });
  assert.equal(result.claims[0].decision, 'note');
});

test('"prints nothing" matches only an empty output', async () => {
  const client = fakeClient(choice('supports', 0.9));
  const outputs = { ...OUTPUTS, 'git diff --stat origin/main -- .agents/skills/pr/': ' x | 2 +-\n' };
  const result = await run({ body: BODY, outputs }, { client });
  assert.deepEqual([result.claims[1].decision, result.claims[1].reason], ['flag', 'not-in-output']);
});

// The band edge sits at 0.8 (EVIDENCE_SUPPORTS_CONFIDENT): a retune that moves it fails these on
// purpose.
test('supports just below the threshold is flagged; at it and just above, noted', async () => {
  for (const [confidence, decision] of [
    [0.79, 'flag'],
    [0.8, 'note'],
    [0.81, 'note'],
  ]) {
    const result = await run({ body: BODY, outputs: OUTPUTS }, { client: fakeClient(choice('supports', confidence)) });
    assert.deepEqual([result.claims[0].decision, result.claims[0].confidence], [decision, confidence], `at ${confidence}`);
  }
});

test('contradicts and silent are flagged however confident', async () => {
  for (const pick of ['contradicts', 'silent']) {
    const result = await run({ body: BODY, outputs: OUTPUTS }, { client: fakeClient(choice(pick, 0.99)) });
    assert.deepEqual([result.claims[0].decision, result.claims[0].reason], ['flag', pick]);
  }
});

test('an output too large to ask about is flagged unasked, and the rest are still asked', async () => {
  const client = fakeClient(choice('supports', 0.9));
  const outputs = { ...OUTPUTS, 'scripts/verify.sh': `ℹ fail 0\n${'x'.repeat(120_000)}` };
  const result = await run({ body: BODY, outputs }, { client });
  assert.deepEqual([result.claims[0].decision, result.claims[0].reason], ['flag', 'too-large']);
  assert.deepEqual(Object.keys(client.calls[0].questions), ['E2']);
});

test('a choice that is not one of the options is an error', async () => {
  const result = await run({ body: BODY, outputs: OUTPUTS }, { client: fakeClient(choice('maybe', 0.9)) });
  assert.equal(result.status, 'error');
  assert.match(result.reason, /maybe/);
});

test('a body with no ## Evidence entries is an error and never reaches Jev', async () => {
  const client = fakeClient(choice('supports', 0.9));
  const result = await run({ body: '## Summary\n\nNo evidence here.\n', outputs: {} }, { client });
  assert.equal(result.status, 'error');
  assert.match(result.reason, /Evidence/);
  assert.equal(client.calls.length, 0);
});

test('outputs that are not an object of strings are an error and never reach Jev', async () => {
  const client = fakeClient(choice('supports', 0.9));
  const result = await run({ body: BODY, outputs: { 'scripts/verify.sh': 3 } }, { client });
  assert.equal(result.status, 'error');
  assert.equal(client.calls.length, 0);
});

test('with no key it skips before any other work, even on input it cannot read', async () => {
  const result = await run(null, { client: createClient({ env: {} }) });
  assert.deepEqual(result, { status: 'skipped', reason: 'TYPESAFE_API_KEY is not set' });
});

test('a failed request is an error, handled like a skip', async () => {
  const jev = await fakeJev(() => ({ status: 401, body: 'invalid key' }));
  try {
    const client = createClient({ env: { TYPESAFE_API_KEY: 'fake-key', TYPESAFE_BASE_URL: jev.url } });
    const result = await run({ body: BODY, outputs: OUTPUTS }, { client });
    assert.equal(result.status, 'error');
    assert.match(result.reason, /401/);
    assert.equal(jev.requests.length, 1);
  } finally {
    await jev.close();
  }
});

// The CLI, run as an agent runs it: a subprocess with a `gh` stub first on PATH that logs every call
// and answers `gh pr view` with $GH_PR. Async, so the fake server in this process can answer.
const CLI = path.join(HERE, 'evidence-cli.mjs');

async function runCli(args, { env = {}, stdin = '' } = {}) {
  const dir = await mkdtemp(path.join(tmpdir(), 'jev-evidence-'));
  const log = path.join(dir, 'gh.log');
  const outputs = path.join(dir, 'outputs.json');
  await writeFile(outputs, JSON.stringify(OUTPUTS));
  await writeFile(
    path.join(dir, 'gh'),
    `#!/bin/sh\necho "$@" >> "${log}"\nif [ "$1 $2" = "pr view" ] && [ -n "$GH_PR" ]; then echo "$GH_PR"; exit 0; fi\nexit 1\n`,
  );
  await chmod(path.join(dir, 'gh'), 0o755);
  try {
    const argv = args.map((a) => (a === 'OUTPUTS' ? outputs : a));
    const child = spawn(process.execPath, [CLI, ...argv], { env: { PATH: dir, ...env } });
    let stdout = '';
    child.stdout.on('data', (chunk) => (stdout += chunk));
    child.stdin.end(stdin);
    const status = await new Promise((resolve) => child.on('close', resolve));
    const ghCalls = existsSync(log) ? (await readFile(log, 'utf8')).trim().split('\n') : [];
    return { status, stdout, ghCalls };
  } finally {
    await rm(dir, { recursive: true, force: true });
  }
}

const ANSWERS = {
  E1: { type: 'choice', choice: 'supports', probabilities: {}, confidence: 0.93 },
  E2: { type: 'choice', choice: 'silent', probabilities: {}, confidence: 0.7 },
};

test('the CLI with no key prints one skip line, exits 0 and never calls gh', async () => {
  const { status, stdout, ghCalls } = await runCli(['7', 'OUTPUTS']);
  assert.equal(status, 0);
  assert.equal(stdout, 'jev evidence: skipped, TYPESAFE_API_KEY is not set; check every entry yourself\n');
  assert.deepEqual(ghCalls, []);
});

test('the CLI on a failed request prints one error line and exits 0', async () => {
  const jev = await fakeJev(() => ({ status: 422, body: 'state too long' }));
  try {
    const env = { TYPESAFE_API_KEY: 'fake-key', TYPESAFE_BASE_URL: jev.url, GH_PR: JSON.stringify({ body: BODY }) };
    const { status, stdout } = await runCli(['7', 'OUTPUTS'], { env });
    assert.equal(status, 0);
    assert.match(stdout, /^jev evidence: error, [^\n]*422[^\n]*; check every entry yourself\n$/);
  } finally {
    await jev.close();
  }
});

test('the CLI prints flags first, one line per claim, reads the PR with gh and never edits it', async () => {
  const jev = await fakeJev(() => ({ status: 200, body: { answers: ANSWERS } }));
  try {
    const env = { TYPESAFE_API_KEY: 'fake-key', TYPESAFE_BASE_URL: jev.url, GH_PR: JSON.stringify({ body: BODY }) };
    const { status, stdout, ghCalls } = await runCli(['7', 'OUTPUTS'], { env });
    assert.equal(status, 0);
    assert.equal(
      stdout,
      'E2: flag (silent, confidence 0.70) - The vendored `pr` skill is unchanged; check it first\n' +
        'E3: flag (no quoted result) - The page renders; check it first\n' +
        'E1: note (supports, confidence 0.93) - The tests pass\n',
    );
    assert.deepEqual(ghCalls, ['pr view 7 --json body']);
  } finally {
    await jev.close();
  }
});

test('the CLI prints JSON with --json, reading the PR body from stdin', async () => {
  const jev = await fakeJev(() => ({ status: 200, body: { answers: ANSWERS } }));
  try {
    const env = { TYPESAFE_API_KEY: 'fake-key', TYPESAFE_BASE_URL: jev.url };
    const { status, stdout, ghCalls } = await runCli(['OUTPUTS', '--json'], { env, stdin: BODY });
    assert.equal(status, 0);
    const result = JSON.parse(stdout);
    assert.equal(result.status, 'ok');
    assert.deepEqual(
      result.claims.map((c) => [c.id, c.decision, c.reason]),
      [
        ['E1', 'note', 'supports'],
        ['E2', 'flag', 'silent'],
        ['E3', 'flag', 'no-quote'],
      ],
    );
    assert.deepEqual(ghCalls, []);
  } finally {
    await jev.close();
  }
});
