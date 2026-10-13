# PULSE service and data readiness

This document records the implementation, dated audits, and remaining gates.
For the live Oracle installation and recovery commands, see
[`deploy/oracle/README.md`](deploy/oracle/README.md). Historical sections below
describe earlier local states and are not the current server status.

## Oracle live deployment (2026-10-13)

`pulseintelligence.tech` and `www.pulseintelligence.tech` resolve to the Oracle
host. Host Nginx serves HTTPS on 443, redirects HTTP and `www` to the apex,
applies request and connection limits, and proxies the frontend and API through
loopback-only container ports. Certbot's renewal dry run passed for both names.
The host firewall keeps web ports and SSH open; Docker, the firewall unit,
Certbot timer, and the five-minute GitHub update timer are enabled.

The server follows `codex/production-readiness` at the same Git commit as the
local checkout and GitHub branch. `pulse-update.service` accepts only a clean,
fast-forward checkout, builds the Compose images, waits for the API and frontend,
and records the deployed commit in `/var/lib/pulse/deployed-commit`. Backend,
frontend, worker, and backup containers run with restart policies. The worker
refreshes at 16:00 UTC and the backup worker snapshots at 04:00 UTC, with
catch-up checks after downtime. The current live worker source audit reports
no failed or stale required sources. The article text model runs as an
unvalidated shadow estimate and remains excluded from usable latest values.

Production signing and backup keys are stored as ignored, owner-restricted
files outside Docker image build contexts; image build cache from an earlier
secret-copy error was purged and the signing and backup keys were rotated.
The backup worker verifies daily SQLite/CMS snapshots and exports an
AES-256-GCM encrypted bundle to a separate Oracle block volume. A restore
rehearsal of the 2026-10-13 snapshot passed, including catalog and account API
checks. That volume is on the same Oracle host, so disaster recovery after
loss of the entire host still needs an independently stored encrypted copy and
separate custody of the backup key. A controlled reboot on 2026-10-13
confirmed that the block volume, host Nginx, firewall, timers, and all four
application containers returned without manual intervention; the public site
and coverage API again returned HTTP 200, and source and backup health checks
remained green.
The current website backend suite passed 97 tests, frontend lint/build and an
isolated Chromium browser smoke passed, the live API audit passed across all
1,480 catalog IDs and 1,018 ranked drugs, and production `npm audit` and
`pip-audit` found no known vulnerabilities. The live auth route returned 429
under a controlled burst, confirming the host rate limit. Reachable Git
history has no tracked `.env`, secret directory, PEM, or key file; a current
tracked-content scan found no common private-key or API-token formats.

## Current local signal audit (2026-10-10)

The checked-in seed manifest now has **1,250 IDs**: 1,212 CMS Part D demand
outputs, 18 legacy ATC outputs, and 20 archived news outputs. After the local
source refresh, the internal historical catalog has **1,480 IDs** and 32,368
records. The latest non-shadow source period is 2026-10-03. The current
publication scope contains **1,018** selected drug projections plus 20 archived
news IDs, whose live article estimates remain shadow-only. The 18 legacy ATC
outputs and 194 unselected seeded drug outputs are retained as history and
excluded from current coverage. The selected drug projections target 2026
from 2024 source claims. The saved research artifact under `model/` is not a live backend
checkpoint. Repeated BLS requests exhausted the public daily quota. The
worker's explicit `--once` mode bypassed its scheduled cooldown, so a run-level
cooldown now also guards the adapter itself. BLS is optional monthly context,
refreshed at most weekly through every invocation path. Failures are retained
in per-source diagnostics but excluded from general signal warnings; failed
fetches write no partial BLS update and do not affect other source families or
the drug ranking.

This section supersedes earlier operational counts in the dated log below.
Those entries preserve the history of the previous 1,312-ID manifest and
4,097-row import; the current importer retains 1,950 historical rows for the
1,250 seed IDs, plus 1,220 older news-bridge rows. The current startup audit
checks seed identity, SQLite integrity and foreign keys, archived row content,
date and timestamp validity, weekly Saturday periods, wastewater site counts,
enforcement window dates, and shadow article provenance. It does not currently
recompute every live source row hash, so older claims of that check below are
historical rather than a current release guarantee.

The current website suite passed 88 tests, frontend lint and build passed,
and the isolated built-browser smoke passed with three years of signal history
and an injected 429 retry. A broader `model/tests` run passed 354 tests and
failed 26. Several failures are blocked by local Git LFS pointer files rather
than hydrated research datasets (including the publishable test suite);
others refer to missing or stale evaluation artifacts. Those model gates are
not satisfied, and the saved research model must remain outside the live API.

The read-only live API audit passed across all 1,480 historical catalog IDs,
1,136 usable latest IDs, and 1,018 ranked drugs after the tiered publication
change. It confirmed that the 20 article outputs and 18 legacy ATC outputs
have no usable latest value. Run it from `website/` with
`python -m scripts.audit_live_signal_api --require-source-refresh --require-drug-baseline`.
The `model/README.md` also describes a `model/rebuilt_demand/` retraining
workflow whose source directory is absent from this checkout and local HEAD.
Its earlier experimental source exists in reachable local Git history, but
the documented commands cannot run from this checkout as written. The
backend's checksum-pinned article inference artifact is present.

### Short-horizon XGBoost boundary (2026-10-11)

The prior public daily outlook used frozen 2025 synthetic sales features in a
2026 inference run. It could not represent current pharmacy demand, so the
worker no longer schedules it and `GET /api/v1/signals/demand/outlook`
returns HTTP 410. Its prior dated rows are retained only as historical
research records. The new `GET /api/v1/signals/demand/horizon-study` route
publishes held-out scores and selected signal IDs from the 30-drug synthetic
next-1/7/14/30-day XGBoost comparison. It returns no live pharmacy forecasts.

The private browser planner now trains separate targets for those four
windows on a user's own sales and inventory history, compares eligible
five-signal models against sales-only on a purged holdout, and keeps private
files on the device. Its results remain demonstration forecasts requiring
local validation before use in purchasing.

### Current drug publication rule

The broad `cms_partd_two_year_persistence_v2` and the stricter 729-drug
`cms_partd_two_year_consistency_v3` runs remain archived. The current
`cms_partd_two_year_tiered_v4` run retains those 729 drugs as
`high_history`: each matched its relative state in the 2019, 2020, and
2021 feature-year folds. It adds 289 `stable_far_from_cutoff` drugs: their
2023 and 2024 claim states agree and their 2024 claims are at least 0.25
log units from each state cutoff. Every API drug row carries its evidence
tier. A retrospective 2021 validation fold included 912 selected drugs with
89.7% balanced accuracy. The later 2022 fold included 905 with 88.4%
balanced accuracy; the 176 added-tier drugs in that fold achieved 77.3%
exact state accuracy on their own. These retrospective checks informed the
publication policy, so they are not an untouched final evaluation. The
four-fold 84.2% balanced accuracy describes the broad baseline before
selection. This qualification is about annual relative claims categories;
it does not validate inventory or purchasing outcomes. If a future release
yields no qualifying drugs, more than 1,200, or less than 85% balanced
accuracy on the later fold, the refresh fails closed and retains the prior
ranking.

The 20 historical news columns were intermediate features in the earlier
1,324-drug research model, which is not the current ranking path. Across all
97 archived months, `national_policy_risk` equals
`national_policy_direction`, and `national_supply_chain_risk` equals
`national_supply_stage_direction`: there are 20 named outputs but 18 distinct
historical series. The article artifact preserves all 20 names and checks both
alias pairs for consistency. The refresh also rejects values outside each
signal's 97-month archived range. Its generated values remain marked unusable
as direct observations; the daily XGBoost and pharmacy models use current
generated values as features beginning at their recorded source timestamps.

The five FDA enforcement IDs now use `rolling_30d` cadence because their
observation date is the FDA update date for a trailing 30-day report window,
which can fall on any weekday. Schema migration 4 replaced their former
`weekly` IDs while preserving the five counts, September 30 source period,
source snapshots, and 30,621 total records. Clients should rediscover these
IDs through `/catalog`. The pre-migration SQLite backup is
`website/data/backups/pre_enforcement_cadence_2026-10-10.sqlite3`.

The current branch has no GitHub Actions workflow. Commit `60ade53` removed
the workflow after a GitHub token without workflow-edit permission rejected
the push. `gh run list` shows no CI runs for this branch. Local backend tests,
frontend lint/build, a browser smoke, and the live checks in the Oracle
runbook are the present release evidence; automated GitHub CI remains a gap.
The 55 KB historical catalog is bundled under `website/catalog/`; signal API
tests compare it with the original fixture and do not depend on an ignored
laptop directory.

On 2026-10-05, the pinned production Python dependencies resolved with a
Python 3.14 wheel-only pip dry run, and `npm audit --omit=dev
--audit-level=high` reported zero vulnerabilities. Those were dated local
checks; the current Oracle image has since been built and run, while this
branch has no GitHub Actions workflow.

On 2026-10-05, an isolated local API database and Vite frontend passed
`scripts/browser_smoke.py --signal-years 3 --simulate-rate-limit`. The browser
requested three years of public history through the API, recovered from an
injected HTTP 429, trained locally, reloaded the encrypted plan, enforced idle
locking and all-session revocation, and sent no private CSV contents to the
API. The temporary account and database were removed after the run. This
checks the browser workflow against a development server; the Compose and
cloud images remain untested locally.
After `npm run build` in `website/frontend/`, repeat the built-browser check
without creating an account in the live database:

```bash
cd website
python -m scripts.browser_smoke_isolated --signal-years 3 --simulate-rate-limit
```

The helper imports the pinned catalog into a temporary database, starts API
and frontend processes on temporary localhost ports, runs Chromium with a
marked stockout in the private sales fixture, and stops both processes.

## Running locally

From `website/`, install `requirements.txt`, then run:

```bash
python -m scripts.import_signal_catalog
python -m backend.worker --once
python -m backend.main
```

Run `python -m backend.worker` as a separate long-running process for a daily
refresh at **16:00 UTC**. On startup, it catches up any source that has no
successful run since the most recent scheduled time. FDA Drugs, MedWatch,
Recalls, and Press RSS feeds provide official drug-event context. The Recalls
and Press adapters keep drug-related items from broader FDA feeds. Each news feed has its own
schedule and failure status, so a failed GDELT retry does not delay the FDA
feeds. `--once` forces every adapter to run.
The GDELT and FDA RSS adapters retry transient connection failures and HTTP
5xx responses up to three times with short backoff. They do not immediately
retry HTTP 429;
the worker waits at least 24 hours before retrying a GDELT 429. When a 429
includes `Retry-After`, its UTC retry deadline is recorded with that refresh
failure and the worker waits until both that deadline and the 24-hour minimum
cooldown have passed. A transient DNS lookup failure gets a 30-minute retry
delay; other source failures keep the six-hour cooldown. FDA
successes remain visible even when GDELT is rate limited.
It checks for failed sources every 15 minutes. BLS is checked at most weekly,
and its adapter independently enforces that interval so explicit `--once`
runs cannot bypass the public API quota guard.
When a qualifying article version from the current or preceding UTC month is
captured after the 20-signal shadow job last succeeded, the worker schedules
another model run at its next 15-minute check. New article evidence also
releases that job's otherwise daily failure cooldown; unchanged evidence
does not cause repeated inference.
Its wait checks wall-clock time at least once a minute, so a laptop
resume triggers a missed-schedule check promptly. Sleep still interrupts
refreshes while the laptop is off.
The refresh worker holds an exclusive OS lock at
`website/data/.refresh_worker.lock` for its whole process lifetime. A second
worker pointed at the same data directory exits before calling any public
source, including when a systemd and Compose worker are started together.
The lock is released by the OS if the process crashes. Run workers only on a
shared mount with reliable file-lock semantics.
If the CMS source check succeeds after an earlier baseline run in the same
daily window, the worker schedules the baseline again at its next 15-minute check
so the ranking uses the newly committed source generation.
Run the frontend from `website/frontend/` with
`npm install` and `npm run dev`. The API is at `http://localhost:8000`; the
frontend is normally at `http://localhost:5173`. After importing or refreshing, run `python -m scripts.audit_signal_store` to
check all 1,250 seed IDs and runtime-generated IDs, SQLite integrity and foreign keys, canonical signal
period dates, finite values, timezone-aware ingestion/source timestamps, and
the exact stored fields of all 1,950 retained rows from the SHA-256-pinned historical
catalog. Existing blank historical source URLs are filled from that source
file; changed nonblank provenance or numeric values fail the audit.
For FluView, NNDSS, and WVAL rows, the audit checks Saturday observation
periods; it also checks wastewater reporting-site counts and shadow-model
article provenance before the API starts.
Blank source times are permitted only for historical catalog and news-bridge
rows whose publication time is unknown. `website/catalog/` includes the
1,250-ID manifest and an exact, SHA-256-pinned copy of the 6,484-row
2023–2025 historical research catalog. The importer retains 1,950 distinct
records for the current seed identities and stays idempotent.
Startup fails if the bundled file is
missing or changed, instead of silently booting a definitions-only service.
The import preserves each actual period and source timestamp and marks legacy
model outputs unusable for current publication. An explicit `--source PATH`
can replace the bundled file when the operator has separately verified it.
Docker Compose starts separate refresh and backup workers and mounts the official CMS Part D
normalized source and its manifest; the refresh worker stages new annual releases in
its writable data volume after checking CMS's live catalog.
The worker also checks the official HHS Medicaid Provider Spending by NDC
dataset page against the pinned July 24, 2026 ZIP version and SHA-256 in
`catalog/hhs_ndc_source.json`. A changed release is recorded as a failed source
check and appears in `/api/v1/signals/freshness`; it requires a new verified
extraction and model evaluation before the training-only ATC data can be used.
The check does not download the 321 MB source on every run or publish ATC values.

On this WSL laptop, systemd is enabled. The local units in
`website/deploy/systemd/` have been installed and enabled as `pulse-api`,
`pulse-worker`, and `pulse-frontend`. They restart crashed processes and start
when the WSL distribution boots. The API binds to `127.0.0.1:8000`; the built
frontend preview is at `http://localhost:3141` and proxies `/api` to the API.
Use `systemctl status pulse-api pulse-worker pulse-frontend` and
`journalctl -u pulse-worker -n 100` to inspect them. These units contain this
laptop's absolute paths and run under its current root-owned WSL checkout;
adapt the working directory, service user, TLS ingress, and secret management
for the eventual cloud host. Laptop sleep, shutdown, or a stopped WSL instance
interrupts the service, so this is not a claim of cloud-style 24/7 uptime.
The local units use an owner-only file umask, isolated temporary directories,
and `NoNewPrivileges`. Move them to a dedicated unprivileged service account
when the cloud filesystem and secret mounts are prepared.

The local `pulse-backup.timer` runs at **04:00 UTC** with catch-up after a missed
timer event. It calls `python -m scripts.backup_databases`, which uses SQLite's
online backup API for both databases, includes the committed CMS Part D source
and its matching manifest, and verifies SHA-256 and SQLite integrity,
and retains the latest 14 committed snapshots under `website/data/backups/`.
When a published drug ranking is present, the backup verifier also requires
its source SHA-256 and source year to match the included CMS source generation.
A backup taken across a source/ranking refresh boundary fails before commit;
the local systemd service retries failed backups after 30 minutes, while the
Compose backup worker retries at its next hourly check.
Snapshot creation and retention hold an exclusive OS lock at
`website/data/backups/.backup.lock`, so the laptop timer and a Compose backup
worker cannot modify the same snapshot directory concurrently.
Backup directories are mode `0700`; database files are `0600`. To inspect a
snapshot, run `python -m scripts.backup_databases --verify PATH_TO_SNAPSHOT`.
Run `python -m scripts.rehearse_restore PATH_TO_SNAPSHOT` to boot the API
against a temporary restored copy and check the 1,250-ID seed catalog, at least
1,950 bundled historical catalog records in the backup itself, signal date and
provenance audit, drug ranking, and CMS source pair without changing the live
databases. It also checks the restored account table and exercises registration,
login, authenticated access, and session revocation using a disposable account
only in the temporary copy. The historical count is checked before API startup can refill it.
Older snapshots with blank historical source URLs receive only that narrow
source-backed migration in the temporary copy before the exact-row audit;
missing rows or changed values still fail rehearsal.
To prepare an encrypted copy for separate storage, create a distinct 32-byte
backup key and keep it outside the data directory and the copy destination:

```bash
umask 077
python -c "import pathlib,secrets; pathlib.Path('backup-key.hex').open('x').write(secrets.token_hex(32) + '\n')"
python -m scripts.encrypted_backup export PATH_TO_SNAPSHOT PATH_TO_COPY.enc --key-file backup-key.hex
python -m scripts.encrypted_backup restore PATH_TO_COPY.enc PATH_TO_EMPTY_RESTORE_DIR --key-file backup-key.hex
python -m scripts.rehearse_restore PATH_TO_EMPTY_RESTORE_DIR
```

The export verifies the source snapshot, encrypts the complete database and
CMS source pair with AES-256-GCM, then decrypts and verifies the bundle before
publishing it. Restore rejects a wrong key, modified ciphertext, unexpected
archive members, and an existing destination. Transfer the encrypted bundle to
separate storage and retain the key in a separate secret store; neither transfer
nor key escrow is configured on this laptop. The cloud Compose backup worker
automates export to its configured mount and retries failed exports at the next
hourly check. It authenticates existing bundles before counting them as done.
Losing the key makes the exported
copy unusable. The key and bundle must not be committed to Git.
For recovery, stop the API and worker, verify the snapshot, copy its two
database files and CMS source/manifest pair into `website/data/` with owner-only
permissions, then restart the services. Preserve the server signing key
separately in a secret manager; the backup intentionally contains no private
sales or inventory CSVs or signing key. These local
snapshots protect against database corruption or accidental changes, but a
cloud deployment still needs a provisioned independent storage mount
and a tested restore procedure for other source artifacts as well. Compose runs its own
backup worker at 04:00 UTC, catches up after downtime, verifies existing
snapshots, and retries failed backups hourly. The WSL timer is specific to this
laptop and should not run alongside the Compose backup worker against the same
data directory.

The Compose frontend uses a multi-stage Node 22 build and Nginx to serve static
assets and proxy same-origin API and documentation routes. The local Compose
ports bind to `127.0.0.1`; a later cloud deployment needs an HTTPS ingress and
explicit public network policy. The frontend dependency lockfile is included
for reproducible builds. Interactive `/docs` serves a pinned Swagger UI bundle,
stylesheet, and favicon from the API's own `/api-doc-assets/` path. Its
initializer is a separate local script, so the docs CSP permits only
same-origin scripts and styles. The vendored package license and SHA-256 are
in `backend/docs_assets/`; `/redoc` redirects to these local docs. The site's
own `/api-guide` is also served locally. Nginx and the
cloud Caddy API route each reject request bodies larger than 256 KiB;
public API calls are small JSON requests, while private sales and inventory
CSV files stay in the browser and never reach this proxy. On 2026-10-03,
`npm audit --omit=dev` reported zero
findings, while the full build-dependency audit reported five high findings
through Tailwind 3's `braces` dependency. The [upstream advisory](https://github.com/advisories/ghsa-vfj7-8cjw-p6xm)
lists no patched `braces` release. Node dependencies stay in the disposable
build stage; the final Nginx image copies only static assets. Track this
build-time finding and reassess the Tailwind upgrade when a compatible path is
available rather than claiming the full audit is clean.
The backend image uses the official Python 3.14 slim image and a 32-package
exact-version runtime lock. Legacy server-side XGBoost and scikit-learn are
absent. Wheel-only resolution of the current lock succeeded on Python 3.14;
the local API and authentication tests pass with its PyJWT version. The lock
uses PyJWT for HS256 session tokens; a legacy
python-jose token fixture verifies existing sessions remain readable. A
`pip-audit` check of the locked runtime packages reported no known findings on
2026-10-05, and CI repeats that check. The previous lock also evaluated the
four CMS baseline folds, served the 1,312-ID catalog, and passed a restored
snapshot rehearsal. Docker is unavailable on this laptop, so the container
image itself has not yet been built here.
The Compose API, refresh worker, and backup worker run as the unprivileged
`pulse` user (UID 10001).
Before they start, a short-lived `data-permissions` service changes ownership
of the bind-mounted `website/data/` tree to that UID, including existing
databases and backups. This changes host file ownership when Compose is first
started; the root-run laptop systemd units can still access these files.
Avoid starting the systemd and Compose workers together against the same
database. The setup service uses root only for this ownership step.
The long-running application containers drop Linux capabilities and prohibit privilege
escalation. The local systemd units remain root-run because this checkout is
under `/root`; the cloud deployment should move the checkout and data directory
to paths accessible by a dedicated service account.

For a later cloud host, `docker-compose.cloud.yml` adds Caddy as the public
HTTPS ingress. Set a real hostname in `PULSE_DOMAIN`, point its DNS at the
server, and allow inbound TCP 80 and 443. Caddy routes `/api/*`, `/docs`, and
`/openapi.json` directly to the backend, and other paths to the frontend.
The API also limits individual signal IDs to 64 characters and search terms
to 120 characters for direct backend requests.
The public signal API has a per-client token bucket: 300 request credits at
startup, refilling at five per second. History/latest calls cost five credits,
catalog/coverage cost three, and other signal calls cost one. Exhaustion
returns HTTP 429 with `Retry-After`; authentication and readiness checks are
outside this budget. The API trusts `X-Real-IP` only from the configured
frontend or Caddy peer, and Uvicorn does not process client-supplied forwarded
headers. This limiter is process-local and assumes the current single API
process; a multi-process or multi-host deployment needs a shared ingress
limit. Network-level abuse protection remains the cloud operator's task.
It sends HSTS, frame-denial, MIME-sniffing, referrer, and permissions
headers on HTTPS responses, including routes proxied directly to FastAPI.
The direct `/docs` and `/redoc` routes also receive the docs-specific CSP used
by the local Nginx proxy. A local Caddy 2.11.7 reverse-proxy rehearsal verified
these headers and HTTP 413 for a request body above 256 KiB.
It overwrites `X-Real-IP` with the connecting client address; the backend
trusts only the Caddy container as a forwarding peer for login limits. Do not
put an additional CDN or proxy in front without configuring its trusted IPs
in Caddy. The cloud overlay sets secure cookies, same-origin CORS, and the
exact `https://` public origin. The base Compose file still binds its API and
frontend host ports only to loopback.

Create `website/.env` from `.env.cloud.example` and replace the example
hostname and `PULSE_OFFSITE_BACKUP_DIR` with the absolute host path to a
storage mount that survives loss of the application host. Provision that mount
before starting Compose and make it writable by UID 10001. A directory on the
same host disk does not provide host-loss recovery. Generate distinct signing
and backup encryption keys into ignored files under `website/secrets/`. Keep
`.env` owner-only (`0600`), and set both secret files to owner-readable and
group-readable (`0640`) with
group ID 10001. The host Compose user remains its owner; the container's
`pulse` user belongs to group 10001. File-backed Compose secrets preserve
host file permissions on Linux, so a root-owned `0600` file would be unreadable
to the unprivileged processes. The API, refresh worker, and backup worker read
the signing key through `/run/secrets/pulse_signing_key`; only the backup
worker reads `/run/secrets/pulse_backup_key`. The cloud overlay does not pass
either value in a container environment variable. The one-shot data-volume
ownership initializer has no network, a read-only container filesystem, and
only the `CHOWN` capability; application containers run as the unprivileged
`pulse` user. Start from `website/` with:

```bash
umask 077
cp .env.cloud.example .env
# Edit .env to set the real hostname and independent storage mount path.
mkdir -p secrets
python -c "import pathlib,secrets; pathlib.Path('secrets/pulse_signing_key').open('x').write(secrets.token_urlsafe(48))"
python -c "import pathlib,secrets; pathlib.Path('secrets/pulse_backup_key').open('x').write(secrets.token_hex(32) + '\n')"
sudo chown "$(id -u):10001" secrets/pulse_signing_key secrets/pulse_backup_key
chmod 600 .env
chmod 640 secrets/pulse_signing_key secrets/pulse_backup_key
git -C .. lfs pull --include="data/targeted_additions/cms_partd_geography_drug/data/arkansas_partd_geography_drug_by_year.csv.gz" --exclude=""
python -m scripts.cloud_preflight
docker compose -f docker-compose.yml -f docker-compose.cloud.yml config --quiet
docker compose -f docker-compose.yml -f docker-compose.cloud.yml up -d --build
```

The preflight rejects an unhydrated Git LFS pointer, a CMS source that fails
its manifest checksum, placeholder domains, missing or insecure secret files,
and an absent or unwritable backup directory. It cannot prove that the backup
directory is an independent mount or that DNS and TLS are ready; verify those
on the chosen server before exposing the service.

Keep the Caddy `/data` volume across deployments because it holds issued TLS
certificates. The Compose backup worker creates verified local snapshots and
exports encrypted bundles to the configured mount. Confirm that mount is
actually remote or independently replicated, and rehearse recovery using the
chosen storage service before relying on it for host-loss recovery. The Caddy
overlay remains a template for other hosts. The Oracle deployment uses host
Nginx and the Oracle Compose overlay; its live API, source refresh, backup,
HTTPS renewal, and reboot recovery were checked on 2026-10-13. The same-host
block volume is still not an independent offsite backup.
The backend startup imports the checked-in catalog, materializes previously
captured NADAC and FDA shortage snapshots into stable source signals, and
audits the database before opening the API. The materializer is idempotent
and uses only stored source records.
Compose probes the refresh worker's database heartbeat every five minutes and
requires a verified backup after the most recent 04:00 UTC schedule. In the
cloud overlay, the backup probe also authenticates the encrypted export and
checks that it matches the verified local snapshot. Run
`python -m scripts.operational_status worker` or `backup` from `website/` to
inspect the same checks as JSON; an unhealthy component exits nonzero. Run
`python -m scripts.operational_status sources` to make the command fail when
an expected source was not checked since the latest daily schedule or its
most recent refresh failed. The worker report lists those sources without
conflating an external outage with a stalled worker. These probes expose
failures to the container runtime; route unhealthy-container and failed-source
events to the chosen host's alert service before a public launch.
Optional sources polled less often than daily, including BLS, are excluded from
this daily health gate; their adapter failures do not affect signal coverage.
When `ENVIRONMENT=production`, startup requires a nontrivial signing key of at
least 32 bytes, secure cookies, a bounded session lifetime, disabled legacy
server training, `PUBLIC_ORIGIN` set to the exact external HTTPS origin, and
either no cross-origin access (`CORS_ORIGINS=[]`) or explicit HTTPS origins.
The laptop's localhost CORS defaults are rejected in production. Configure the
actual domain and TLS ingress before switching modes. Both the API and worker
need `PUBLIC_ORIGIN` and `CORS_ORIGINS` because both load the same production
configuration.
Production registration and cookie-session login require an `Origin` header
matching `PUBLIC_ORIGIN`; this closes the headerless form path for login CSRF.
The separate bearer-token endpoint accepts headerless API clients and sets no
session cookie.

The API process is a reader and account server; the worker owns network
refreshes. This prevents each API replica from running the same scheduled job.
The `refresh_runs` table records success and failure with UTC timestamps.
The worker records a heartbeat before and after each 15-minute source check.
`/api/v1/signals/freshness` reports whether a heartbeat was recorded within
two hours and shows each source's last attempt, last success, and latest
status. It also returns `failed_sources` so a fallback source failure is
visible even while the worker is healthy; the signals page displays that
partial-failure warning. Its `news_model` object separately reports whether
the legacy 20-signal inference stage is `not_configured`, `running`, `failed`,
or awaiting validation, along with its signal count, latest recorded period, and latest
run. Those states never imply publishability. The signals page warns when the
worker is stale and when the news-model stage cannot publish. `/health` checks API
process liveness; `/ready` requires every ID in the checked-in 1,312-ID seed
manifest and all 4,097 bundled historical catalog records. Evaluated CMS
outputs may add stable definitions for newer drugs. Both local systemd and Compose run the read-only
signal-store audit after import and before starting the API. Neither
claims that every upstream source has published a current observation.

## Public signal API

### Upstream data services and credentials

The current `pulse-worker` schedule is configured for **16:00 UTC**. Its
existing source adapters use public endpoints and do not require per-source API
keys:

| Input | Current adapter | Credential status |
| --- | --- | --- |
| General recent news | GDELT DOC API | Public; no key configured. HTTP 429 responses are recorded as source failures; the worker observes `Retry-After` when provided and enforces a 24-hour minimum cooldown. |
| Drug safety and pharmacy context | FDA Drugs, MedWatch, Recalls, and Press RSS feeds; openFDA shortage and drug-enforcement APIs | Public; no key configured. `OPENFDA_API_KEY` is optional for regular-use rate capacity. |
| Influenza-like illness context | Delphi FluView ILINet V5 weekly Arkansas ILI, national ILI, and national weighted ILI | Public anonymous access works locally; an optional Delphi API token removes anonymous rate limits. These are surveillance percentages, not demand outputs. |
| Notifiable disease context | CDC NNDSS provisional weekly table for the six saved model disease labels, with Arkansas and U.S. rows | Public CDC Socrata access works locally without a key. Missing or suppressed metric cells remain absent. The four CDC measures are stored separately and are not yet the saved model's annual features. |
| Wastewater context | CDC site-level WVAL dataset, aggregated as a transparent reporting-site mean for Arkansas and the U.S. | Public CDC Socrata access works locally without a key. Each value includes its contributing-site count; these means are not CDC's official geographic medians or validated live inputs for the saved demand model. |
| Archived 20-output news estimate | Local TF-IDF/Ridge model prefers captured titles and summaries for the last closed UTC month, and falls back to a current-month-to-date estimate targeted at month end. Its JSON weights are SHA-256 pinned. Results are stored with `usable: false` as direct observations and may enter XGBoost forecasts as source-timestamped features. | No key; requires captured article text. |
| Labor and price context | BLS Public Data API v1; CMS NADAC download | Public; no key configured. BLS checks run at most weekly because its observations are monthly and its anonymous endpoint has a strict daily quota. An adapter failure preserves prior observations and does not affect general signal coverage or ranking. |
| Arkansas public demand and context | CMS Part D catalog/source, CMS Geographic Variation API, Medicaid State Performance API, Arkansas SDUD downloads, and HHS NDC release catalog | Public; no key configured. The Part D source is checksum- and manifest-validated before the daily projection is published. |

The production deployment still needs operator-managed secrets for session
signing and encrypted backups; those are not upstream API keys. The historic
`NEWS_API_KEY` in an old `model/prod_pipeline.py` revision was never used by its
news loader. No NewsAPI integration is configured. The historical
FLAN-T5-small bridge is historical data; its original inference pipeline is
not in this checkout. A locally saved TF-IDF/Ridge model is now packaged as a
checksum-pinned, non-executable JSON artifact and scheduled as a daily shadow
job after source refresh. It estimates the same 20 archived outputs from
captured titles and summaries, preferring the previous closed UTC month and
falling back to a current-month-to-date estimate targeted at month end when
the closed month has no captured text. This is not the original model: it was
fit on ten matched article months, and its live summary-text inputs differ
from the archived full-text training corpus. Its rows are stored with
`usable: false` as direct observations and are excluded from the current
private demand trainer.
The old ATC-derived rows remain excluded from operational latest demand. No key
is needed for the currently configured public feeds. They remain model
estimates rather than observed article or pharmacy measurements.

Each shadow output now has database provenance in
`news_model_record_provenance` and `news_model_record_inputs`: the model artifact
checksum, estimate kind, ordered captured article-version hashes, and an
article count. The linked versions retain their actual feed names, URLs,
timestamps, titles, and summaries. A shadow output has no single upstream
source URL because a run may combine FDA feeds and GDELT. The release audit
recomputes each output's row hash from that evidence and fails if a link is
missing or mismatched. Older shadow rows can be linked by rerunning the
idempotent article-model job when their original captured inputs are present.
Inference chooses the latest captured version within each feed and article
URL before selecting the richest available copy of a URL across feeds.

The daily drug-enforcement adapter captures every FDA report in the 30
inclusive report-date days ending on the API's `last_updated` date. It stores
the raw source rows and generation links, then emits five source-defined
signals: report counts for Classes I, II, III, Not Yet Classified, and Total.
The source update date is the observation period; the retrieval timestamp is
stored separately. These are counts of published reports, not active recalls,
Arkansas stockouts, or demand. The legacy `recall_active` seed ID remains
unusable because its original identity dimensions were collapsed. The new
counts do not automatically satisfy the older model's `recall_count_*`
feature contract without a compatible mapping and validation.

All routes are also described at `/docs` and in the frontend API guide.

| Route | Meaning |
| --- | --- |
| `GET /api/v1/signals/catalog` | All 1,312 checked-in seed IDs plus stable IDs added for evaluated newer-drug outputs and newly materialized source-grouped signals; identity fields, units, source, and last period. Search and pagination are supported. |
| `GET /api/v1/signals/catalog/seed` | Exactly the 1,312 checked-in seed definitions and stable IDs. Definitions only; query `/latest` or `/history` for recorded values. |
| `POST /api/v1/signals/latest` | Latest usable recorded observations in `values` for up to 1,500 IDs per request. Page through `/catalog` and batch IDs when retrieving the larger full catalog. `latest_recorded_values` contains the absolute latest stored row for every requested ID with a record, including unvalidated rows flagged `usable: false`. For IDs without a usable value, `unusable_recorded_values` highlights that archived row; `missing_ids` and `missing_details` report the usable-value gap. Unknown IDs have no recorded row. Date filters are rejected; unresolved same-revision conflicts carry `ambiguous: true` and are excluded from usable values. |
| `POST /api/v1/signals/history` | Recorded values for up to 100 IDs on an exact `date` or any `start_date`/`end_date` range, including the full available 2013–present history. The newest source revision for each period is returned by default; `include_revisions: true` returns each recorded revision for point-in-time training. Missing dates are absent. A request exceeding 10,000 raw source rows returns HTTP 413 with no truncated result; split IDs or dates. Browser training retries smaller ID batches automatically. |
| `GET /api/v1/signals/freshness` | Catalog counts, latest periods, and last worker run. |
| `GET /api/v1/signals/coverage` | Per-ID gap status and age of the latest observation. |
| `GET /api/v1/signals/coverage/summary` | Exact 1,312-seed counts for usable recorded values, recent source observations, current-target demand projections, older usable values, and unavailable values. Recent source periods use 14 days for weekly, 60 days for monthly, and 400 days for annual observations; a demand output must target the current year or later. A current-target projection can use an older source period. This display policy is not an upstream completeness claim. |
| `GET /api/v1/signals/recent` | Public source context recorded in the last 1–7 days, with each true observation period, source update time, and recording time. The FDA enforcement total appears only when its source period is inside that window. Selected Arkansas FluView ILI, NNDSS current-week cases, and WVAL reporting-site means appear only for source periods within 14 days and source updates within the requested window. WVAL rows expose contributing-site counts in `data_quality` and are not official CDC medians. Unresolved same-revision conflicts are omitted; inspect `/history` for them. |
| `GET /api/v1/signals/demand/drugs` | Searchable, paged ranking of the evaluated Arkansas CMS Part D claims baseline. Until a baseline run succeeds, the endpoint returns an explicit unavailable status instead of promoting unvalidated legacy outputs. |
| `GET /api/v1/signals/news/recent` | Recorded news or FDA feed updates from the requested recent window. Headlines come from immutable article versions used by the 20-signal shadow job, deduplicated by URL; older legacy headline rows are retained when no version exists. Each row includes `timestamp_kind`: `gdelt_first_seen` or `rss_pub_date`. The legacy `published_at` field holds that source timestamp; it is not always the publisher's publication time. `source_checks` reports each feed's latest attempt and success separately, including failures when fallback items are present. |
| `GET /api/v1/signals/sources/shortages/recent` | Recent changes in the latest complete openFDA shortage fetch, with its UTC snapshot date and retrieval time. Supply context, not demand. |
| `GET /api/v1/signals/sources/nadac/latest` | Latest official NADAC rate snapshot grouped by rate classification and pricing unit. Price context, not demand. |
| `GET /api/v1/signals/sources/sdud/latest` | Latest Arkansas Medicaid quarterly prescription counts by product name. Suppressed NDC rows remain unknown, so reported totals are lower bounds. Search and pagination are supported. |

The stable ID hashes signal origin, measure, cadence, geography, and entity.
Each row retains its period end, signal date, source timestamp when supplied,
ingestion time, source URL, source kind, forecast horizon, and quality fields. A source
timestamp of `""` means the historical artifact did not supply one; it is not
silently replaced with the import time. Conflicting source rows are preserved,
and callers should not select one without resolving the source discrepancy.
Browser training requests all revisions and uses the newest period and revision
available on each historical feature day. A later revision to an older period
cannot replace a newer published period. Values with unknown source
availability remain excluded from point-in-time training.
An early schema used a separate `signal_observations` table. Startup retains
that table if found: matching total row counts cannot prove its records were
migrated. Remove it only after a row-level audit of that database.

Both the signal and account SQLite databases now use explicit `user_version`
schema versions. Startup applies idempotent version-1 migrations once while
holding an OS file lock shared by API processes, rejects databases created by
a newer service version, and keeps legacy tables until their rows have been
audited. The signal store's current schema migration retains the older
`signal_observations` table for that reason. A fresh verified database backup
was taken before setting the migration versions on the live service.

## Current coverage, as of 2026-10-09

The imported historical file has 1,312 distinct signal identities and 4,097
distinct retained source rows. It ends in 2025 for weekly/monthly observations
and in 2024 for the annual drug output's observation period. The legacy catalog
drug states target 2025. **Those rows are not current 2026 medication demand rankings.** The
catalog also contains 120 same-ID/same-period groups with conflicting numeric
values; these are flagged by the history endpoint.

A separate checked-in news bridge has 20 signal columns and 97 monthly periods
from January 2018 through January 2026. Its bundled copy is SHA-256 pinned;
all 720 values overlapping the 2023–2025 historical catalog match exactly.
Startup backfills only absent periods (1,220 rows on the laptop), retaining the
catalog's original rows. The bridge has no verified per-row publication time,
and its upstream extraction runner is absent. Its rows therefore have an empty
source timestamp, are marked unusable in `/history`, cannot be selected for
point-in-time browser training, and remain excluded from `/latest`. The January
2026 period is a historical artifact value, not a current news-model refresh.

Future daily FDA and GDELT captures retain each distinct source-visible
article version in `news_article_versions`, including the feed name, timestamp
kind, source timestamp, first capture time, title, and available summary text.
Repeated captures of the same version do not change its first capture time;
source revisions remain separate. Older `news_articles` rows are not
retroactively assigned a first capture time, because their `fetched_at` field
was previously overwritten on repeat refresh. This evidence supports a future
chronological news pipeline but does not validate or publish the 20 legacy
news-model output IDs. The read-only signal-store audit verifies each archived
version's content hash and aware source/capture times; backup restore rehearsal
reports the audited version count. On 2026-10-06 UTC, a live FDA Press refresh
captured its first version, and a new local snapshot restored with one audited
news version, the 1,312 seed IDs, and 1,324 ranked drugs.

The gap report now marks 1,324 drug IDs with a separate evaluated
two-year baseline projection for 2026 and 18 ATC demand outputs that still
require current source data and a validated model rerun. The 20 news-model
outputs have no verified live refresh path; 62 external variables have
separate source-specific status.
The Medicaid state-performance adapter refreshes eight Arkansas monthly
identities. Its latest published reporting period is June 2026; all eight
values are flagged preliminary. The official API provides period and revision
status but no row publication timestamp, so the first retrieval time is stored
as the known availability time. It prefers final updated rows for months where
both preliminary and final versions are present. The live refresh recorded 650
nonmissing values across 110 monthly periods and wrote no duplicates on a
repeat run.
The BLS adapter now refreshes three raw monthly series, 30 lag, difference,
and rolling identities, and six seasonal identities. Its lag and rolling
formulas were checked against 852 historical catalog values without a mismatch;
the seasonal baseline and anomaly were checked against all 210 historical
catalog values without a mismatch. The seasonal baseline uses all prior years
from the same calendar month, starting with 2000 observations. The adapter
requests official BLS v1 history in ten-year windows and retains gaps instead
of filling missing months. It published 2026-08 observations for all 39 IDs.
The CMS geographic-variation adapter checks nine national annual identities
against the official dataset. The source still ends at 2024, matching all
2023 and 2024 values already in the catalog. The worker records when it checked
the published rows without relabeling them as 2026 observations. A repeat run
wrote no duplicate values. The gap report now marks 56 external IDs as having
live source observations and six as having collapsed identity dimensions. A live-source status describes
the check, not the age of the upstream observation; read each row's period.
The two event-derived FDA IDs need identity repair before live publication:
`shortage_active` has one date with conflicting 0/1 values, and
`recall_active` has 92 such dates. Their current national IDs collapse
different event rows into one identity, so a single current value is not
well-defined. The API preserves and flags those conflicts.
The worker now writes additional `fda_shortage_status_current` identities at
the exact source generic-name grain. Each dated value is 1 when any FDA-listed
presentation for that name is `Current`, or 0 when its listed presentations
are all `Resolved` or `To Be Discontinued`. An absent source record remains
unknown. This is FDA listing context, not Arkansas inventory or demand, and
does not make the collapsed legacy `shortage_active` ID usable.
The four NADAC catalog IDs also collapse their original rate-classification
and pricing-unit dimensions. The January 2023 rows mix prices per each and
per millilitre. The daily worker now records the official 2026 NADAC snapshot
separately, preserving those dimensions. The first live snapshot is dated
2026-09-30 and contains 30,079 source rows in 11 groups. It is available at
`/api/v1/signals/sources/nadac/latest`; it does not replace the ambiguous
legacy catalog values with a made-up aggregate. All six collapsed IDs are
history-only; `/latest` reports `identity_dimensions_collapsed` for them.
Daily source capture updates matched external-variable IDs. The separate
annual claims baseline appends 2026 projections for 1,212 matching drug IDs
while retaining their 2025 forecast horizon in history.
The drug ranking endpoint selects only evaluated v2 runs; an older v1 run
may remain in the database for audit but cannot become the published ranking.
The worker does not
write current values for the 18 ATC or 20 news-model IDs. The historical ATC
rows came from the legacy pipeline's zero-filled live feature vector;
`/latest` omits them and `/history` marks them unusable. The 20 historical
news-model features remain in `/history`, marked as historical-only;
`/latest` omits them until a verified live refresh path exists. This prevents an FDA
shortage record or an article timestamp from being misrepresented as a drug
demand prediction.
The historical downstream fit code is recoverable from commit `d5e11df` and
now reads the canonical bundled news table through the model adapter. An
offline fit on 2026-10-07 succeeded with 20 news inputs (monthly history ends
2026-01), 18 Arkansas ATC classifier heads, and five CMS state classifiers
covering 1,368 drug keys. The CMS component is five shared one-vs-rest heads,
not 1,368 per-drug models. `build_state_demand_view` forms one-year
transitions and drops the last source year without a following label. Since
the local CMS source ends in 2024, the latest transition row has feature year
2023 and target year 2024. The old output fits on all those transitions and
predicts the latest row in-sample; it is not a held-out 2025 forecast and
cannot produce a 2026 value under that contract. The current public API
continues to publish the separately evaluated two-year CMS persistence
projection for 2024→2026. The integrated historical fit is therefore
reproducible, but not yet the live model service.
The `/latest` API returns `missing_details` for IDs without a usable value,
with a coverage reason and last recorded period; unknown IDs receive
`unknown_id`. Its separate `unusable_recorded_values` array lets callers
retrieve the absolute latest archived row without presenting it as a current
observation or valid demand estimate.
`latest_recorded_values` exposes the newest stored row for every requested ID,
even when an older validated row remains in `values`; callers must inspect
`usable` and `unusable_reason` before interpreting it.
The publication check is fail-closed: a newly inserted ATC or news-model row
with a different `source_kind` still remains unusable, and a Part D drug-model
row is eligible for `/latest` only with the evaluated
`cms_partd_two_year_persistence_v2` source kind. A future validated pipeline
must add an explicit reviewed promotion rule before its rows can be published.
Historical drug model states remain outside `/latest`'s `values` array until
the evaluated claims baseline has a corresponding row. They appear only in
`unusable_recorded_values`, so a partial or failed baseline run cannot
silently fall back to an old state.

The worker captures the official 2026 Arkansas State Drug Utilization Data as
a separate observed source. The first live snapshot contains only 2026 Q1. Of
22,703 NDC/utilization rows, 12,264 have suppressed prescription counts. The
API exposes the remaining reported count as a lower bound with the source
period and suppression count. The public signals page includes a collapsible,
searchable table of the latest quarter's reported product names, sorted by
that lower bound, with suppressed row counts visible. Names may be abbreviated
in the source. These quarterly statewide prescriptions cannot
be spliced into the monthly pharmacy-provider ATC target without a validated
cross-source model, so the 18 ATC outputs remain unpublished.
The checked-in NDC-to-ATC crosswalk covers only 2,236 of the 22,703 current
SDUD rows (9.8%), representing 44.9% of the reported, unsuppressed
prescriptions. It was built for the historical pharmacy-provider NDC set;
extending it requires a current, source-backed NLM mapping and an evaluated
bridge across the different target definitions.
A reproducible 24-month persistence stress test of the existing HHS/ATC panel
(`PYTHONPATH=model python model/scripts/audit_atc_24_month_baseline.py`)
compared 797 observed class-month pairs across all 18 IDs. It scored 40.5%
five-state accuracy, 35.2% balanced accuracy, and 122.4% weighted absolute
percentage error. Its source still ends in December 2024; this exploratory
proxy is not eligible for live publication. The separate research evaluator's
next-month score does not validate a nearly two-year gap to the present.

CMS currently labels **2024** as the latest available year for its Medicare
Part D Geography and Drug dataset. The local HHS Medicaid Provider Spending by
NDC artifact ends in **December 2024**; the [official federal release notice](https://www.govinfo.gov/content/pkg/FR-2026-07-23/pdf/2026-14947.pdf)
also defines that source's published claim window as January 2018–December
2024. Those sources cannot supply direct
2026 pharmacy demand observations. See the [CMS dataset](https://data.cms.gov/provider-summary-by-type-of-service/medicare-part-d-prescribers/medicare-part-d-prescribers-by-geography-and-drug)
and [HHS catalog](https://opendata.hhs.gov/). The old `model/prod_pipeline.py`
previously used a zero-filled ATC inference placeholder. That emission path is
now disabled; the script cannot overwrite its checked-in legacy example or
publish a live-looking forecast without a new, evaluated runner.

The legacy `model/artifacts/evaluation/publishability_audit.json` reports
`publishable: false` with 15 failed diagnostics. The current project auditor
explicitly treats that legacy report as nonblocking compatibility evidence;
it must not be presented as the sole reason the daily model is unavailable.
On 2026-10-05, rerunning `model/scripts/audit_project_status.py` against the
current artifacts independently returned `proxy_library_ready: false`,
`learned_architecture_ready: false`, and `project_complete: false`. Its
blocking failures were proxy coverage, the learned end-to-end accuracy
contract, and missing research-exhaustion evidence. A stricter rerun now also
rejects the operational forecast surface: it has 43,366 unique rows across 14
targets, but only the annual Part D target is qualified in the metric-library
audit. The other 13 targets retain stale qualified labels in that research
artifact; they cannot pass the project status gate. These results
do not prove that the forecast rows can be regenerated from today's inputs.
The historical metric feature-store and NADAC panel builders were restored
from repository history after model tests exposed their missing imports. The
feature-store key now includes therapeutic class and pathogen, preserving 52
ATC class rows that otherwise collided under the older key. On 2026-10-05,
the local ignored research forecast was found to contain 43,366 rows across 14 targets,
while the current metric audit qualifies only the annual Part D target. The
builder now requires that audit and fails if rejected targets are present
unless `--qualified-only` is explicit. The fixture packager records source and
audit hashes and writes only the 1,212 qualified rows to a tracked, 23 KB
forecast snapshot. CI verifies the fixture hashes and builds one feature from
it in a clean checkout; the filter behavior has a separate focused test.
This verifies an audit-qualified feature-store
transformation, not the model's live publishability.
The broader model research suite is not yet green: some tests still expect
proxy promotions that the checked-in metric audit now rejects, and many
research inputs remain unhydrated Git LFS pointers. Those tests and artifacts
need source-backed reconciliation before they can serve as a release gate.
**Current model inventory (2026-10-09):** the main model package is present at
`model/arkansas_pharma_signal/`, and a locally trained artifact is present at
`model/artifacts/trained/models.json`. It was trained in operational feature
mode against a 544,070-row panel covering 2013–2024. The artifact's own
input contract is not operationally ready: 56 near-real-time variables still
lack ready adapters, so the normal `forecast` command fails closed. The API
worker does not load this artifact today. The generated `model/artifacts/`
directory is ignored by Git, so this local trained file is not a portable or
versioned deployment artifact.
The model forecast commands now recompute source and feature readiness from
the artifact's trained feature list, require both that current audit and any
saved artifact gate to pass, and fail closed if the feature list is missing.
The 2026-10-09 retrain also corrected a label-leaking blend calibration in the
annual training command. A ridge model fit on all rows had been used to select
the validation blend weight. With a prior-years-only fit and identity encoder,
the held-out 2023 feature-year weight changed from 0.70 to 0.00 and validation
WAPE from the invalid 0.14609 to 0.14846. The corrected artifact remains
unpublishable because 56 source features are still unready. The standard
forecast command now requires a training-panel SHA-256 match and a saved
leakage-safe blend declaration as well as the source-readiness gate.
The annual forecast writer was also narrowed to its trained one-year horizon.
It now emits one `all_context` row per available city/drug target rather than
repeating identical predictions under disease names, leaves unsupported
intervals null, and omits shortage-risk outputs when no fitted risk model
exists. Its claims driver list is empty for the current zero-weight ridge
blend. This writer is still separate from the public API worker.

The saved artifact's 56 pending variables group into six source families.
These are the inputs that would need compatible, point-in-time feature
adapters before activating that annual city/drug model; the listed public
endpoints do not by themselves prove feature equivalence or model readiness.

| Pending feature family | Variables | Historical source or candidate API | Current integration gap |
| --- | ---: | --- | --- |
| FluView ILI | 4 | Delphi Epidata FluView ILINet V5 (`source=fluview_ilinet`) | The worker records three source-published Arkansas/national weekly series through 2026-10-03, with release times. A separate point-in-time bridge now computes complete-calendar-year candidates from captured rows and rejects partial years; it does not feed the saved model. The saved national annual builder groups by `issue` year: its 2024 rows actually cover epidemiological weeks 2022-40 through 2023-39. Live V5 observation-year means are therefore not drop-in equivalents and require model retraining. The fourth saved feature, `ar_wili_mean`, used a legacy state `wili` column copied from unweighted ILI; V5 does not publish state weighted ILI. The separate Arkansas annual source file is currently an unhydrated Git LFS pointer. |
| NNDSS disease reports | 12 | CDC NNDSS Weekly Data (`x9gk-5huc`) | The worker now stores the four numeric CDC fields separately for six exact disease labels and two geographies, retaining row update timestamps and missing cells. The first capture wrote 6,921 observations across 48 source-native IDs through MMWR week ending 2026-10-03. The saved model's annual feature builder takes a maximum across four unlike measures; a reviewed point-in-time replacement and retraining are still required. Arkansas source rows in this feed start in 2025. |
| Wastewater | 6 | CDC Wastewater Viral Activity Level (`atcp-73re`) | The worker now records six weekly unweighted reporting-site means and contributing site counts through 2026-10-03; the latest Arkansas means each have one site. These are not CDC's official state/national medians. CDC revised its WVAL method in August 2026 and recalibrated history, after the saved research file was captured, so the annual model features need source-compatible rebuilding and revalidation. |
| FDA shortage | 8 | openFDA drug shortages | Raw daily snapshots exist; the model's annual reason, event, and labeler features are not reconstructed or validated. |
| FDA enforcement/recall | 15 | openFDA drug enforcement | Complete dated 30-day report counts now exist. They do not equal the saved model's full-year, drug/labeler, keyword, and class features. Published status does not establish `recall_active`. |
| News article counts | 11 | FDA RSS plus GDELT DOC | Live FDA titles/summaries exist, but GDELT is currently rate limited and the historical corpus/keyword feature contract has no validated live equivalent. |

The candidate public feeds above do not require a mandatory API key in the
current configuration. `OPENFDA_API_KEY` can be supplied for regular FDA API
use. The local model artifact must also be packaged with a pinned checksum
and reevaluated after the feature builders and live data contract are fixed.

The separate historical `existing_models/news_signal_model` directory is
absent from the checkout. The original FLAN-T5 inference runner and matching
checkpoint for the dated 20-column news output have not been recovered. The
repository-wide search on 2026-10-05 examined hidden and ignored files, model
and data subtrees, Git LFS paths, reachable commits, and three recovered
checkpoint commits reported by `git fsck --no-reflogs --unreachable`. It
found a dated 97-row, 20-column news output CSV and completion metadata in
`6d13c14`, plus a recovery README in `d6ca4b7` explicitly stating that the
original inference code, weights, and validation artifacts were absent. The
current `news_signals.py` is a separate article-event feature layer; it does
not generate those 20 named news-model columns. The later local Ridge shadow
artifact is also a distinct replacement, not that historical generator.
The available GDELT article research corpus has 354 retained articles from
2023–2025, including 292 full-text rows, while the saved news signal table
contains 97 monthly observations from 2018–2026. That sampled corpus is not
the original monthly extraction input and cannot reproduce or validate its
20 outputs by itself. A replacement needs its own dated acquisition contract,
article-level category labels or other independent validation, and a measured
chronological evaluation before publication under a new model version.
The primary Arkansas model code and a local trained model are therefore
available, but they are not yet a live API model: the near-real-time input
adapters and operational contract must be completed before publication. The
exact historical article-to-20-signal generator remains a separate unresolved
component. A replacement must use a versioned acquisition contract and pass
chronological validation before its outputs can be published as usable signal
values.
To repeat the audit without replacing checked-in evidence:

```bash
PYTHONPATH=model website/.venv/bin/python model/scripts/audit_project_status.py --output /tmp/pulse-project-status.json
```

The Arkansas annual Part D five-state forecast currently uses the latest
published year's claim bucket as a next-year persistence state; its evaluation
reports identical 0.891 model and persistence accuracy. These artifacts do
not establish a validated 2026 drug-demand output, even though the historical
2025 states are useful as clearly dated public context.

A separate annual baseline job now reads the official Arkansas Part D
generic-drug claim file through 2024 and publishes **1,324 projections for
2026** to the public drug-ranking endpoint. It carries each drug's observed
claims category forward two years, with thresholds learned only from prior
published claim years. Four rolling holdouts (target years 2021–2024) achieved
84.2% mean balanced five-state accuracy. Training, validation, and test labels
respect the annual publication lag. The worker reruns the evaluation daily,
records the source SHA-256 and metrics, and writes no duplicate rows when the
source is unchanged. The bundled source manifest now pins its SHA-256, and
runtime source generations use a SHA-256 filename. Readers verify the file
bytes against that digest before evaluating, publishing, or backing up a
ranking. A mismatch fails the refresh and leaves the prior ranking in place.
The output is an annual Medicare Part D claims proxy,
not an estimate of current dispensing, pharmacy inventory, or units to order.
The drug-ranking API returns the four historical annual-claims cutoffs used to
assign its five ordinal states as `state_thresholds_claims`; it does not turn
those states into pharmacy purchase units.
The original 1,312 seed IDs and their historical records remain intact. The
1,212 matching drug IDs have an additional 2026 forecast-horizon record; 112
newer CMS drug outputs receive deterministic IDs when the evaluated baseline
is recorded. `/latest` selects the usable 2026 horizon, while `/history`
retains prior horizons. The current database therefore has 1,424 signal
definitions, including all 1,312 seed IDs and 1,324 uniquely identified drug
outputs.
This baseline does not clear the universal model audit or provide a daily
news-conditioned drug forecast. The new local 20-output Ridge runner can emit
shadow estimates from captured article text, but the original FLAN-T5 output
path remains absent and the downstream historical ATC fit is not promoted.
When a closed month has no captured text, the runner can now record a
month-to-date estimate targeted at that month's end. Those target-period rows
remain explicitly unusable and must not be treated as observations.

## Live inputs and keys

| Input | Current implementation | Credential needed |
| --- | --- | --- |
| [openFDA drug shortages](https://open.fda.gov/apis/drug/drugshortages/how-to-use-the-endpoint/) | Daily full snapshot, source `last_updated`, raw record JSON, record change dates, and an immutable membership list for each successful fetch. Pages are sorted by package NDC; changed revision/count, unstable page boundaries, and incomplete fetches fail closed. Exact duplicate source payloads are counted and stored once. The latest API view reads one complete fetch even when the source changes twice on the same UTC day. The worker also writes dated generic-name `Current` status indicators with stable IDs; the aggregate seed ID remains unusable. | A free `OPENFDA_API_KEY` is recommended for sustained deployment; the local two-page daily pull works without a key under [openFDA's lower unauthenticated limits](https://open.fda.gov/apis/authentication/). |
| [GDELT DOC 2.0](https://blog.gdeltproject.org/gdelt-doc-2-0-api-debuts/) | Daily recent article metadata, title relevance, and GDELT `seendate` (first seen by the feed; publisher publication time is not verified). The worker catches up at most 90 days in three-day windows, splits result-capped windows, and waits 10 seconds between follow-up requests (64-request hard limit). GDELT documents a rolling three-month search limit and warns that its DOC API is rate limited; this conservative delay has not yet been verified against a successful catch-up. HTTP 429 retry deadlines persist across schedule boundaries; without a valid header, the retry waits at least 24 hours. | No key for the DOC API, but outbound access to `api.gdeltproject.org` is needed. |
| [Delphi FluView ILINet V5](https://cmu-delphi.github.io/delphi-epidata/api/v5-signals/fluview_ilinet.html) | Daily complete source snapshot for Arkansas ILI, national ILI, and national weighted ILI. The backend records each Saturday observation with Delphi's release timestamp and retains revised values. The first capture wrote 3,673 dated source rows across three stable IDs, through 2026-10-03. State weighted ILI is absent from V5 and is not fabricated. These weekly surveillance inputs are not yet transformed into the saved annual model feature contract. | Anonymous public access works locally; an optional Delphi API token removes anonymous rate limits. |
| [CDC NNDSS Weekly Data](https://data.cdc.gov/NNDSS/NNDSS-Weekly-Data/x9gk-5huc) | Daily complete query for six saved disease labels across Arkansas and both historical U.S. resident labels. Current-week cases, previous-52-week maximum, current-year cumulative, and prior-year cumulative counts remain separate stable IDs. CDC's row update time and MMWR week end are retained; missing cells are skipped. Dataset revision metadata is checked before and after pagination. The first capture wrote 6,921 source rows through 2026-10-03. | Public Socrata API, no key required for this local query. |
| [CDC Wastewater Viral Activity Level](https://data.cdc.gov/Public-Health-Surveillance/CDC-Wastewater-Viral-Activity-Level-for-SARS-CoV-2/atcp-73re) | Daily source-side unweighted mean of numeric site WVAL rows by week and pathogen for Arkansas and all reporting U.S. sites. The six IDs include contributing-site counts in quality metadata; latest Arkansas coverage is one site per pathogen. These computed means match the historical file's aggregation rule but are not CDC's official geographic medians. Capture checks dataset revision before and after both queries and stores only changed mean/count pairs. The first capture wrote 1,323 rows through 2026-10-03. CDC's August 2026 method change prevents assuming numerical continuity with the saved model. | Public Socrata API, no key required for this local query. |
| [FDA Drugs RSS](https://www.fda.gov/about-fda/contact-fda/subscribe-podcasts-and-news-feeds) | Checked independently each day for recent FDA drug approval, recall, shortage, and safety event titles, even when GDELT fails. A named medicine can qualify without a generic “drug” keyword; generic approval-notification index pages are excluded. A feed update is not necessarily the date a medical event occurred. | No key. |
| [FDA MedWatch RSS](https://www.fda.gov/safety/medwatch-fda-safety-information-and-adverse-event-reporting-program/medwatch-rss-feed) | Checked independently for drug-keyword safety alerts. Device-only paths and items without drug terms are excluded; an empty three-day window stays empty. The RSS date is the feed item date, not a demand observation. | No key. |
| [FDA Recalls RSS](https://www.fda.gov/about-fda/contact-fda/subscribe-podcasts-and-news-feeds) | Checked independently for recent drug-related recall notices. Food-only notices are excluded. The RSS date is the feed item date, not a demand observation. | No key. |
| [FDA Press Releases RSS](https://www.fda.gov/about-fda/contact-fda/subscribe-podcasts-and-news-feeds) | Checked independently for recent drug-related announcements. Device-only and general regulatory releases are excluded. The RSS date is the feed item date, not a demand observation. | No key. |
| [BLS Public Data API](https://www.bls.gov/developers/api_faqs.htm) | Weekly poll of three published monthly series through unregistered v1; records source months and preliminary flags, and derives the catalog's preceding-observation lags, differences, rolling values, and same-month historical baselines/anomalies. The first retrieval time is stored because the response omits a publication timestamp. Failed refreshes write no partial BLS update and are omitted from general signal warnings. | No key for v1. The initial history backfill uses nine queries; later refreshes use three. A seven-day adapter cooldown protects every invocation path. |
| [Medicaid and CHIP enrollment and performance](https://data.medicaid.gov/dataset/6165f45b-ca93-5bb5-9d06-db29c692a360) | Daily poll of eight Arkansas monthly measures via the official data API. Preliminary and final revisions are distinguished; absent cells are skipped. The first retrieval time is stored because the row publication timestamp is unavailable. | No key for the public data API. |
| [CMS Medicare Geographic Variation](https://data.cms.gov/summary-statistics-on-use-and-payments/medicare-geographic-comparisons/medicare-geographic-variation-by-national-state-county) | Daily check of nine national annual catalog measures. The latest official year is 2024 as of this check; no 2025 or 2026 value is inferred. | Public data API, no key. |
| [NADAC 2026](https://data.medicaid.gov/dataset/fbb83258-11c7-47f5-8b18-5f8e79f7e704) | Daily full latest-date snapshot; computes rate counts and min/mean/max within each rate classification and pricing unit. It does not publish to four legacy IDs with collapsed dimensions. | No key for the public data API. Annual dataset ID rollover must be checked before 2027. |
| [CMS Part D Geography and Drug](https://data.cms.gov/provider-summary-by-type-of-service/medicare-part-d-prescribers/medicare-part-d-prescribers-by-geography-and-drug) | The daily worker checks CMS's `data.json` catalog for published annual CSVs and the latest CSV's `Last-Modified` header for same-URL revisions. It aggregates Arkansas state rows by generic drug and total claims, commits a versioned normalized panel through an atomic manifest pointer, then reruns the evaluated two-year persistence baseline. After an outage it imports every newer published year in order; unpublished years stay absent. As of this check, 2024 remains the latest release. The historical 20-news-feature downstream fit is trainable offline, but its source data ends in 2024 for CMS claims and its upstream live news inference path is absent. | Public download/API, no key required. |
| [HHS Medicaid Provider Spending by NDC](https://opendata.hhs.gov/datasets/medicaid-provider-spending-ndc/) | Historical local source through 2024-12. The official July 2026 release also describes coverage ending in December 2024; no 2025 or 2026 monthly claim line is inferred. | Public download, no key identified. |
| [CMS State Drug Utilization Data 2026](https://data.medicaid.gov/dataset/2957a7f9-9a15-453e-9afd-3bbdcbac8fd3) | The worker discovers the latest annual SDUD release from the official Medicaid metastore each day, then captures Arkansas rows by NDC and utilization type. It stores the catalog modification time, retrieval time, and separate content revisions. Suppressed counts remain unknown. On 2026-10-03 only Q1 was published: 22,703 Arkansas rows, 12,264 suppressed. The 1,368,827 reported prescriptions are a lower bound. This is a quarterly statewide Medicaid source, not the monthly pharmacy-provider target of the historical ATC model. | No key for the public data API. |
| CDC, NOAA, NWS, FEMA | Research-package adapters exist, but the 1,312-signal production refresh has not been connected and verified. | Check each official source's current access rules before deployment. |

Run `python -m scripts.audit_atc_bridge` from `website/` to compare the
latest stored Arkansas SDUD period with the manifest-verified historical
RxNorm/ATC crosswalk. For the 2026-Q1 snapshot checked on 2026-10-04, only
1,205 of 14,510 distinct SDUD NDCs (8.3%) map to an ATC group in that
crosswalk. Mapped rows account for 614,797 of 1,368,827 **reported**
prescriptions (44.9%); another 12,264 rows have suppressed, unknown counts.
All 18 target ATC groups appear somewhere in the mapped subset, but that does
not make the subset representative. The audit reports source and mapping
hashes and fails if the mapping no longer matches its source manifest. The
quarterly statewide prescription source differs from the historical monthly
pharmacy-provider claim-line target, so it cannot supply a valid current
feature vector for the 18 model IDs. This remains true even if the crosswalk
is expanded; source and outcome compatibility must be evaluated separately.

At the 2026-10-07 UTC check, GDELT's most recent scheduled attempt returned HTTP 429; FDA Drugs, MedWatch, Recalls, and Press RSS checks succeeded. The updated worker restarted at 02:29 UTC and its heartbeat was current. No GDELT request had run under the new pacing at that point.
During that 2026-10-07 check, the FDA Drugs feed succeeded and recorded one
recent drug-event item. A third adapter now reads the [official FDA MedWatch
RSS feed](https://www.fda.gov/safety/medwatch-fda-safety-information-and-adverse-event-reporting-program/medwatch-rss-feed)
and retains drug-keyword safety items, excluding device-only alerts.
The fourth adapter reads FDA's official Recalls RSS feed and retains drug-related
notices while excluding food-only recalls. Its first local run found no
qualifying items in the three-day display window.
The fifth adapter reads FDA's official Press Releases RSS feed and retains
drug-related announcements while excluding device-only releases.
The freshness endpoint keeps independent status for all five feeds; working
FDA feeds do not claim broad news coverage. Do not fill
the missing GDELT window with inferred articles or model-news values. A cloud
host should monitor `failed_sources` and verify its own access to GDELT before
depending on that feed for recent context.
For an operator-side check from `website/`, run
`python -m scripts.operational_status worker` to check the heartbeat and
`python -m scripts.operational_status sources` to fail on missing, stale, or
failed scheduled sources. The API's `/health` is process liveness, `/ready`
checks the catalog and database bootstrap, and
`/api/v1/signals/freshness` exposes per-source state for external monitoring.

On 2026-10-09 UTC, the live API health check returned `healthy`. The latest
GDELT attempt (02:24 UTC) returned HTTP 429; its last successful refresh was
2026-10-06 00:48 UTC. FDA Drugs, MedWatch, Recalls, and Press RSS checks
succeeded between 18:01 and 18:09 UTC. A month-to-date shadow run at
18:10 UTC wrote 20 estimates targeted at 2026-10-31 from eight captured
FDA Drugs and FDA Press articles. The API marks them `usable: false`; the target
date is not an observed period. The latest archived news output remains
2026-01-31. After the FluView and NNDSS captures, the API contains
1,770 definitions and 34,042 observations, plus ten article versions. The
57 new surveillance IDs contribute 11,917 dated source observations; they
do not change the fixed 1,312-ID seed catalog. The 44 NADAC group IDs have 88
dated rows across two official source snapshots, and the 240 FDA shortage
generic-name IDs have 1,186 dated rows across six UTC snapshot dates. The
latest FDA capture contains 238 generic-name values for 2026-10-09. Coverage classified
1,324 drug outputs as
evaluated two-year baseline projections, 18 ATC outputs as requiring a
current compatible source and validated rerun, six identities as collapsed,
and 56 source signals as having a recorded live observation. Of the 1,312
seeded IDs, `/api/v1/signals/latest` returned usable values for 1,268; the
other 44 are explicitly missing from usable output: 20 unvalidated news-model
shadows, 18 ATC outputs awaiting a compatible rerun, and six identities whose
catalog dimensions are collapsed. These counts are a point-in-time operational
snapshot, not a claim that every upstream source is complete through the
current date. No values were backfilled by interpolation or presented as
observations to close those gaps.

The six identity gaps are semantic, not merely stale-feed gaps. The four
NADAC seed metrics are defined with an empty drug entity, while the live
adapter returns separate groups by `classification_for_rate_setting` and
`pricing_unit`; merging those groups into one price value would mix unlike
units. The worker now publishes additional stable signal IDs at each
classification/unit grain, without changing the 1,312 seed IDs. The original
four aggregate seed rows remain unusable. The shortage and recall seed
indicators also have no drug entity, while their source records are
drug-level. The shortage source now has separate IDs for its exact generic
names and dated status semantics. The recall source still needs a validated
entity mapping and event/status definition. Do not make the aggregate seed
IDs usable by selecting an arbitrary group or drug.

On 2026-10-03, the worker downloaded the official 2024 CMS CSV once to verify
the previously imported normalized panel before trusting its modification
header. The Arkansas drug rows matched, so the source generation and forecast
values were unchanged. Future same-URL changes to that header trigger another
content check; a missing header requires a content check on each daily run.

Source adapters must preserve release and retrieval timestamps. A daily worker
may observe the same monthly or annual value repeatedly; it must not create a
new observation for every day without a new source record.
Worker schedules, source period checks, shortage snapshot days, and coverage
ages use the UTC calendar date, including when the laptop timezone differs.

## Private workspace and security

The React dashboard reads public signal history from the API for the selected
one-to-three-year window ending on the uploaded sales history's last date, or
trains without public signals when the user chooses zero years.
Sales and inventory CSVs are read by a Web Worker in the browser and trained there with
the pinned Pyodide XGBoost runtime. The frontend build vendors Pyodide 0.29.4
and its 12 locked package wheels, verifies each wheel against Pyodide's SHA-256
lockfile, and serves the runtime from the app's origin. Chromium training
succeeded with every outside-host request blocked. The current per-drug models
fit separate 1-, 7-, 14-, and 30-day targets using purged validation splits.
Public signals are eligible only when their recorded
source timestamp is no later than the feature date. Unusable article shadow
values and older catalog rows with unknown or later retrieval times are
excluded. Lagged dated inventory is a
required model feature; the latest balance drives the replenishment calculation.
When the sales CSV supplies `stockout_flag`, every training target
containing a marked stockout is excluded because observed sales were censored
by unavailable stock. If no uncensored target remains, training fails with an
explicit input error. Unmarked stockouts cannot be inferred from zero sales.
Selected public features are retained only when their model improves purged
holdout weighted absolute percentage error over the private sales and
inventory model; otherwise the plan uses private features alone. Saved plans
from earlier browser model versions require retraining.
The inventory CSV must cover at least 180 sales days per drug with a same-day
or previous-day snapshot. A single latest snapshot is rejected. Each row needs
a real date, and each drug's latest inventory date must equal its last sales date.
If a selected public-signal window yields no eligible features, the dashboard
states that explicitly while retaining the private-sales forecast and stock
plan.
The 14-day forecast and stock balance therefore share one starting day;
plans calculated under the earlier one-day tolerance require retraining.
Outstanding orders are counted only after their stated expected
arrival date; an order with unknown timing is shown but excluded from stock
coverage. The suggested order cannot be smaller than the largest forecast
shortfall through day 14. Saved plans from earlier inventory rules require
retraining before they can be displayed.
On 2026-10-04 UTC, an isolated Chromium end-to-end run used synthetic daily
sales and inventory files, selected one year of public signals, registered a
temporary account, fetched the catalog and eligible signal history, trained
the model, displayed a replenishment plan, and unlocked the encrypted saved
plan after a page reload. Request inspection found no private CSV content in
API POST bodies. This verifies the local preview path; it does not establish
cross-browser or cloud-container compatibility.

The private plan is encrypted on the device with **AES-256-GCM**, using a
**PBKDF2-SHA-256** key derived from the account password. It is stored in
IndexedDB, and a reload requires password unlock. Raw CSVs are not persisted
or sent to the API. The unlocked plan is bound to the authenticated username;
its first salt is created in one IndexedDB write transaction, and a revision
check rejects a stale tab's save instead of replacing a newer encrypted plan.
Account switches and logout clear the in-memory key, and a browser storage
event locks other open tabs. The browser rechecks the authenticated account
every minute and when the tab becomes visible. It locks after 15 minutes of
inactivity and cancels any active training when locked. A real Chromium check
confirmed that revoking the server session and simulating an idle interval
both returned the dashboard to its locked state. New server password hashes use
**Argon2id** with 19 MiB memory, two passes, and one lane;
the account database and its SQLite journal are owner-readable only (`0600`)
on the local Linux host;
legacy scrypt and bcrypt hashes are verified and upgraded after a successful
login without changing the account password. On 2026-10-05, 31 authentication
and API tests passed, including both legacy hash migrations; a live Chromium
run also passed registration, local training, encrypted reload, idle locking,
and session revocation with Argon2id enabled. A ten-sample laptop benchmark
measured a 97 ms median for hashing plus verification; cloud capacity still
needs measurement on the chosen host. Browser sessions use HttpOnly,
SameSite cookies with a double-submit CSRF check. The browser's `/auth/session`
and `/auth/register` responses contain no bearer token; `/auth/token` creates
a separate bearer session for explicit API clients and sets no browser cookie.
Logging out one session revokes that session only. Login attempts are rate limited, and
registration is limited to five attempts per source IP in 15 minutes. Login
uses both a five-attempt account/IP limit and a 30-attempt IP limit; checks
reserve an attempt atomically before password verification. Browser login and
signup reject cross-site Fetch Metadata and unlisted Origin headers. For a
cloud reverse proxy, set `PUBLIC_ORIGIN` to the exact public HTTPS origin and
use `CORS_ORIGINS=[]` for a same-origin frontend. The browser authentication
origin check then works even if the API sees the proxy's internal HTTP URL.
Other CORS origins may access public signal routes but cannot create browser
sessions; the private dashboard requires the configured same-origin frontend.
Set `TRUSTED_PROXY_IPS` or `TRUSTED_PROXY_HOSTNAMES` only to proxy peers that
overwrite `X-Real-IP`; never trust arbitrary client-supplied forwarding
headers. Compose trusts its `frontend` service name so per-IP signup and login
limits use the actual client address when requests pass through Nginx. If a
cloud load balancer sits in front of Nginx, configure Nginx's real-IP trust
for that balancer's exact address ranges before relying on per-client limits.
The API marks account responses `Cache-Control: no-store`. The local built
frontend preview and Compose Nginx serve a response-header CSP with
`frame-ancestors 'none'`, `X-Frame-Options: DENY`, MIME sniffing protection,
and restricted browser permissions. The Nginx policy is repeated in static
asset locations because their cache headers override inherited `add_header`
directives. Set a unique
`SECRET_KEY`, `PUBLIC_ORIGIN`, `ENVIRONMENT=production`, and `COOKIE_SECURE=true` behind HTTPS
before any hosted deployment.

For operator-assisted account recovery, run this from `website/` on the account
database host:

```bash
python -m scripts.reset_account_password USERNAME
```

The command prompts for a new password, requires an explicit `RESET`
confirmation, updates the Argon2id hash, clears failed-login attempts, and
revokes every active session for that account. It does not expose a public
password-reset endpoint. Saved browser plans are encrypted with the previous
password; if the user does not know it, the plan cannot be recovered and must
be retrained from their local sales and inventory files.

The old `/api/demand/*` server upload and training routes are disabled by
default. They can be enabled for local migration testing with
`ENABLE_LEGACY_SERVER_TRAINING=true`, but production configuration rejects
that setting. The current SQLite store and its versioned startup migrations
are scoped to a single API host with one persistent data volume. Before
running concurrent cloud API replicas, move to a shared database service such
as PostgreSQL and deploy database-native migration and connection-pooling
support; the SQLite file locks do not make a multi-host database safe.
Self-service account recovery, complete source refresh coverage,
monitoring/alert routing, and a deployment rehearsal remain open production
gates.
