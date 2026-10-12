# Deployment

Everything ships from CI. Nothing ships from a laptop.

That is not a style preference. Production sat three merges stale because
deploys were run manually with `vercel --prod`, and the working copy happened to
be on a feature branch nine commits behind `main` — so the command succeeded,
reported success, and published the wrong code. CI has no checkout to get wrong.

## What runs when

| Trigger              | Workflow         | Effect                                                          |
| -------------------- | ---------------- | --------------------------------------------------------------- |
| Draft PR             | `ci.yml`         | Static checks only (the `pnpm verify --fast` set)               |
| PR ready for review  | `ci.yml`         | Every check, then a preview deployment                          |
| Merge to `main`      | `ci.yml`         | Checks, then production deploys, then the "Version packages" PR |
| Merge the version PR | —                | Nothing ships. The bumps land on `main` and wait.               |
| Manual               | `publish.yml`    | Publishes to npm                                                |
| Manual               | `hq-indexes.yml` | Applies hq's MongoDB indexes                                    |

The gate set itself lives in `verify.yml`, a reusable workflow that `ci.yml` and
`publish.yml` both call. It used to be written out twice — `ci.yml` ran it on
every push, and `release.yml` ran nine of the same gates again on the same
commit, on a second runner — which cost a full extra machine per merge and was
free to drift apart the moment one file was edited and not the other.

**Nothing publishes on a merge.** Merging the version PR lands the bumps and
stops there; shipping is **Actions → Publish to npm → Run workflow**, on
purpose. The site can ship many times a day, but an npm release changes what
every existing consumer resolves to and should happen when someone decided it
would. Its **Mode** dropdown defaults to `publish`; pick `dry-run` to rehearse
every gate, pack every tarball and print `changeset publish-plan` without
shipping.

Every job past the gates declares `needs: [gates]`, so a red build can reach
neither production nor npm. This is the main reason deployment lives here rather than in
Vercel's own Git integration — that integration deploys on every push whether or
not the checks passed, which is the wrong default for a site publishing WCAG
conformance and healthcare guidance.

## CI runners

Every job runs on GitHub-hosted `ubuntu-latest`. The repository is public, and
for a public repository those runners cost nothing: a fresh 4-vCPU, 16 GB VM
per job, thrown away when the job ends.

From 17 September 2026 the jobs ran on self-hosted AWS EC2 runners. They came
off again when the repository went public, and **they must stay off while it
is public**.

### Why not self-hosted, on a public repository

A pull request from a fork runs the workflow files _from that pull request_.
Anyone can open one, change `runs-on` to our runner label, and run any command
they like on our EC2 instance: inside our VPC, holding the instance's IAM role
through the metadata service, and on a machine that may run someone else's job
next. Approving first-time contributors does not close this; after one
harmless PR, the next is not held for approval. GitHub's own guidance is not to
use self-hosted runners with public repositories.

It follows that editing `runs-on` in our workflows is not enough. The runners
themselves have to be unreachable from this repository:

- **Repository-level runners**: remove them in _Settings → Actions → Runners_,
  and disable the scale-up webhook so none are launched again.
- **Organisation-level runners**: put them in a runner group with _Allow public
  repositories_ turned off (the default), and do not grant this repository
  access to it.

If CI needs more speed than `ubuntu-latest` gives, use GitHub's larger hosted
runners (_Organisation settings → Actions → Runners → New GitHub-hosted
runner_). They are paid, but they are VMs GitHub throws away after each job.

### Moving back to EC2

Only if the repository is private again. Then:

1. **Labels.** Every job becomes
   `runs-on: [self-hosted, on-demand] # Must match your runner_extra_labels`.
   `self-hosted` is added by the runner itself, and `on-demand` must match
   `runner_extra_labels` in the AWS runner module. A job whose labels no runner
   carries queues forever and never fails. The jobs are `verify` (in
   `verify.yml`, the one that matters), the four deploy jobs and `version` in
   `ci.yml`, `publish.yml`, `codeql.yml`, `sbom.yml` and `hq-indexes.yml`.
   `grep -rn "runs-on" .github/workflows` lists them all.
2. **actionlint.** Declare each custom label in `.github/actionlint.yaml`. It
   is already there for `on-demand`; `pnpm lint:actions` fails on any label it
   does not know.
3. **Smoke test.** Run _Actions → Test AWS Runner_ (`test-spot-runner.yml`,
   manual only) first. It prints the host, checks outbound access, and reads
   the instance type through IMDSv2.
4. **Worker count.** The coverage step sets `VITEST_MAX_WORKERS: "3"`. Leave it
   unless the instance is known to have the memory for more. Uncapped on a
   16-vCPU instance, Vitest and Turbo together started ~150 Node processes, and
   runs failed with "Failed to start forks worker ... Timeout waiting for
   worker to respond" even though every test had passed.
5. **Instance image.** It needs passwordless `sudo apt-get` for `playwright
install-deps`, plus `git` and `curl`. Node and pnpm are installed per job by
   `.github/actions/setup` from `.nvmrc`, so the image does not need them.
6. **Cost per job.** Every job boots an instance, so fewer, larger jobs are
   cheaper. This is why the two scans live inside `verify` rather than in jobs
   of their own. Job timeouts include boot time.

## Secrets and variables

Set under **Settings → Secrets and variables → Actions**.

| Name                   | Kind     | Needed for  | Notes                                                                                  |
| ---------------------- | -------- | ----------- | -------------------------------------------------------------------------------------- |
| `VERCEL_TOKEN`         | secret   | all deploys | Vercel → Account Settings → Tokens. Scope it to the team.                              |
| `VERCEL_PROJECT_ID_HQ` | variable | hq deploys  | From `apps/hq/.vercel/project.json` after linking. The hq job skips until this exists. |
| `HQ_DATABASE_URL`      | secret   | indexes     | Connection string for the `hq`-scoped database user — see below.                       |
| `NPM_TOKEN`            | secret   | npm publish | Optional — see below.                                                                  |

The Vercel org and docs project IDs are in `ci.yml` in plain text on purpose.
They are identifiers, not credentials: they sit in `.vercel/project.json` on
every machine that has ever run `vercel link`. Treating them as secrets adds
setup friction and protects nothing.

### npm publishing

Preferred is **trusted publishing** (OIDC): configure it per package in the npm
UI against this repository, and `NPM_TOKEN` can stay unset. Nothing is stored,
nothing expires, and npm attests the tarball came from this repo at this commit.

Two limits decide how the first release has to work. Trusted publishing
authenticates with an OIDC token that only a CI runner can mint, so it cannot
publish from a laptop at all; and it is configured per package under Packages →
the package → Settings → Trusted publishing, which requires the package to
already exist. All 28 of ours are new, so OIDC cannot perform their first
publish however it is set up. A granular access token with _Bypass two-factor
authentication_ is the only way to bootstrap them.

That bootstrap credential is on a clock. npm is deprecating direct publishing
with bypass-2FA tokens: since August 2026 they can no longer perform
account-identity or governance actions, and **the ability to publish with one
is removed in January 2027**. The trigger was Mini Shai-Hulud, where a single
stolen token pushed 639 malicious versions across 323 packages in 22 minutes.

So the token is a one-time bootstrap, not the steady state. Configure trusted
publishing on all 28 packages as soon as the first release lands, then revoke
it. Leaving the migration until the deadline means doing it under time pressure
across 28 packages at once.

### pnpm cannot do OIDC or provenance, and changesets picks pnpm

This is the constraint that shapes the whole release design, so it is worth
stating plainly. `changeset publish` chooses its publish tool by detecting the
workspace — `getPublishTool` in `@changesets/cli` returns pnpm here — and
`pnpm publish --help` on 9.15.4 offers only `--access`, `--otp` and `--tag`.
There is no `--provenance` and no OIDC.

Two consequences, both easy to miss because neither fails loudly:

- `NPM_CONFIG_PROVENANCE` is inert. It has been set in the publish workflow since
  provenance was introduced, and no release has ever been attested, because the
  tool reading it was never npm.
- Configuring trusted publishing and deleting `NPM_TOKEN` would break the
  release outright. pnpm would have no credential and no way to mint one.

Swapping to `npm publish` is not the fix either: `publishConfig`'s rewrite of
`main`, `types` and `exports` to `./dist` is a pnpm feature that npm ignores, so
npm would publish entry points still pointing at `./src/index.ts`.

The way out is that `pnpm pack` bakes the rewritten manifest _into the tarball_ —
verified: the tarball for `@zoblocks/intl` carries `main: ./dist/index.js`. A
tarball published by npm keeps the manifest it already has. So packing with pnpm
and publishing that tarball with npm gets both halves: pnpm resolves the
workspace ranges and applies `publishConfig`, npm supplies OIDC and provenance.

Upgrading to pnpm 10, which did support OIDC, is the other option. Note that
pnpm 11 regressed it, so that route needs a version pin and a watch on the
upstream issue.

Until one of those lands, CI publishes with `NPM_TOKEN` and ships unattested.

Before any release: `pnpm gen && pnpm build && pnpm release:check`. It packs
every publishable package with pnpm and fails on a missing README or LICENSE, an
entry point absent from the tarball, a leftover `workspace:` range, test files,
or an import Node cannot resolve. `gen` comes first because `@zoblocks/mcp`
bundles the generated catalog manifest; its own `scripts/check-tarball.mjs`
fails a bundled catalog that does not match the one `gen` just wrote, and its
build is never cached (`turbo.json`) so a cache hit cannot restore a stale one. CI and `publish.yml` run the same script — and
`publish.yml` runs it even under `skip-checks`, because it is the one assertion
that is about the artifact rather than about the source.

### The `@zoblocks` scope is not the `zoworkhq` org

An npm scope maps one-to-one onto the account of the same name. Owning the
`zoworkhq` org grants `@zoworkhq/*` and nothing else, so `@zoblocks/react` needs
an account literally named `zoblocks` — there is no way to alias one scope onto
another org, and no setting that grants it.

Orgs are free for unlimited public packages, so the fix is to create a second
one named `zoblocks` and publish under that. Renaming the packages instead would
mean rewriting the scope in about 570 files and would leave the docs site, the
registry and the `zoblocks` CLI binary reading as a different product.

### Provenance needs the repository names to agree

Every manifest declares `repository.url` as `github.com/zoworkhq/zoblocks`, and
the repository is still called `zoworkhq/oxygenui`. npm attests provenance <!-- rename-sweep-exempt: the repository's actual name until it is renamed -->
against the repository that built the tarball and the registry rejects an
attestation that names a different one, so asking for provenance while the two
disagree fails the publish rather than skipping the attestation.

`publish.yml` therefore reads the declared repository, compares it with the one
running the job, and sets `NPM_CONFIG_PROVENANCE` from the result. Releases ship
unattested with a warning in the log until the repository is renamed, and
attestation turns itself back on the moment it is — no workflow edit, and no
window where a release quietly ships unattested because a flag was left off.

Publishing from a laptop is unattested either way: provenance requires the OIDC
token only a CI run holds.

### Publishing from a developer machine

The first release is being cut by hand, before CI holds any credential. `pnpm
release` is the same path the workflow takes — build, inspect every tarball,
then `changeset publish`.

1. **Log in.** `npm login`, then `npm whoami` to confirm. `npm org ls zoblocks`
   should list you.
2. **Version.** `pnpm changeset version`. This consumes the pending changesets
   and writes the CHANGELOG entries. Do it before publishing, not after: the
   changes those changesets describe are already in the code, so publishing
   first ships them under a version whose changelog does not mention them.
3. **Prove the permission on one package.** `pnpm gen && pnpm build`, then
   `cd packages/intl && pnpm publish --access public --no-git-checks`.

   pnpm, never npm — `publishConfig` here rewrites `main`, `types` and
   `exports` to `./dist`, and that rewrite is a pnpm feature. npm honours only
   `access`, `registry`, `tag` and `provenance`, so an `npm publish` ships
   entry points still pointing at `./src/index.ts` and breaks every consumer
   that does not compile TypeScript out of `node_modules`. `--no-git-checks`
   because step 2 has just left version bumps uncommitted in the tree.

   `intl` is one of six packages carrying a `prepublishOnly` guard that refuses
   npm outright; the other 21 would publish a broken tarball without complaint.
   `pnpm release` is safe for all 28 whatever the guard says — `changeset
publish` detects the workspace and shells out to `pnpm publish` — so the gap
   only bites a hand-run `npm publish`, which is to say this step.

   This release creates 28 packages that do not yet exist, and creating a
   package is a different permission from publishing a new version of one. An
   account with developer rather than admin rights on the org is exactly where
   that distinction bites, and `changeset publish` walks the packages one at a
   time: a permission error partway leaves some of the 28 on npm and the rest
   not. A published version cannot be replaced, and an unpublished name is
   blocked for 24 hours, so an aborted run is genuinely awkward to redo.

   `intl` is the cheapest probe — eight files, no `@zoblocks` dependencies, so
   it can go first without anything else being on the registry yet. A 403 here
   means ask an org owner for publish rights; nothing else has moved.

4. **Publish the rest.** `pnpm release`. It skips `intl`, whose version is now
   on the registry, and publishes the other 26. Commit the version bumps
   afterwards.
5. **Check.** `npm view @zoblocks/cli version`, then
   `npx @zoblocks/cli@latest add pulse-loader` in an empty directory.

If the account has 2FA set to "authorization and writes", `changeset publish`
will prompt for an OTP once per package — 28 times. Either set 2FA to
"authorization only" for the duration, or publish with a granular access token,
which is exempt.

Everything after this first release should go through CI, which runs gates a
laptop does not.

### First publish through CI

Nothing is on npm under this scope yet, so trusted publishing cannot be set up
first. In order:

1. **Token.** On npmjs.com, create a granular access token: read and write,
   scoped to the `@zoblocks` org, 7-day expiry. Add it as the `NPM_TOKEN`
   repository secret.
2. **Version PR.** Either tick _Settings → Actions → General → Allow GitHub
   Actions to create and approve pull requests_, or open the PR by hand from the
   `changeset-release/main` branch the version job pushes. Check every package
   reads `0.2.0` (`fhir` included) before merging.
3. **Merge it, then publish.** Merging only lands the bumps. Run **Actions →
   Publish to npm → Run workflow** to ship all 28 packages — with provenance
   only once the repository rename above has landed. A `dry-run` first tells you
   exactly which versions the registry does not have yet.
4. **Check.** `npm view @zoblocks/cli version` and
   `npx @zoblocks/cli@latest add pulse-loader` in an empty project.
5. **Switch to OIDC.** For each package on npmjs.com, add a trusted publisher:
   repository `zoworkhq/zoblocks`, workflow `publish.yml`. Then delete
   `NPM_TOKEN` and revoke the token.

There is no old scope to retire. This step used to say to `npm deprecate` the
two pre-rename packages named in `.changeset/the-rename.md`; that changeset has
since been consumed, and `@oxygenui/intl` and `@oxygenui-design/react` both <!-- rename-sweep-exempt: names the retired packages -->
return 404 on the registry — the rename happened before anything was ever
published. `@zoblocks/codemod` still rewrites those imports, which is worth
keeping for anyone who used the packages from source, but nothing on npm needs
deprecating.

## Setting up hq

hq is a **separate Vercel project** on the same repository:

1. Create the project, Root Directory **`apps/hq`**.
2. Set `DATABASE_URL` in its environment to a connection string for a database
   user **scoped to the `hq` database** — see below. hq always opens the
   database named `hq` inside that cluster, never the site's, so the two cannot
   collide.
3. Move the `hq.zoblocks.design` domain onto it. It is currently attached to the
   docs project, which would serve the marketing site from that hostname.
4. Add `VERCEL_PROJECT_ID_HQ` and `HQ_DATABASE_URL` to the repository.
5. Run `hq-indexes` once, then merge to `main`.

Both projects must have their Root Directory set explicitly. With two apps in
one repository, a project that defaults to the root builds the wrong app.

hq's `vercel.json` pins its functions to `bom1`, next to the Atlas cluster in
`ap-south-1`. That is load-bearing, not a preference — on the default region the
functions ran in Virginia and every query crossed the Atlantic twice. See
[apps/hq/README.md](apps/hq/README.md#why-verceljson-pins-the-region-to-bom1).
The docs site is unaffected: it is static and served from the edge cache.

### The database user hq should hold

hq currently shares the marketing site's Atlas credential. That credential can
read and write the site's Payload database, so the blast radius of a bug or a
leak in hq is the production website's content — a scope hq has no reason to
have, and one that is invisible until it matters.

Fixing it is one Atlas user. **Create it yourself** — it involves choosing a
password, which is not something to hand to a tool or paste into a chat.

In Atlas → **Database Access → Add New Database User**:

- Authentication: password. Generate one; do not reuse the site's.
- Built-in role: **Read and write to any database** → change to **Specific
  Privileges**, granting `readWrite` on database `hq` only.
- Restrict to the same network access list the site user uses.

`readWrite` on `hq` is exactly the privilege hq needs and no more. That is not
a guess — the surface is small and checkable:

| Fact                                            | Where                                                                            |
| ----------------------------------------------- | -------------------------------------------------------------------------------- |
| One database, named in code, never from the URI | a single `client.db(DB_NAME)` in `apps/hq/src/db/client.ts`                      |
| Six collections                                 | `users`, `sessions`, `tasks`, `comments`, `activity`, `counters`                 |
| Reads and writes documents                      | `findOne`, `countDocuments`, `insert*`, `update*`, `delete*`, `findOneAndUpdate` |
| Creates its own indexes                         | `ensureIndexes`, run by the `hq-indexes` workflow                                |

No aggregation, no `dropDatabase`, no administrative commands, and no second
database — so nothing here needs a role broader than `readWrite`, and index
creation is already inside it.

Then, in order:

1. Update `DATABASE_URL` in the hq Vercel project (all environments) to the new
   string. Keep the `hq` database name in the path or leave it off — the code
   ignores it either way.
2. Update the `HQ_DATABASE_URL` repository secret, which the indexes workflow
   uses.
3. Redeploy hq and sign in once to confirm.
4. Only then, rotate the site credential hq was borrowing. Until that rotation
   the old credential is still valid and still known to two systems.

## What the deploy jobs assert

A 200 response is not evidence that a deploy worked. Both production jobs check
the thing that would actually be broken:

- **docs** — fetches the deployed registry and fails unless it references
  `@zoblocks/fhir` _and_ the dependency is version-pinned. A stale or
  malformed registry is a broken install for every customer, and it is precisely
  what went unnoticed for three merges. It then runs
  `scripts/check-agent-endpoints.mjs` against what coding agents read — see
  [Coding agents](#coding-agents-the-mcp-server-and-skill).
- **hq** — requests `/tasks` signed out and fails unless it redirects. A wrong
  Root Directory would serve the marketing site from `hq.zoblocks.design`, and
  that redirect is what distinguishes them.

The release job inspects the tarball before publishing: entry points present,
README and LICENSE present, no test files, no extensionless relative imports in
`dist`. Each of those is a defect that actually shipped in `0.1.0`.

## Coding agents: the MCP server and skill

ADR 0017. Three things are served by the docs site and one is on npm:

| What                | Where                              | Made by                    | Read by                          |
| ------------------- | ---------------------------------- | -------------------------- | -------------------------------- |
| Catalog manifest    | `zoblocks.design/ai/manifest.json` | `pnpm gen`, at build       | `@zoblocks/mcp` on start         |
| Skill bundle        | `zoblocks.design/ai/skill.json`    | `pnpm gen`, from `skills/` | anything that wants it whole     |
| Remote MCP endpoint | `zoblocks.design/mcp`              | `apps/docs/src/app/mcp`    | agents `mcp init` set up         |
| Local MCP server    | `npx -y @zoblocks/mcp`             | `packages/mcp`, via npm    | agents `mcp init --local` set up |

### Release order

The site first, then npm. `zoblocks mcp init` writes the `/mcp` URL into an
agent's config, and `@zoblocks/mcp` fetches the manifest, so a release that
ships ahead of the deploy points agents at URLs that do not answer yet.
`zoblocks skill add` is not in this: it writes the skill bundled in the CLI
(`packages/cli/src/generated/skill.ts`, from `pnpm gen`) and never fetches,
so the skill reaches users with a CLI release.

1. Merge to `main`. The docs deploy runs `check-agent-endpoints.mjs` against
   production: the manifest is in the schema this commit's server reads and
   lists every component `registry.json` ships, the served skill bundle is
   well-formed, and `/mcp` answers a handshake, lists the seven tools as
   read-only, finds `switch` for "toggle", and refuses a foreign Origin.
2. Merge the Version PR.
3. **Publish to npm.** `publish.yml` runs the same check before it publishes,
   and stops if the site is not serving those URLs. `pnpm release:check-site`
   runs it from a laptop.
4. Update the MCP Registry listing (below).

### `@zoblocks/mcp` is the 28th package

It is new, so everything under [npm publishing](#npm-publishing) about the
first release applies to it: the bootstrap token publishes it once, then
configure trusted publishing for it like the others. If the other 27 are
already out when it ships, it is the only one the token needs to create.

### What reaches agents without a release

The catalog. A component change goes `pnpm gen` → merge → deploy, and the
remote endpoint serves it at once; the local server fetches the live manifest
on every start and only falls back to the snapshot bundled in its tarball when
offline or unreachable. `/ai/*` is cached for an hour at the edge, like `/r/*`.

A new npm version of `@zoblocks/mcp` is needed only when the server itself
changes — a tool, its input, the instructions — or the schema does.

### Changing the manifest schema

`schemaVersion` in the manifest, and `SUPPORTED_SCHEMA_VERSION` in
`packages/mcp/src/manifest.ts`, change only for a change an existing server
would misread: a field removed, renamed or given a new meaning. Adding a field
is not one — the server's schema is loose and ignores what it does not know.

A server that meets a newer schema logs that it is out of date, names the
upgrade, and serves its bundled snapshot rather than failing. So a schema bump
is safe for users who have not updated, but they get a frozen catalog until
they do. Bump both together, release `@zoblocks/mcp` in the same release, and
the post-deploy check will fail any deploy where the two disagree.

### The MCP Registry listing

`packages/mcp/server.json` lists the package and the remote endpoint in the
official [MCP Registry](https://registry.modelcontextprotocol.io). It is named
`design.zoblocks/mcp` — a namespace proven by owning `zoblocks.design`, not by
the GitHub org, whose repository name does not match the manifests yet (see
above). The registry checks that `mcpName` in the _published_ `package.json`
equals that name, so the listing can only go up after the npm publish.

`pnpm version-packages` (and the Version PR) keeps its version in step with the
package; `test/mcp-registry.test.ts` fails if they drift.

Listing is manual, from a laptop, and public — decide before doing it:

```bash
mcp-publisher login dns --domain zoblocks.design --private-key <hex>
cd packages/mcp && mcp-publisher publish
```

The first time, generate an Ed25519 key pair and add the TXT record
`v=MCPv1; k=ed25519; p=<public key>` at the apex of `zoblocks.design`. The
private key is a credential: keep it in a password manager, not the repository.
Re-run `publish` after each `@zoblocks/mcp` release.

### Before a release

`pnpm ai-evals` (from your own terminal — it runs Claude Code headless) grades
an agent on five prompts against the tools and skill, and `pnpm ai-evals
--baseline` without them. Run both after changing the skill, the server's
instructions or tool descriptions, and compare. It needs a built
`@zoblocks/mcp`, and is not part of CI: it spends model tokens.

## Indexes

`hq-indexes` is manual and requires typing `apply` to confirm. Mongo has no
schema to migrate — collections appear on first write — so the only thing
applied deliberately is the indexes.

Two of them are correctness, not performance:

- `users.emailLower` unique — stops `Ada@` and `ada@` becoming two accounts,
  which would silently split one person's task list in two.
- `tasks.ref` unique — stops two tasks both being called `HQ-42`.

A unique index **fails to build if existing data already violates it**, which is
the one case worth watching rather than firing and walking away.

Three more are TTL indexes, and they replace cleanup the SQL version needed a
sweep for: sessions, reset grants, and failed sign-in attempts expire on their
own.

## Rollback

Vercel keeps every deployment. Promote a previous one from the dashboard, or:

```bash
vercel rollback <deployment-url>
```

Rolling back code does not roll back the database. Documents written under the
new code keep whatever shape it gave them, and Mongo will not complain — so a
rollback that matters is a forward fix, not a reversal.
