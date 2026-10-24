---
name: playwright-evidence-qa
description: Use when diagnosing Playwright test failures using tripartite evidence triage (screenshot, DOM snapshot, console logs) to classify root causes into application defects, selector drift, or timing flakiness.
allowed-tools: [read_file, write_file, edit_file, create_file, search_code, run_tests, run_linter, run_build, execute_command]
---

# Playwright Evidence QA

Diagnose, classify, and resolve Playwright end-to-end and component test failures by systematically analyzing tripartite execution evidence (screenshots, DOM snapshots, and console/network telemetry) to distinguish application defects from selector drift and timing flakiness.

## Core Rules

- **Tripartite Evidence Invariant**: Every test failure diagnosis must evaluate all three evidence pillars before drawing conclusions or proposing code modifications:
  1. *Screenshot Artifact*: High-resolution visual capture of the viewport at the exact failure timestamp. Inspect for visual clipping, unrendered icons, modal backdrops, overlapping elements, and layout shifts.
  2. *DOM Snapshot & Accessibility Tree*: Serialized HTML state, computed styles, accessible names, and visibility states (`aria-hidden="true"`, `display: none;`, `opacity: 0`). Inspect whether the target element exists in the DOM but is obscured or positioned offscreen.
  3. *Console Telemetry & Network Trace*: Uncaught runtime exceptions, unhandled Promise rejections, console errors, failed HTTP requests (4xx/5xx status codes), CORS/CSP violations, and HAR network timings.
- **The 3-Way Root Cause Classification Taxonomy**:
  - *Application Defect*: The application broke. Characterized by uncaught runtime exceptions in console logs, 500 server responses, broken business calculations, or missing UI components despite valid selectors and complete network loading. Remediation: Fix application code; never weaken test assertions.
  - *Selector Drift*: The application functions correctly, but the test cannot locate the element. Characterized by clean console logs, visual evidence showing the target control rendered and visible, but locator timeout errors due to renamed CSS classes, restructured DOM wrappers, or changed text copy. Remediation: Modernize test selectors using Playwright accessible locators.
  - *Timing Flakiness*: The test failed due to execution race conditions. Characterized by intermittent passes/fails across runs, assertions executing before client hydration completes, animations running during click dispatch, or slow network responses. Remediation: Replace arbitrary delays with web-first assertions and locator auto-waiting.
- **Actionability Checks & Auto-Waiting**: Playwright executes 7 actionability checks prior to dispatching actions: Visible, Stable (not animating), Receives Events (not obscured by backdrop or toast), Enabled, Editable, Attached to DOM, and Within Viewport. Diagnose which actionability check failed before attempting a fix.
- **Trace Viewer Deep-Dive Protocol**:
  When inspecting `trace.zip`, analyze all four diagnostic views:
  1. *Filmstrip View*: Step through visual frames to identify the exact paint where UI drift or errors appeared.
  2. *Action Log*: Verify before/after DOM snapshots and check locator candidate match counts (flag multiple matches).
  3. *Source Tab*: Pinpoint the exact line of code triggering locator timeouts or assertion rejections.
  4. *Network Waterfall*: Filter for failed requests (`status >= 400`) and high-latency payloads (`duration > 1000ms`).
- **Hydration Race Condition Guard**: On SSR frameworks (Next.js, Astro), controls may appear visually rendered before client-side hydration attaches click event listeners. Verify whether clicks trigger events by asserting on post-click state changes rather than raw click dispatch.
- **Console Telemetry Triage**: Distinguish benign telemetry noise from fatal errors. Uncaught errors (`pageerror`), uncaught promises, and React render crashes are blocking defects; external analytics warnings must be categorized separately.
- **Visual Stability Stabilization**: Eliminate font rendering jitter and animation race conditions during visual snapshot captures by awaiting `document.fonts.ready` and disabling transitions:
  ```ts
  await page.addStyleTag({ content: '*, *::before, *::after { transition: none !important; animation: none !important; }' });
  ```
- **Deterministic Viewport Dimensions**: Visual regression and layout assertions must lock explicit viewport dimensions (e.g. `1280x720` desktop, `375x667` mobile) and `deviceScaleFactor: 1` to prevent CI rendering divergence.
- **Accessible Locator Hierarchy**:
  When repairing selector drift, always select locators in order of resilience:
  1. `page.getByRole('button', { name: 'Submit' })` (Resilient to styling and DOM changes).
  2. `page.getByLabel('Email Address')` (Resilient form field binding).
  3. `page.getByText('Welcome back', { exact: true })` (User-visible textual landmarks).
  4. `page.getByTestId('checkout-cta')` (Stable automated hook when accessibility roles are ambiguous).
  5. *Strictly Prohibited*: Brittle CSS classes (`.btn-primary-v2`, `.css-1x8g5`), absolute XPath paths (`/html/body/div[2]/button`), and test IDs reflecting styling (`data-testid="blue-btn"`).
- **Zero-Sleep Invariant**: Arbitrary time-based pauses (`page.waitForTimeout()`, `sleep()`) are strictly forbidden. All synchronizations must rely on Playwright web-first assertions (`await expect(locator).toBeVisible()`) or state hooks (`page.waitForLoadState('networkidle')`).
- **Network Determinism & HAR Sanitization**: Isolate frontend tests from third-party and backend flakiness by intercepting network traffic with MSW v2 handlers or HAR replays (`page.routeFromHAR('fixtures/api.har')`). Strip authorization headers and session cookies from recorded HAR files to prevent credential leakage.
- **Remediation Verification Gate**: Any flakiness remediation must be verified by running the affected test 10 consecutive times (`--repeat-each=10`) with zero failures before declaring resolution.

## Suggested Process

1. **Extract Tripartite Evidence**:
   - Locate test artifacts in `test-results/` (or Playwright trace viewer: `npx playwright show-trace trace.zip`).
   - Open the failure screenshot, inspect the serialized DOM snapshot at the failure frame, and review browser console outputs.
   - Inspect action timing waterfall to locate the exact failing step.
2. **Collect Console & Network Telemetry**:
   - Programmatically capture console and network failures via page listener fixtures:
     ```ts
     page.on('console', msg => { if (msg.type() === 'error') consoleErrors.push(msg.text()); });
     page.on('pageerror', err => pageErrors.push(err.message));
     page.on('response', resp => { if (resp.status() >= 400) failedReqs.push(`${resp.status()} ${resp.url()}`); });
     ```
3. **Perform Root Cause Classification**:
   - Check console logs for red exceptions (`TypeError`, `ReferenceError`, unhandled rejections). If present $\rightarrow$ Classify as **Application Defect**.
   - Check screenshot: is the expected element visible on screen with expected text? If yes and locator timed out $\rightarrow$ Classify as **Selector Drift**.
   - Check execution history: did the test pass on a retry or fail on animation/network latency? If yes $\rightarrow$ Classify as **Timing Flakiness**.
4. **Reproduce in Isolated Debug Mode**:
   - Run the failing spec in isolation with headed execution or UI mode:
     `npx playwright test tests/e2e/checkout.spec.ts --debug`
   - Step through locators to inspect actionability assertions in real-time.
5. **Implement Targeted Fix**:
   - For *Application Defect*: Create regression test case, trace root cause to application source, apply fix.
   - For *Selector Drift*: Refactor locator to accessible role or label locator.
   - For *Timing Flakiness*: Replace manual waits with web-first assertions, await animations, or stub network latency.
6. **Execute Repeatability Gate**:
   - Run the modified test across 10 iterations:
     `npx playwright test tests/e2e/checkout.spec.ts --repeat-each=10 --workers=4`
7. **Emit Structured Test Report**: Record failure category, tripartite evidence findings, and verification outcomes.

## Failure Classification Matrix

| Symptom | Tripartite Evidence Indicator | Root Cause Category | Action Required |
|---|---|---|---|
| Locator timeout; element visible in screenshot | Clean console; element present in DOM with changed class | Selector Drift | Migrate locator to `getByRole` or `getByLabel` |
| Element clipped or offscreen in screenshot | No JS errors; CSS `transform` or overflow clipping | Application Defect | Fix CSS responsive boundaries and z-index |
| `TypeError: Cannot read properties of undefined` | Console shows uncaught exception stack trace | Application Defect | Fix application logic and null checks |
| Intermittent timeout on click action | DOM shows element animating or covered by backdrop | Timing Flakiness | Await animation end or backdrop detachment |
| Assertion fails on fast CI runners, passes locally | Network trace shows late API response | Timing Flakiness | Assert on loading indicator departure or response mock |
| Form field input ignored | Console shows hydration mismatch warning | Timing Flakiness | Await client hydration before interaction dispatch |

## Anti-Patterns To Reject

- **Sleep Patching**: Adding `page.waitForTimeout(3000)` to mask race conditions instead of using web-first locators.
- **Assertion Weakening**: Deleting strict assertions or lowering expectations to turn failing tests green.
- **Brittle CSS Locators**: Writing complex nested CSS selectors (`div > ul.list > li:nth-child(3) > a`) that break on markup tweaks.
- **Single-Pillar Triage**: Diagnosing a failure solely from console text without inspecting the failure screenshot and DOM snapshot.
- **Blind Selector Updates**: Updating a selector without verifying whether the UI changed due to an intended redesign or a bug.
- **Unverified Flakiness Claims**: Labeling a test as flaky without capturing multi-run execution proof or identifying race conditions.

## Output Contracts

- Emits `contracts/schemas/test-report.json` documenting failure classifications, triage evidence hashes, root cause diagnoses, and flakiness verification metrics.

## Checklist

- [ ] Ingest all three evidence artifacts (screenshot, DOM snapshot, console/network trace) for the failure.
- [ ] Inspect console telemetry for uncaught JavaScript exceptions, 5xx responses, or CORS blocks.
- [ ] Inspect failure screenshot for visual clipping, missing elements, or overlay modals blocking pointer events.
- [ ] Inspect DOM snapshot to determine whether target element is present, detached, or obscured.
- [ ] Classify failure root cause into Application Defect, Selector Drift, or Timing Flakiness.
- [ ] Check Playwright actionability criteria (visible, stable, receives events, enabled, in viewport).
- [ ] Verify SSR hydration state before dispatching interaction assertions.
- [ ] Eliminate all arbitrary `page.waitForTimeout()` calls in favor of web-first assertions.
- [ ] Upgrade drifted locators to accessible queries (`getByRole`, `getByLabel`, `getByTestId`).
- [ ] Verify fix by running test 10 consecutive times (`--repeat-each=10`) with zero failures.
- [ ] Ensure recorded HAR files and traces do not leak sensitive auth headers or cookies.
- [ ] Emit structured QA report conforming to `contracts/schemas/test-report.json`.

## Related Skills

- **frontend-testing**: Executes automated component, accessibility, and visual regression tests.
- **write-tests**: Implements unit and integration test assertions covering discovered edge cases.
- **systematic-debugging**: Provides a 4-phase root-cause diagnosis when stress testing reveals unexpected breakage.
- **hostile-component-stress-testing**: Injects boundary stress inputs into UI components prior to E2E triage.
