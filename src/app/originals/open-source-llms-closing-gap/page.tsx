import { Metadata } from 'next';
import Link from 'next/link';
import { ArrowLeft, Clock } from 'lucide-react';
import { ArticleJsonLd } from '@/components/seo/JsonLd';

export const metadata: Metadata = {
  title: 'Open Source LLMs Are Closing the Gap Faster Than Anyone Expected',
  description:
    'Qwen 3.5 9B beats GPT-OSS-120B on GPQA Diamond. Gemma 4 runs on phones. Bonsai ships 1-bit models. Apache 2.0 licensing is making frontier performance free. What this means for the industry.',
  openGraph: {
    title: 'Open Source LLMs Are Closing the Gap Faster Than Anyone Expected',
    description: 'Qwen 3.5 9B beats GPT-OSS-120B on GPQA Diamond. Open source models are matching frontier performance at a fraction of the cost.',
    type: 'article',
    publishedTime: '2026-04-01T12:00:00Z',
    authors: ['Kira Nolan'],
  },
  twitter: {
    card: 'summary_large_image',
    title: 'Open Source LLMs Are Closing the Gap Faster Than Anyone Expected',
    description: 'Qwen 3.5 9B beats GPT-OSS-120B on GPQA Diamond. Open source models are rewriting the rules.',
  },
};

export default function OpenSourceLLMsPage() {
  return (
    <article className="max-w-3xl mx-auto px-4 sm:px-6 py-10">
      <ArticleJsonLd
        title="Open Source LLMs Are Closing the Gap Faster Than Anyone Expected"
        description="Qwen 3.5 9B beats GPT-OSS-120B on GPQA Diamond. Gemma 4 runs on phones. Apache 2.0 licensing is making frontier performance free."
        datePublished="2026-04-01"
        author="Kira Nolan"
      />

      {/* Back link */}
      <Link
        href="/originals"
        className="inline-flex items-center gap-1.5 text-sm text-text-muted hover:text-accent-primary transition-colors mb-8"
      >
        <ArrowLeft className="w-4 h-4" />
        Back to Originals
      </Link>

      {/* Header */}
      <header className="mb-10">
        <h1 className="text-3xl sm:text-4xl font-bold text-text-primary mb-4 leading-tight">
          Open Source LLMs Are Closing the Gap Faster Than Anyone Expected
        </h1>
        <div className="flex items-center gap-3 text-sm text-text-muted">
          <span className="text-text-secondary font-medium">Kira Nolan</span>
          <span>&middot;</span>
          <time dateTime="2026-04-01">April 1, 2026</time>
          <span>&middot;</span>
          <span className="flex items-center gap-1">
            <Clock className="w-3.5 h-3.5" />
            5 min read
          </span>
        </div>
      </header>

      {/* Article body */}
      <div className="prose-custom space-y-6 text-text-secondary leading-relaxed">
        <p className="text-lg text-text-primary leading-relaxed">
          Six months ago, if you told me a 9 billion parameter open source model would beat a 120 billion
          parameter model on graduate-level science questions, I would have been skeptical. That&apos;s
          exactly what happened. Alibaba&apos;s Qwen 3.5 9B outperformed OpenAI&apos;s GPT-OSS-120B on
          GPQA Diamond, one of the hardest LLM benchmarks in existence.
        </p>

        <p>
          This isn&apos;t an isolated result. Across the board, open source models are matching or beating
          closed-source alternatives that are 10x their size. The gap that everyone assumed would persist
          for years is closing in months.
        </p>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">The Benchmark Shock</h2>

        <p>
          Let me put the Qwen result in context. GPQA Diamond is a benchmark designed to be so hard that
          even expert PhD holders in the relevant field only score around 65%. It tests deep scientific
          reasoning, not pattern matching or trivia recall. Scoring well on GPQA Diamond requires genuine
          understanding.
        </p>

        <p>
          Qwen 3.5 9B scored 49.2% on GPQA Diamond. GPT-OSS-120B, OpenAI&apos;s open source release with
          over 13x the parameters, scored 47.8%. A model you can run on a single consumer GPU beat a
          model that needs a multi-GPU server.
        </p>

        <p>
          The implication is huge. Parameter count is no longer a reliable proxy for capability. Training
          methodology, data quality, and architectural innovations matter more than raw scale. Alibaba&apos;s
          team proved that a well-trained small model can outperform a brute-force large one.
        </p>

        <p>
          You can see how these models compare on our{' '}
          <Link href="/benchmarks" className="text-accent-primary hover:underline">benchmarks page</Link>,
          which tracks scores across GPQA, MMLU, HumanEval, and other major benchmarks.
        </p>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">The New Open Source Leaders</h2>

        <div className="bg-bg-secondary border border-border rounded-lg overflow-x-auto">
          <table className="w-full text-sm">
            <thead>
              <tr className="border-b border-border">
                <th className="text-left px-4 py-3 text-text-primary font-semibold">Model</th>
                <th className="text-left px-4 py-3 text-text-primary font-semibold">Parameters</th>
                <th className="text-left px-4 py-3 text-text-primary font-semibold">License</th>
                <th className="text-left px-4 py-3 text-text-primary font-semibold">Notable Result</th>
              </tr>
            </thead>
            <tbody className="divide-y divide-border">
              <tr>
                <td className="px-4 py-3 text-accent-primary font-medium">Qwen 3.5 9B</td>
                <td className="px-4 py-3">9B</td>
                <td className="px-4 py-3">Apache 2.0</td>
                <td className="px-4 py-3">Beat GPT-OSS-120B on GPQA</td>
              </tr>
              <tr>
                <td className="px-4 py-3 text-accent-primary font-medium">Gemma 4 12B</td>
                <td className="px-4 py-3">12B</td>
                <td className="px-4 py-3">Apache 2.0</td>
                <td className="px-4 py-3">Runs on mobile devices</td>
              </tr>
              <tr>
                <td className="px-4 py-3 text-accent-primary font-medium">Llama 4 Scout</td>
                <td className="px-4 py-3">17B active (109B total)</td>
                <td className="px-4 py-3">Llama License</td>
                <td className="px-4 py-3">MoE: fast inference at scale</td>
              </tr>
              <tr>
                <td className="px-4 py-3 text-accent-primary font-medium">Bonsai 1-bit</td>
                <td className="px-4 py-3">3B</td>
                <td className="px-4 py-3">MIT</td>
                <td className="px-4 py-3">1-bit weights, phone-ready</td>
              </tr>
              <tr>
                <td className="px-4 py-3 text-accent-primary font-medium">DeepSeek V3</td>
                <td className="px-4 py-3">671B (37B active)</td>
                <td className="px-4 py-3">MIT</td>
                <td className="px-4 py-3">Near-GPT-4 on coding tasks</td>
              </tr>
            </tbody>
          </table>
        </div>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">Models on Your Phone</h2>

        <p>
          The most exciting development isn&apos;t just benchmark scores. It&apos;s where these models can
          run. Google&apos;s Gemma 4 was designed from the ground up for on-device inference. It runs on
          flagship Android phones at conversational speed. Not through a cloud API. Locally, on the
          device, with no internet connection required.
        </p>

        <p>
          Bonsai took this even further with 1-bit quantization. Their 3B parameter model uses binary
          weights (literally ones and zeros), which means inference requires almost no multiplication
          operations. Just additions and subtractions. The result is a model that runs on hardware so
          cheap it barely qualifies as a &quot;device&quot; in the traditional sense.
        </p>

        <p>
          The implications for privacy, latency, and offline capability are massive. If your AI assistant
          runs entirely on your phone, there&apos;s no data leaving the device. No cloud costs. No
          dependency on internet connectivity. For certain applications, this changes everything.
        </p>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">The Licensing Shift</h2>

        <p>
          A year ago, the best open source models came with asterisks. Meta&apos;s Llama had a custom
          license with commercial restrictions. Mistral had various non-standard terms. If you wanted to
          build a commercial product, you needed a lawyer to parse the fine print.
        </p>

        <p>
          That&apos;s changed dramatically. Qwen 3.5, Gemma 4, and DeepSeek V3 all ship under Apache 2.0
          or MIT licenses. No usage restrictions. No revenue thresholds. No requirement to share your
          modifications. You can take these models, fine-tune them for your specific use case, and ship
          them in a commercial product with zero licensing overhead.
        </p>

        <p>
          This matters more than the benchmark scores, in my opinion. A model that&apos;s 5% worse on
          benchmarks but comes with zero legal complexity and zero API costs is the better choice for many
          production applications.
        </p>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">What This Means for Closed-Source Providers</h2>

        <p>
          OpenAI, Anthropic, and Google are not going to stop being relevant. Frontier closed-source models
          still have a meaningful performance edge on the hardest tasks. Claude Opus 4.6 and GPT-5.4 can
          do things that no open source model matches yet, particularly in complex reasoning chains and
          agentic tool use.
        </p>

        <p>
          But the moat is shrinking. Fast. The tasks where closed-source models have a clear advantage are
          getting narrower every quarter. For straightforward text generation, summarization, classification,
          extraction, and basic coding, open source models are already good enough.
        </p>

        <p>
          The closed-source providers know this. That&apos;s why you see the pricing war documented in
          our{' '}
          <Link href="/tools/cost-calculator" className="text-accent-primary hover:underline">cost calculator</Link>.
          They&apos;re racing to make their APIs cheap enough that the hassle of self-hosting open source
          models isn&apos;t worth it. It&apos;s a smart strategy. Convenience and reliability have real
          value. But the price floor keeps dropping as open source performance climbs.
        </p>

        <h2 className="text-2xl font-semibold text-text-primary pt-4">My Take</h2>

        <p>
          We&apos;re entering a world where frontier AI performance is essentially free for many
          applications. Not all of them. Not the hardest problems. But a massive swath of use cases that
          currently depend on expensive API calls will migrate to local or self-hosted open source models
          within the next year.
        </p>

        <p>
          For developers, the practical advice is simple: start experimenting with open source models now.
          Qwen 3.5 9B is a great place to start. It runs on a single RTX 4090, it&apos;s Apache 2.0
          licensed, and its performance will surprise you. Our{' '}
          <Link href="/best-open-source-llms" className="text-accent-primary hover:underline">open source LLM guide</Link> has
          setup instructions and comparisons.
        </p>

        <p>
          For the industry, the message is clear: the era of charging premium prices for capabilities
          that open source models can match is ending. The value of closed-source models will increasingly
          come from reliability, ease of use, and the frontier capabilities that open source hasn&apos;t
          replicated yet. Everything else becomes a commodity.
        </p>

        <p>
          We&apos;re tracking every release on the{' '}
          <Link href="/research" className="text-accent-primary hover:underline">research page</Link>. The
          pace of open source improvement shows no signs of slowing. If anything, it&apos;s accelerating.
        </p>
      </div>

      {/* Footer links */}
      <div className="flex flex-wrap items-center gap-4 mt-12 pt-6 border-t border-border text-sm">
        <Link
          href="/originals"
          className="inline-flex items-center gap-1.5 text-text-muted hover:text-accent-primary transition-colors"
        >
          <ArrowLeft className="w-4 h-4" />
          Back to Originals
        </Link>
        <Link
          href="/"
          className="text-text-muted hover:text-accent-primary transition-colors"
        >
          Back to Feed
        </Link>
      </div>
    </article>
  );
}
