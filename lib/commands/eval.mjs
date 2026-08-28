// Jobfaro — `jobfaro eval`. Evaluation is the MODEL's job (career-ops: discover → evaluate → build); the
// deterministic CLI does not score fit. Two paths:
//   • Record:   `jobfaro eval --save --url <u> --score <0.0–5.0> [--band ..] [--company ..] [--role ..] [--note ..]`
//               The model (run via your AI CLI on the rubric in modes/eval.md) calls this to persist its
//               verdict to the pipeline so it surfaces in `jobfaro tui`. Band is derived from score if omitted.
//   • Guidance: `jobfaro eval <url|->`  prints how to run the model-backed eval (no local model until Phase 8).
// Either way, the scanner never fabricates a score — only an actual evaluation writes one.

import { loadProfile, loadCv, paths } from '../config.mjs'
import { getT } from '../i18n.mjs'
import { parseFlags, resolveLang } from '../cli.mjs'
import { upsertEval, bandConflict, readPipeline, pendingQueue } from '../evaluations.mjs'
import { existsSync } from 'node:fs'
import path from 'node:path'
import { fetchJobDescription } from '../../providers/_contract.mjs'
import { extractText, isExtractable } from '../docparse.mjs'
import { selectActive, submitBatch } from '../inference.mjs'
import { evalRole, preConfirm, isBorderline, prepEval, buildVerdict, evalSystemFor } from '../eval_engine.mjs'
import { clampLogEntry, logClamp, buildBatchRequests, parseBatchResults } from '../eval_ops.mjs'
import { createRadar } from '../progress.mjs'
import { color, heading } from '../ui.mjs'

const sleep = (ms) => new Promise((r) => setTimeout(r, ms))

// Batch ceiling for `--next N`: a typo ("--next 500") must not queue an afternoon of model calls.
export const NEXT_MAX = 50

// `--next` bare keeps its guidance meaning (the AI-CLI loop in modes/eval.md depends on it);
// `--next <N>` is the human shortcut "score the next N for me". Returns null unless N is a whole
// number ≥ 1; caps at NEXT_MAX and says so via `capped`.
export function parseNextCount(v) {
  if (typeof v !== 'string' || !/^\d+$/.test(v.trim())) return null
  const asked = parseInt(v.trim(), 10)
  if (asked < 1) return null
  return { n: Math.min(asked, NEXT_MAX), asked, capped: asked > NEXT_MAX }
}

// After anything records, the user always learns where the report lives, how to view it, and —
// while roles are still pending — how to keep going (the 5 / 10 / 15 quick sizes, up to 50).
// The scope line (1.52.0) states what a score is NOT: nothing here vets the employer behind the JD.
export function reportFooterLines(t, { file, pending }) {
  const lines = ['', t('eval.report_where', { file }), color.dim('  ' + t('eval.report_view'))]
  if (pending > 0) lines.push(color.dim('  ' + t('eval.report_more', { pending })))
  lines.push(color.dim('  ' + t('eval.report_scope')))
  return lines
}

// Honest-distribution note (1.52.0): the 2026-08-19 run put 54% of scored roles in Apply with a
// 17-way tie at 4.8 — and nothing in the UX noticed. Pure so it's unit-tested; returns '' when the
// run looks healthy (small runs stay quiet — 8+ verdicts before a share is worth calling a pattern).
export function distributionWarning(t, { evaluated, applyCount }) {
  if (!evaluated || evaluated < 8) return ''
  const share = applyCount / evaluated
  if (share < 0.6) return ''
  return t('eval.dist_warn', { applyCount, evaluated, pct: Math.round(share * 100) })
}

function printReportFooter(t) {
  const file = path.join(paths.dataDir, 'pipeline.tsv')
  if (!existsSync(file)) return
  const pending = pendingQueue(readPipeline(), { includeScreened: false }).length
  for (const line of reportFooterLines(t, { file, pending })) console.log(line)
}

// 8c.3: a JD reference can be a URL (fetched via a provider) or a local file (PDF/DOCX/text, extracted
// on-device). Returns the provider Desc shape { title, description }.
async function getJd(ref) {
  if (ref && isExtractable(ref) && existsSync(ref)) {
    const d = extractText(ref)
    return { title: String(ref).split('/').pop(), description: d.error ? '' : d.text }
  }
  return fetchJobDescription(ref)
}

export async function runEval(argv = []) {
  const { flags, positionals } = parseFlags(argv)
  const lang = resolveLang(flags, loadProfile())
  const t = getT(lang)

  // --- Record path: the model persists its verdict here. ---
  if (flags.save || flags.record || flags.score != null) {
    const url = typeof flags.url === 'string' ? flags.url : positionals[0]
    const score = Number(flags.score)
    if (!url || !Number.isFinite(score)) {
      console.error(t('eval.save_usage'))
      process.exitCode = 1
      return { saved: false }
    }
    const clamped = Math.max(0, Math.min(5, score))
    // 1.52.0 honesty: the band ALWAYS derives from the score. An explicit --band that contradicts it
    // (e.g. `--score 1.0 --band apply`) used to persist as-is and render identically to an engine
    // verdict — refuse instead of recording a score/band pair that lies about itself.
    const { derived, conflict } = bandConflict(clamped, typeof flags.band === 'string' ? flags.band : '')
    if (conflict) {
      console.error(t('eval.band_mismatch', { band: flags.band, score: clamped.toFixed(1), derived }))
      process.exitCode = 1
      return { saved: false }
    }
    const verdict = {
      url,
      score: clamped,
      band: derived,
      company: typeof flags.company === 'string' ? flags.company : '',
      role: typeof flags.role === 'string' ? flags.role : '',
      location: typeof flags.location === 'string' ? flags.location : '',
      recommendation: typeof flags.note === 'string' ? flags.note : typeof flags.rec === 'string' ? flags.rec : '',
      source: 'manual', // provenance: recorded via --save, no gates/clamp ran (the engine writes 'engine')
    }
    upsertEval(verdict, new Date().toISOString().slice(0, 10))
    heading(t('eval.title'))
    console.log(`  ${color.green('✓')} ${t('eval.saved', { role: verdict.role || url, score: clamped.toFixed(1), band: t('bands.' + bnd) })}`)
    printReportFooter(t)
    return { saved: true, verdict }
  }

  // --- Auto path (8a): score roles automatically against the configured inference backend. ---
  if (flags.auto) return runAutoEval(flags, positionals, t)

  // `eval --next 5` (a number) = auto-score the next 5 — the shortcut a person types. Bare
  // `--next` (no number) stays the guidance path below, which the AI-CLI model loop depends on.
  if (parseNextCount(flags.next)) return runAutoEval(flags, positionals, t)

  // --- Guidance path: evaluation is model-backed. Fetch the role's JD (any provider) so the model can
  // score it without its own fetch tool — uniform across greenhouse / workday / icims. ---
  let url = typeof flags.url === 'string' ? flags.url : positionals[0]
  heading(t('eval.title'))

  // --next: pop the BEST pending (un-evaluated) role from the pipeline so the model loop is just
  // "eval --next → score → eval --save" with no URL copying. Order is the prescreen-ranked queue
  // (likelihood score desc, then freshness); roles prescreen gated out stay excluded unless
  // --include-screened — they're never deleted, just demoted with their reason on the row.
  if (flags.next && !url) {
    const rows = readPipeline()
    const pending = pendingQueue(rows, { includeScreened: Boolean(flags['include-screened']) })
    if (!pending.length) {
      console.log(color.dim(t('eval.next_none')))
      const hidden = pendingQueue(rows, { includeScreened: true }).length
      if (hidden > 0) console.log(color.dim(t('eval.next_screened_hint', { count: hidden })))
      return { saved: false }
    }
    const row = pending[0]
    url = row.url
    console.log(t('eval.next_for', { role: row.role, company: row.company, remaining: pending.length }))
    if (String(row.screen_reason || '').trim()) console.log(color.dim('  ' + t('eval.next_screened_note', { reason: row.screen_reason })))
    console.log(color.dim(`  ${url}\n`))
  }
  if (url) {
    try {
      const jd = await getJd(url)
      if (jd && jd.description) {
        console.log(color.bold(t('eval.jd_for', { role: jd.title || url })))
        console.log('\n' + jd.description + '\n')
      } else {
        console.log(color.dim(t('eval.jd_none', { url })))
      }
    } catch (err) {
      console.log(color.dim(t('eval.jd_error', { error: err.message })))
    }
  }
  console.log(color.dim(t('eval.today', { date: new Date().toISOString().slice(0, 10) })))
  console.log(t('eval.model_needed'))
  console.log(color.dim('  ' + t('eval.save_hint')))
  return { saved: false }
}

// `jobfaro eval --auto [<url> | --next | --all-pending]` — score roles against the inference backend and
// record each verdict via the existing --save path. One JD per request; walks the prescreen-ranked queue.
async function runAutoEval(flags, positionals, t) {
  const profile = loadProfile()
  const cv = loadCv()
  const today = new Date().toISOString().slice(0, 10)
  const transferable = flags.transferable ? true : undefined // flag forces on; else profile.transferable_skills
  heading(t('eval.title'))

  // Résumé-blind guard (1.52.0) — serve and the native app already refuse this; the CLI auto path was
  // the one entry point that would happily score with no résumé (the model fabricates one and returns a
  // confident, meaningless verdict). Refuse honestly instead.
  if (!String(cv || '').trim()) {
    console.log(color.yellow(t('eval.no_cv')))
    console.log(color.dim('  ' + t('eval.no_cv_hint')))
    process.exitCode = 1
    return { evaluated: 0 }
  }

  const active = await selectActive(profile)
  if (!active.up) {
    console.log(color.yellow(t('eval.auto_backend_down', { reason: active.reason })))
    console.log(color.dim('  ' + t('backend.install_hint')))
    console.log(color.dim('  ' + t('backend.check_hint')))
    process.exitCode = 1
    return { evaluated: 0 }
  }

  const rows = readPipeline()
  // `eval --auto <url>` parses as flags.auto='<url>' (value-less flag eats the next token), so accept
  // a string-valued --auto as the URL too — alongside --url and a bare positional.
  const url = (typeof flags.auto === 'string' && flags.auto) || (typeof flags.url === 'string' ? flags.url : positionals[0])
  let targets
  if (url) targets = [rows.find((r) => r.url === url) || { url, company: '', role: '', location: '' }]
  else {
    const q = pendingQueue(rows, { includeScreened: Boolean(flags['include-screened']) })
    const nextN = parseNextCount(flags.next)
    if (nextN && nextN.capped) console.log(color.yellow('  ' + t('eval.next_capped', { n: nextN.asked, max: NEXT_MAX })))
    targets = flags['all-pending'] ? q : q.slice(0, nextN ? nextN.n : 1) // default --next: the single best
  }
  const limit = Number(flags.limit) > 0 ? Number(flags.limit) : Infinity
  targets = targets.slice(0, limit)
  if (!targets.length) {
    console.log(color.dim(t('eval.next_none')))
    return { evaluated: 0 }
  }
  console.log(t('eval.auto_running', { count: targets.length, backend: active.runtime || active.kind }))
  // 8a.7: --batch submits one Batches-API job (api only, 50% price) instead of N live calls.
  if (flags.batch && active.kind === 'api' && targets.length > 1) return runBatchEval({ targets, active, profile, cv, today, t, transferable })
  if (flags.batch) console.log(color.dim('  ' + t('eval.batch_skipped'))) // requested but not eligible → run live

  // 8a.4a / low-end tuning: evalRole auto-selects the guaranteed-JSON path on capable local backends
  // (default-on; opt out with profile.eval_grammar:false), so no per-call responseFormat is computed here.
  // Multi-role runs get the radar sweep (TTY only — pipes keep plain per-role lines); every
  // outcome ticks it honestly, and persistent ✓/skip lines print above the live bar.
  const multi = targets.length > 1
  const radar = createRadar({
    total: targets.length,
    tallies: [
      { key: 'apply', fmt: (n) => color.green(`${n} ${t('bands.apply')}`) },
      { key: 'research', fmt: (n) => color.cyan(`${n} ${t('bands.research')}`) },
      { key: 'dont', fmt: (n) => color.dim(`${n} ${t('bands.dont')}`) },
      { key: 'failed', fmt: (n) => color.red(`✗ ${n}`) },
      { key: 'skipped', fmt: (n) => color.dim(`– ${n}`) },
    ],
  })
  const say = (line) => (multi ? radar.log(line) : console.log(line))
  if (multi) radar.start()

  let evaluated = 0
  let failed = 0
  let skipped = 0
  let applyCount = 0
  let first = true
  for (const row of targets) {
    if (!first) await sleep(800) // politeness between calls (one JD per request)
    first = false
    radar.label(`${row.company || row.url}${row.role ? ' — ' + row.role : ''}`)
    let jd = ''
    try {
      const d = await getJd(row.url)
      jd = (d && d.description) || ''
    } catch {
      jd = ''
    }
    if (!jd) {
      say('  ' + color.dim(t('eval.auto_no_jd', { role: row.role || row.url })))
      failed++
      radar.tick('failed')
      continue
    }
    // 8a pre-confirm (--confirm): a cheap AI triage that skips clearly-wrong roles before full scoring.
    if (flags.confirm) {
      try {
        const pc = await preConfirm({ active, jd, cv, profile, transferable })
        if (pc.verdict === 'skip') {
          say('  ' + color.dim(t('eval.preconfirm_skip', { role: row.role || row.url, reason: pc.reason })))
          skipped++
          radar.tick('skipped')
          continue
        }
      } catch {
        /* pre-confirm is best-effort — fall through to the full eval */
      }
    }
    try {
      const v = await evalRole({ active, jd, cv, profile, today, location: row.location, transferable })
      if (!v.ok) {
        say('  ' + color.yellow(t('eval.auto_unparsed', { role: row.role || row.url })))
        failed++
        radar.tick('failed')
        continue
      }
      let verdict = v
      // 8a.9 escalation ladder: re-score a borderline local verdict on the api backend (accuracy upgrade).
      if (flags.escalate && isBorderline(v)) {
        try {
          const esc = await selectActive({ ...profile, inference: 'api' })
          if (esc.up && esc.kind !== active.kind) {
            const v2 = await evalRole({ active: esc, jd, cv, profile, today, location: row.location, transferable })
            if (v2.ok) {
              say('  ' + color.dim(t('eval.escalated', { from: v.score.toFixed(1), to: v2.score.toFixed(1) })))
              verdict = v2
            }
          }
        } catch {
          /* escalation is best-effort — keep the primary verdict */
        }
      }
      upsertEval({ url: row.url, score: verdict.score, band: verdict.band, company: row.company, role: row.role, location: row.location, recommendation: verdict.recommendation, source: 'engine' }, today)
      if (verdict.clamped) logClamp(clampLogEntry(verdict, row), today) // 8a.5: persist the override for drift tracking
      evaluated++
      if (verdict.band === 'apply') applyCount++
      const tag = verdict.clamped ? color.yellow(' (' + t('eval.auto_clamped') + ')') : ''
      say(`  ${color.green('✓')} ${verdict.score.toFixed(1)} ${t('bands.' + verdict.band)}${tag}  ${row.company} — ${row.role}${verdict.pay ? color.dim('  ' + verdict.pay) : ''}`)
      radar.tick(verdict.band)
    } catch (e) {
      say('  ' + color.red(t('eval.auto_error', { role: row.role || row.url, error: e.message })))
      failed++
      radar.tick('failed')
    }
  }
  radar.stop()
  console.log('\n' + t('eval.auto_done', { evaluated, failed }))
  if (skipped) console.log(color.dim(t('eval.preconfirm_thinned', { skipped })))
  const warn = distributionWarning(t, { evaluated, applyCount })
  if (warn) console.log(color.yellow(warn))
  printReportFooter(t)
  return { evaluated, failed, skipped }
}

// 8a.7: batch path — fetch+prep every role, submit ONE Batches job, then record each verdict. api only.
async function runBatchEval({ targets, active, profile, cv, today, t, transferable }) {
  // Prep phase: a determinate radar over the JD fetches (the only slow local part of this path).
  const prep = createRadar({
    total: targets.length,
    tallies: [
      { key: 'ready', fmt: (n) => color.green(`✓ ${n}`) },
      { key: 'failed', fmt: (n) => color.red(`✗ ${n}`) },
    ],
  })
  const say = (line) => (targets.length > 1 ? prep.log(line) : console.log(line))
  if (targets.length > 1) prep.start()
  const prepped = []
  let noJd = 0
  for (const row of targets) {
    prep.label(`${row.company || row.url}${row.role ? ' — ' + row.role : ''}`)
    let jd = ''
    try {
      const d = await getJd(row.url)
      jd = (d && d.description) || ''
    } catch {
      jd = ''
    }
    if (!jd) {
      say('  ' + color.dim(t('eval.auto_no_jd', { role: row.role || row.url }))) // don't vanish silently
      noJd++
      prep.tick('failed')
      continue
    }
    const { gates, decision, user } = prepEval({ jd, cv, profile, today, location: row.location })
    prepped.push({ row, jd, gates, decision, custom_id: `r${prepped.length}`, user })
    prep.tick('ready')
  }
  prep.stop()
  if (!prepped.length) {
    console.log(color.dim(t('eval.next_none')))
    return { evaluated: 0 }
  }
  const xfer = transferable === undefined ? Boolean(profile.transferable_skills) : transferable
  const requests = buildBatchRequests(prepped.map((p) => ({ custom_id: p.custom_id, user: p.user })), { model: active.model, system: evalSystemFor(xfer) })
  // Waiting on the Batches API is open-ended — the honest display is the bouncing sweep + true
  // elapsed time, never a made-up percent. Non-TTY keeps the old one-dot-per-poll heartbeat.
  const wait = createRadar({ total: null })
  wait.start(t('eval.batch_waiting'))
  let results
  try {
    results = await submitBatch(active, requests, { onPoll: () => (wait.active ? undefined : process.stdout.write('.')) })
    if (!wait.active) process.stdout.write('\n')
  } catch (e) {
    console.log('\n' + color.red(t('eval.auto_error', { role: 'batch', error: e.message })))
    process.exitCode = 1
    return { evaluated: 0 }
  } finally {
    wait.stop()
  }
  const byId = parseBatchResults(results)
  let evaluated = 0
  for (const p of prepped) {
    const r = byId[p.custom_id]
    if (!r || !r.text) continue
    const v = buildVerdict({ text: r.text, jd: p.jd, gates: p.gates, decision: p.decision, profile, usage: r.usage, model: active.model, backend: 'api', transferable: xfer })
    if (!v.ok) continue
    upsertEval({ url: p.row.url, score: v.score, band: v.band, company: p.row.company, role: p.row.role, location: p.row.location, recommendation: v.recommendation, source: 'engine' }, today)
    if (v.clamped) logClamp(clampLogEntry(v, p.row), today)
    evaluated++
    const tag = v.clamped ? color.yellow(' (' + t('eval.auto_clamped') + ')') : ''
    console.log(`  ${color.green('✓')} ${v.score.toFixed(1)} ${t('bands.' + v.band)}${tag}  ${p.row.company} — ${p.row.role}`)
  }
  console.log('\n' + t('eval.auto_done', { evaluated, failed: prepped.length - evaluated + noJd }))
  printReportFooter(t)
  return { evaluated }
}
