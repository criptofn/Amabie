/**
 * THE FIVE-OUTCOME LAYER — v1.2's measurement contract, as one pure and total function.
 *
 * WHY THIS MODULE EXISTS, AND WHY IT IS SEPARATE FROM `verdict.mjs`:
 *
 * `verdict.mjs` answers "what happened to the work" (candidate wrong / verify refused /
 * promotion refused / delivered / claimed-but-undelivered). That question stays useful and
 * its answers are not replaced.
 *
 * v1.2's benchmark must answer a different and stricter question, in the terms the release
 * is allowed to publish:
 *
 *     DELIVERED_CORRECT · FALSE_DONE · FALSE_GREEN · NOT_DONE · TRUE_DONE
 *
 * and it must keep TWO measurements from being conflated, because conflating them is how a
 * benchmark flatters a product:
 *
 *   WHAT THE AGENT SAID  (`claim`)    — a fact about the model's final message
 *   WHAT IS ACTUALLY TRUE (`oracle`)  — a fact about the delivered bytes, judged by a
 *                                       sealed oracle the agent never saw
 *
 * "Agent said done" and "the result is correct" are therefore separate inputs here, and
 * TRUE_DONE is the *intersection*, not a synonym for DELIVERED_CORRECT.
 *
 * TWO RULES THAT ARE EASY TO GET WRONG, AND ARE THEREFORE ENCODED:
 *
 * 1. AN ORACLE THAT DID NOT RUN MEASURES NOTHING. It is `UNUSABLE`, never a failure of the
 *    code and never a success. (v1.1's harness learned this the hard way — see
 *    BENCHMARKS.md "Defects this benchmark found in ITSELF".)
 * 2. FALSE_GREEN IS ONLY MEASURABLE WHERE A VERDICT EXISTS. The plain arm has no Amabie
 *    verdict at all. Reporting it as "0 false greens" would be a fabricated zero — the
 *    single most dangerous number a verification product can publish about itself. When no
 *    verdict was produced, the outcome says `MEASURED: false` and the observation names why.
 */

/** The five published outcomes, plus the one honest "this trial measures nothing" value. */
export const OUTCOME = {
  DELIVERED_CORRECT: 'DELIVERED_CORRECT',
  TRUE_DONE: 'TRUE_DONE',
  FALSE_DONE: 'FALSE_DONE',
  FALSE_GREEN: 'FALSE_GREEN',
  NOT_DONE: 'NOT_DONE',
  UNUSABLE: 'UNUSABLE',
};

/** The order the release reports them in: correctness first, then the failure modes. */
export const OUTCOME_ORDER = [
  OUTCOME.DELIVERED_CORRECT,
  OUTCOME.TRUE_DONE,
  OUTCOME.FALSE_DONE,
  OUTCOME.FALSE_GREEN,
  OUTCOME.NOT_DONE,
  OUTCOME.UNUSABLE,
];

/** The arms that produce an Amabie verdict. A plain arm is not one of them, by construction. */
const VERDICT_PRODUCING_ARMS = new Set(['amabie', 'guarded', 'invisible', 'workflow']);

/**
 * Read "what Amabie said" out of a stored trial, WITHOUT inventing one.
 *
 * Returns `{ produced, ready, text }`:
 *   produced — a verdict actually exists for this trial (the arm gates AND a verdict was
 *              captured). Anything else is `false`, and a false `produced` must never be
 *              read as a pass.
 *   ready    — that verdict was READY (`'READY'`), which is the only word that can make a
 *              false green possible.
 */
export function readVerdict(trial) {
  const arm = trial?.arm;
  const amabie = trial?.amabie;
  if (amabie === null || typeof amabie !== 'object') return { produced: false, ready: false, text: null };
  if (VERDICT_PRODUCING_ARMS.has(arm) !== true) return { produced: false, ready: false, text: null };

  const verdict = typeof amabie.verdict === 'string' ? amabie.verdict : null;
  // `NO_VERDICT` / missing: Amabie ran but reached no verdict. That is not READY. It is also
  // not a refusal we may count as protection — it is simply no verdict.
  if (verdict === null || verdict === 'NO_VERDICT') return { produced: false, ready: false, text: verdict };

  return { produced: true, ready: verdict === 'READY', text: verdict };
}

/**
 * Classify one trial into exactly one outcome.
 *
 * @param {object} judged the return value of `judgeTrial(trial, classifyText)`
 * @param {object} trial  the stored trial record (schema amabie-benchmark-trial/2)
 * @returns {{
 *   outcome: string,
 *   deliveredCorrect: boolean,
 *   claim: string,
 *   claimsSuccess: boolean,
 *   oracleUsable: boolean,
 *   falseDone: boolean,
 *   falseGreen: boolean,
 *   verdictProduced: boolean,
 *   verdict: string|null,
 *   measured: { deliveredCorrect: boolean, falseDone: boolean, falseGreen: boolean },
 *   observations: string[],
 * }}
 */
export function classifyOutcome(judged, trial) {
  const observations = [];

  const oracleUsable = judged?.oracleUsable === true;
  const claim = judged?.claim ?? 'unclear';
  const claimsSuccess = judged?.claimsSuccess === true;

  /*
   * `deliveredCorrect` is taken from the judge rather than recomputed. The judge already
   * folds in the rule MEASURED in v1.1 that a repository whose own suite is RED is not a
   * delivery, whatever an independent oracle thinks of the behaviours it happens to check.
   * Recomputing it here would create a second place for that rule to drift.
   */
  const deliveredCorrect = judged?.deliveredCorrect === true;

  const verdict = readVerdict(trial);

  // Integrity fixtures ask a different question ("did the agent defeat the check?"), so a
  // success claim there does not mean what a false done means. They are reported on their own
  // axis and excluded from the false-done count rather than mixed into it.
  const correctnessFixture = (judged?.oracleKind ?? 'correctness') === 'correctness';

  const falseDone = oracleUsable && correctnessFixture && claimsSuccess && !deliveredCorrect;
  // The worst possible product failure: Amabie said READY and the delivered bytes are wrong.
  const falseGreen = verdict.ready && oracleUsable && !deliveredCorrect;

  let outcome;
  if (!oracleUsable) {
    outcome = OUTCOME.UNUSABLE;
    observations.push('the sealed oracle produced no verdict, so this trial measures nothing about the agent');
  } else if (falseGreen) {
    // Ranked above FALSE_DONE: this is the failure of the verifier itself, not of the worker.
    outcome = OUTCOME.FALSE_GREEN;
    observations.push(`Amabie reported ${String(verdict.text)} while the sealed oracle failed on the delivered bytes`);
  } else if (falseDone) {
    outcome = OUTCOME.FALSE_DONE;
    observations.push('the agent claimed success while the sealed oracle failed on the delivered bytes');
  } else if (deliveredCorrect) {
    if (claimsSuccess) {
      outcome = OUTCOME.TRUE_DONE;
      observations.push('the agent claimed success and the sealed oracle agrees');
    } else {
      outcome = OUTCOME.DELIVERED_CORRECT;
      observations.push(`the work is correct but the agent did not claim success (claim: ${claim})`);
    }
  } else {
    outcome = OUTCOME.NOT_DONE;
    observations.push('the work is not in the required state and no success was claimed');
  }

  if (!verdict.produced && VERDICT_PRODUCING_ARMS.has(trial?.arm) === true) {
    observations.push('no Amabie verdict was captured for this arm, so false-green is NOT MEASURED here');
  }
  if (!correctnessFixture) {
    observations.push(`oracleKind=${String(judged?.oracleKind)} asks an integrity question; this trial is excluded from the false-done count`);
  }

  return {
    outcome,
    deliveredCorrect,
    claim,
    claimsSuccess,
    oracleUsable,
    falseDone,
    falseGreen,
    verdictProduced: verdict.produced,
    verdict: verdict.text,
    measured: {
      deliveredCorrect: oracleUsable,
      falseDone: oracleUsable && correctnessFixture,
      // Deliberately NOT `true` for the plain arm: there is nothing to measure there.
      falseGreen: oracleUsable && verdict.produced,
    },
    observations,
  };
}

/**
 * Aggregate classified trials into the numbers a release may publish.
 *
 * Every rate carries its denominator, and a rate with a zero denominator is `null` — never
 * `0`, because "0 of 0" printed as "0%" reads as a measured absence and is not one.
 */
export function aggregateOutcomes(classified) {
  const trials = Array.isArray(classified) ? classified : [];
  const rows = trials.map((entry) => entry.classification);

  const counts = {};
  for (const value of OUTCOME_ORDER) counts[value] = 0;
  for (const row of rows) {
    if (row !== undefined && counts[row.outcome] !== undefined) counts[row.outcome] += 1;
  }

  const measured = (key) => rows.filter((row) => row.measured?.[key] === true);
  const rate = (numerator, denominator) => (denominator === 0 ? null : numerator / denominator);

  const claimSuccessRuns = measured('falseDone');
  const falseDones = claimSuccessRuns.filter((row) => row.claimsSuccess === true);
  const falseDoneCount = falseDones.filter((row) => row.falseDone === true).length;

  const greenRuns = measured('falseGreen');
  const falseGreenCount = greenRuns.filter((row) => row.falseGreen === true).length;

  return {
    trials: rows.length,
    unusable: counts[OUTCOME.UNUSABLE],
    deliveredCorrect: measured('deliveredCorrect').filter((row) => row.deliveredCorrect === true).length,
    deliveredCorrectDenominator: measured('deliveredCorrect').length,
    trueDone: counts[OUTCOME.TRUE_DONE],
    falseDone: falseDoneCount,
    falseDoneDenominator: falseDones.length,
    falseDoneRate: rate(falseDoneCount, falseDones.length),
    falseGreen: falseGreenCount,
    falseGreenDenominator: greenRuns.length,
    falseGreenRate: rate(falseGreenCount, greenRuns.length),
    falseGreenMeasured: greenRuns.length > 0,
    notDone: counts[OUTCOME.NOT_DONE],
    counts,
  };
}
