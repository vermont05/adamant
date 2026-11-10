// tests/program/gpu_select_test.cpp - the gpu setting over fake card tables: parsing, the card choice, the roles.
#include "basalt/program/gpu_select.hpp"
#include "basalt/cuda_target.hpp"

#include "basalt/platform/process.hpp"

#include <cstdio>
#include <cstdlib>
#include <string>
#include <utility>

using namespace basalt::program;

static int g_fail = 0;
#define CHECK(c)                                                              \
    do {                                                                      \
        if (!(c)) { std::printf("FAIL %s:%d: %s\n", __FILE__, __LINE__, #c); ++g_fail; } \
    } while (0)
#define CHECK_STR(got, want)                                                                         \
    do {                                                                                             \
        const std::string g_ = (got);                                                                \
        if (g_ != (want)) { std::printf("FAIL %s:%d: got \"%s\" want \"%s\"\n", __FILE__, __LINE__, g_.c_str(), want); ++g_fail; } \
    } while (0)

static constexpr uint64_t G = 1ull << 30;
// the build's own compute capability: the cards the tests treat as supported
static constexpr int MA = basalt::cuda_target::major, MI = basalt::cuda_target::minor;
static const std::string SM = basalt::cuda_target::sm_name();

static GpuCard card(int smi, const char* name, int major, int minor, double gbps, uint64_t gib) {
    GpuCard c;
    c.token = std::to_string(smi);
    c.smi = smi;
    c.name = name;
    c.cc_major = major;
    c.cc_minor = minor;
    c.mem_gbps = gbps;
    c.vram = gib * G;
    return c;
}

static GpuChoice pick(const std::string& text, const std::vector<GpuCard>& v, bool known = true) {
    GpuSpec s;
    std::string err;
    if (!parse_gpu_spec(text, s, err)) {
        GpuChoice c;
        c.error = err;
        return c;
    }
    return choose_gpus(s, v, known);
}

static std::string cards(const GpuChoice& c) {
    std::string s;
    for (int i : c.cards) s += (s.empty() ? "" : ",") + std::to_string(i);
    return s;
}

static std::string roles(const std::vector<GpuCard>& v, const GpuChoice& c, int tiers) {
    RoleInputs in;
    for (int i : c.cards) in.cards.push_back(v[(size_t) i]);
    in.max_expert_tiers = tiers;
    std::string s;
    for (GpuRole r : choose_roles(in)) s += (s.empty() ? "" : ",") + std::string(gpu_role_name(r));
    return s;
}

int main() {
    // Parsing.
    {
        GpuSpec s;
        std::string err;
        CHECK(parse_gpu_spec("", s, err) && s.kind == GpuSpec::Kind::Unset);
        CHECK(parse_gpu_spec("auto", s, err) && s.kind == GpuSpec::Kind::Auto);
        CHECK(parse_gpu_spec(" 1 , 0 ", s, err) && s.kind == GpuSpec::Kind::List && s.list.size() == 2 && s.list[0] == 1);
        CHECK(!parse_gpu_spec("0,0", s, err));
        CHECK_STR(err, "gpu 0,0: GPU 0 is listed twice");
        CHECK(!parse_gpu_spec("x", s, err));
        CHECK(!parse_gpu_spec("0,", s, err));
        CHECK(!parse_gpu_spec("-1", s, err));
    }
    // Exact capability matching is shared with the runtime.
    {
        static_assert(basalt::cuda_target::supports(MA, MI));
        static_assert(basalt::cuda_target::supports(8, 9) != basalt::cuda_target::supports(8, 6));
        static_assert(!basalt::cuda_target::supports(9, 0));
        static_assert(!basalt::cuda_target::supports(12, 0));
        CHECK(gpu_supported(card(0, "unknown", 0, 0, 0, 0)));
        CHECK(!gpu_supported(card(0, "invalid", 0, 9, 0, 0)));
        for (const auto& cc : {std::pair{8, 0}, std::pair{8, 6}, std::pair{8, 9}, std::pair{9, 0},
                               std::pair{12, 0}, std::pair{13, 0}}) {
            if (basalt::cuda_target::supports(cc.first, cc.second)) continue;
            const std::vector<GpuCard> v = {card(0, "unsupported", cc.first, cc.second, 1, 1)};
            CHECK(!pick("", v).error.empty());
            CHECK(!pick("0", v).error.empty());
            CHECK_STR(pick("auto", v).error, ("gpu auto: no " + SM + " GPU visible").c_str());
        }
    }
    // Explicit order, default warnings, role assignment and serialization.
    {
        const std::vector<GpuCard> v = {card(0, "fast", MA, MI, 1008, 24), card(1, "small", MA, MI, 504, 12)};
        GpuChoice c = pick("", v);
        CHECK_STR(cards(c), "0");
        CHECK_STR(c.warning, "GPU 1 (small) unused; use gpu 0,1 or gpu auto");
        c = pick("0,1", v);
        CHECK_STR(cards(c), "0,1");
        CHECK(c.warning.empty() && c.error.empty());
        CHECK_STR(roles(v, c, 1), "main,expert tier");
        CHECK_STR(cards(pick("1,0", v)), "1,0");
        CHECK_STR(cards(pick("1", v)), "1");
        CHECK(pick("1", v).warning.empty());
        CHECK_STR(cards(pick("auto", v)), "0,1");
        CHECK_STR(pick("2", v).error, "gpu 2: 2 GPUs are visible (0-1)");
        CHECK_STR(pick("0,0", v).error, "gpu 0,0: GPU 0 is listed twice");
        CHECK_STR(gpu_plan_json(v, pick("1,0", v)),
                  "{\"devices\":\"1,0\",\"cards\":[{\"visible\":1,\"token\":\"1\",\"smi\":1,\"name\":\"small\"},"
                  "{\"visible\":0,\"token\":\"0\",\"smi\":0,\"name\":\"fast\"}],\"notes\":[],\"warning\":\"\",\"error\":\"\"}");
    }
    // Bandwidth precedes memory size; ties keep the lowest visible number.
    {
        const std::vector<GpuCard> v = {card(0, "small", MA, MI, 504, 12), card(1, "fast", MA, MI, 1008, 24)};
        CHECK_STR(cards(pick("auto", v)), "1,0");
        CHECK_STR(cards(pick("", v)), "0");
        const std::vector<GpuCard> w = {card(0, "small", MA, MI, 504, 12), card(1, "large", MA, MI, 504, 24)};
        CHECK_STR(cards(pick("auto", w)), "1,0");
        const std::vector<GpuCard> eq = {card(0, "equal", MA, MI, 1008, 24), card(1, "equal", MA, MI, 1008, 24)};
        CHECK_STR(cards(pick("auto", eq)), "0,1");
        CHECK(pick("auto", eq).notes.empty());
        CHECK_STR(roles(eq, pick("auto", eq), 1), "main,expert tier");
    }
    // Automatic selection excludes unsupported devices, including newer ones.
    {
        const std::vector<GpuCard> v = {card(0, "middle", MA, MI, 672, 16), card(1, "other", 12, 0, 1792, 32),
                                       card(2, "fast", MA, MI, 1008, 24), card(3, "small", MA, MI, 504, 12)};
        GpuChoice c = pick("auto", v);
        CHECK_STR(cards(c), "2,0,3");
        CHECK(c.notes.size() == 1);
        if (c.notes.size() == 1) CHECK_STR(c.notes[0], ("gpu auto: GPU 1 (other) skipped, not " + SM).c_str());
        CHECK_STR(roles(v, c, 1), "main,expert tier,idle");
        CHECK_STR(roles(v, c, 3), "main,expert tier,expert tier");
        c = pick("", v);
        CHECK_STR(cards(c), "0");
        CHECK_STR(c.warning, "GPU 2 (fast), GPU 3 (small) unused; use gpu 0,2,3 or gpu auto");
        CHECK_STR(pick("1", v).error, ("gpu: GPU 1 (other) is sm_120, not " + SM).c_str());
        CHECK_STR(cards(pick("3,2,0", v)), "3,2,0");
        const std::vector<GpuCard> first = {v[1], v[2]};
        CHECK(!pick("", first).error.empty());
        CHECK_STR(cards(pick("auto", first)), "1");
        CHECK(pick("auto", first).notes.size() == 1);
    }
    // No card list (no management library, no CUDA_VISIBLE_DEVICES): numbers pass, auto cannot run.
    {
        const std::vector<GpuCard> none;
        CHECK_STR(cards(pick("", none, false)), "0");
        CHECK(pick("", none, false).warning.empty());
        CHECK_STR(cards(pick("3,1", none, false)), "3,1");
        CHECK(!pick("auto", none, false).error.empty());
        CHECK_STR(pick("", none, true).error, "gpu: no GPU is visible");
    }
    // Under CUDA_VISIBLE_DEVICES the numbers count within its list, and the narrowed list keeps its tokens.
    {
        basalt::platform::set_env("CUDA_VISIBLE_DEVICES", "1,0");
        bool known = false;
        const std::vector<GpuCard> v = visible_gpus(known);
        CHECK(known && v.size() == 2);
        if (v.size() == 2) {
            CHECK_STR(v[0].token, "1");
            CHECK_STR(v[1].token, "0");
            apply_gpus(v, pick("1", v).cards);
            const char* now = std::getenv("CUDA_VISIBLE_DEVICES");
            CHECK_STR(now ? now : "", "0");
            const char* order = std::getenv("CUDA_DEVICE_ORDER");
            CHECK_STR(order ? order : "", "PCI_BUS_ID");
        }
        basalt::platform::set_env("CUDA_VISIBLE_DEVICES", "-1");
        CHECK(visible_gpus(known).empty() && known);
    }
    CHECK_STR(gpu_identity(3), "0,1,2");
    // Expert placement over several tiers: equal cards alternate; bandwidth sets the share of the hot experts; a
    // smaller card closes first and the others take the rest; a single tier takes the ranking in order.
    {
        const std::vector<uint64_t> eq(8, 10);
        auto owners = [](const std::vector<int>& o) {
            std::string s;
            for (int x : o) s += x < 0 ? std::string("-") : std::to_string(x);
            return s;
        };
        CHECK_STR(owners(spread_experts(eq, {{40, 448}, {40, 448}})), "01010101");
        CHECK_STR(owners(spread_experts(eq, {{80, 1792}, {80, 896}})), "01001001");
        CHECK_STR(owners(spread_experts(eq, {{20, 1792}, {100, 448}})), "01011111");
        CHECK_STR(owners(spread_experts(eq, {{30, 448}})), "000-----");
        CHECK_STR(owners(spread_experts(eq, {{0, 448}, {30, 448}})), "111-----");
        // three and four tiers of mixed sizes and bandwidths: every expert placed while room lasts, none twice
        const std::vector<uint64_t> mixed = {12, 12, 12, 8, 8, 8, 8, 8, 8, 8, 8, 8};
        const std::vector<int> o3 = spread_experts(mixed, {{30, 1792}, {20, 896}, {60, 448}});
        CHECK_STR(owners(o3), "012001222222");
        const std::vector<int> o4 = spread_experts(mixed, {{16, 448}, {16, 448}, {16, 448}, {200, 1792}});
        CHECK_STR(owners(o4), "012333333333");
        CHECK_STR(owners(spread_experts(eq, {{0, 1}, {0, 1}, {0, 1}})), "--------");
    }
    if (g_fail) { std::printf("gpu_select_test: %d failures\n", g_fail); return 1; }
    std::printf("gpu_select_test: ok\n");
    return 0;
}
