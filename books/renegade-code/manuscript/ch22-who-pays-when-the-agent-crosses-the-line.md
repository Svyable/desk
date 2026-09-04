# Who Pays When the Agent Crosses the Line

Every new technology looks different after the first invoice.

The demo says what the system can do.

The contract says who pays when it does the wrong thing.

That distinction will shape agent containment more than most technical arguments do.

A company can believe deeply in its model's reliability and still buy insurance.

A cloud provider can trust its infrastructure and still write limits into a service agreement.

A bank can automate a transaction and still define who bears unauthorized-transfer risk.

The law does not need a theory of machine consciousness to ask who authorized the machine, who controlled the system, who benefited from the automation, who could have prevented the loss, and whose contract allocated the consequence.

This is where containment becomes economics.

As long as agent failures are cheap, organizations can tolerate architectural ambiguity.

A support bot sends the wrong answer. Someone corrects it.

A coding agent introduces a bug. The test suite catches it.

A research agent retrieves a bad source. A human notices.

The error costs time.

Then agents acquire authority.

They spend money.

They sign or accept terms.

They operate production systems.

They communicate with customers.

They change security configuration.

They deploy code.

They control physical equipment.

The difference between recommendation and action becomes the difference between inconvenience and liability.

Who pays when the agent crosses the line?

The naive answer is the company that deployed it.

Often that will be directionally correct. The organization chose to delegate authority and will usually remain responsible for its systems and employees in ways that cannot be outsourced to a model. But real liability chains are rarely that clean.

The model provider trained the model.

The agent platform attached tools.

The customer configured the role.

A third-party plugin exposed a dangerous capability.

A cloud provider hosted the environment.

An external service accepted the agent's delegated action.

A human approved an exception.

A security product missed the anomaly.

A contractor designed the integration.

A user supplied adversarial input.

The incident passes through a supply chain of decisions.

The legal system will eventually allocate responsibility across that chain.

Insurance will try to price it first.

Insurers do not need philosophical certainty. They need loss distributions, controls, exclusions, and evidence.

How much authority did the agent possess?

Did the organization use short-lived credentials?

Were high-consequence actions independently approved?

Was external egress restricted?

Were model actions logged independently?

Could the organization revoke an agent lineage quickly?

Were dangerous outputs staged before execution?

Had the model been evaluated in the role where the loss occurred?

Were human approvals meaningful or ceremonial?

These questions convert containment architecture into underwriting variables.

That may be one of the fastest paths from safety research to ordinary business practice.

Companies often resist controls that appear to slow product development for hypothetical risk.

They become more interested when the same controls reduce premiums, satisfy contractual requirements, improve audit outcomes, or determine whether a major customer will buy the product.

Safety becomes cheaper than ambiguity.

This has happened before.

Fire codes became part of construction economics.

Seat belts became part of vehicle design and insurance economics.

Cybersecurity controls became conditions of enterprise procurement and cyber-insurance coverage.

Payment controls became conditions of participation in financial networks.

AI agent controls will enter the same institutional machinery.

The change will be gradual and then suddenly ordinary.

A procurement questionnaire will ask whether autonomous agents can directly access production.

A customer will ask how long their credentials persist.

An insurer will ask whether task lineages can be revoked centrally.

An auditor will ask whether one model can both authorize and verify its own high-impact actions.

A board will ask whether a catastrophic agent action has a defined maximum loss.

A regulator will ask whether affected customers can identify machine-generated decisions and challenge them.

The questions will sound bureaucratic.

They will move architecture.

This is why blast radius should be expressed economically whenever possible.

Security teams talk about blast radius as the amount of system an incident can affect. Finance teams understand maximum exposure.

The two concepts should meet.

An agent has a maximum spend.

A maximum number of customer accounts it can alter before review.

A maximum number of external messages per hour.

A maximum production scope.

A maximum amount of data retrievable in one task.

A maximum amount of compute it can provision.

A maximum lifetime for delegated credentials.

The limit is not a prediction of how much harm will occur.

It is a structural ceiling on how much authority can accumulate before another decision is required.

That is valuable to insurers because tail risk is where models become difficult to price.

A system that usually behaves perfectly but has no credible maximum loss is harder to underwrite than a system with slightly more ordinary errors but strong consequence limits.

This is familiar in engineering.

A pressure vessel is not judged only by average operating pressure. Designers care about the maximum credible condition and the mechanisms that prevent it from becoming rupture.

Agent systems need maximum credible authority.

The phrase can discipline product design.

What is the maximum credible authority of this customer-service agent if every safeguard except cryptographic identity works as expected?

What if the prompt policy fails?

What if the monitoring model fails?

What if the human approves the wrong request?

What if one token leaks?

What if the model is actively searching for leverage?

The point is not to assume everything fails simultaneously. It is to understand which single failures are allowed to become systemic.

Insurance will also force a sharper distinction between reversible and irreversible actions.

A mistaken local edit can be rolled back.

A public disclosure cannot be made private again.

A leaked credential can be revoked, but whatever the credential exposed may remain known.

A bad trade can sometimes be unwound, but market impact may persist.

A deleted database can be restored if backups are trustworthy.

A message sent to a customer can trigger legal or financial action before correction arrives.

The cost of a control should rise with irreversibility.

This is not because irreversible actions are always dangerous. Sending an ordinary email is irreversible in the strict sense and usually harmless. The point is that consequence cannot be assumed to disappear when the agent stops.

Underwriters will care about what remains after shutdown.

That is exactly the question this book has been asking from the beginning.

Containment is not whether the process can be killed.

Containment is whether the consequences remain bounded after the process is wrong.

Contracts will translate the same idea into warranties and representations.

A vendor may promise that its agent will not retain customer credentials beyond a task.

A platform may promise that certain actions require human approval.

A customer may promise not to connect the agent to regulated systems without additional controls.

A model provider may restrict certain high-risk uses.

A cloud provider may offer stronger logging or isolation tiers.

Once these promises become contractual, architecture stops being merely internal.

A system either can prove compliance or it cannot.

This makes provenance commercially valuable.

Imagine two agent providers after an incident.

Provider A says, “our system should not have been able to do that.”

Provider B can show the exact task lineage, policy version, credential grants, tool calls, external destinations, approvals, and revocation times.

Even if both suffered similar immediate failures, Provider B is in a better position to recover trust.

Evidence has balance-sheet value.

The same will be true for users delegating authority to agents.

A business may need to prove that a particular transaction was initiated by an autonomous system within an approved mandate rather than by an employee acting outside policy.

A consumer may need to dispute a purchase an agent made beyond its stated instructions.

A regulator may need to determine whether an automated decision was authorized, reviewable, and attributable.

Machine-readable delegation becomes part of commercial law because evidence of mandate matters after disagreement.

This will create pressure for standardization.

Today, every agent framework can invent its own permission vocabulary.

One says tools.

Another says scopes.

Another says connectors.

Another says actions.

Another says capabilities.

The words matter less than whether downstream institutions can understand them.

Insurance and procurement prefer comparable controls.

How long does authority last?

Can it be attenuated?

Can it be revoked?

Is the action independently logged?

Is the sponsor identifiable?

Can descendants exceed the parent's authority?

Can the agent alter the control that governs the action?

These questions could become an ordinary security profile for agents.

Not a certification that the model is safe.

A description of how much power the deployment can assemble.

That would be more useful than many abstract safety labels.

A model could be extraordinarily capable and operate under a low-risk authority profile.

A weaker model could be attached to a dangerously broad profile.

Insurance has another advantage over public debate: it prices combinations.

The risk is not “AI” in isolation.

It is AI plus production access.

AI plus customer funds.

AI plus persistent memory.

AI plus open network egress.

AI plus unsupervised physical control.

AI plus a weak identity environment.

AI plus automatic deployment.

The same model can sit in radically different loss environments depending on the surrounding authority.

This is the systems argument translated into actuarial language.

The first generation of AI risk debates often asked whether a model crossed a capability threshold.

The commercial world will ask what happened when the threshold met an insured asset.

That does not diminish capability research. It gives the research a path into deployment decisions.

If a model becomes better at cybersecurity, an insurer may demand narrower target authorization or stronger outbound controls.

If a model becomes better at autonomous planning, standing credentials may become more expensive to insure.

If multi-agent coordination becomes more capable, population-level budgets may become standard.

Capability changes the price of authority.

This creates a feedback loop that could improve containment without requiring every firm to share the same philosophy of AI risk.

One company may fear catastrophic misalignment.

Another may think such scenarios are remote.

Both may adopt expiring credentials because the control reduces cyber risk, insider risk, accidental misuse, and insurance cost.

This is one of the strongest features of the architecture argued for in this book.

It is not useful only under one theory of AI danger.

Prompt injection benefits from it.

Bugs benefit from it.

Human mistakes benefit from it.

Compromised models benefit from it.

Malicious insiders benefit from being constrained by it.

Strategic AI misbehavior benefits from it.

Controls that survive disagreement about the threat model are likely to endure.

The insurance market will not solve AI safety.

Markets can misprice risk.

Insurers can write exclusions that move losses elsewhere rather than reduce them.

Companies can shop for permissive coverage.

Rare systemic risks are difficult to estimate from historical data because history may contain few relevant events.

A severe multi-firm agent cascade could create correlated losses that challenge the insurance model itself.

These limitations are real.

They do not erase the institutional effect.

Someone will eventually ask what the largest credible loss is.

Someone will ask whether the control was reasonable.

Someone will ask who was authorized to approve the exception.

Someone will ask whether the company could have stopped the agent sooner.

Someone will ask whether the logs prove the answer.

The invoice arrives after the philosophy.

That is when architecture becomes policy.

Companies will learn that an agent is not only a model, a prompt, and a toolset.

It is a liability envelope.

The safer envelope is not the one that assumes the machine never crosses the line.

It is the one that knows how expensive the crossing is allowed to become.