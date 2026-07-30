# image-generator

Standalone microservice that renders pet NFT art. A pet's DNA is decoded into
visual traits, those traits build a fixed prompt, and Cloudflare Workers AI
turns the prompt into an image. See
[`docs/plan-future-features-roadmap.md`](../docs/plan-future-features-roadmap.md) §9
for the design rationale.

## The one hard constraint: generate once, then never again

DNA -> traits -> prompt is exact integer math and reproducible forever. The
diffusion step is not: the same prompt and seed give the same image only for one
model version on one provider, so a model deprecation or a silent weights update
would change what an already-minted NFT looks like. Every generated image must
therefore be written to immutable content-addressed storage on first request and
served from there afterwards. Regenerating on cache miss is a correctness bug,
not a performance one.

That also happens to fit the free allocation: Workers AI bills per request, so
one image per pet for the lifetime of the pet keeps a collection's cost bounded
by the number of pets rather than by traffic.

## Why it is a separate package

It shares no code with `backend`, `frontend`, or `shared`, and nothing in the
monorepo imports it. That is deliberate: the service is deployable and testable
on its own, and work here does not touch files other branches are editing. The
one thing it re-implements is `digitPair` (two-digit decimal slicing of DNA,
canonically `contracts/ethereum/src/DnaLib.sol`); it is not combat math, so
there is no golden-vector obligation and nothing to drift.

## Status

Built incrementally. Done so far:

- [x] DNA -> visual trait derivation (`src/traits.ts`)
- [x] Traits -> deterministic prompt and seed (`src/prompt.ts`)
- [x] Cloudflare Workers AI client and `pnpm generate` CLI (`src/workersAi.ts`)
- [x] Immutable image store: R2, filesystem, memory (`src/store.ts`, `src/r2Store.ts`)
- [x] Generate-once pipeline with in-flight dedupe (`src/pipeline.ts`)
- [x] On-chain reads: tokenId -> dna/rarity/speciesId (`src/chain.ts`)
- [x] HTTP surface and ERC-721 metadata (`src/routes.ts`, `src/metadata.ts`)
- [x] Deployment: `Dockerfile`, plus the Render block in Deployment below
- [x] `PetCore.tokenURI` can be pointed here (owner-settable base URI)
- [x] Burst handling: retry with backoff, bounded concurrency (`src/retry.ts`)
- [x] Chain-agnostic routing, ready for a second reader (`src/readerRouter.ts`)
- [ ] A live generation run: no real image has been produced yet
- [ ] A Solana reader. Pets are addressed by their Metaplex Core asset pubkey
      (`PetAccount` PDA seeds are `[b"pet", asset]`) and `species_id` is `0` until
      species pools land there, which must be treated as *unset* or every Solana
      pet gets the same body. Undecided: whether to take a `@solana/web3.js`
      dependency or hand-roll the JSON-RPC call and account decode.

The Workers AI and R2 request/response shapes are written against Cloudflare's
documented contracts and covered by mocked tests only. The first live
`pnpm generate` against a real bucket is what actually validates them.

## Traits

Every visual trait comes from its own DNA digit pair, so changing one look does
not disturb another:

| Trait | Source | Range |
| --- | --- | --- |
| `element` | pair 0 % 6 | 6 palette families |
| `body` | `speciesId % 8`, else pair 6 % 8 | 8 silhouettes, aligned to the 8 skill archetypes |
| `pattern` | pair 7 % 5 | 5 coats |
| `eyes` | pair 7 / 5 % 4 | 4 eye styles |
| `marking` | pair 7 / 20 % 5 | 5 face markings |
| `aura` | rarity - 1 | 5 frame/glow tiers |
| `build` | HP gene (pair 1) | 0-99 body girth |
| `spark` | INT gene (pair 4) | 0-99 eye/aura intensity |

Cosmetic pair 7 decomposes exactly (5 x 4 x 5 = 100), so all 100 of its values
map to a distinct pattern/eye/marking combination. Pair 6 is already spent on
species at mint time (`PetCore._resolveSpecies`), so the HP and INT genes supply
the remaining per-pet variation. Art reads DNA and never feeds back into combat.

## HTTP surface

| Route | Purpose |
| --- | --- |
| `GET /health` | Store and model in use |
| `GET /image/:chain/:tokenId.png` | The pet's art. Generates on first request, cached forever after. 302s to the bucket when `R2_PUBLIC_BASE_URL` is set |
| `GET /metadata/:chain/:tokenId` | ERC-721 metadata, what `tokenURI` should point at |

`:chain` is `evm` today, but the routing is chain-agnostic: identifiers pass
through as strings and each reader validates its own format, because a pet id is
decimal on EVM and a base58 Core asset pubkey on Solana. `createReaderRouter` is
where a second reader plugs in, and it separates two failures worth keeping apart:
an unimplemented chain is a permanent 400, while a supported chain this deployment
has no credentials for is a 501, an operator problem rather than a caller one.

One trap in that identifier pattern: it accepts alphanumerics rather than the
base58 alphabet, because base58 excludes `0` and would 404 every EVM pet whose id
contains one.

**Metadata never triggers generation.** A marketplace indexing a whole
collection hits every metadata URL at once; if that generated images it would
bill thousands of inferences in a burst. Art is generated when an image is first
actually fetched.

Token ids are resolved by reading `PetCore.getPet` directly over RPC, not via the
backend. The backend's roster is an indexer projection that can lag, and a wrong
`dna` here does not render a slightly stale pet, it renders a *different* pet and
then caches that mistake permanently.

One sharp edge in that contract: **`getPet` has no `entryExists` modifier.** It
reads the mapping directly, so an unminted tokenId returns a zero-valued struct
rather than reverting. Taken at face value that would generate art for a pet that
does not exist and cache it forever, so existence is checked against
`totalPets()`, mirroring PetCore's own `petId > 0 && petId <= _petCount`. The two
calls are issued in parallel, so the check costs an extra `eth_call` and no extra
latency.

Status codes are deliberately distinguishable: 404 unminted pet, 400 bad chain or
token id, 502 Workers AI failure (nothing was cached, so a retry can succeed).

## Storage

`IMAGE_STORE` selects the backend: `r2` (production), `filesystem` (dev), or
`memory` (tests and one-shot CLI runs; never persists). All three implement the
same two-method `ImageStore` interface, so an IPFS or Arweave pin can be added
later without touching the pipeline.

**The key is derived from a pet's art identity — `(dna, rarity, speciesId)` —
not from the prompt.** That distinction is the whole point. Keying on the prompt
would mean any wording tweak in `prompt.ts` becomes a cache miss and a brand-new
image for a pet somebody already owns. Keying on identity means an existing pet
keeps its art however much the prompt table later evolves. Pets with identical
dna, rarity, and species are identical by construction, so they share a key and
one generation covers both.

Regenerating art for existing pets is therefore an explicit decision: bump
`ART_VERSION` in `src/store.ts`. Keys are namespaced by version, so old art stays
readable and a bump can be rolled back. Every owner sees their pet change, which
makes it a product call, not a refactor.

Each image is written alongside a JSON manifest recording the traits, model,
prompt, seed, and timestamp that produced it. Once a model version moves on, that
manifest is the only record of how a given pet came to look the way it does.

## Burst behaviour

Image generation is a paid, rate-limited upstream, and the natural access pattern
is bursty: a marketplace loading a collection's images arrives as N requests at
once. Three things keep that from turning into N failures.

- **Bounded concurrency** (`CF_MAX_CONCURRENT`, default 2). Excess callers queue
  rather than fail, because waiting a few seconds beats being told a pet has no
  image. Deliberately low: the free allocation is small and the queue drains fast.
- **Retry with backoff** (`CF_MAX_ATTEMPTS`, default 3) on 429 and 5xx, honouring
  `Retry-After` when the upstream sends one, capped so a hostile value cannot pin a
  request open. A 4xx other than 429 is not retried: the request itself is wrong,
  so another attempt buys the same error. Retrying a 429 is free (a rejected
  request was never billed); a 5xx may have been billed, which is the honest cost.
- **Bounded total spend.** Nonexistent pets are rejected before generation, so the
  lifetime inference count is bounded by the number of minted pets, not by traffic.

Concurrent first-ever requests for the same pet are collapsed into one
generation, so a pet's page open in two tabs bills one inference rather than two.
The dedupe is per process; with several instances the race is still possible, and
the honest bound is that R2 resolves it last-write-wins and the pet is stable
from then on. A shared lock is only worth adding if that shows up in practice.

## Commands

Run from this directory. The service is deliberately *not* a member of the root
`pnpm-workspace.yaml`, so it keeps its own `pnpm-lock.yaml` and needs
`--ignore-workspace` on install; a plain `pnpm install` here walks up to the
monorepo root and installs that instead, leaving this package with no
`node_modules`. `pnpm --filter` from the repo root does not reach it either.

```bash
pnpm install --ignore-workspace
pnpm test          # vitest
pnpm lint          # eslint
pnpm build         # tsc -> dist/
pnpm typecheck     # tsc including the specs, which build/ excludes
pnpm dev           # watch mode on :8787
pnpm start         # run the built server

# One-shot generation. Prints traits, seed, and prompt before it needs
# credentials, so prompt wording can be iterated on with no token set.
cp env.example .env   # then fill in CF_ACCOUNT_ID / CF_API_TOKEN
pnpm generate --dna=7934056188134207 --rarity=3 --out=pet.png

# Defaults to the filesystem store, so running the same pet twice serves the
# second from cache and bills nothing. --store=memory forces a fresh inference.
pnpm generate --dna=7934056188134207 --rarity=3 --store=memory
```

## Model choice

Default is `@cf/bytedance/stable-diffusion-xl-lightning`. It takes an explicit
`seed`, so a pet's image is re-derivable from its DNA, and it is tuned for 4-8
steps, which keeps free-allocation usage low.
`@cf/black-forest-labs/flux-1-schnell` also works via `CF_IMAGE_MODEL`: it
returns base64 in a JSON envelope instead of raw PNG bytes and rejects SDXL's
extra knobs, and the client handles both. No LLM is involved anywhere; prompts
come from a lookup table, because an LLM would add nondeterminism and a second
inference cost to something a table does exactly.

## Deployment

The `Dockerfile` builds from this directory alone, with no monorepo context. That
falls out of the service not being a workspace member: its lockfile is
self-contained, so the image is small and the build cannot break because another
package changed.

```bash
docker build -t image-generator .
docker run --rm -p 8787:8787 --env-file .env image-generator
```

Set `IMAGE_STORE=r2` in production. The container runs unprivileged and needs no
writable volume, which is only true because R2 is the store; the filesystem store
would need one.

The commands the image runs are verified against the built output: `node
dist/main.js` boots, the `HEALTHCHECK` probe returns 0, `--frozen-lockfile`
resolves, the compiled JS imports nothing outside `dependencies` (so the `--prod`
runtime stage is complete), and `SIGTERM` stops the listener and exits without
lingering handles. The image build itself is unverified: there is no Docker on the
machine this was written on, so alpine and layer specifics need one real
`docker build`.

### Render

Render reads only the repo-root `render.yaml`, so this block is documented here
rather than left as inert config in this directory. Adding it is the one edit
outside `image-generator/`, deliberately deferred so this branch stays isolated:

```yaml
  - type: web
    name: do-not-stop-image-generator
    runtime: node
    plan: free
    rootDir: image-generator
    # --ignore-workspace: this package is not a pnpm workspace member and has
    # its own lockfile, so the monorepo root must not be resolved here.
    buildCommand: |
      export PNPM_PREFIX="$HOME/.npm-global"
      export PATH="$PNPM_PREFIX/bin:$PATH"
      npm install -g --prefix "$PNPM_PREFIX" pnpm@9.15.9
      pnpm install --ignore-workspace --frozen-lockfile && pnpm build
    startCommand: node dist/main.js
    healthCheckPath: /health
    envVars:
      - key: PUBLIC_BASE_URL
        sync: false     # must match the service's own URL
      - key: IMAGE_STORE
        value: r2
      # Set in the dashboard, not here: CF_ACCOUNT_ID, CF_API_TOKEN, R2_BUCKET,
      # R2_ACCESS_KEY_ID, R2_SECRET_ACCESS_KEY, EVM_RPC_URL, PETCORE_ADDRESS.
```

Two notes carried over from the existing blueprint: do not set
`NODE_ENV=production` in `buildCommand`, since it skips the TypeScript
devDependency the build needs, and free web services sleep when idle. Sleeping is
harmless here as long as `IMAGE_STORE=r2`, because art already generated survives
in the bucket; a service that slept on the `filesystem` store would wake up and
regenerate.

### Why not Cloudflare Workers

Workers would remove both credentials: Workers AI and R2 are available as
bindings rather than as authenticated HTTP APIs. It would also mean a different
runtime (no `node:http`, no S3 client) and a rewrite of the server and store
layers. Worth doing if this service grows, not worth it to ship the first
version.

### Pointing tokenURI here

`PetCore.tokenURI` used to hardcode `https://api.cryptopets.io/metadata/`, which
does not resolve. It now prefixes an owner-settable base, so it can point at this
service. This is the one change outside `image-generator/`
(`contracts/ethereum/src/PetCore.sol` plus `scripts/upgrade-pet-core.ts`).

An upgrade alone changes nothing: with no base set, `tokenURI` returns exactly its
old value via `DEFAULT_BASE_TOKEN_URI`. Pointing it here is a separate owner call,
so the two steps verify independently and the URI can move later without
redeploying.

```bash
# Upgrade the implementation and point tokenURI at this service in one run.
pnpm --prefix contracts/ethereum exec tsx scripts/upgrade-pet-core.ts \
    --network=base-sepolia --base-uri=https://art.cryptopets.io/metadata/evm/

# Or change only the URI later, with no redeploy.
pnpm --prefix contracts/ethereum exec tsx scripts/upgrade-pet-core.ts \
    --network=base-sepolia --skip-upgrade --base-uri=https://art.cryptopets.io/metadata/evm/
```

The token id is appended verbatim, so the base must end with its own separator
(`/`, or `=` for a query-style base). The script warns when it does not, rather
than refusing, since a wrong value is visible in the next `tokenURI` read and
fixed by re-running.

## License

PolyForm Noncommercial 1.0.0, the root [`LICENSE`](../LICENSE), same as every
non-contract package in this repo.
