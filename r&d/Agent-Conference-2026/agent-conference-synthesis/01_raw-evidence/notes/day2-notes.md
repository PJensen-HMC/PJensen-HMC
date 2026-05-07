UPWORK CEO -- he's been working things before it was cool.
UPWORK: what he's working on: a marketplace for hiring freelancers for clients.
UPWORK: it's become a work delivery platform -- speak to "Uma" to ask for the outcome they're looking for.
UPWORK: they get an outcome delivered to them.

Brad:
CUSTOMER: Over the last decade they're been building a modern CRM system. Being doing it before AI was cool. But now ..
CUSTOMER: We're able to infuse magic.
CUSTOMER: They're "super charging" with AI -- creators -> reviewer (I disagree)
CUSTOMER: Humans and AI work together -- exceptions overrides -- empathy? Best outcomes.

Ping / QUEST
CRESTRA: a platform for empowering the customer journey
CRESTRA: theh're analyzing data post-hoc -- feedback loop, flywheel (hinted at)
The application -- the defintion -- ambient agents -- in the browser, the can hear, they can see -- they work alongside.
Expanding more to --- mid office, back office business processes. Dispute handling. Not all are customer facing.
He thinks AI as enabler -- how many humans you can cut is the wrong thing -- 50% of the calls are unanswered -- workforce scarsity.

BRAD / CUSTOMER: being OUTCOME driven -- I agree with this.
He thinks it can tell you what to do, he thinks it'll help you do that
Humans are required for empathy -- supercharging those humans.

DISCORD: freed up customer service people can work feedback -- higher level critical thinking.

Intelligence:
1. What do do
2. Doing the work <-- machines here
3. Evaluating

No shit. Humans become Advisers and Verifiers. They only possess the intelliegence of the training data. Certain personality. Etc.
In order for intelligence to evolve -- learn from experiences (yep, obvious) -- 

He posits that you can allow agents to try new things to try new things -- video games: world model is available -- similar to real world.

UNPOPULAR OPINONS

Something the audiience will disagree with us on.

1. BRAD -- he thinks its magic -- it'll transform the workforce -- he does not think it's going down to 5 employeees -- humans that learn to multiply themselves. AI will replace people who do not jump on the bandwagon. Fine.
2. PING: Ai will lead to massive unemplioyment --- he doesn't buy it: the AI layoffs -- excuse, overhiring during 0% rate - he's talking steam engines, I've read the same material. the coding timescale is moving at a different rate to the rest of the world -- I agree with this -- layers and different timescales. Agree.
2. ANDREW: he does not think AI is magic -- (I agree) statistical model -- 60 years since inception -- 3-4 relevant algos -- data/compute/pipelines -- 
he thinks we're pretty far from AGI -- he's comparing brain to LLM -- I know what he's referencing -- we're missing something, scaling laws can only take us so far.

Connecting around hard problems:

1. DISCORD: he wants to understand the real use cases -- where do people feel comfortable -- non-answer
2. BRAD: he's trying to convert the entire company -- fine -- it's been a interesting journey over the last 6 months. "governance extra fun"
3. PING: he sees when AI fails -- hes' interested in turning customer support into a coding problem. tasks simulation that can close the loop.



--------- ONWARD TO BANKING -----------

a centralized approach to governance -- they have moderate trust in AI agents; fair, Agentic architectures <-- bing 

"A way to wrap the core to get agiltiy without risking stability"

The tension between the spirit of innovation, challenges -- slows the adoption. 

Orgs sits on piles of ancient tech stacks. Banks whoever need an agentic systems platform. 

Builds a context graph of everything that exists -- existing traces, some huge pile of sub-systems "Axos Bank -- log analysis -- document mapping.

Kevin Hearn joins the discussion. Axos Bank. Founded in 200 -- first online only digitial bank. 
Rebranded. 30B in assets. Consumer banking. Self directed. Commercial lending. Whitelabel RA, broker dealer -- a lot of banking.

Moderator: had a lunch, some CTO spending millions, nothing in prodution -- contrasting this mindset. 
The oppertunity is too great he says -- interesting -- "Agent Workbench" -- narrow focus on use cases -- teams dedicated to that.
Finite group focused on soliving that problem.

What was the first agent they built?
Workbench -- how do I augment every persoa -- he had a MOUNTAIN of logs -- this is where they built their first agent.
Making meaningful work out of logs -- fine -- neat, boil things up --- they iterated: the agent is now alerting teams and recommnding improvements. It feeds log streaming.
SDLC personas -- agents for pull requests, qualtiy agents, scrum masters, using the agent workbench -- he started by cleaning up his own house -- nailing speed.

VALUE: what agentic system has the highest ROI -- his bottleneck is around code review -- increase velocity without comprimising quality -- I dunno -- I'm not sure I love what he's saying -- he's got some kind of code review agent -- personalized coaaching -- capturing: recurring regression patterns (cool) -- 50% reduction on cycle time for pull requests. 

governing agents -- sub agents -- fine -- one thing I liked -- he likes fine grained agents -- agent workbench, dev-ex, dev-ops, kubernetes -- his most successful developers are the kids hes getting out of college -- that's pretty wild; it speaks to fearlessness, and not nesissarily knowing.

TODAY: he's building an agent to help with management -- (1) that hes getting his monies worth (2) timecards monitoring -- what applications are they running -- approve timecards -- this sounds disgusting -- role specificity; 80% on whatever project, KPI -- they're in teams -- youtube -- 

His goal by the end of the year -- moving everything to "Outsystems" -- I've got to read up on that.

Beyond that: he wants to look at loan orgination.

ADVICE: network, learn share, foster an enviornment.


=======================
BAUPLAN: CEO
1140 -- Coding Agents for Data at Scale
The road to autonomous coding.
The point: "relax" the need of the person in the flow -- that takes care of things; make sure you dont have to be in the flow all the time.
If you want agents to be E2E -- eventually, the agent will touch your data -- datalakes, corrupted.
> Why dont you figure out why this is corrupted and fix it.
Take an action, change a table -- change a something.
How many of you would let an agent touch production data: no one raises their hand.
Two problems: the horror stories on twitter -- there is no clear mental model -- how to let an agent touch your data, we've comfortable writing code and reading.
BUT: drop a table, write a table, write some files -- slowdown when it touches data. 
What can we do??
Bring some lessons that we'e learned -- from coding. (Ralph is unshaken by failure) -- "Ralph Wigam" -- favor GRIT over intelligence <-- I really like this
TRY: fail, CONTEXT <-- -- try again <-- context --- sure; iterative processes; run as many tiems as its needed to be right.
In code: we have a clear harness -- we have GIT -- allows agents to fail safely -- (YES I AGREE COMPLETELY) -- this is effectively trying something in a safe way.
MOVE FAST, FAIL FAST, BREAK LOCAL THINGS <-- a takeaway -- enthusiastic failure
DATA IS DIFFERENT -- failure is catastrophic (agree) broken pipelines, inconsistent states, work together -- -constant sync, YOLO -- no build in versioning makes recovery and auditing impossible.
AGAIN: no clear mental model for conflict resolution
They move slow, they fail slow, they break shared things. 8-hour runs, woops -- 
BAUPLAN: allowing agents to touch your data so you can sleep at night. Analytics. Datapipeline.
They run at scale a bunch of agents -- internalize lessons around SWE, bringing it into the ops.

GIT: for your data (good idea) -- data lake invoked -- import some new data -- change a pipeline. It looks like S3 from here. Creates a branch -- a local copy -- "agent.feature_br" -- 

HONESTLY: I'm not sure if branching "data" is real -- git LFS -- review, statistical testing, 

COMPLEX INFRA: everything is expressed in code -- agents can write python flawlessly, two tracks: code ++ data :: branches of both -- 

Use Case -- some property management software -- LINEAR -- automating ticketing <-- linear has showed up MANY times
Engineers: go from doing the work to validating it -- code branch, data branch -- BAUPLAN -- agents are doing everything -- you wake up to a bunch of attempted fixes.
WHAT does the agent do: it RALPHS -- you MUST allow it to fail without the disruptive consequences (completely agree)
If you have a system with pockets of air -- you must allow it to be wrong as many times as it is needed to be right. You have to trust it. 
The problem is not intelligence: context (of course) *** infrastructure -- a thing where you cannot be wrong **

IF you dont success at first -- skydiving is not for you.

DO NOT ASSUME THAT THE AGENT IS TRUSTWORTHY.

Assume they are not -- dial in the blast radius.

=========================== :: here 45 minutes early -- shows real demand.

VIKAS BHAMBRI -- comments about a lack of dropoff

-- clearly :: the tech is not the hard part -- no kidding :: https://url.us.m.mimecastprotect.com/s/EXufCVOW6YTlo20NFGfBUEJH4y?domain=rasa.com -
-- rasa has been around for 10 years -- they power some highly used agents, CX, EX side - dev platform - voice digital, what's app -- etc
-- 40 million customer conversations (voice & chat) - hosting in your enviornment becomes crucial -- LLM mkt is changing in dramatic fashion, hourly, daily
-- how do we keep up? -- we still do not understand the costs :: the future is 100% multi-moodal -- agree, no question -- he's saying voice.
-- enterprise:: engineering teams are starting to build -- scattered throughout the enterprise - multi-modal -- multi-team -- multi-agent
-- public seccor: EU -- services provided to citizens -- the next 12 months -- will separate all the different teams
-- thesis: developer first -- (fine, but I'm not sure they're not SME types)

========= READY SET === SYSTEMS DESIGN FOR NON HUMAN ACTORS == (Generative AI Blackbelt, Heiko Hotz)-- ARCHITECTING FOR AGENTIC CUSTOMER
REMEMBER THESE: shows picture of amazon echo, alexa, google home, siri -- smart speakers ==> promise --> over time these speakers will get better, switch on light, ask for weather, more actions -- buy, etc.
Smart speaker -- fine for re-ordreing coffee -- but laptop charger -- not so much; systems not built for conversation.
BUDDY WORKS AT GOOGLE: generative AI blackbelt -- works at google cloud -- works with customers to build-out -- LangChain - ADK, etc, A2A is HEATING UP -- the designs the systems; A2A comms.
HE STARTED LOOKING INTO: Commerce -- one of the first verticals where A2A is happening -- interactions transactions, blast radius is small -- fine.
Agentic Commerce <> Agentic Commerce -- Conversational Commerce -- "I want a coffee machine" -- discovery, GPT, back and forth, preferences, maybe checkout -- human driving -- fine
THE SYSTEMS HES INTERESTED IN: It does discovery, comparisons, A1A, UCP, AP2 (agent payments) -- automonous commerce -- protocols are being built. Universal Commerce Protocol.

HALLUCINATIONS -- the thought of sending one out to buy something is facinating and scarry -- mis undersanding -- overspend, 
MANIPULATIONS: authority, social proof, loss aversion -- fake credentials, claims warnings

ITS NOT ONE LLM WITH TOOLS

** how can we leverage strengths ** --- a deterministic layer ==> UCP -- they see your website through structured data.

The sandwhich architecture

layer 1 -- translator -- water_resist >= 15k
layer 2 -- executor -- deterministic code UCPM endpoint, dumb deterministic filtering
layer 3 -- the judge -- two results back, preferences -- human in the loop layer

Implications -- merchant side ==> how should they expose their data :: Persuasion will not go away -- two chargers -- one has an extra feature

INTERESTING -- agent rates UL certified -- UCP progress :: it seems like everyone is in -- introduced by Google in January. AMAZON || MSFT | SALES FORCE || GOOGLE --> etc

What he's investigating in agentic commerce -- how to build storefronts -- structured data -- pricing; all of thse --questions, "ACO" agent optimized -- trust -- audit -- whole trnasactions

====================== JULIE YAUNCHES :: SENIOR AI ENGINEER -- NVIDIA -- she's on applies AI at NVidia :: leave the craziness behind two stories

mid-2025 -- applied AI lab -- building chatbots, pipelines, orchestration, normal software, inference at different points -- started using coding harnesses CLIs plug into their harnesses.
They started building a range of CLIs -- 

interesting -- she's building CLIs -- to plug into harnesses -- JAN 2026 -- claude code becomes available to all of NVidia -- someone discovreed the e-mail CLI -- it became a whole thing
They built 25 CLIs in 10 weeks -- normal code, same shit -- outlook-cli, dl-cli, they were building a PILE of CLIs -- the adoption EXPLODED (I really like this story) -- 
Emerging slack shanneles named automate everything -- executives were in an playing with it -- this was all Q1

Prompt -- Microsite Recipe --> VM ++ DNS -- GH -- this presentation is a micro-site :: she is NEVER producing a deck -- "Elements"

WHERE IS HERE TEAM RIGHT NOW -- they're still supporting CLIs (adopting continues to grow) -- moving to NEMO-CLAW
30-40 PRS PER DAY on DEMO LAW -- 4 ENGINEERS ON THE CLI TEAM

### STRAIGHT TO ENGINERING PRACTICES (IM HERE ALREADY)

*** THE VELOCITY GAP -- two rates -- writing code \\\ validation -- verification --> how to bring it up to the pace -- dozens of community PRs per day

*** WHAT OUR PROCESSES CAN OBSORB -- 100% of code was agent built -- has not looked at a line of code

RESEARCH -- GATES -- SWEEPS
inspect history, standards, sweeps -- BINGO -- this is nailing it
-- this matches my own thinking precisel

RESEARCH - same tools we use to write code we do for our research -- critically important -- I agree - (map, history, seams, artifact) -- 
produce a diagram -- sure -- I'm there -- human is digging in to the topology :: the concept, interrogating the diagram. whats happening, what will change -etc

GATES AND SWEEPS
the gate is what prevents rot from entering production -- 

LAYERED PR GATES
-- github workflows -- fast feedback, looking over the PR, determining what suite to run -- cost factors in (interesting)
-- behavioral vertification :: E2E in real containers
-- how you do PR reviews -- 4 engineers they skipped sweeping ::

drift detection, conflicting PR, sec review, arch alignment, test coverage assessment <-- all good things (from her personal review process)

** funny -- whats happening the behind the scenes -- it's agents going back and forth but there are no humans -- lol

COVERAGE RATCHETS <-- I fucking love this
PR LIIMITS
DEPENDENCY PINNING
MIGRATION GARUDS
ODEOWNERS
COMMIT LINTING

Sweeps clean what gates cannot see -- Nighly E2E -- repeated review patterns

Research, Gates, Sweeps -- NOT A CHECKLIST -- ongoing evolution ==> sharper gates

^^ I really liked her talk -- I liked the CLIs -- I liked

shes on github ** def check her out.

====================== NEXT TALK: COCKROACH LABS -- SPENCER KIMBALL -- CEO -- this should be wild -- I talked to them earlier -- their name is insane.

cockroach is a legacy system -- the binding constraints -- it's not the model || its the INFRASTRUCTURE -- will determine if you success if surviable. 2025 seems like an age ago.

100K of code in 5 weeks -- buddy was an SWE -- 100k lines of code -- was usually years (YUP)

** settled question -- 

THE KNOWLEDGE PROBLEM -- Citta -- these huge storhouse -- transcripts from customer calls -- GONG calls -> snowflake -- 150k Q&A pairs -- 10k canonical questions
there is an ONTOLOGY -- (yuuup) -- that resonates -- every agent context :: needs a curated knowledge domain -- that agents can safely draw from
back to context engineering -- why, point in time -- its about gevernance - about recall -- to solve their problems -- not a new idea.

EVERYONE IS CONVERGING ON A SINGLE USE CASE: Corporate AGI -- cochroachDb -- what substrate will survive -- 

agent driven load HAS NOT FUCKINNG LANDED -- 1000 agents vs 1000 humans is RADICALLY different (my editorializg -- things are about to get HARD) -- with humans the database can breath.
with agents -- agents proliferate -- you may have 50k agents -- then you may have 250k agents -- whats the natural limit -- how many -- O(10B) agents -- orders of magnitude :: more TPS --
COMPOUNDING LOAD PROBLEM --- history of data under manageent -- 10x evrey 10 years :: agentic patterns are radicaly different ;; 2030 -- 2027 -- 10x in 3-5 years, next:: 1 year

COSTS :: HOLY SHIT -- I'm ahead here -- 2025 was all outages -- capacity planning showing strain, outages everywhere, thees are not isolated -- exhaustive autonomous query pattenrs.
THe bottleneck is systems of record -- messaging, durability, correctness, elastic scale, surge > surge > surge -- state of AI 2026 -- leadership is radically underestimating the situation.

building infrastructure -- NOT EVEN CLOSE TO FREE :: ARCHITECTURAL REASONING -- IS ABSOLUTELY SHITTY -- technologies from the before time. that gap will close.

Were all buiding ABOVE THE DATABASE -- right instinct, shitty legacy achitecture -- 

the vibe coder scaling disaster -- postgres -- runaway hit, scale --> WALL SSHHHHHIT!

** starting on distributed infrastructure -- consistency -- SINDLE NODE compound into full rewrite (whackamole) -- DO NOT START ON POSTGRES. (I agree)

-- coachroach vs postgres -- buddy does not operate coachroach -- nice it's been out there for a while -- so the models know his tech.

|| do NOT BE MONOLITHIC -- || start th right way -- building different assumptions in every line of code -- COACHROACH --.survivable

hierachy of concerns -- acure constraint here is a monaster pressure point directly into databases -- commoidty hardware chained together.

complexity -- TCO :: complexity -- monolithic -- 32 - 64 --> who wants to spent 100x more on databases. distributed architecture -- this is a mandate for the future -- extremely elastic -- autoscaling
all the area under the curve -- every enterprise wants to run 1000 applications -- 
MILLIONS OF DATABASES -- cost efficincy at scale -- the only moat is velocity -- switching costs are going down -- we gotta put this on lightspeed.
system of record must be indestructable :: IT dependences -- if agents cannot come to work -- your company is not running that day

IMPERATIVE :: modles - tiers whatever -- it's WHAT YOU BUILD ON TOP OF -- or its going to be a FORCED REWRITE :: shit is collapsing :: starting right is a free lunch.

THE NEXT ERA:: will be limite by INFRASTRUCTURE :: inteligence is abundant and cheapt


======================== NEXT TALK -- senior software engineer form
this talk is a panel -- ryan hamilton :: millions of pipelines guy
-- circle CI -- lets go; databricks, open-ai -- KEVIN from databricks -- OPENAI -- Kyle :: building AGENT SDK :: AGENT KIT :: WOrkspace agents
 DX study -- 400 ompanies -- 14 months -- 10% productivity gain -- 2-3 100x? reality -- MODEST 10% gain, 
there is a speed and perception gap -- way way higher than reality -- we're not as productive as we think.
-- code you ship -- code you understabd :: 28 million pipelines per month :: 
WOW -- this guy sees things that we could not see:
*PIPELINES ARE FAILING AT A RATE THEYVE NEVER SEEN BEFORE -- this is circle CI speaking -- hes in the catbird seat.
It's pareto distributed -- bottom quartile is getting an insane 0-4% lift -- while the top teams are - power users are increasing -- more seniority are using it more -- bigger boost
Ultra-leading edge adopters -- disseminating information -- outside of engineering : designers and PMs are using it to communicate :: pack a prototype ;; share it -- ground to debate over
CHRIS: from OpenAI -- you need to know how to use the AI to get the most out of it ~~ systems in place to take advantage of it :: non-technical people using it -- 
DESIGNERS: in cursor -- product people are shipping PRs -- everyone is trying to ship at circle CI -- 
everyone thinks that they're going to 100x their productivity -- is there a perception gap -- siesmic shift :: new tools -- the tool are catching up -- productivity gains are catching up
METER: released an updated version of the study -- now it's showing 15% -- 
 --- fast inner loop :: bottleneck outer loop :: ouch, throughput limit -- PRs -- multiple models doing the review, CI is a huge pain, wait for 2H, shift things left -- (this matches my work
*** HUMAN TASTE -- monsterous bottleneck -- how SHOULD we build this project, minimal number of concepts -- HUGE HUGE BOTTLENECK
*** DECISION MAKING CLARITY: who owns the truth, which people
** BUDDY IS SAYING:: CONFLICTING CODE -- suggestion that GIT itself may be dead ;; interesting -- I'm not sure -- git is distributed -- I think he's missing the boat -- code shape // arch

Q: do we trust automated review -- nessisary but not sufficient -- agent automatically react -- 

ANEDOTELY: plan -- 5 other agents -- continuous loop -- approval from at least four agents <-- this is fucking good -- closes the confidence gap. -- each of the 5 focuses on sub-goals
^^ the whole room just went "aha" -- it was subtle but I heard it. --

PIPELINES CAN GET BEEFY -- little micro Ci's closer to the inner loop -- smart -- give agent context to iterate quicly

DROP SOME GEMS -- KEVIN: words of wisdom :: focus on the human bottlenecks (agreed) -- OBSERVABILITY (cant manage what you cant measure)
THE FASTEST IS WRONG: feel confident about kicking off whatever you need -- (shoot -- I'm going to BURN tokens) -- get your shit set up -- let your agents rip with confidence.

-=-=-=-=-=-=-=- 30 MINUTE BREAK ~+~+~+~++~+~+~+~+~
NEXT: garbage data --> garbage agents:::::::::::::
--------------------------------------------------

BARR MOSES -- MONTECARLO CEO -- MISSON: to enable enterprises to adopt trusted AI -- >> garbage data --> garbage agents (how do we avoid both)
AGENT ICEBERG AGAIN -- what you dont see is often the problem

EVERYONE IS BUILDING AGENTS -- very few are running relian -- deploy gap -- 

** failures // blindspots // lack of trust -- RAMPANT :: 20 --> 200 whats stopping is all trust

* 64% incorrect response -- confident wrong answers
** 59% not confident in visibiity (table stakes)
* 48% performance ussyes -- latency
* 49% accessing data or systems are not aware of -- woops, 1/2 in chance it accesses a bad dataset.

the above is why fewer 

-- source table -- schema change -- etc -- agent failures -- are sometimes data failures in disguse.
-- the model isnt good enough, my prompts, etc -- actually -- underlynng driver is source table
-- no one monitors the data feeding the agents

*** this situation compounds ** 

1. source data
2. chunking -- where it splits
3. embedding -- embeddings
4. vector store -- retrieval

^^ I am intimately familar with this whole situation.

Data ++ AI must become ONE HOLISTIC SYSTEM

-- they are intertwined -- data and AI state as one.

CONTEXT, PERF, BEHAVIOR (decison making), OUTPUTS

if it can show me the sources -- psychology -- strong OBSERVABILITY :: (this keeps coming up) -- not to hear about it downstream -- remediate in an agentic first way

How do we make sure they're pulling the right tool at the right time -- it can have all of these right -- and it can still hallucinate.
UUnderstandig the quality of the output -- (I'm waiting for how)

EXAMPLE OF THIS IN THE WILD

troubleshooting agent -- automates how teams identify and resolve agentic failures -- agents monitoring agents

MONTECARLO -- looks like they have a product for this whole situation -- an agent automatically identified problems :: I wonder :: 

the agent needs to detect and troublehoot --shes using a temporal correlation -- draw the full linear, an upstream DAG, source fail, all the way down -- 

the point is :: agentic workflow to trace all the way upstream -- agent took 12 seconds -- you get FAST TRIAGE -- drafted slack messgae -- > add a circuit breaker :: stop the agent from having bad conversations

ALL OF THIS IS DONE IN PRODUCTION -- this is self healing -- 

here point -- we're not going to be able to keep monitoring by hand -- this is an area where we can find the highest LIFT for the organization -- I agree, inspirational -- 

TAKEAWAY -- 

DATALAYER, SEMANTIC LAYER, AGENT BUILD LAYER, TRUST LAYER
-----------------------------------------------
the bedrock --- maximixes context relevance --- dont bet on one platform multi-builder plan for diversity it's ---- trust: not a box on top

https://url.us.m.mimecastprotect.com/s/ZfiuCW614ZFjm6zRfxhYUo66y0?domain=crew.ai
SERIURA 
DECAGON

THE AGENT READINESS SCORE CARE <-- this is awesome --- DO YOU HAVE AGENTS DOING THE OBSERABILITY FOR YOU.

She posits that AI lets you leapfog all the way to level 3 -- it's a nice ROI for the -- AI happy hour -- good talk.

-=-=-=-=-=-=-=-=-=-= 
NEXT TALK: ARCADE :: ALEX SALAZAR :: 
---------------------
buddy was trying to build a site reliability agent -- that was difficult :: scoped delegated user auth, for agents -- didnt exist -- 

ARCADE :: MCP RUNTIME that enables agents to connect -- 

HOBSPOT guy -- scaling security has been stable -- > 3000 tools that an agent could call :: WILD -- seems FUCKED -- but its hubspot

-- MCPs have evolved a lot in the last 8 months -- this guy works at gouppon :: 16 countries :: people love them he says -- what kind of troubes:

RALPH BIRD -- SRE agents -- dev-ops, nocs, to deal with incidents -- Mike would like this -- MCP bagloads of MCPs flooding tokens -- yup.

contextualixing the work -- how many agents -- 

HUBSPOT -- 2500 distinct agents -- flagging, SRE, -- for MCP servers -- SINGLE SERVER -- exposes everything -- backs all 3k of those tools.
the agents are composing

GROUPON: 150 agents -- many subagents -- 45-60 agents -- this guy is in infrastructure -- so it's about criticality (a good point) -- 12-20 MCPs -- data catalog, graphana, ape, GCP stack.

PAGER DUTY: 5 customer facing agents -- we'll be rebuilding agents -- they have single MCP - on for traditional APIs -- 

externally facing MCP -- big challenge: getting people to trust it - validate it -- it doesn't work on some small edge case -- (how do you show the value) -- slack, 

HUBSPOT: customer facing -- exteral facing :: security -- two subsets, we operate it, security is a little easier, the union of user || agent permissions -- an MCP they ship, but they dont control the agent -- a lot tricker -- what the user can do in the application -- ONE PATTERN: "as the user" no seperaation -- what happens when agent hallucinates -- intent vs actuality -- 1st party they can, since they know the source :: trcky upcoming problem, using MCP -- in the age of AI people will work around whatever they can. differentiate user to agent permission -- limiting the MCP is shifting the problem -- 

and so -- you would rather log and audit -- dont hard delete :: internal agents are a very different game <-- yup :: graphana -- MCP call deleted whole policy -- indident management was blacked out.
service accounts -- doesn't support MCP natively -- seperate graphana server -- different folders for different teams :: focused on criticality (repeated) -- skill -- 

where are limitations of service accounts -- SRE agents -- indident -- many people speaking to the agent -- what auth does it have?? mmulti-agent conversaitons -- hmm, interesting -- a matrix of permissions
has a different opinion about what they want -- configurabiiity (custommer faciing agents) -- who has access -- flip side :: ergonomics -- service account granularity

what is preventing the general employee access to the general agents -- hubspot HAS given it out -- DATA LEAKAGE -- users want to share - supposing you do integrate -- 
things finding their way into traces -- private HR conversations -- hmm, interesting -- user made the choice -- its less obvious in AI systems :: DLP APIS -- pager duty guy last word

** data leakage -- its getting easier for it to happen :: hardware scaling, graphana, github recently, more security -- more governance.

-------------------------------
_++_+_+_+_+_+_+_+_+_+_++_+_++__+
NEXT TALK --- DIRECTOR OF PRODUCT MANAGEMENT :: RING CENTRAL
__________________________________________
MAYANK ARGAWAL --- SOLO talk -- saved the best for last -- M
DETERMINISTIC vs AGENTIC
NOT EVERYTHING NEEDS TO BE AN AGENT <-- yuuuup -- YUUUP
be on the lookout for deterministic workflowsvs -- vs -- judgement -- hyptothis - open ended reasoning, direction -- dont know the answer in advance.
BRIGHT LINE ----------- between these two things :: super common architectural pipeline :: every time you add an agent instead of a pipeline -- (I'kk champion this)
MACRO TRADING -- asset class, chraracteristics, strategies, FX vs futures, vs whatever -- all different -- no single researcher will be an expert across all -- 

SPECIALIZATION -- one agent per -- deterministic system -- own the strategy -- e2e -- TWO layers -- 
SWARM ARCHITECTURE -- this is cool as shit -- (( SWARM LEVEL REFLECTION -- portfolio level decisions)
---------
deterministic layer belowo -- well engineered determinstic software -- agents produce straegies -- deterministic system runs them -- that separation -- allows agents to focus on what they do best.
-- still grooving on this.

---------- DRAW THE BOUNDARY -- enforce it -- do not let agents leak into the exe--cution layer --THIS IS VERY FUCKING COOL -- I'm jazzed about what he's saying.
if a strategy falls below performance -- signal decay -- new signal -- new hypotesis -- this cycle -- demands an agent -- open ended reason -- 

SPECIALIZE DEPELY -- they tried generalist agent ;; research quality dropped :: hypothsis -- shallow -- 

EQUITY MOMENTUM
COMMODITY
FX CARRY

all were WEAK -- that narrowing, produced significant shift in quality --- way way more nuanced --deep expertise beats broad coverage -- no distraction

QUALITY GATES -- just backtesting well is not good enough -- overfitting -- candidate stragegy must pass through quality gates -- regeime stress testing, capacity and impact, 
prevents the swarm from fooling itself -- 

SWARM LEVEL REFLECTION -- "a managed research organization" -- fascinating -- orchestrator is evaluating all strategies as a whole. -- can push constraints down to the agents -- 
prevents cross-strategy correlation detection -- common risk patterns, agggregate risk envelope.emergence; freezes deployment -- agent performanc ranking, agent lifecycle management.

FAILURE MODES ---

overfitting :: more iterations didnt mean better strategies (overfitting detectors into the loop itself, punish too many parameters)
correlatioed convergence -- only checking correlation at deployment -- regimes shifted -- they all drew down at the same time -- continuous monitoring
strategy drift -- agent improved its strategy -- and -- it was undebuggable -- woops :: learned: interperability, if it cannot explain, it cannot ship.
runaway research compute: exploration budget -- it would chase for weeks -- going to try and improve something that would never improve.


HOW DOES THIS ALL TRANSLATE TO ENTREPRISE AI -- EVERYTHING HERE MAPS TO AGENTIC SYSTEMS -- SAME ARCHITECTURE -- 
-- domain experts -- yup, that fits.
-- WHICH AGENTS DELIVER ROI -- analyzing patterns -- why eval times are increasing -- deploying through governance layer
-- swarm level reflection - measureable ROI -- vs consuming ROI retired vs spun out - deterministic execution layer. these handle known prodecures (and do not need agents)
-- reasoning, iteration, judgement

TAKEAWAYS	

1. respect the bright line between agents -- and determism
2. specialize deeply -- quality collapsed for generalists
3. reflect at the swarm level -- we need orchestration that evaluates collective quality -- emeergent risks
4. govern the boundary beween research and production -- quality gates -- 

CLOSING THOUGHT __ 

you are not building an agent -- you are building an autonoumous evlaution -- archtecture is the management structure.

MY NOTES (DURING TRAIN RIDE)
--- knowing the domain -- software fully democratized - coding is the easy part

