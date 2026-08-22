@doc
Feature: Engine switch day

  A pricing change, a policy change, a vendor doing something nobody liked —
  and the team is moving to a different engine. This is the day ctxloom's whole
  premise gets tested, because the premise is that your context is yours: the
  fragments, the profiles, the trust decisions and the history belong to the
  team, not to whichever assistant happened to be fashionable when they were
  written.

  On paper it is one command. `agent edit dev --llm <new>` swaps the engine
  under the binding; profiles are engine-neutral by construction, so the same
  content composes for the new engine's own native surfaces; the canonical
  transcript keeps the history readable; and reaching for a session the tee
  never covered still rescues whatever the abandoned vendor's private store
  holds.

  In practice Alice discovers the pieces exist and the FLOW does not. No
  migration story narrates the order, nothing verifies the result, and the one
  thing she most wants to know — what does the new engine NOT do that the old
  one did — has no surface at all. Nothing here is structural for the
  mainstream engines, which is exactly the finding: the portability story is
  sellable and untold.

  # NOTE ON SCOPE. J000400 (j000400_multi_engine.feature) is the axis's REFERENCE
  # feature — one profile, many engines, a matrix row per engine — and it is
  # deliberately not a journey. This file does not turn it into one. What it
  # asserts is what a matrix cannot express: that the swap is a SEQUENCE with a
  # before and an after, and that the context surviving it is the SAME context
  # rather than merely a valid one.
  #
  # NOTE ON THE CENTRAL ASSERTION. The comparison is between two real
  # materializations, captured on either side of the swap, compared as bytes.
  # A migration that delivers different-but-valid content is worse than one
  # that fails, because the team's assistant quietly knows something different
  # on Monday and nobody is told what.
  #
  # NOTE ON TAGS. Each scenario carries its own note: an untagged one records
  # the mutation that proves it can still fail, a @wip one the product surface
  # that does not exist yet.

  Background:
    Given Alice's team has standardised on one engine and is moving to another

  # THE MIGRATION ITSELF, as a sequence rather than a capability. The swap is
  # asserted on the file ON DISK and on what `agent show` reports — the two can
  # disagree, and a binding that changed in config while the inspector still
  # reports the old engine is a migration nobody can verify.
  #
  # UNTAGGED: confirmed to pass as written, and confirmed to BITE. Dropping
  # `entry.Engine = orKeep(...)` from operations.SetAgent — so `agent edit
  # --llm` reports "Updated agent" and writes the old engine back — turns
  # this red on the on-disk assertion, which is the failure the scenario names.
  Scenario: The engine changes under the binding and the context does not
    Given the team's guidance reaches the old engine's own surface
    When Alice swaps the engine under the binding
    Then the binding on disk names the new engine, and so does what ctxloom reports
    And the same guidance reaches the new engine's own surface, unchanged

  # FOLDED (Phase 3, D-row not previously numbered): "manage install --engine
  # <unknown>" used to have its own scenario here too, but cli/manage.feature's
  # "A misspelled engine is refused by name, and nothing is scaffolded" already
  # covers the identical claim with a STRONGER assertion — it checks that
  # .ctxloom/config.yaml and .mcp.json were never written, not just that the
  # error message named the engines. Nothing here was worth moving down; the
  # duplicate scenario is deleted and the noun's own spec is where that leaf's
  # coverage lives now. What remains below is the validation gap
  # cli/manage.feature does NOT cover: the same mistake one layer up, at the
  # `agent edit --llm` binding.
  #
  # The same validation question one layer up, at the binding. The two commands
  # take the same kind of argument on the same day and are asserted separately,
  # because they are separate code paths and a fix to one says nothing about
  # the other. cli/agent.feature explicitly defers this leaf's `--llm`
  # validation coverage here rather than duplicating it (see its own "create
  # and edit are NOT an upsert" Rule comment).
  #
  # MEASURED: RED, and worse than the command above. `ctxloom agent edit dev
  # --engine bogus-engine` exits 0 and WRITES the nonexistent engine into the
  # binding. Nothing validates the name at the moment it becomes the team's
  # configuration, so the failure surfaces later, somewhere else, as whatever a
  # missing engine happens to look like downstream.
  #
  # UNTAGGED: `agent edit --llm` now validates its argument and names the
  # engines it knows. The check lives in operations.SetAgent — `agent create`
  # and `agent edit`'s single shared body, so both verbs are covered — and
  # rejects before the write, so a typo'd edit cannot corrupt a live binding.
  # Membership is operations.AvailableLLMNames (registered backends UNION the
  # config's declared labels), the same set `llm default` accepts and offers,
  # because an agent's engine is a LABEL and `--engine claude-fast` is one of
  # this command's own documented examples.
  Scenario: Binding an agent to an engine that does not exist is refused
    When Alice types an engine name that does not exist while swapping the binding:
      """
      ctxloom agent edit dev --llm bogus-engine
      """
    Then ctxloom refuses and names the engines it knows

  # THE PORTABILITY PAYOFF, and the reason owning a canonical transcript is
  # worth its cost. History that dies with the engine that produced it is
  # history rented from a vendor. The assertion is deliberately cheap and
  # deliberately present: it is the property most likely to be broken by an
  # unrelated change and least likely to be noticed, because nobody looks for
  # old sessions until they need one.
  #
  # UNTAGGED, but only after the assertion was made capable of failing. As
  # written it searched the COMBINED output for the harp, and Manager.Reconcile
  # warns "session <harp> dropped from the index" when it reaps one — so the
  # message announcing the history was deleted satisfied the check for the
  # history surviving. Measured: with operations.isUnrecoverable inverted for
  # distilled entries the listing returned zero rows and the scenario stayed
  # green. It now reads the ROWS out of `session list --all --format json`
  # stdout, and that same mutation turns it red.
  Scenario: History recorded under the old engine survives the move
    Given a session was recorded under the old engine before the switch
    When Alice swaps the engine under the binding
    Then the sessions recorded under the old engine are still listed after the switch

  # THE MISSING FLOW, stated as the question a migrating team actually asks.
  # Not "did it work" — they can see that — but "what did I just give up?"
  # The concrete, verified loss on this exact engine pair: codex has no
  # session_end hook. A team moving from claude-code to codex loses a hook
  # event they may well have built on, and no surface anywhere mentions it,
  # before or after the switch. They will find out when something stops
  # happening.
  #
  # This is the same shape as U3's missing per-engine capability-loss report,
  # arriving through a different door: there, a new hire silently inherits less
  # than his deskmate; here, a whole team silently loses something it had.
  #
  # UNTAGGED (trusting-ambiguity): all three probed surfaces now report it —
  # `doctor` (DOCTOR-CHECK-CAPABILITY-LOSS-u1), `manage check` (its "Capability
  # loss" section) and `agent show <name>`. The Then step requires EVERY one of
  # them, not any one: while only `agent show` was wired, the any-of form left
  # this row green over a gap that was half present, and a user who ran
  # `doctor` still learned nothing.
  #
  # The mechanism behind all three — operations.CapabilityLoss wraps the SAME
  # backends.UncarriedSurfaces read `profile materialize` already performed
  # (whiny-exclusive), against the resolved agent's ACTUAL backend and
  # profiles rather than a materialize target, read once per configured agent.
  # codex declaring only a whole-mechanism noHooksReason (empty for
  # codex — it has hooks) could not have caught this: the gap was PER-EVENT,
  # so agentDescriptor gained unsupportedHookKinds (codex: session_end →
  # codex.NoSessionEndReason, the SAME string addUnifiedHooks' route already
  # used to warn at write time) and UncarriedSurfaces now checks it too.
  Scenario: Nothing tells her what the team just gave up
    When Alice swaps the engine under the binding
    And Alice asks ctxloom what the switch changed and what to verify
    Then ctxloom names what the new engine cannot do that the old one could
