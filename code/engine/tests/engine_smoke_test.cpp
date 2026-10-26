// Engine：端到端 smoke test
// 职责：验证文本输入经过 tokenizer、Runtime 和 decode 后返回完整结果。
// 通过条件：prompt、generated、output 数量和 finished 状态符合断言。
// 验证：code/engine/scripts/run.sh。
#include "cpp_llm_engine/engine.h"

#include <cassert>

namespace {

class FixedTokenizerBackend final : public cpp_llm_engine::TokenizerBackend {
public:
    std::size_t vocab_size() const override { return 64; }
    chapter01::TokenSequence encode(std::string_view) const override { return {7, 8}; }
    std::string decode(const chapter01::TokenSequence&) const override { return "fixed"; }
};

}  // namespace

int main() {
    cpp_llm_engine::ModelConfig config;
    config.max_new_tokens = 3;
    const cpp_llm_engine::Engine engine(config);
    const cpp_llm_engine::GenerationResult result = engine.generate("hello");

    assert(result.prompt_tokens.size() == 5);
    assert(result.generated_tokens.size() == 3);
    assert(result.output.size() == 3);
    assert(result.finished);

    const chapter01::Tokenizer tokenizer(config.vocab_size);
    const cpp_llm_engine::TokenTensor tokens(tokenizer.encode("a!"));
    assert(tokens.size() == 2);
    assert(tokens.values()[0] == 1);
    assert(tokens.values()[1] == 0);

    config.max_new_tokens = 1;
    const cpp_llm_engine::Engine injected_engine(
        config, std::make_unique<FixedTokenizerBackend>());
    const auto injected_result = injected_engine.generate("real prompt");
    assert(injected_result.prompt_tokens == chapter01::TokenSequence({7, 8}));
    assert(injected_result.output == "fixed");
    return 0;
}
