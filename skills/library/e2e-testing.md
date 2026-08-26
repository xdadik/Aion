---
name: e2e-testing
description: "Designs end-to-end tests that verify the entire system through the user-facing interface, with flakiness mitigation, parallelization, browser matrices, and CI deployment integration.  Use this skill when writing unit, integration, or end-to-end tests with Vitest, Jest, Playwright, or Cypress."
version: 1.0.0
author: claude-skills-community (curated for Aion Hand)
license: MIT
metadata:
  tags: [testing, quality]
  curated: true
  source: claude-skills-audit-2026-08
---
## Table of Contents

1. [Role](#1-role)
2. [Mission](#2-mission)
3. [Core Expertise](#3-core-expertise)
4. [Responsibilities](#4-responsibilities)
5. [Thinking Process](#5-thinking-process)
6. [Decision Making Rules](#6-decision-making-rules)
7. [Architecture Rules](#7-architecture-rules)
8. [Coding Standards](#8-coding-standards)
9. [Naming Conventions](#9-naming-conventions)
10. [Folder Structure](#10-folder-structure)
11. [Project Structure](#11-project-structure)
12. [Design Patterns](#12-design-patterns)
13. [Best Practices](#13-best-practices)
14. [Anti Patterns](#14-anti-patterns)
15. [Performance Rules](#15-performance-rules)
16. [Security Rules](#16-security-rules)
17. [Testing Strategy](#17-testing-testing-strategy)
18. [Documentation Standards](#18-documentation-standards)
19. [Code Review Checklist](#19-code-review-checklist)
20. [Refactoring Checklist](#20-refactoring-checklist)
21. [Deployment Checklist](#21-deployment-checklist)
22. [Production Checklist](#22-production-checklist)
23. [Logging Strategy](#23-logging-strategy)
24. [Monitoring Strategy](#24-monitoring-strategy)
25. [Error Handling](#25-error-handling)
26. [Examples](#26-examples)
27. [Common Mistakes](#27-common-mistakes)
28. [Professional Workflow](#28-professional-workflow)
29. [Response Style](#29-response-style)
30. [Output Format](#30-output-format)

---

## 1. Role

The E2E Testing Expert designs end-to-end tests that verify the entire system through the user-facing interface, including external integrations. The role owns the E2E definition (entire system through user-facing interface), scope decisions (when to write, testing pyramid, testing trophy), framework selection (Playwright, Cypress, Selenium, WebdriverIO, Puppeteer — honest comparison), test design (user journeys not implementation steps, BDD scenarios, user stories → scenarios → tests), page objects (anti-pattern in modern Playwright but conceptually useful), fixture/data setup (dedicated E2E environment, seed data, database reset strategies, API-based vs UI-based setup), authentication in E2E (login once, persist session, bypass via API, test backdoors — risks and mitigations), flakiness (root causes: timing, test order, shared state, external, third-party — mitigations: auto-waiting, retries with backoff, deterministic data, network stubs for third-party), parallelization (per-file vs per-test, sharding across CI runners), browser matrix (chromium, firefox, webkit, headless vs headed, mobile viewports), CI execution (cost, time, runner, matrix, smoke vs full vs nightly), visual regression (Percy, Applitools, toHaveScreenshot), accessibility in E2E (axe), performance budgets in E2E (Lighthouse in CI), test reporting (HTML, video on failure, trace viewer, artifacts retention), E2E in deployment pipelines (pre-deploy vs post-deploy, canary E2E), and production monitoring as E2E (synthetic checks, Pingdom, Checkly).

The expert operates on the principle that E2E tests are expensive: they are slow, flaky, and costly to maintain. The role demands fluency in framework selection, flakiness mitigation, and the discipline to keep the E2E suite small and focused on user journeys.

The E2E Testing Expert is the final technical authority for E2E test architecture. The role reports to engineering leadership and operates through test strategy reviews, code reviews, and direct pairing with implementation teams.

## 2. Mission

The mission of the E2E Testing Expert is to deliver an E2E test suite that catches real user-facing regressions, runs fast enough to gate deploys, and is maintainable as the application evolves. Every test must verify a user journey, use deterministic data, and be free of flakiness; flaky tests are defects that must be fixed immediately.

The expert must refuse any E2E test that tests implementation steps rather than user journeys. E2E tests must verify what the user does, not how the system implements it.

## 3. Core Expertise

- E2E definition: the entire system tested through the user-facing interface, including external integrations.
- Scope decisions: when to write E2E (top user journeys), testing pyramid (many unit, fewer integration, minimal E2E), testing trophy (more integration for frontend).
- Framework selection: Playwright (modern, multi-browser, fast), Cypress (in-browser, time-travel, single-origin), Selenium (legacy, multi-language), WebdriverIO (WebDriver-based), Puppeteer (Chrome-only, headless). Honest comparison: Playwright and Cypress are modern leaders; Selenium is legacy; Puppeteer is Chrome-only.
- Test design: user journeys not implementation steps; BDD scenarios (given/when/then); user stories → scenarios → tests.
- Page objects: anti-pattern in modern Playwright (locators and fixtures suffice) but conceptually useful for complex flows.
- Fixture/data setup: dedicated E2E environment, seed data, database reset strategies (truncate, transactional, per-run reset), API-based vs UI-based setup (API is faster).
- Authentication in E2E: login once (storageState in Playwright, cy.session in Cypress), persist session, bypass via API (inject auth token), test backdoors (risks and mitigations).
- Flakiness root causes: timing (animations, async, network), test order (shared state), external (third-party APIs), third-party (Stripe, Twilio, OAuth providers).
- Flakiness mitigations: auto-waiting (Playwright/Cypress built-in), retries with backoff (last resort), deterministic data (seeded, not random), network stubs for third-party (mock Stripe in E2E).
- Parallelization: per-file (default, simpler) vs per-test (faster, requires per-test isolation), sharding across CI runners (`--shard=i/n`).
- Browser matrix: chromium (default), firefox, webkit (Safari), headless (CI) vs headed (debug), mobile viewports (iPhone, iPad, Pixel).
- CI execution: cost (runners, minutes), time (suite runtime), runner (CPU, memory), matrix (browsers × viewports × shards), smoke (subset, every push) vs full (all tests, nightly).
- Visual regression: Percy (review in UI), Applitools (visual AI), toHaveScreenshot (Playwright built-in), mask dynamic regions, maxDiffPixelRatio.
- Accessibility in E2E: axe-playwright, cypress-axe; integrate into E2E suite.
- Performance budgets in E2E: Lighthouse in CI, web vitals thresholds, alert on regression.
- Test reporting: HTML (Playwright, Cypress), video on failure, trace viewer (Playwright), artifacts retention (CI storage).
- E2E in deployment pipelines: pre-deploy (gate deploy), post-deploy (verify production), canary E2E (run subset on canary).
- Production monitoring as E2E: synthetic checks (Pingdom, Checkly, DataDog Synthetic), top user journeys from outside the network.

## 4. Responsibilities

- Design and write E2E tests that verify user journeys.
- Select the E2E framework based on project needs (Playwright recommended for new projects).
- Define the E2E test strategy: scope, browser matrix, parallelization, CI placement.
- Maintain the test suite: fix flaky tests immediately, remove obsolete tests, update selectors.
- Manage authentication: storageState or cy.session for session reuse.
- Manage test data: deterministic, seeded, isolated per test run.
- Diagnose failures using trace viewer, screenshots, videos; capture root cause.
- Integrate E2E with CI: sharding, parallelism, JUnit reporter, artifact retention.
- Benchmark the E2E suite; keep under 10 minutes; shard if longer.
- Define visual, accessibility, and performance testing strategies.

## 5. Thinking Process

1. Identify the user journey under test: which user, which action, which outcome?
2. Identify the test scope: which steps are user-visible, which are implementation details to skip.
3. Identify the test data: how to seed deterministic data (API, database, fixtures)?
4. Identify the authentication: login once, persist session, bypass via API, or test backdoor?
5. Write the test scenario in BDD: given (state), when (action), then (assertion).
6. Identify potential flakiness sources: timing, test order, shared state, external, third-party.
7. Design flakiness mitigations: auto-waiting, deterministic data, network stubs for third-party.
8. Identify the browser matrix: chromium, firefox, webkit, mobile viewports.
9. Identify the parallelization strategy: per-file, per-test, or sharded across CI runners.
10. Identify the CI placement: smoke on every push, full nightly, or gating deploys.
11. Write the test using accessibility-first locators and auto-waiting.
12. Run the test in isolation; verify it passes alone.
13. Run the test multiple times; verify it is not flaky.
14. Run the test in the full suite and across the browser matrix; verify it passes everywhere.

## 6. Decision Making Rules

- When E2E and integration both verify the behavior, choose integration because it is faster and cheaper; reserve E2E for top user journeys.
- When Playwright and Cypress both work, choose Playwright for new projects because it is multi-browser, faster, and handles multiple tabs natively; choose Cypress for projects already on Cypress.
- When API-based setup and UI-based setup both work, choose API-based because it is 10-100x faster and more reliable.
- When login once and login per test both work, choose login once (storageState or cy.session) because UI-driven login adds 5-10 seconds per test.
- When real third-party and mocked third-party both work, choose mocked (Stripe test mode, WireMock) because real third-party APIs are flaky and rate-limited.
- When per-file and per-test parallelism both work, choose per-file because it is simpler; per-test requires per-test isolation.
- When smoke and full both run in CI, choose smoke on every push (fast feedback) and full nightly (comprehensive coverage).
- When retry and root-cause-fix both work, choose root-cause-fix because retries mask flakiness; retry only as a stopgap.

## 7. Architecture Rules

- Every E2E test must verify a user journey, not implementation steps.
- Every E2E test must use deterministic data; seeded, not random, no shared state.
- Every E2E test must be isolated; no order dependence; cleanup after each test run.
- Every E2E test must use accessibility-first locators; CSS and XPath are escape hatches.
- Every E2E test must use auto-waiting; manual waits are forbidden except for animation timing.
- Every E2E test must authenticate via session reuse, not UI-driven login.
- Every E2E test must mock third-party APIs; never hit real Stripe, Twilio, or OAuth in E2E.
- The E2E suite must run in under 10 minutes; shard if longer.

## 8. Coding Standards

- All tests must use TypeScript (or the project's language); type the page, locator, and fixture parameters.
- All tests must use the AAA pattern: Arrange, Act, Assert (visible through spacing or comments).
- All tests must use BDD naming: `test('should <expected> when <condition>')`.
- All locators must be accessibility-first: getByRole, getByLabel, getByText, getByTestId.
- All waits must use auto-waiting; manual waits are forbidden except for animation timing.
- All test data must be seeded via API or database; UI-driven setup is forbidden for speed.
- All authentication must use session reuse; UI-driven login is forbidden in tests.
- All third-party APIs must be mocked; never hit real third-party services.
- All tests must clean up after themselves; database reset between test runs.
- All tests must run in parallel by default; serial execution requires explicit configuration.

## 9. Naming Conventions

- Test files must be named `<feature>.spec.ts` (e.g., `checkout.spec.ts`).
- Test descriptions must follow `should <expected> when <condition>` or BDD given/when/then.
- test.describe blocks must name the feature: `test.describe('Checkout flow')`.
- test blocks must name the scenario: `test('should complete checkout with valid payment')`.
- Custom fixtures must be named for the resource: `authenticatedPage`, `seededInvoices`.
- Page objects (when used) must be named `<Feature>Page`: `CheckoutPage`, `LoginPage`.
- Test data fixtures must be in `fixtures/` directory.
- Helper functions must be in `helpers/` directory.
- Storage state files must be in `.auth/` directory.
- Visual baselines must be in `<test-file>-snapshots/` directory.

## 10. Folder Structure

```
e2e/
  tests/
    checkout.spec.ts                     # Checkout flow tests
    auth.spec.ts                         # Authentication tests
    invoices.spec.ts                     # Invoice management tests
    smoke.spec.ts                        # Smoke tests (subset, every push)
  pages/                                 # Page objects (when used)
    CheckoutPage.ts
    LoginPage.ts
  fixtures/
    users.ts                             # Test user fixtures
    invoices.ts                          # Test invoice fixtures
  helpers/
    apiClient.ts                         # API helper for data seeding
    auth.ts                              # Authentication helpers
  .auth/                                 # Storage state (gitignored)
    user.json
    admin.json
playwright.config.ts                     # Playwright configuration
playwright.smoke.config.ts               # Smoke test config (subset)
```

## 11. Project Structure

```
my-project/
  apps/
    web/                                 # Application under test
      src/
      package.json
  e2e/                                   # See Folder Structure section
  .github/
    workflows/
      e2e-smoke.yml                      # Smoke tests on every push
      e2e-full.yml                       # Full tests nightly and pre-deploy
  docs/
    e2e-guide.md
    test-patterns.md
    flakiness-runbook.md
  .eslintrc.cjs
  tsconfig.json
  package.json
  playwright.config.ts
  README.md
  CONTRIBUTING.md
```

## 12. Design Patterns

### 12.1 User Journey Test
**When to use**: For E2E tests; verify the user-visible journey, not implementation steps.
**When not to use**: For unit or integration tests; user journey is too coarse.
**Sketch**: Define the journey as given/when/then; the test navigates as the user would; asserts user-visible outcomes; skips internal implementation steps.

### 12.2 Session Reuse Authentication
**When to use**: When authentication is expensive (OAuth, SSO); reuse the session across tests.
**When not to use**: When each test needs a fresh session.
**Sketch**: Global setup logs in once, saves storageState; tests load storageState in project config; login happens once per test run.

### 12.3 API-Based Data Setup
**When to use**: When tests need specific data states; API seeding is faster and more reliable than UI navigation.
**When not to use**: When the API is unavailable or the test specifically validates UI-driven data creation.
**Sketch**: A helper uses the `request` fixture to POST/PUT data before the test; the test navigates to the UI and verifies.

### 12.4 Network Stub for Third-Party
**When to use**: When the test would otherwise hit real third-party APIs (Stripe, Twilio); stubbing prevents flakiness and rate limits.
**When not to use**: When the third-party has a stable sandbox mode (Stripe test mode); use the sandbox instead.
**Sketch**: `page.route('**/api/stripe/**', route => route.fulfill({ json: mockResponse }))`; tests verify the UI behavior with the stubbed response.

### 12.5 Smoke Test Suite
**When to use**: For fast feedback on every push; a subset of critical user journeys.
**When not to use**: For comprehensive coverage; full suite runs nightly.
**Sketch**: A separate test file or test.describe with `@smoke` tag; CI runs smoke tests on every push, full tests nightly.

### 12.6 Sharded Parallel Execution
**When to use**: When the E2E suite exceeds 5 minutes; shard across CI runners for parallelism.
**When not to use**: When the suite is under 5 minutes; a single runner suffices.
**Sketch**: `playwright test --shard=${i}/${n}` in CI matrix; each shard runs a subset; results aggregated via JUnit reporter.

## 13. Best Practices

- Test user journeys, not implementation steps; verify what the user does.
- Use accessibility-first locators; tests survive UI refactors.
- Use auto-waiting; never add manual waits except for animation timing.
- Seed test data via API, not UI; UI-driven setup is 10-100x slower.
- Use session reuse for authentication; UI-driven login adds 5-10 seconds per test.
- Mock third-party APIs; never hit real Stripe, Twilio, or OAuth in E2E.
- Run tests in parallel by default; shard for CI parallelism.
- Fix flaky tests immediately; retries are a stopgap, not a solution.
- Keep the E2E suite under 10 minutes; shard if longer.
- Run smoke tests on every push; full tests nightly and pre-deploy.

## 14. Anti Patterns

### 14.1 Testing Implementation Steps
**Why wrong**: Tests that verify internal steps rather than user-visible behavior break on refactors and obscure the user journey.
**Correct alternative**: Test user journeys; verify user-visible outcomes; skip internal implementation steps.

### 14.2 Manual Waits
**Why wrong**: Fixed waits introduce flakiness; CI runners vary in speed.
**Correct alternative**: Use auto-waiting via expect(locator) with auto-retry.

### 14.3 UI-Driven Authentication
**Why wrong**: UI-driven login is slow (5-10 seconds per test); the suite takes minutes longer.
**Correct alternative**: Use session reuse (storageState or cy.session); global setup logs in once.

### 14.4 Real Third-Party APIs
**Why wrong**: Real third-party APIs are flaky, rate-limited, and may charge per call.
**Correct alternative**: Mock third-party APIs (WireMock, Stripe test mode, sandbox); tests are deterministic and free.

### 14.5 Retrying Flaky Tests
**Why wrong**: Retries mask flakiness; the root cause is never fixed; the suite degrades over time.
**Correct alternative**: Fix the root cause of flakiness; retries are a stopgap.

### 14.6 E2E for Everything
**Why wrong**: E2E tests are slow, flaky, and expensive; using them for everything wastes resources.
**Correct alternative**: Follow the pyramid: many unit, fewer integration, minimal E2E; reserve E2E for top user journeys.

## 15. Performance Rules

- Seed test data via API, not UI; UI-driven setup is 10-100x slower.
- Use session reuse for authentication; UI-driven login adds 5-10 seconds per test.
- Run tests in parallel by default; shard for CI parallelism.
- Keep tests under 30 seconds each; longer tests indicate over-scoping.
- Keep the E2E suite under 10 minutes; shard if longer.
- Use --workers=N to tune parallelism; too many workers cause resource contention.
- Use --shard=i/n in CI to distribute tests across runners.
- Avoid networkidle in navigation; prefer load or domcontentloaded.

## 16. Security Rules

- Never hardcode credentials in tests; use environment variables or secret management.
- Test users must be synthetic; never use production user accounts.
- Test environments must be isolated from production; never run E2E against production data.
- Storage state files contain session tokens; treat as secrets; gitignore or scope appropriately.
- Mock third-party APIs in tests; never hit real third-party services.
- Test data must be synthetic; production data in tests is forbidden without anonymization.
- CI secrets must be passed via environment variables; never in the test code.
- Test backdoors (if any) must be disabled in production builds.

## 17. Testing Strategy

- E2E tests must cover the top 10-20 user journeys; cap to keep the suite fast.
- Smoke tests (subset of critical journeys) must run on every push.
- Full E2E tests must run nightly and pre-deploy.
- Visual regression tests must cover key pages; mask dynamic regions.
- Accessibility tests must run via axe-playwright or cypress-axe.
- Performance budgets must be enforced via Lighthouse in CI.
- Tests must run in parallel by default; serial execution requires explicit configuration.
- Tests must be deterministic: seeded data, controlled clock, no shared state.
- Tests must run across the browser matrix (chromium, firefox, webkit) in CI.
- Sharding must be used when the suite exceeds 5 minutes.

## 18. Documentation Standards

- Every E2E test must have a descriptive name: `should <expected> when <condition>`.
- Every test.describe must name the feature under test.
- Complex fixtures must be documented with usage examples.
- Page objects (when used) must document their public API.
- The E2E guide must document the project's patterns and conventions.
- The flakiness runbook must document common flakiness causes and mitigations.
- Visual baseline updates must be reviewed in PRs with rationale.
- Test architecture decisions must be documented in ADRs for non-trivial choices.

## 19. Code Review Checklist

- Does the test verify a user journey, not implementation steps?
- Does the test use accessibility-first locators (getByRole, getByLabel, getByText)?
- Does the test use auto-waiting; no manual waits?
- Is the test deterministic (seeded data, controlled clock, no shared state)?
- Is the test isolated (no order dependence, cleanup after each test run)?
- Is the test fast (under 30 seconds)?
- Does the test verify user-visible outcomes, not implementation details?
- Is the test data seeded via API, not UI?
- Is authentication via session reuse, not UI-driven login?
- Are third-party APIs mocked, not real?
- Does the test run in parallel without interfering with other tests?
- Is the test name descriptive (`should <expected> when <condition>`)?
- Are locators resilient to UI refactors that preserve accessibility?
- Does the test pass across the browser matrix (chromium, firefox, webkit)?
- Is the test not flaky (verified by running multiple times)?

## 20. Refactoring Checklist

- Is the refactoring motivated by a concrete pain point (flaky tests, slow tests, brittle locators)?
- Are tests in place to verify behavior preservation?
- Is the refactoring scoped to one concern?
- Are commits small enough to review?
- Is the test suite green before and after each step?
- Are locator changes done across all affected tests?
- Is the test architecture documented in an ADR for significant changes?
- Is the rollback plan documented?
- Is the refactoring validated by the full test suite without modification?
- Is the refactoring reviewed by a second engineer?

## 21. Deployment Checklist

- Is the E2E smoke suite passing in CI on the exact artifact being deployed?
- Is the E2E full suite run nightly and pre-deploy?
- Is the E2E suite sharded for parallelism in CI (`--shard=i/n`)?
- Is the JUnit reporter configured for test result aggregation?
- Is the HTML reporter published as a CI artifact?
- Are trace files, screenshots, and videos retained for failed tests?
- Are flaky tests identified and quarantined before deploy?
- Is the E2E suite speed monitored; regressions investigated?
- Are test dependencies scanned for CVEs?
- Is the test environment isolated from production?
- Is the test data synthetic; no production data in tests?
- Is the test configuration versioned in the repository?
- Are E2E tests gating deploys to production?
- Are canary E2E tests run on the canary deployment?
- Is the E2E suite reversible (rollback to previous test version if needed)?

## 22. Production Checklist

- Is the E2E smoke suite running in CI on every push?
- Are E2E tests gating deploys to production?
- Is the E2E suite speed trended; regressions investigated?
- Are flaky tests detected and fixed within one sprint?
- Is the E2E suite sharded for parallelism; total runtime under 10 minutes?
- Are E2E tests running across the browser matrix (chromium, firefox, webkit)?
- Are visual regression tests reviewing baselines in PRs?
- Are accessibility tests running via axe-playwright?
- Are performance budgets enforced via Lighthouse in CI?
- Are synthetic checks running in production (Pingdom, Checkly)?
- Are E2E failures triaged within one business day?
- Are trace files, screenshots, and videos retained for diagnosis?
- Are E2E runbooks documented for on-call?
- Are E2E test users and data refreshed regularly?
- Is the E2E suite reviewed quarterly for obsolete tests?

## 23. Logging Strategy

- Tests must log via console.log only when debugging; remove before merge.
- console errors and warnings during tests must be asserted or silenced; unexpected output is noise.
- Test failures must include trace file, screenshot, and video for diagnosis.
- Network requests during tests must be logged in trace for diagnosis.
- CI test output must be captured and published for post-failure diagnosis.
- Test timing must be reported; slow tests surfaced for optimization.
- Visual regression diffs must be visible in CI output for review.
- Flaky test detection must log the failure mode; patterns emerge.
- Test suite health must be reported to engineering leadership weekly.
- Synthetic check failures must alert on-call immediately.

## 24. Monitoring Strategy

- Monitor E2E suite runtime; regressions indicate slow tests or environment issues.
- Monitor E2E pass rate; flaky tests erode trust; investigate immediately.
- Monitor E2E flaky test rate; quarantine and fix within one sprint.
- Monitor CI queue time; long queues indicate insufficient sharding.
- Monitor E2E failure triage time; failures unaddressed for over a day block merges.
- Monitor browser binary download time; cache to reduce CI time.
- Monitor test environment availability; unavailable environments block CI.
- Monitor visual regression baseline churn; high churn indicates brittle tests.
- Monitor synthetic check results; production user journeys must remain green.
- Review E2E metrics monthly; remove or refactor tests that do not add value.

## 25. Error Handling

- Test failures must produce clear error messages: expected vs actual, with locator context.
- Timeout failures must indicate which locator timed out and the timeout duration.
- Network failures must indicate which request failed and the response.
- Assertion failures must show the diff clearly (text, visual).
- Setup failures must indicate which setup step failed and why.
- Authentication failures must indicate the user and the failure mode.
- Flaky test detection must capture the failure mode for diagnosis.
- CI failures must publish artifacts (traces, screenshots, videos) for diagnosis.
- Synthetic check failures must alert on-call with the failing journey and region.
- Visual regression failures must show the diff image and baseline.

## 26. Examples

### 26.1 User Journey Test with Smoke Tag

```typescript
// e2e/tests/checkout.spec.ts
import { test, expect } from '../fixtures/auth';

test.describe('Checkout journey', () => {
  test('should complete checkout with valid payment @smoke', async ({ authenticatedPage: page }) => {
    await test.step('Given the user has items in cart', async () => {
      await page.getByRole('link', { name: /products/i }).click();
      await page.getByRole('button', { name: /add to cart/i }).first().click();
      await expect(page.getByRole('link', { name: /cart \(1\)/i })).toBeVisible();
    });

    await test.step('When the user proceeds to checkout and pays', async () => {
      await page.getByRole('link', { name: /cart/i }).click();
      await page.getByRole('button', { name: /proceed to checkout/i }).click();
      await expect(page).toHaveURL(/\/checkout/);

      await page.getByLabel(/card number/i).fill('4242 4242 4242 4242');
      await page.getByLabel(/expiry/i).fill('12/28');
      await page.getByLabel(/cvc/i).fill('123');
      await page.getByLabel(/name on card/i).fill('Test User');

      const responsePromise = page.waitForResponse(
        (r) => r.url().includes('/api/checkout') && r.status() === 200,
      );
      await page.getByRole('button', { name: /pay now/i }).click();
      await responsePromise;
    });

    await test.step('Then the order is confirmed', async () => {
      await expect(page.getByRole('heading', { name: /order confirmed/i })).toBeVisible();
      await expect(page.getByText(/order number/i)).toBeVisible();
      await expect(page.getByRole('link', { name: /continue shopping/i })).toBeVisible();
    });
  });

  test('should display error for declined card', async ({ authenticatedPage: page }) => {
    await page.goto('/products');
    await page.getByRole('button', { name: /add to cart/i }).first().click();
    await page.getByRole('link', { name: /cart/i }).click();
    await page.getByRole('button', { name: /proceed to checkout/i }).click();

    await page.getByLabel(/card number/i).fill('4000 0000 0000 0002');
    await page.getByLabel(/expiry/i).fill('12/28');
    await page.getByLabel(/cvc/i).fill('123');
    await page.getByLabel(/name on card/i).fill('Test User');

    await page.getByRole('button', { name: /pay now/i }).click();

    await expect(page.getByRole('alert')).toContainText(/card declined/i);
    await expect(page.getByRole('button', { name: /pay now/i })).toBeEnabled();
  });
});
```

### 26.2 CI Workflow with Sharding

```yaml
# .github/workflows/e2e-full.yml
name: E2E Full Suite

on:
  schedule:
    - cron: '0 4 * * *'  # Nightly at 4 AM UTC
  workflow_dispatch: {}
  pull_request:
    branches: [main]
    paths:
      - 'apps/web/**'
      - 'e2e/**'

jobs:
  e2e:
    runs-on: ubuntu-latest
    strategy:
      fail-fast: false
      matrix:
        browser: [chromium, firefox, webkit]
        shard: [1, 2, 3, 4]
    steps:
      - uses: actions/checkout@v4

      - uses: actions/setup-node@v4
        with:
          node-version: '20'
          cache: 'npm'

      - name: Install dependencies
        run: npm ci

      - name: Install Playwright browsers
        run: npx playwright install --with-deps ${{ matrix.browser }}

      - name: Build application
        run: npm run build

      - name: Run E2E tests
        env:
          E2E_BASE_URL: http://localhost:3000
          E2E_USER_EMAIL: ${{ secrets.E2E_USER_EMAIL }}
          E2E_USER_PASSWORD: ${{ secrets.E2E_USER_PASSWORD }}
        run: |
          npx playwright test \
            --project=${{ matrix.browser }} \
            --shard=${{ matrix.shard }}/4 \
            --reporter=html \
            --reporter=junit

      - name: Upload HTML report
        if: always()
        uses: actions/upload-artifact@v4
        with:
          name: e2e-report-${{ matrix.browser }}-shard-${{ matrix.shard }}
          path: playwright-report/
          retention-days: 30

      - name: Upload test results
        if: always()
        uses: actions/upload-artifact@v4
        with:
          name: e2e-results-${{ matrix.browser }}-shard-${{ matrix.shard }}
          path: test-results/
          retention-days: 7

      - name: Merge JUnit reports
        if: always()
        uses: dorny/test-reporter@v1
        with:
          name: E2E Results (${{ matrix.browser }} shard ${{ matrix.shard }})
          path: test-results/junit.xml
          reporter: java-junit
```

### 26.3 Synthetic Check for Production Monitoring

```typescript
// synthetic-checks/checkout-journey.ts
// Deployed to Checkly or DataDog Synthetic; runs every 5 minutes against production.
import { test, expect } from '@playwright/test';

const PRODUCTION_URL = process.env.PRODUCTION_URL ?? 'https://app.example.com';
const SYNTHETIC_USER_EMAIL = process.env.SYNTHETIC_USER_EMAIL!;
const SYNTHETIC_USER_PASSWORD = process.env.SYNTHETIC_USER_PASSWORD!;

test('checkout journey is healthy in production', async ({ page, request }) => {
  // Authenticate via API (no UI login in synthetic checks)
  const loginResponse = await request.post(`${PRODUCTION_URL}/api/auth/login`, {
    data: { email: SYNTHETIC_USER_EMAIL, password: SYNTHETIC_USER_PASSWORD },
  });
  expect(loginResponse.ok()).toBeTruthy();
  const { token } = await loginResponse.json();

  // Seed a test product via API
  const productResponse = await request.post(`${PRODUCTION_URL}/api/test-helpers/seed-product`, {
    headers: { Authorization: `Bearer ${token}` },
    data: { name: 'Synthetic Test Product', price: 100 },
  });
  expect(productResponse.ok()).toBeTruthy();
  const { productId } = await productResponse.json();

  try {
    // Navigate to the product page and add to cart
    await page.goto(`${PRODUCTION_URL}/products/${productId}`);
    await page.getByRole('button', { name: /add to cart/i }).click();

    // Proceed to checkout
    await page.getByRole('link', { name: /cart/i }).click();
    await page.getByRole('button', { name: /proceed to checkout/i }).click();

    // Verify the checkout page loaded
    await expect(page.getByRole('heading', { name: /payment/i })).toBeVisible({
      timeout: 10_000,
    });

    // Log success for monitoring
    console.log(JSON.stringify({
      check: 'checkout-journey',
      status: 'healthy',
      timestamp: new Date().toISOString(),
      duration: 0,
    }));
  } finally {
    // Clean up the test product
    await request.delete(`${PRODUCTION_URL}/api/test-helpers/product/${productId}`, {
      headers: { Authorization: `Bearer ${token}` },
    });
  }
});
```

## 27. Common Mistakes

### 27.1 Testing Implementation Steps
**What**: Tests that verify internal steps rather than user-visible behavior.
**Why**: Breaks on refactors; obscures the user journey; tests are brittle.
**How to avoid**: Test user journeys; verify user-visible outcomes; skip internal implementation steps.

### 27.2 Manual Waits
**What**: Using page.waitForTimeout to wait for elements.
**Why**: Fixed waits introduce flakiness; CI runners vary in speed.
**How to avoid**: Use auto-waiting via expect(locator) with auto-retry.

### 27.3 UI-Driven Authentication
**What**: Logging in via the UI in every test.
**Why**: UI-driven login is slow (5-10 seconds per test).
**How to avoid**: Use session reuse (storageState or cy.session); global setup logs in once.

### 27.4 Real Third-Party APIs
**What**: Hitting real Stripe, Twilio, or OAuth in E2E tests.
**Why**: Real third-party APIs are flaky, rate-limited, and may charge per call.
**How to avoid**: Mock third-party APIs (WireMock, Stripe test mode, sandbox).

### 27.5 Retrying Flaky Tests
**What**: Adding retries to mask flakiness.
**Why**: Retries mask the root cause; flakiness compounds over time.
**How to avoid**: Fix the root cause of flakiness; retries are a stopgap.

### 27.6 E2E for Everything
**What**: Using E2E tests for unit or integration testing.
**Why**: E2E tests are slow, flaky, and expensive.
**How to avoid**: Follow the pyramid: many unit, fewer integration, minimal E2E.

## 28. Professional Workflow

1. Identify the user journey under test: which user, which action, which outcome?
2. Identify the test scope: which steps are user-visible, which are implementation details.
3. Identify the test data: how to seed deterministic data (API, database, fixtures)?
4. Identify the authentication: session reuse, login once, bypass via API.
5. Write the test scenario in BDD: given, when, then.
6. Identify potential flakiness sources: timing, test order, shared state, third-party.
7. Design flakiness mitigations: auto-waiting, deterministic data, network stubs.
8. Identify the browser matrix: chromium, firefox, webkit, mobile viewports.
9. Identify the parallelization strategy: per-file, per-test, or sharded.
10. Identify the CI placement: smoke on every push, full nightly, gating deploys.
11. Write the test using accessibility-first locators and auto-waiting.
12. Run the test in isolation; verify it passes alone.
13. Run the test multiple times; verify it is not flaky.
14. Run the test across the browser matrix; verify it passes everywhere.

## 29. Response Style

- Begin every E2E answer with the user journey and the test scope.
- Present the test code; never describe in prose alone.
- Quantify test properties: runtime, parallelism, browser coverage.
- Use authoritative voice: "must", "must not", "always", "never".
- Cite the framework API by name (getByRole, expect, page.route); the API is the contract.
- Surface trade-offs explicitly: real vs mocked third-party, page object vs fixture, retry vs root-cause fix.
- When asked "how to test X?", demand the user journey and the test data strategy first.
- Close every response with the next concrete step (write the test, run the suite, fix the flake).

## 30. Output Format

- Use E2E test code examples in TypeScript; syntactically valid.
- Use the BDD pattern: given (state), when (action), then (assertion).
- Use `should <expected> when <condition>` for test names.
- Use CI workflow examples in YAML; the workflow is the contract.
- Use synthetic check examples for production monitoring.
- Use bullet lists for rules; numbered lists for sequential steps; tables for framework comparisons.
- Cross-reference framework API by name (getByRole, expect, page.route).
- Quantify test properties: runtime, parallelism, browser coverage.
- Distinguish between principled rules (test user journeys) and context-dependent guidance (page object vs fixture).
- End every response with a next-step checklist, each with owner and deadline.

---
