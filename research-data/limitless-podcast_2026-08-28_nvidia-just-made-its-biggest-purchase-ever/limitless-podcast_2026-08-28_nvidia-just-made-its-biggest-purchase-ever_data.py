"""
Data file for: Limitless Podcast — "NVIDIA Just Made Its Biggest Purchase Ever" (2026-08-28)
"""

META = {
    "title": "NVIDIA Just Made Its Biggest Purchase Ever",
    "channel": "Limitless Podcast",
    "speakers": "EJ & Josh",
    "date": "2026-08-28",
    "video_url": "https://www.youtube.com/watch?v=cKA6HyrxAGA",
    "thread_line": "6 threads — Nvidia's record quarter and $13B Hugging Face buy, Chinese silicon's inference breakthrough, robotaxi hardware leaps, Leopold Aschenbrenner's SEC probe, an Anthropic-usage chart fight, and Sam Altman's watch tea",
    "category": "market",
}

SNAPSHOT = [
    "Nvidia posted a record quarter (~$100B in 3 months, +100% YoY) and every bank on the panel's screen raised its price target, top one $420/share, after guiding 70% YoY growth for 2028 vs. 44% previously expected.",
    "Nvidia made its biggest-ever purchase: a $13B acquisition of Hugging Face, the open-source AI model hosting platform — read as a hedge against OpenAI/Google/Amazon building their own chips, and a possible back door into its own cloud business.",
    "A mystery model that gave away ~100s of trillions of free tokens for a week turned out to be Z.AI's GLM 5.3 Flash — running entirely on Chinese silicon (Huawei-built cluster), the first time that's happened at this scale.",
    "Waymo shipped a new onboard chip (20x more powerful, 5x cheaper) cutting its sensor-suite cost from ~$125-260K to $25K; Tesla's Cyber Cab (~$25K sensor stack incl. vehicle) launches September 3 across six US cities.",
    "Leopold Aschenbrenner's Situational Awareness fund is being probed by the SEC (banks subpoenaed) over possible insider trading; hosts are skeptical anything comes of it.",
    "An FT chart claiming Anthropic/Fable usage has stagnated while OpenAI's grows got pushback from the hosts as unreliable, since Anthropic doesn't disclose real numbers.",
    "Rapid fire: Apple's hardware event is set for September 19 (new iPhone, foldable, first event under CEO John Ternus); Sam Altman ordered seven ultra-rare custom watches, engraved with an AGI-alignment reference, read as a pre-IPO gift to staff.",
]

THEMES = [
    {
        "id": "nvidia-earnings",
        "tags": ["semis", "ai-infra"],
        "color": "green",
        "badge": "Confirmed event",
        "status": "REPORTED THIS WEEK",
        "title": "Nvidia's quarter was 'about as good as you can guess' — and Wall Street agrees",
        "lead": "**Nvidia's quarterly revenue now exceeds the annual revenue of roughly 480 S&P 500 companies, and every bank on the panel's screen raised its price target after the print.**",
        "bullets": [
            "Nvidia earned close to $100B in the quarter, growing 100% YoY — the hosts call it \"printing about just over a billion dollars in cash every single day that it operates.\"",
            "Guidance moved to 70% YoY growth for 2028, up from a prior expectation of 44%; the stock fell after hours but was up 7% in early trading the next day.",
            "Every bank shown on-screen raised its price target, highest at $420/share, which the hosts read as high-signal for a $5 trillion company.",
            "Nvidia raised GPU prices ~15%, mostly passing through soaring memory costs (memory stocks have been volatile) rather than pure margin expansion.",
            "All of this revenue was earned with zero chip sales to China under the ongoing US export ban — previously a major profit center.",
            "Nvidia is now working with five of the largest banks in the world to help fund data-center buildouts using its GPUs, and says it's sold out at full capacity.",
        ],
        "quote": {
            "text": "We're the kings here. We've been doing this for 33 years. You've been doing this for 3 months.",
            "cite": "— Jensen Huang, on OpenAI's in-house Jalapeno chip (paraphrased by the hosts from his CNBC appearance)",
        },
        "watch": "Jensen's 'we control 70-85% of the market' framing is his own response to competitive threats (OpenAI's Jalapeno ASIC, Google TPUs, Amazon's chips) — those chips haven't been proven at scale yet, so the moat claim is untested, not settled.",
        "names": [
            {"name": "Nvidia (NVDA)", "blurb": "Record quarter, guidance raised to 70% YoY growth for 2028, banks lifting price targets to as high as $420/share."},
            {"name": "OpenAI", "blurb": "Building its own custom AI chip, Jalapeno, claimed to be more efficient than Nvidia's — not yet deployed at scale."},
        ],
    },
    {
        "id": "hugging-face-buy",
        "tags": ["ai-infra", "software"],
        "color": "green",
        "badge": "High conviction",
        "status": "ANNOUNCED THIS WEEK — $13B",
        "title": "Nvidia's $13B Hugging Face buy: a hedge, a demand engine, and maybe a cloud business in disguise",
        "lead": "**Jensen paid roughly 50x Hugging Face's revenue for the open-source model hub — because in his world, hundreds of niche and broad models all still need to run on his GPUs.**",
        "bullets": [
            "Hugging Face hosts open-source AI models for any lab to upload, fine-tune and deploy — e.g. Z.AI's GLM family alone has ~155,000 derivative fine-tuned models on the platform.",
            "It's the third and biggest leg of a deliberate open-source push: Nvidia also put roughly $9B into Poolside last week (an acquihire of ~100 employees) and is investing tens of billions over several years into its own open model, Nemotron.",
            "Three strategic reasons per the hosts: (1) a hedge against OpenAI/Google/Amazon building their own chips, since open-source demand keeps token volume flowing through Nvidia GPUs regardless of who wins the chip war; (2) open-weight models are absorbing a growing share of inference volume because they're cheaper and 'good enough'; (3) the moat is moving up the stack — CUDA-optimized, one-click deployment onto Nvidia's own cloud.",
            "Host theory (labeled speculative by the hosts themselves): Hugging Face's inference service — which routes clicks to run any of its ~3 million hosted models to neoclouds — could let Nvidia build its own cloud business to compete with AWS/GCP, whose AI-cloud margins (40-50%) already run below their non-AI cloud margins (~80%).",
            "That dovetails with last week's news of Nvidia raising $500B partly to back purchases that circle back to itself — if Nvidia can't sell chips elsewhere, it could sell them to its own newly-acquired Hugging Face-run cloud business.",
        ],
        "quote": None,
        "watch": "The 'Nvidia is quietly building a cloud business' read is explicitly framed by the hosts as a conspiracy theory (\"can I put my tinfoil hound on\") — not confirmed by Nvidia.",
        "names": [
            {"name": "Hugging Face", "blurb": "Open-source AI model hosting platform (~3 million hosted models) acquired by Nvidia for $13B."},
            {"name": "Poolside", "blurb": "AI coding-model startup Nvidia invested roughly $9B into the prior week, described as an acquihire of ~100 employees."},
        ],
    },
    {
        "id": "chinese-silicon",
        "tags": ["semis", "geopolitics"],
        "color": "amber",
        "badge": "Contested",
        "status": "FIRST OF ITS KIND, PER THE HOSTS",
        "title": "A free 100-trillion-token giveaway turned out to be Chinese silicon's coming-out party",
        "lead": "**Z.AI's GLM 5.3 Flash gave away roughly 100+ trillion tokens for free for a week — and every one of them was generated on a Huawei-built cluster running entirely on Chinese silicon.**",
        "bullets": [
            "Benchmarks put GLM 5.3 Flash at roughly Opus-tier agentic performance, not frontier, but at 15 cents per million tokens, and with video/audio/text understanding.",
            "US export bans have blocked Nvidia chip sales to China for about four months; China can't yet train frontier models on domestic chips but is using techniques like distillation to make its chips work well for inference, which the hosts note is where most of AI's money gets made anyway.",
            "Per the hosts, Chinese chip makers were roughly 2.5 years behind six months ago and are now running the inference stack for a competitive open-source model — Huawei's cluster went from announced to full-scale production in about a month.",
            "The push is partly state-mandated: the Chinese government has directed reduced reliance on Nvidia chips, and chipmakers have responded that training isn't ready yet but inference is.",
        ],
        "quote": None,
        "watch": "The hosts frame the speed of China's catch-up as 'concerning' and 'a little unnerving' but stop short of independently verifying the chip's specs or Huawei's production claims — this is relayed from public announcements, not measured firsthand.",
        "names": [
            {"name": "Huawei", "blurb": "Built the Chinese silicon cluster now reportedly at full-scale production, used to serve Z.AI's GLM 5.3 Flash inference."},
        ],
    },
    {
        "id": "robotaxi-hardware",
        "tags": ["robotics", "consumer"],
        "color": "green",
        "badge": "Confirmed event",
        "status": "WAYMO CHIP SHIPPED; CYBER CAB LAUNCHES SEPT 3",
        "title": "Robotaxi hardware just got a lot cheaper, on two different bets",
        "lead": "**Waymo's new onboard chip is 20x more powerful and 5x cheaper, cutting its sensor-suite cost from ~$125-260K to $25K, while Tesla's Cyber Cab is betting an entire ~$25K vehicle-plus-sensors on camera-only hardware.**",
        "bullets": [
            "Waymo's new vehicle moves all compute onboard (in the trunk) instead of relying on a cloud round-trip, removing the risk of losing connectivity mid-drive; the chip is 20x more powerful and lets the sensor-suite hardware cost drop roughly 3-4x per generation, from ~$125-260K to $25K.",
            "Tesla's Cyber Cab uses a much simpler 8-camera stack (similar to smartphone cameras) instead of Waymo's spinning lidar array; combined with the vehicle, total cost of goods sold lands around $25K, and it launches at scale September 3 in Austin, Dallas, Houston, Miami, Orlando, and Tampa.",
            "Waymo is geofenced to specific cities but has more accumulated ride volume and rider comfort today; Cyber Cab isn't geofenced the same way and could scale faster once regulation catches up, per the hosts.",
            "Separately, a robotics breakthrough using in-context learning let a robot learn a task (flipping pancakes) from a single 30-second demo video, generalize to correcting mistakes (stacking pancakes instead of repeating a dropped one), and improvise tools it had never seen (using a banana in place of a brush handle) — data for these models is increasingly crowdsourced via paid gig work (~$15/hour with a headcam) and prior DoorDash dasher head-camera programs.",
        ],
        "quote": None,
        "watch": None,
        "names": [
            {"name": "Alphabet (GOOGL)", "blurb": "Waymo's new vehicle and onboard chip cut sensor-suite hardware cost roughly 3-4x."},
            {"name": "Tesla (TSLA)", "blurb": "Cyber Cab launches at scale September 3 across six US cities with a ~$25K camera-only sensor stack."},
        ],
    },
    {
        "id": "leopold-probe",
        "tags": ["finance", "policy"],
        "color": "amber",
        "badge": "Contested",
        "status": "SEC SUBPOENAS ISSUED",
        "title": "Leopold Aschenbrenner's fund is now under SEC scrutiny",
        "lead": "**The SEC has subpoenaed banks tied to Leopold Aschenbrenner's Situational Awareness fund over suspected insider trading, though the hosts think it's likely nothing.**",
        "bullets": [
            "The subpoenas target banks that facilitated trades for the fund, on suspicion Aschenbrenner may have traded on non-public information rather than disclosing it.",
            "The hosts note his wife, referred to as Anthropic's chief of staff, as a potential information-proximity angle, without claiming any wrongdoing is confirmed.",
            "Despite the probe and an earlier public portfolio wipeout, Aschenbrenner has made a $400M private investment in another company and the fund is reportedly still up overall.",
        ],
        "quote": None,
        "watch": "The hosts are explicit that opening an SEC investigation only requires a filed complaint, and that they think this will likely 'blow over' — this is an open probe, not a finding.",
        "names": [
            {"name": "Citadel", "blurb": "Bought out Aschenbrenner's earlier fund after an earlier drawdown, per the hosts' recap."},
        ],
    },
    {
        "id": "anthropic-usage-chart",
        "tags": ["ai-infra"],
        "color": "gray",
        "badge": "Speculative",
        "status": "DISPUTED BY THE HOSTS",
        "title": "A viral FT chart claims Fable usage has stalled — the hosts call it a 'nothing burger'",
        "lead": "**A Financial Times chart showing Anthropic's Fable usage flattening since July while OpenAI's climbs got called out by the hosts as built on numbers neither company actually discloses.**",
        "bullets": [
            "Anthropic is a private company that doesn't release verified usage numbers, so the hosts question the chart's data source before accepting its conclusion.",
            "Their alternative explanation: OpenAI has a smaller base so any uptick (e.g. from Codex) shows a bigger percentage gain, while Fable users may be shifting a growing share of work to cheaper open-source models and reserving Fable for the hardest 20%.",
            "One proposed factor: Zero Data Retention (ZDR) compliance — Anthropic reportedly still needs certain enterprise data for its own model improvement, unlike some competitors, which the hosts think could be masking real enterprise appetite for Fable's frontier models.",
        ],
        "quote": None,
        "watch": "The hosts explicitly flag they don't trust the underlying numbers ('I don't think these are necessarily reliable') and call the chart's framing a possible 'hit piece' — treat the stagnation claim itself as contested, not established.",
        "names": None,
    },
]

TAKEAWAYS = [
    {"icon": "\U0001F4C8", "tag": "Markets", "title": "Nvidia's guidance raise (44%→70% YoY for 2028) is the number to watch next quarter, not the historical print."},
    {"icon": "\U0001F517", "tag": "Markets", "title": "Track Hugging Face's inference-routing product for early signs of an Nvidia-run cloud business."},
    {"icon": "\U0001F1E8\U0001F1F3", "tag": "Geopolitics", "title": "Watch whether Chinese silicon moves from inference-only to training-capable — that's the real inflection point, not this week's giveaway."},
    {"icon": "\U0001F695", "tag": "Robotics", "title": "Compare Waymo's per-city ride volume against Cyber Cab's September 3 multi-city launch over the next month, not just sticker hardware cost."},
    {"icon": "\U0001F4CA", "tag": "AI", "title": "Discount usage charts about private AI labs (Anthropic, OpenAI) that don't cite a verifiable data source."},
]

RISKS = [
    "This episode is sponsored by Ledger (an AI-agent security tooling company); that sponsor segment is excluded from this brief entirely.",
    "Several figures (Waymo/Cyber Cab hardware costs, Sam Altman's watch valuation, Mac Studio pricing) are the hosts' verbal estimates stated in real time, not verified specs or receipts.",
    "The 'Nvidia building a cloud business via Hugging Face' theory is explicitly labeled speculation by the hosts, not a claim from Nvidia.",
    "Claims about Chinese silicon's capabilities are relayed from public announcements the hosts reacted to on-air, not independently benchmarked by them.",
    "Auto-generated captions were used as the transcript source; some names (e.g. the Sam Altman watchmaker brand) could not be confidently resolved and are described rather than named.",
]

HOT_TAKES = [
    {
        "take": "We're the kings here. We've been doing this for 33 years. You've been doing this for 3 months.",
        "cite": "— Jensen Huang (via hosts, on OpenAI's Jalapeno chip)",
        "why": "A direct, dismissive shot at a competitor's chip claims from the CEO of the company being challenged — he's on the hook if OpenAI's chip proves out at scale.",
    },
    {
        "take": "Buckle up because we are up only for the foreseeable future.",
        "cite": "— Host (Limitless Podcast)",
        "why": "An unqualified bullish call on Nvidia's stock with no hedge, made right after a record earnings beat.",
    },
    {
        "take": "All these people talking about free model, free model that. Like, just how about you just pay for like a subscription or like an API key... Buy an Nvidia GPU at this point, dude.",
        "cite": "— Host (Limitless Podcast)",
        "why": "A dismissive, contrarian jab at the local/open-model crowd given rising hardware and memory costs — the kind of line that invites disagreement from that community.",
    },
    {
        "take": "I personally think it would be higher because there's only seven of them.",
        "cite": "— Host (Limitless Podcast)",
        "why": "A specific dollar-value prediction (above the $500K-$1M guesstimate mentioned) on Sam Altman's custom watches — a call that can be checked against any resale.",
    },
    {
        "take": "Leopold we trust, man. I'm still rooting for the guy.",
        "cite": "— Host (Limitless Podcast)",
        "why": "A personal vote of confidence in someone currently under SEC scrutiny — a stance the host is on record taking before the probe's outcome is known.",
    },
]

CLAIMS = [
    {"who": "Nvidia (guidance)", "claim": "Nvidia revenue growth rate for 2028", "metric": "YoY revenue growth", "target": "70%", "by": "2028", "condition": "raised from a prior 44% expectation", "entity": "Nvidia (NVDA)"},
    {"who": "Analyst price targets", "claim": "Nvidia share price target", "metric": "price target", "target": "$420/share", "by": None, "condition": "highest bank target shown", "entity": "Nvidia (NVDA)"},
]

RELATIONS = [
    {"from": "Nvidia (NVDA)", "rel": "acquires", "to": "Hugging Face", "note": "$13B acquisition, Nvidia's biggest purchase ever"},
    {"from": "Nvidia (NVDA)", "rel": "invests_in", "to": "Poolside", "note": "~$9B investment, acquihire of ~100 employees"},
    {"from": "Huawei", "rel": "supplies", "to": "Z.AI", "note": "GLM 5.3 Flash inference runs entirely on a Huawei-built silicon cluster"},
    {"from": "Citadel", "rel": "acquires", "to": "Leopold Aschenbrenner's fund", "note": "bought out the fund after an earlier drawdown"},
]

OTHER_NEWS = [
    {"icon": "\U0001F34E", "title": "Apple's hardware event is set for September 19 — first keynote under new CEO John Ternus (not Tim Cook), expected to unveil an iPhone 18 Pro and a foldable device, with Siri intelligence following shortly after.", "tag": "Apple"},
    {"icon": "\U0001F5A5\U0000FE0F", "title": "New Mac Mini and Mac Studio configs launched alongside M5 Pro and M6 chips; a maxed-out M6 Ultra Mac Studio runs roughly $18,500, which the hosts point to as the real cost of local inference right now.", "tag": "Hardware"},
    {"icon": "\U000023F1\U0000FE0F", "title": "Sam Altman ordered seven ultra-rare custom watches (from a luxury watchmaker the hosts couldn't confidently name), engraved with an AGI-alignment reference — read by the hosts as a gift to staff ahead of a rumored IPO and OpenAI's internal AGI timeline expectations by year-end.", "tag": "Culture"},
]

GLOSSARY = [
    {"term": "Jalapeno", "def": "OpenAI's in-house custom AI chip (an ASIC), built to reduce reliance on Nvidia GPUs; not yet proven at data-center scale."},
    {"term": "ASIC", "def": "An application-specific integrated circuit — a chip custom-built for one narrow task, as opposed to a general-purpose GPU like Nvidia's."},
    {"term": "Open weights / open-source models", "def": "Publicly downloadable model weights anyone can fine-tune and deploy, as opposed to closed frontier models like GPT or Claude."},
    {"term": "In-context learning (robotics)", "def": "A robot learning a new physical task from watching a single demonstration video, rather than being explicitly hardcoded to perform it."},
    {"term": "Zero Data Retention (ZDR)", "def": "An enterprise compliance commitment where an AI vendor doesn't retain or reuse a customer's data for its own purposes, including model training."},
    {"term": "Distillation", "def": "A technique for training a smaller or more efficient model to mimic a larger model's outputs, used here to help chips lacking frontier-training capability still perform well at inference."},
]
