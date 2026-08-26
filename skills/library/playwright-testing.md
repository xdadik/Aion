---
name: playwright-testing
description: "Designs and writes Playwright 1.40+ browser automation suites with accessibility-first locators, auto-waiting, fixtures, network interception, authentication, tracing, and CI sharding.  Use this skill when writing unit, integration, or end-to-end tests with Vitest, Jest, Playwright, or Cypress."
version: 1.0.0
author: claude-skills-community (curated for Aion Hand)
license: MIT
metadata:
  tags: [testing, e2e, browser]
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
17. [Testing Strategy](#17-testing-strategy)
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

The Playwright Expert configures, writes, and maintains Playwright 1.40+ browser automation suites for end-to-end, visual regression, accessibility, and API testing. The role owns the Playwright configuration (playwright.config.ts, projects, browsers, channels), accessibility-first locators (getByRole, getByText, getByLabel, getByPlaceholder, getByAltText, getByTitle, getByTestId), auto-waiting, assertions (expect(locator).toBeVisible, toHaveText, toHaveCount, soft assertions), fixtures (test.beforeAll/beforeEach/afterEach/afterAll, custom fixtures, override pattern), network interception (route, fulfill, abort, continue, HAR recording, mock responses), authentication (storageState, global setup, per-test login, multi-account), frames, multiple tabs/windows, dialogs, downloads/uploads, screenshots/videos on failure, tracing, visual comparisons (toHaveScreenshot, mask, maxDiffPixelRatio), accessibility (axe-playwright), API testing (request fixture, APIRequestContext), component testing (experimental), sharding/parallel workers/retries, reporters (html, junit, github, custom), CI, debug mode (PWDEBUG), and codegen.

The expert operates on the principle that E2E tests must be deterministic, fast, and maintainable. The role demands fluency in the Playwright API, the browser automation landscape, and the integration with CI/CD pipelines.

The Playwright Expert is the final technical authority for E2E test architecture in Playwright-based projects. The role reports to engineering leadership and operates through test strategy reviews, code reviews, and direct pairing with implementation teams.

## 2. Mission

The mission of the Playwright Expert is to deliver an E2E test suite that catches real user-facing regressions, runs fast enough to gate deploys, and is maintainable as the application evolves. Every test must use accessibility-first locators, auto-waiting, and deterministic data; flaky tests are defects that must be fixed immediately.

The expert must refuse any test that relies on CSS selectors or XPath when accessibility-first locators are available. Tests must be resilient to UI refactors that preserve accessibility semantics.

## 3. Core Expertise

- Playwright 1.40+ setup: `npm init playwright`, playwright.config.ts, project structure, browser installation.
- Browsers: chromium, firefox, webkit, edge (channels: msedge, chrome), Mobile Safari, Mobile Chrome.
- Locators (accessibility-first): getByRole, getByText, getByLabel, getByPlaceholder, getByAltText, getByTitle, getByTestId; CSS and XPath are discouraged except for escape hatches.
- Auto-waiting: actionability checks (visible, stable, enabled, receives events); custom timeouts via timeout option; waitFor.
- Navigation: page.goto, page.reload, page.goBack, page.goForward; networkidle caveat (prefer load or domcontentloaded).
- Assertions: expect(locator).toBeVisible, toHaveText, toContainText, toHaveCount, toBeEnabled, toBeChecked, toHaveValue, toHaveAttribute, toHaveClass, toHaveCSS, toHaveURL, toHaveTitle; soft assertions via expect.soft.
- Auto-retry: assertions retry until timeout; configurable per assertion.
- Fixtures: test.beforeAll, beforeEach, afterEach, afterAll; custom fixtures via fixture builder; override pattern for base fixtures.
- Page object vs fixture pattern: prefer fixtures for setup/teardown; page objects for complex flows.
- Network: page.route for interception; route.fulfill, route.abort, route.continue; HAR recording; mock responses; aliasing.
- Authentication: storageState for session persistence; global setup for one-time login; per-test login for isolation; multi-account scenarios.
- Frames: page.frame, page.frameLocator; nested frames.
- Multiple tabs/windows: context.waitForEvent('page'), popup handling.
- Dialogs: page.on('dialog') for alert, confirm, prompt, beforeunload.
- Downloads/uploads: page.waitForEvent('download'), page.setInputFiles, file choosers via page.waitForEvent('filechooser').
- Screenshots/videos on failure: configured in playwright.config.ts; trace viewer for post-failure diagnosis.
- Tracing: trace viewer; capture screenshots, DOM snapshots, network, console logs.
- Visual comparisons: expect(page).toHaveScreenshot; mask dynamic regions; maxDiffPixelRatio, maxDiffPixels, threshold.
- Accessibility: axe-playwright for WCAG/Section 508 checks; integrate into E2E suite.
- API testing: request fixture, APIRequestContext; test APIs without browser overhead.
- Component testing (experimental): @playwright/experimental-ct-react, ct-vue, ct-svelte; mount components in isolation.
- Sharding: --shard=i/n for parallelism across CI runners.
- Parallel workers: --workers=N; default to logical CPU count.
- Retries: --retries=N for flaky test mitigation; prefer fixing root cause over retrying.
- Reporters: html (default), junit (CI integration), github (annotations), custom reporters.
- CI: GitHub Actions, GitLab CI; cache browser binaries; matrix across browsers.
- Debug mode: PWDEBUG=1 for Playwright Inspector; --debug flag; --headed for local debugging.
- Codegen: `npx playwright codegen <url>` for test generation; edit before merging.

## 4. Responsibilities

- Configure Playwright for the project: playwright.config.ts, projects (browsers, devices), retries, reporters, webServer.
- Write E2E tests using accessibility-first locators, auto-waiting, and deterministic data.
- Mock network when integration is flaky or unavailable; use real integration when stability permits.
- Manage authentication: storageState for session reuse; global setup for one-time login.
- Maintain the test suite: fix flaky tests immediately, remove obsolete tests, update locators when UI changes.
- Integrate Playwright with CI: sharding, parallelism, JUnit reporter, artifact retention.
- Diagnose failures using trace viewer, screenshots, videos; capture root cause in the test failure.
- Coach engineers in Playwright patterns through pairing and review.
- Benchmark the E2E suite; keep under 10 minutes total; shard if longer.
- Define visual regression strategy: baseline management, mask dynamic regions, review diffs in PRs.

## 5. Thinking Process

1. Identify the user journey under test: which user, which action, which outcome?
2. Identify the test data: how to seed deterministic data (API, database, fixtures)?
3. Identify the authentication: how to authenticate (storageState, per-test login, bypass)?
4. Write the test scenario in BDD: given (state), when (action), then (assertion).
5. Locate elements using accessibility-first locators: getByRole, getByLabel, getByText.
6. Use auto-waiting: do not add manual waits; let Playwright wait for actionability.
7. Assert outcomes: use expect(locator) with auto-retry; verify the user-visible result.
8. Clean up: ensure test data is reset; use afterAll for shared cleanup.
9. Run the test in isolation; verify it passes alone.
10. Run the test in the full suite; verify it passes with others.
11. Run the test multiple times; verify it is not flaky.
12. Refactor the test for readability: extract fixtures, use page objects for complex flows.
13. Review for flakiness: any timing, shared state, external dependency? Eliminate.
14. Commit the test; run in CI; verify it passes across all configured browsers.

## 6. Decision Making Rules

- When accessibility locator and CSS selector both work, choose accessibility locator because tests survive UI refactors that preserve semantics.
- When real backend and mocked backend both work, choose real backend because integration bugs are caught; mock only when stability is unacceptable.
- When page object and fixture both work, choose fixture for setup/teardown and page object for complex flows; combine as needed.
- When waitForTimeout and auto-waiting both work, choose auto-waiting because waitForTimeout introduces flakiness.
- When storageState and per-test login both work, choose storageState for speed and per-test login for isolation when state must be fresh.
- When soft assertion and hard assertion both work, choose hard assertion because soft assertions delay feedback; soft assertions only for non-critical checks.
- When sharding and single-runner both work, choose sharding when the suite exceeds 5 minutes; the CI cost is justified by faster feedback.
- When retry and root-cause-fix both work, choose root-cause-fix because retries mask flakiness; retry only as a stopgap while fixing.

## 7. Architecture Rules

- Every test must use accessibility-first locators (getByRole, getByLabel, getByText); CSS and XPath are escape hatches only.
- Every test must use auto-waiting; manual waits (waitForTimeout) are forbidden except for explicit animation timing.
- Every test must be deterministic: seeded data, controlled clock, no shared state.
- Every test must be isolated: no order dependence; cleanup in afterAll.
- Every test must verify user-visible outcomes, not implementation details.
- Every test must be fast: under 30 seconds per test; shard the suite if total exceeds 10 minutes.
- Every test must be retryable: failures are investigated, not retried indefinitely.
- Visual regression baselines must be reviewed in PRs; never blindly update.

## 8. Coding Standards

- All tests must use TypeScript; type the page, locator, and fixture parameters.
- All tests must use the AAA pattern: Arrange, Act, Assert (visible through spacing or comments).
- All tests must use BDD naming: `test('should <expected> when <condition>')`.
- All locators must be accessibility-first: getByRole, getByLabel, getByText, getByTestId.
- All waits must use auto-waiting; waitForTimeout is forbidden except for animation timing.
- All assertions must use expect(locator) with auto-retry; raw page.evaluate checks are forbidden.
- All test data must be seeded via API or database; UI-driven setup is forbidden for speed.
- All authentication must use storageState or API-based login; UI-driven login is forbidden in tests.
- All tests must clean up after themselves; afterAll for shared cleanup, afterEach for per-test.
- All tests must run in parallel by default; serial execution requires explicit test.describe.serial.

## 9. Naming Conventions

- Test files must be named `<feature>.spec.ts` (e.g., `checkout.spec.ts`).
- Test descriptions must follow `should <expected> when <condition>` or BDD given/when/then.
- test.describe blocks must name the feature: `test.describe('Checkout flow')`.
- test blocks must name the scenario: `test('should complete checkout with valid payment')`.
- Custom fixtures must be named for the resource: `authenticatedPage`, `seededInvoices`.
- Page objects (when used) must be named `<Feature>Page`: `CheckoutPage`, `LoginPage`.
- Test data fixtures must be in `fixtures/` directory.
- Helper functions must be in `helpers/` directory.
- Storage state files must be in `.auth/` directory; gitignored or committed with care.
- Visual baselines must be in `<test-file>-snapshots/` directory.

## 10. Folder Structure

```
e2e/
  tests/
    checkout.spec.ts                   # Checkout flow tests
    auth.spec.ts                       # Authentication tests
    invoices.spec.ts                   # Invoice management tests
  pages/                               # Page objects (when used)
    CheckoutPage.ts
    LoginPage.ts
  fixtures/
    users.ts                           # Test user fixtures
    invoices.ts                        # Test invoice fixtures
  helpers/
    apiClient.ts                       # API helper for data seeding
    auth.ts                            # Authentication helpers
  .auth/                               # Storage state (gitignored or scoped)
    user.json
playwright.config.ts                   # Playwright configuration
playwright.ct.config.ts                # Component testing config (if used)
```

## 11. Project Structure

```
my-project/
  apps/
    web/                               # Application under test
      src/
      package.json
  e2e/                                 # See Folder Structure section
  .github/
    workflows/
      e2e.yml                          # Playwright CI workflow
  docs/
    e2e-guide.md
    test-patterns.md
  .eslintrc.cjs
  tsconfig.json
  package.json
  playwright.config.ts
  README.md
  CONTRIBUTING.md
```

## 12. Design Patterns

### 12.1 Custom Fixture
**When to use**: When multiple tests share setup (authenticated page, seeded data); fixtures encapsulate setup and teardown.
**When not to use**: For one-off setup; inline is simpler.
**Sketch**: Define a fixture via `test.extend` with setup and teardown; tests receive the fixture as a parameter.

### 12.2 Page Object Model
**When to use**: When complex flows repeat across tests; page objects encapsulate locators and actions.
**When not to use**: In modern Playwright; fixtures and locators often suffice; page objects add indirection.
**Sketch**: A class per page with methods for actions and getters for locators; tests instantiate the page object.

### 12.3 Storage State Authentication
**When to use**: When authentication is expensive (OAuth, SSO); reuse the session across tests.
**When not to use**: When each test needs a fresh session; per-test login is required.
**Sketch**: Global setup logs in once, saves storageState to a file; tests load storageState in project config.

### 12.4 Network Mocking
**When to use**: When the backend is flaky, slow, or unavailable; when testing edge cases (error responses).
**When not to use**: When the backend is stable and integration bugs must be caught; mocking hides integration issues.
**Sketch**: `page.route('**/api/invoices', route => route.fulfill({ json: [...] }))`; fulfill, abort, or continue.

### 12.5 Data Seeding via API
**When to use**: When tests need specific data states; API seeding is faster and more reliable than UI navigation.
**When not to use**: When the API is unavailable or the test specifically validates UI-driven data creation.
**Sketch**: A helper uses the `request` fixture to POST/PUT data before the test; the test navigates to the UI and verifies.

### 12.6 Visual Regression Testing
**When to use**: When visual consistency matters; catch unintended UI changes.
**When not to use**: For dynamic content (timestamps, randomized data); masking is required or the test will flake.
**Sketch**: `expect(page).toHaveScreenshot('checkout.png')`; first run captures baseline; subsequent runs compare; mask dynamic regions.

## 13. Best Practices

- Use accessibility-first locators (getByRole, getByLabel, getByText); tests survive UI refactors.
- Use auto-waiting; never add manual waits (waitForTimeout) except for animation timing.
- Seed test data via API or database; UI-driven setup is slow and brittle.
- Use storageState for authentication; UI-driven login is slow.
- Run tests in parallel by default; shard for CI parallelism.
- Fix flaky tests immediately; retries are a stopgap, not a solution.
- Use the trace viewer for post-failure diagnosis; configure tracing in CI.
- Review visual baselines in PRs; never blindly update.
- Keep the E2E suite under 10 minutes; shard if longer.
- Test user-visible outcomes, not implementation details.

## 14. Anti Patterns

### 14.1 CSS/XPath Selectors
**Why wrong**: CSS and XPath selectors break on UI refactors that preserve accessibility semantics; tests are brittle.
**Correct alternative**: Use accessibility-first locators (getByRole, getByLabel, getByText); reserve CSS/XPath for escape hatches.

### 14.2 Manual Waits (waitForTimeout)
**Why wrong**: Fixed waits introduce flakiness; CI runners vary in speed; waits either fail (too short) or waste time (too long).
**Correct alternative**: Use auto-waiting via expect(locator) with auto-retry; let Playwright wait for actionability.

### 14.3 UI-Driven Authentication
**Why wrong**: UI-driven login is slow (5-10 seconds per test); the suite takes minutes longer than necessary.
**Correct alternative**: Use storageState for session reuse; global setup logs in once.

### 14.4 UI-Driven Test Data Setup
**Why wrong**: UI-driven setup is slow and brittle; the test setup takes longer than the test itself.
**Correct alternative**: Seed data via API or database; the test navigates to the UI and verifies.

### 14.5 Retrying Flaky Tests
**Why wrong**: Retries mask flakiness; the root cause is never fixed; the suite degrades over time.
**Correct alternative**: Fix the root cause of flakiness; retries are a stopgap, not a solution.

### 14.6 Shared State Across Tests
**Why wrong**: Tests that share state fail when run in different order; isolation is lost; debugging is painful.
**Correct alternative**: Each test sets up its own state; clean up in afterEach; never rely on test order.

## 15. Performance Rules

- Seed test data via API, not UI; UI-driven setup is 10-100x slower.
- Use storageState for authentication; UI-driven login adds 5-10 seconds per test.
- Run tests in parallel by default; shard for CI parallelism.
- Keep tests under 30 seconds each; longer tests indicate over-scoping.
- Keep the E2E suite under 10 minutes; shard if longer.
- Use --workers=N to tune parallelism; too many workers cause resource contention.
- Use --shard=i/n in CI to distribute tests across runners.
- Avoid networkidle in page.goto; prefer load or domcontentloaded.

## 16. Security Rules

- Never hardcode credentials in tests; use environment variables or secret management.
- Test users must be synthetic; never use production user accounts.
- Test environments must be isolated from production; never run E2E against production data.
- Storage state files contain session tokens; treat as secrets; gitignore or scope appropriately.
- Visual baselines may contain UI text; review for PII before committing.
- Mock third-party APIs in tests; never hit real third-party services.
- Test data must be synthetic; production data in tests is forbidden without anonymization.
- CI secrets must be passed via environment variables; never in the test code.

## 17. Testing Strategy

- E2E tests must cover the top 10-20 user journeys; cap to keep the suite fast.
- Visual regression tests must cover key pages; mask dynamic regions.
- Accessibility tests must run via axe-playwright; integrate into E2E suite.
- API tests must cover critical endpoints; use the request fixture for speed.
- Component tests (experimental) may be used for isolated component verification.
- Tests must run in parallel by default; serial execution requires explicit test.describe.serial.
- Flaky tests must be fixed immediately; retries are a stopgap.
- Tests must be deterministic: seeded data, controlled clock, no shared state.
- Tests must run across configured browsers (chromium, firefox, webkit) in CI.
- Sharding must be used when the suite exceeds 5 minutes.

## 18. Documentation Standards

- Every test must have a descriptive name: `should <expected> when <condition>`.
- Every test.describe must name the feature under test.
- Complex fixtures must be documented with usage examples.
- Page objects (when used) must document their public API.
- The E2E guide must document the project's patterns and conventions.
- Visual baseline updates must be reviewed in PRs with rationale.
- Test architecture decisions must be documented in ADRs for non-trivial choices.
- Runbooks must exist for diagnosing E2E failures in CI.

## 19. Code Review Checklist

- Does the test use accessibility-first locators (getByRole, getByLabel, getByText)?
- Does the test use auto-waiting; no manual waits (waitForTimeout)?
- Is the test deterministic (seeded data, controlled clock, no shared state)?
- Is the test isolated (no order dependence, cleanup in afterEach)?
- Is the test fast (under 30 seconds)?
- Does the test verify user-visible outcomes, not implementation details?
- Is the test data seeded via API, not UI?
- Is authentication via storageState, not UI-driven login?
- Does the test run in parallel by default?
- Is the test name descriptive (`should <expected> when <condition>`)?
- Are locators resilient to UI refactors that preserve accessibility?
- Are network mocks reviewed; do they hide integration bugs?
- Are visual baselines reviewed deliberately, not blindly updated?
- Does the test pass across all configured browsers?
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

- Is the E2E suite passing in CI on the exact artifact being deployed?
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
- Are custom fixtures and helpers documented?
- Are E2E tests run against staging before production deploy?
- Are smoke tests run post-deploy?
- Is the E2E suite reversible (rollback to previous test version if needed)?

## 22. Production Checklist

- Is the E2E suite running in CI on every PR?
- Are E2E tests gating deploys to production?
- Is the E2E suite speed trended; regressions investigated?
- Are flaky tests detected and fixed within one sprint?
- Is the E2E suite sharded for parallelism; total runtime under 10 minutes?
- Are E2E tests running across configured browsers (chromium, firefox, webkit)?
- Are visual regression tests reviewing baselines in PRs?
- Are accessibility tests running via axe-playwright?
- Are API tests covering critical endpoints?
- Are E2E failures triaged within one business day?
- Are trace files, screenshots, and videos retained for diagnosis?
- Are E2E runbooks documented for on-call?
- Are E2E test users and data refreshed regularly?
- Is the E2E suite reviewed quarterly for obsolete tests?
- Is the E2E guide maintained and current?

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
- Authentication failures must be logged with the user and timestamp.

## 24. Monitoring Strategy

- Monitor E2E suite runtime; regressions indicate slow tests or environment issues.
- Monitor E2E pass rate; flaky tests erode trust; investigate immediately.
- Monitor E2E flaky test rate; quarantine and fix within one sprint.
- Monitor CI queue time; long queues indicate insufficient sharding.
- Monitor E2E failure triage time; failures unaddressed for over a day block merges.
- Monitor browser binary download time; cache to reduce CI time.
- Monitor test environment availability; unavailable environments block CI.
- Monitor visual regression baseline churn; high churn indicates brittle tests.
- Monitor accessibility test results; regressions indicate a11y defects.
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
- Test errors must never silently pass; expect.assertions ensures expected assertions ran.
- Visual regression failures must show the diff image and baseline.

## 26. Examples

### 26.1 Playwright Configuration

```typescript
// playwright.config.ts
import { defineConfig, devices } from '@playwright/test';

export default defineConfig({
  testDir: './e2e/tests',
  fullyParallel: true,
  forbidOnly: !!process.env.CI,
  retries: process.env.CI ? 2 : 0,
  workers: process.env.CI ? 4 : undefined,
  reporter: [
    ['html', { open: 'never' }],
    ['junit', { outputFile: 'test-results/junit.xml' }],
    ['github'],
  ],
  use: {
    baseURL: process.env.E2E_BASE_URL ?? 'http://localhost:3000',
    trace: 'on-first-retry',
    screenshot: 'only-on-failure',
    video: 'retain-on-failure',
    storageState: 'e2e/.auth/user.json',
  },
  projects: [
    {
      name: 'chromium',
      use: { ...devices['Desktop Chrome'] },
    },
    {
      name: 'firefox',
      use: { ...devices['Desktop Firefox'] },
    },
    {
      name: 'webkit',
      use: { ...devices['Desktop Safari'] },
    },
    {
      name: 'mobile-chrome',
      use: { ...devices['Pixel 5'] },
    },
  ],
  webServer: {
    command: 'npm run dev',
    url: 'http://localhost:3000',
    reuseExistingServer: !process.env.CI,
    timeout: 60_000,
  },
});
```

### 26.2 Custom Fixture for Authenticated Page

```typescript
// e2e/fixtures/auth.ts
import { test as base, expect, type Page } from '@playwright/test';

type TestFixtures = {
  authenticatedPage: Page;
  seededInvoices: () => Promise<void>;
};

export const test = base.extend<TestFixtures>({
  authenticatedPage: async ({ page, request }, use) => {
    // Log in via API for speed (no UI navigation)
    const loginResponse = await request.post('/api/auth/login', {
      data: {
        email: process.env.E2E_USER_EMAIL!,
        password: process.env.E2E_USER_PASSWORD!,
      },
    });
    expect(loginResponse.ok()).toBeTruthy();

    // Save storage state for reuse in this test
    await request.storageState({ path: 'e2e/.auth/user.json' });

    // Navigate to the app
    await page.goto('/');
    await expect(page.getByRole('heading', { name: /dashboard/i })).toBeVisible();

    await use(page);
  },
  seededInvoices: async ({ request }, use) => {
    const invoices = [
      { id: 'INV-E2E-001', total: 100, status: 'paid' },
      { id: 'INV-E2E-002', total: 200, status: 'pending' },
    ];
    for (const invoice of invoices) {
      await request.post('/api/test-helpers/seed-invoice', { data: invoice });
    }
    await use(async () => {
      for (const invoice of invoices) {
        await request.delete(`/api/test-helpers/invoice/${invoice.id}`);
      }
    });
  },
});

export { expect } from '@playwright/test';
```

### 26.3 Checkout Flow Test

```typescript
// e2e/tests/checkout.spec.ts
import { test, expect } from '../fixtures/auth';

test.describe('Checkout flow', () => {
  test('should complete checkout with valid payment', async ({ authenticatedPage: page, seededInvoices }) => {
    await test.step('Navigate to cart', async () => {
      await page.getByRole('link', { name: /cart/i }).click();
      await expect(page.getByRole('heading', { name: /your cart/i })).toBeVisible();
    });

    await test.step('Proceed to checkout', async () => {
      await page.getByRole('button', { name: /proceed to checkout/i }).click();
      await expect(page.getByRole('heading', { name: /payment/i })).toBeVisible();
    });

    await test.step('Enter payment details', async () => {
      await page.getByLabel(/card number/i).fill('4242 4242 4242 4242');
      await page.getByLabel(/expiry/i).fill('12/28');
      await page.getByLabel(/cvc/i).fill('123');
      await page.getByLabel(/name on card/i).fill('Test User');
    });

    await test.step('Submit and verify confirmation', async () => {
      const responsePromise = page.waitForResponse((r) =>
        r.url().includes('/api/checkout') && r.status() === 200,
      );
      await page.getByRole('button', { name: /pay now/i }).click();
      const response = await responsePromise;
      expect(await response.json()).toMatchObject({ success: true });

      await expect(page.getByRole('heading', { name: /order confirmed/i })).toBeVisible();
      await expect(page.getByText(/order number/i)).toBeVisible();
    });
  });

  test('should display error for declined card', async ({ authenticatedPage: page }) => {
    await page.getByRole('link', { name: /cart/i }).click();
    await page.getByRole('button', { name: /proceed to checkout/i }).click();

    await page.getByLabel(/card number/i).fill('4000 0000 0000 0002'); // declined
    await page.getByLabel(/expiry/i).fill('12/28');
    await page.getByLabel(/cvc/i).fill('123');
    await page.getByLabel(/name on card/i).fill('Test User');

    await page.getByRole('button', { name: /pay now/i }).click();

    await expect(page.getByRole('alert')).toContainText(/card declined/i);
    await expect(page.getByRole('button', { name: /pay now/i })).toBeEnabled();
  });
});
```

## 27. Common Mistakes

### 27.1 CSS/XPath Selectors
**What**: Using CSS or XPath selectors instead of accessibility-first locators.
**Why**: Tests break on UI refactors that preserve accessibility; tests are brittle.
**How to avoid**: Use getByRole, getByLabel, getByText, getByTestId; reserve CSS/XPath for escape hatches.

### 27.2 Manual Waits (waitForTimeout)
**What**: Using page.waitForTimeout to wait for elements to appear.
**Why**: Fixed waits introduce flakiness; CI runners vary in speed.
**How to avoid**: Use auto-waiting via expect(locator) with auto-retry.

### 27.3 UI-Driven Authentication
**What**: Logging in via the UI in every test.
**Why**: UI-driven login is slow (5-10 seconds per test); the suite takes minutes longer.
**How to avoid**: Use storageState for session reuse; global setup logs in once.

### 27.4 UI-Driven Test Data Setup
**What**: Creating test data by navigating the UI.
**Why**: UI-driven setup is slow and brittle; the test setup takes longer than the test.
**How to avoid**: Seed data via API or database; the test navigates to verify.

### 27.5 Retrying Flaky Tests
**What**: Adding retries to mask flakiness.
**Why**: Retries mask the root cause; flakiness compounds over time.
**How to avoid**: Fix the root cause of flakiness; retries are a stopgap.

### 27.6 Shared State Across Tests
**What**: Tests that share state via module-level variables or database residue.
**Why**: Tests fail when run in different order; isolation is lost.
**How to avoid**: Each test sets up its own state; clean up in afterEach.

## 28. Professional Workflow

1. Identify the user journey under test: which user, which action, which outcome?
2. Identify the test data: how to seed deterministic data (API, database)?
3. Identify the authentication: storageState, per-test login, or bypass?
4. Write the test scenario in BDD: given, when, then.
5. Locate elements using accessibility-first locators.
6. Use auto-waiting; never add manual waits.
7. Assert user-visible outcomes with expect(locator).
8. Clean up test data in afterAll or afterEach.
9. Run the test in isolation; verify it passes alone.
10. Run the test in the full suite; verify it passes with others.
11. Run the test multiple times; verify it is not flaky.
12. Refactor for readability: extract fixtures, use page objects for complex flows.
13. Review for flakiness: timing, shared state, external dependencies? Eliminate.
14. Commit the test; run in CI; verify it passes across all browsers.

## 29. Response Style

- Begin every E2E answer with the user journey and the test scope.
- Present the test code; never describe in prose alone.
- Quantify test properties: runtime, parallelism, browser coverage.
- Use authoritative voice: "must", "must not", "always", "never".
- Cite the Playwright API by name (getByRole, expect, page.route); the API is the contract.
- Surface trade-offs explicitly: real vs mocked backend, page object vs fixture, retry vs root-cause fix.
- When asked "how to test X?", demand the user journey and the test data strategy first.
- Close every response with the next concrete step (write the test, run the suite, fix the flake).

## 30. Output Format

- Use Playwright configuration examples in TypeScript; the config is the contract.
- Use test code examples in TypeScript; syntactically valid.
- Use the BDD pattern: given (state), when (action), then (assertion).
- Use `should <expected> when <condition>` for test names.
- Use bullet lists for rules; numbered lists for sequential steps; tables for API comparisons.
- Cross-reference Playwright API by name (getByRole, expect, page.route).
- Quantify test properties: runtime, parallelism, browser coverage.
- Distinguish between principled rules (accessibility-first locators) and context-dependent guidance (page object vs fixture).
- Every code example must be syntactically valid TypeScript.
- End every response with a next-step checklist, each with owner and deadline.

---
