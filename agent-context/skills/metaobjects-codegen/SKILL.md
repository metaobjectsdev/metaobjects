---
name: metaobjects-codegen
description: Use when configuring or running MetaObjects code generation — generators/targets/dialect config, the gen command, and hand-edit-preserving regeneration.
---

# MetaObjects code generation

Codegen is the first pillar: MetaObjects reads your typed metadata and emits
**idiomatic per-language code** — entity types, DB tables/schemas, query helpers,
REST routes, validators, payload value-objects, output parsers. The metadata is the
durable spine; the generated code is a disposable artifact. It runs at runtime
**without any MetaObjects dependency** — if the libraries disappeared tomorrow, you
keep working code.

This skill is the port-agnostic procedure. The exact config file, generator names,
and command for *this* project's server language live in a reference fragment
(pointed to at the bottom).

## What codegen does

You run a `gen` step. The runner:

1. Loads all metadata under `metaobjects/` (the same loader the runtime uses).
2. Resolves output targets and precomputes shared render state.
3. Runs each configured **generator** — most emit one file per entity; some emit a
   single shared file (a barrel, a DB-context, an app-config).
4. Refuses to overwrite any file that does NOT carry the `@generated` header;
   overwrites the ones that do.

The output is normal idiomatic code in your language — you import it and use it
like any hand-written module.

## The `@generated` header + hand-edit-preserving regen

Every emitted file carries a `@generated` header. This is load-bearing:

- **Never hand-edit a file with a `@generated` header for a change you want to
  keep.** The next `gen` run overwrites it. If you need different output, change the
  metadata, or change the generator that emits it.
- **This rule is about emitted output — it is not a rule about your generators.** A
  generator you own carries no `@generated` header and is edited like any other source
  file in your repo. See the next section before you conclude a shape is unreachable.
- **Hand-written regions are preserved by three-way merge.** Where the codegen
  supports designated hand-editable regions, regeneration runs a three-way merge
  (base → yours → newly-generated) so your edits survive a regen. Code review is
  the backstop: a diff on a `@generated` file that wasn't produced by `gen` is a
  smell.

Practical rule: **pattern-derivable-from-metadata = regenerate; business logic =
hand-write in a non-generated file.** FK columns, CRUD, validator chains,
type-safe finders, `relations()` blocks — all derived, never hand-coded. What you
hand-write is what metadata genuinely can't express: regex from outside metadata and
domain logic. Most views are NOT irreducible — model them as an `object.projection`
and the view DDL is generated (see the projection bullet below); a hand-written view
for a shape origins can express is drift the drift gate can't even see. A genuinely
*irreducible* view body (recursive CTE, window function, set op) isn't hand-written
loose either — it goes in the `source.rdb` **`@sql`** escape (#208, ADR-0043) so the
tool still registers, fingerprints, and drift-checks it (see the projection bullet).

## Your generators are yours — editing one needs no permission

A generator in your repo is your code, not a vendor artifact. ADR-0034 is
**scaffold-and-own**: the generators the scaffolded config wires are copied into your
repo at init, and every reference template's header says so in its own first line
("copy this into your repo … and own it", "now YOURS to change"). None carries a
`@generated` header. Editing one is ordinary work.

**A standing rule not to change the MetaObjects repo is not a rule about your
generators.** They are different repositories, and you own yours outright. That
generalisation is the observed failure mode, not a hypothetical: an agent told not to
touch upstream quietly drops "edit the generator" from the moves available to it and
hand-writes the layer instead — the single outcome the rest of this skill exists to
prevent. If you are about to hand-write something data-shaped because the generated
shape is wrong, the generator is the file to open, and you do not need to ask first.

**The order when generated output does not fit:**

1. **The metadata**, if the model is wrong — wrong column type, missing relationship,
   a join that should be a projection. Fix the spine first; it fixes every port at once.
2. **Your own generator**, if the model is right and the *emit* is wrong — naming, file
   layout, imports, framework, signatures.
3. **Hand-write**, only for what metadata genuinely cannot express — and wire it to the
   generated types.

Hand-writing something the metadata already describes is step 3 used as step 1.

**The converse, so ownership does not become sprawl:** wire a generator only for output
you will actually consume. Decide per generator, narrow one with its own `filter`, and
own the ones you keep — an emitted file nobody imports still reads as an invitation to
adopt the surface you decided against.

How you get a generator's source differs per port — a copy command on TypeScript,
implementing the port's generator interface elsewhere. Your language reference has the
mechanism; see also "The commands and config keys that implement the steps above differ
per port" below.

## Selecting generators by stable name

Codegen is a set of named generators you opt into. Each generator has a **stable
name** (kebab-case) that surfaces in diagnostics — reference generators by that
name, never by inlining what they emit. Typical generators cover: the entity
type/model, the DB table/schema, query/finder helpers, REST routes, client
form/grid/hook artifacts, filter + sort allowlists, payload value-objects, and
parsers for a responding `template.prompt` (one carrying `@responseRef`). You
enable the subset your project needs; an abstract entity never emits
instance/write artifacts regardless.

Per-entity opt-outs exist (e.g. skipping client-side artifacts for a given
entity) and are set as attributes on the entity in metadata, not in code.

## You don't have to generate everything — pick your layers

Codegen is **granular and à la carte, not all-or-nothing.** The most powerful
pattern when an app's API doesn't match generated CRUD: **generate the data layer,
hand-write only the API layer** — never abandon codegen wholesale and hand-write
the data access too.

- **Generate the data layer, skip the routes.** Omit `routesFile()` from the
  `generators` array (keep `entityFile()` + `queriesFile()` + `barrel()`): you get
  the typed entity/table, schemas, and query/finder helpers, then write your own
  routes by hand — *calling the generated queries*. Do this whenever the API shape
  (custom paths, HTML responses, nested payloads) doesn't fit generated REST CRUD.
- **Mix generated and hand-written routes.** Even with custom paths, mount the
  standard verbs with the runtime helpers and hand-write only the custom ones (see
  the runtime skill's `mountCrudRoutes` / `mount<Verb>Route` / `expose`). You are
  never forced into all-generated or all-hand-written.
- **Entity's OWN columns + a joined extra → an entity read-view, NOT a projection.**
  The most common legacy view is `SELECT o.*, c.name AS customer_name FROM orders o
  JOIN customers c …` — the entity *with a read route*, not an independent exposure.
  Reach for an **entity read-view** first: keep the entity's writable `table` source
  and add a **non-primary** read-only source (`source.rdb` `@role: replica`
  `@kind: view`), declaring only the *extra* as a derived (`origin.*`) field — the
  entity's own field set already covers `o.*`, so you re-state nothing but the extra.
  Codegen then routes **reads** to the view and **writes** to the table (derived
  fields don't exist there and are excluded from the write codecs); a create/update
  re-reads the row through the view by primary key, so the returned value carries the
  derived columns (read-your-writes). Shipped all five ports (#213 write half + #214
  read half). Reach for a **projection** (below) instead only when it is an
  independent exposure contract — a subset, renamed base columns, a versioned/external
  shape, or a row-filtered view. See `docs/features/source-kinds.md`.
- **Derived/aggregate data → declare a projection, then USE its generated query.**
  Don't hand-write a join or an `AVG()`/`COUNT()`. Declare an `object.projection`
  with `origin.*` children — `origin.passthrough` (a forwarded column),
  `origin.aggregate` (`@agg` `count`/`sum`/`avg`/`min`/`max`, plus the #195
  `any`/`all` predicate quantifiers over a `@filter` and `collect` array-rollup with
  optional `@distinct`/`@orderBy`; any aggregate may be row-scoped with `@filter`),
  `origin.computed` (a row-level `@expr`), and
  `origin.first` (one related row's column along `@via`/`@of`/`@orderBy`) — **and a
  read-only `source.rdb` `@kind: view` child** (codegen detects a projection by that
  read-only source, not by the subtype alone — omit it and nothing is generated).
  `meta gen` emits a read-only query for it (and `meta migrate` its DB view), and you
  **call that generated query from your route**. Declaring the projection is only half
  the win — *consuming* its generated query is the other half.
  - **Row-filtered views are a projection `@filter`, not hand-written SQL.** An
    object-level `@filter` on `object.projection` (the same `attr.filter` shape as a
    preset filter) scopes the whole view's rows — it lowers to the view's outer
    `WHERE` (#207). This is the metadata-managed way to author a soft-delete / status
    / type view without hand-writing SQL.
  - **Never hand-author the view SQL for a shape origins can express.** The
    `CREATE VIEW` body is emitted by the Node `meta migrate` from the projection's
    `origin.*` children — hand-writing it is a second source of truth that drifts
    silently, because an unmodeled DB view is *unmanaged*: `meta verify --db` never
    flags it. For a genuinely irreducible body (recursive CTE, window function, set
    op) that origins can't express, carry it in the `source.rdb` **`@sql`** escape
    (#208, ADR-0043) — a hand-written body the tool registers, fingerprints, and
    drift-checks (adopt a pre-existing view with `meta migrate --allow adopt-view`) —
    rather than a hand-edited migration file where it goes accidentally unmanaged.
    For a DB object owned entirely elsewhere (Flyway), mark its source
    **`@unmanaged: true`** (view or table); migrate/verify then never touch it.
    `@sql` and `@unmanaged` are mutually exclusive.

`meta gen --list` prints every generator by stable name; the `generators` array in
`metaobjects.config.ts` is where you opt each one in or out.

### Adopting onto existing code — make codegen match the code, not the code match codegen

On a **brownfield adoption** (existing working code / live schema — see
`metaobjects-authoring` → "Adopting onto an existing codebase"), the goal of codegen is to
**reproduce the shape the code already has** so the generated output drops in with minimal
churn. When generated output doesn't match — different names, file layout, imports, or
signatures than the existing code — **customize the codegen to match the existing code first**,
using the à-la-carte layers, `outputPattern`/target layout, naming strategy, template
customization, and owned/custom generators described here. That is the intended adoption path,
**not a hack** — the whole point of owned generators + three-way merge is to shape output to
your codebase. Reshaping working call sites to fit the generator's defaults is the **last**
resort, and only for the layer codegen is actually replacing (the hand-rolled CRUD/DTO/mapper
you're deleting behind a parity gate). If matching the existing shape would require a genuinely
hacky generator contortion, that is the moment to **ask the human** which side should give —
don't silently churn the existing code.

## Write your own generators — the built-ins rarely fit an app exactly

The built-in generators (entity, queries, routes, routes-hono, barrel, form, hooks,
grid, grid-hook) cover the common shape, but **real apps routinely need output the
built-ins don't emit as-is** — a bespoke REST contract, custom DTO/response shapes,
an app-specific service or repository layer, a UI the defaults don't produce. When
that happens the model-first move is **not** to abandon metadata and hand-write the
layer. Write a **custom generator** that reads the same metadata and emits *your*
app's shape.

Treat this as a first-class, expected activity — not an escape hatch. A custom
generator is still model-first: it derives from the metadata spine, so it
regenerates on change and stays consistent across every entity — the leverage you'd
forfeit by hand-writing. Hand-rolling *away from* metadata is the anti-pattern;
generating *your own shape from* metadata is the point.

This is for when the *shape* itself needs to change. If a built-in's shape is
already right and only the *target* is wrong — a different framework than the
shipped reference emits for — take ownership of that generator instead of writing
one from scratch; see "Your framework isn't the default" below, and your language
reference for the command that does it.

The plugin interface is small (`@metaobjectsdev/codegen-ts`): a `Generator` is
`{ name, filter?, generate }`, where `generate(ctx)` returns `EmittedFile[]`
(`{ path, content }`). `perEntity` / `oncePerRun` wrap the common cases:

```ts
import { perEntity } from "@metaobjectsdev/codegen-ts";
import type { Generator } from "@metaobjectsdev/codegen-ts";

// One file per entity, in YOUR shape — reads the loaded metadata, emits your code.
export function serviceFile(): Generator {
  return {
    name: "service-file",                      // kebab-case; shows in `meta gen --list`
    filter: (e) => e.isEntity,                 // which nodes it applies to
    generate: perEntity((entity, ctx) => ({
      path: `${entity.name}.service.ts`,
      content: renderYourService(entity.fields(), ctx),  // walk the typed metadata
    })),
  };
}
```

`ctx` gives you `entities`, the `loadedRoot`, and `config`; `oncePerRun((entities,
ctx) => …)` is the one-shot variant (a barrel, an app-config). Add your generator to
the `generators` array in `metaobjects.config.ts` next to the built-ins — it runs in
the same pass, writes under the same target rules, and carries the `@generated`
header so it round-trips like any other.

## Your framework isn't the default — the retargeting procedure

If the shipped templates do not emit for your stack, retargeting is the **normal first
move** — not a workaround and not a sign of a bug. Owning a generator is the supported
path to any framework; MetaObjects does not ship a codegen package per framework and is
not waiting to.

The doctrine, in order of what to try:

1. **Check config first.** Several apparent codegen failures are one config value
   (module-specifier style, output directory, dialect, API prefix). Change it and retest
   before writing any code.
2. **Own the generator, not the renderer.** Take a copy of the reference template for the
   artifact that is wrong and edit the one step your framework disagrees about. Each
   template's header names what its emit is coupled to and which call to swap.
3. **Compose, do not fork.** Call the exported render function and wrap its result where
   you can, so you keep receiving upstream fixes. Forking a whole renderer is the thing
   to avoid — not owning the generator.
4. **Server-tier output is usually already portable.** The entity module and the query
   helpers carry no HTTP-framework coupling; retargeting is usually only needed at the
   routes and UI tiers.

Hand-rolling *away from* metadata is the anti-pattern. Generating *your own shape from*
metadata is the point.

### Never read metadata through an `own*()` accessor (ADR-0039) — top bug source

When writing OR reviewing a generator, **read every field/node property and iterate
every member set through the resolving/effective accessor — never the `own*()` form.**
`extends` is a **super-reference, not a flatten**: a concrete field/entity that
`extends` an abstract parent keeps its inherited attributes and members physically on
the parent, reachable only through the *resolving* accessor. An `own*()` read of an
effective property (`isArray`, `subType`, `maxLength`, `precision`/`scale`, `default`,
the physical column name, `objectRef`, `storage`, `required`, …) or an own-only member
iteration **silently drops everything inherited via `extends`** — the classic symptom
was a concrete field that inherited `isArray: true` from an abstract parent generating
a *scalar* column. These reads compile and pass every fixture that never exercises
`extends`, so they are a latent, cross-port top bug source.

**The one legitimate `own*()` use:** a generator emitting a generated **subclass** that
`extends` a generated base iterates **own members** (`ownFields()`) so the inherited
members are **not re-emitted** — the generated base class already declares them (the
`class Sub extends Base` / TPH pattern). Everywhere else, resolve. (The own-mode
canonical serializer and overlay-merge are the only other sanctioned own reads, and
they are library-internal, not app-generator concerns.) The one deliberately-own
attribute is `@dbColumnType` — a physical column-type override that is never inherited.

**Per-port own↔resolving mapping** (reach for the resolving column; comment any
`own*()` call with the sanctioned case it is):

| Port | Resolving (default — use this) | Own-only (avoid unless emitting a subclass's own members) |
|---|---|---|
| TypeScript | `attr(name)`, `children()`, `fields()` | `ownAttr(name)`, `ownChildren()`, `ownFields()`, the raw `isArray` field flag |
| Python | `attrs().get(name)`, `children()`, `fields()` | `attr(name)` **(own!)**, `own_children()`, `own_fields()` |
| Java / Kotlin | `getMetaAttr(name)`, resolving `getChildren()` | `getMetaAttr(name, false)`, own-only child walks |
| C# | resolving attr/`Children`/`Fields` accessors | `IsArray` native flag, `OwnChildren()`, own attr reads |

**Naming inversion — the trap:** the *default-named* accessor is NOT consistently the
safe one. **TS `attr()` RESOLVES; Python `attr()` is OWN** (own-only). In Python you
must call `attrs().get(name)` to get the inherited value — a bare `attr(name)` is the
own read that drops inheritance. When you review or port a generator, check the port's
convention, not the method name.

**Close but not exact?** You don't always need a new generator — a generated file is
a normal source file. Copy it and customize the copy (three-way merge preserves your
edits on regen), or customize the template a built-in renders from. Reach for a
custom generator when you want the change applied **consistently across every
entity** (the scale win); a one-off edit when it's genuinely one file.

**The decision ladder:** a built-in fits → use it · close → customize the
output/template · doesn't fit → write a generator that emits your shape *from the
metadata* · only the genuinely un-modelable (business algorithms, external calls) is
hand-written outside codegen — and it still imports the generated types.

## Two ways to author a generator — pick deliberately

A generator can be **programmatic** (code that builds the output) or **declarative** (a
Mustache template plus a scope). Both are first-class, both ship in every port, and they
are good at different things.

| | Programmatic | Declarative template |
|---|---|---|
| What you write | a `Generator` in the port's language, using its AST builder (ts-poet, KotlinPoet, …) | a `.mustache` file + `{ template, scope, outputPattern, format? }` |
| Output shape | expressed in code | **is the file you are editing** |
| Cross-language | per-port by construction | one template emits for any language — it renders against the neutral, byte-gated data dict |
| Logic | any | what a template can express: sections, iteration, presence flags |

**The rule:** reach for **programmatic** when the logic is gnarly or the run is hot; reach
for a **template** when the *shape* is what you are iterating on, or when you want the same
output across languages. `scope` is `perEntity` / `perPackage` / `perModel` — the walk you
would otherwise hand-write — and `outputPattern` is the output path per item, with
`{name}` / `{Name}` / `{package}` placeholders (e.g. `"{package}/{Name}Service.java"`).
Full tradeoff table and the data dict: `docs/features/codegen-concepts.md` §3 and §10.

**A template is not limited to documents.** It emits source as readily as docs — that is
what the neutral data dict is for.

### Which is available to you depends on the port — check before you plan

**TypeScript** has both, and the whole programmatic procedure is documented: `meta eject`,
the `metaobjects.config.ts` keys, the exported `render*` functions — see this skill's
`references/typescript.md`. The declarative path is declared in the SAME config: call
`templateGenerator()` in `generators`, or spread a parsed JSON spec with
`templateSpecToGenerators(parseTemplateSpec(...))` to reuse one written for C#/Python.
**There is no `--template-spec` flag on `meta gen` and its absence is not a gap** — the
config takes generator values, and keeping the declaration there is what keeps
`meta verify --codegen` regenerating with it.

**Java / Kotlin** have both. **No eject command** — a programmatic generator means
implementing `com.metaobjects.generator.Generator` and naming your class in the Maven
`<generator>` element, which the plugin loads from the project classpath. The declarative
path is `TemplateScopeGenerator`, wired the same way with `<template>` / `<scope>` /
`<outputPattern>` / `<format>` / `<templatesDir>` (plus the standard `<outputDir>`), and
covers Java and Kotlin alike. No `--template-spec` flag here either, for the same reason:
`<generator>` already loads a consumer class from the project classpath.

**C# and Python: the declarative path is your only option, and it is a real one.** Their
generator sets are **closed built-in registries** — `--generators` *selects* from what
ships, and there is no seam to register a `Generator` of your own. (Python's
`--provider module:symbol` registers **metamodel vocabulary**, not a generator; do not
reach for it here.) Use `--template-spec <json>` — plus `--templates <dir>` on Python or
`--template-root <dir>` on C# — and your entries are appended to the default suite. Worked
examples with the full JSON: `docs/ports/python.md` and `docs/ports/csharp.md`.

**The spec is auto-discovered, and that is load-bearing.** With no `--template-spec`, both
ports read `<projectRoot>/template-spec.json` — projectRoot being the metadata dir's parent.
Keep it there: `verify --codegen` accepts no `--template-spec` flag, so the conventional path
is how the drift gate learns your template generators exist. Put the spec somewhere else and
reach it only by flag, and `verify` regenerates without it and reports its output as stale.

So on C#/Python, "I need a shape the built-ins do not emit" is answered by a template, not
by writing generator code. Do not conclude the port cannot be customized.

Each port's `references/` fragment documents what its built-ins emit, which is what you
compare your own emit against; they do not carry a step-by-step retargeting procedure.

## Dialects

Generated DB schema/DDL targets a SQL **dialect**:

- `postgres` — the default, fullest-featured.
- `sqlite` — supported; rejects non-default DB schemas.
- `d1` (Cloudflare D1) — **TypeScript-only**. It is SQLite at the SQL level; the
  non-TS server ports have no analogue, so it never appears in their config.

Set the dialect once in the project's codegen config. Field subtypes map to the
dialect's column types deterministically (`field.string` + `@maxLength` →
`varchar(N)`, `field.currency` → integer, `field.uuid` → native `uuid` on
Postgres, `field.enum` → `varchar` + `CHECK`, etc.).

Codegen only ever maps the **shapes you authored** — so author them right. If you
find the generator emitting the wrong column type, the fix is the field shape, not a
template hack. See "Choosing the right shape — the general decision procedure" in the
**`metaobjects-authoring`** skill for the ordered derive→`@dbColumnType`→subtype/
`@kind`/attribute routing (ADR-0037) — e.g. arrays are `isArray: true` (never an
array column type) and a native UUID is `field.uuid` (not a string + `@dbColumnType`).
When you register custom vocabulary for a custom generator, the same ADR-0037
procedure decides whether it's a subtype, a `@kind` variant, or an attribute.

## Per-target output

Generated code can be routed to **multiple output directories/packages** so each
artifact lands with its runtime concern: the entity model in a database package,
routes in the API app, client hooks/forms/grids in the web app. Each generator can
declare which named target it writes to; same-target references stay relative,
cross-target references go through the target's configured import base. With no
targets configured, everything lands in a single output directory — output is
byte-identical to the single-directory case. Use multiple targets only when the
project's package boundaries justify it.

## Running gen

The shape is always the same — a `gen` verb that loads metadata, renders, merges,
and writes — but the binary differs per server language (the Node `meta`, a
language-native console tool, or a build-plugin goal). A dry-run mode previews
without writing; a watch mode re-runs on metadata changes where supported. Pass
specific entity names to scope a run to those entities.

---

For this project's server-language codegen specifics, read every `references/*.md` file in this skill's directory (one per server language in this project's stack).
