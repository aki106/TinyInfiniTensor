#include "operators/matmul.h"
#include "utils/operator_utils.h"

namespace infini
{

    MatmulObj::MatmulObj(GraphObj *graph, Tensor A, Tensor B, Tensor C, bool transA,
                         bool transB)
        : OperatorObj(OpType::MatMul, TensorVec{A, B}, {C}),
          transA(transA), transB(transB)
    {
        IT_ASSERT(checkValid(graph));
    }

    string MatmulObj::toString() const
    {
        std::ostringstream os;
        os << "Matmul([" << (transA ? "A^T" : "A") << "," << (transB ? "B^T" : "B]")
           << ",A=" << inputs[0]->getGuid()
           << ",B=" << inputs[1]->getGuid() << ",C=" << outputs[0]->getGuid()
           << ",mnk=[" << m << "," << n << "," << k << "])";
        return os.str();
    }

    optional<vector<Shape>> MatmulObj::inferShape(const TensorVec &inputs)
    {
        const auto a = inputs[0]->getDims();
        const auto b = inputs[1]->getDims();
        IT_ASSERT(a.size() >= 2 && b.size() >= 2);

        m = transA ? a.back() : a[a.size() - 2];
        const int aK = transA ? a[a.size() - 2] : a.back();
        const int bK = transB ? b.back() : b[b.size() - 2];
        n = transB ? b[b.size() - 2] : b.back();
        IT_ASSERT(aK == bK);
        k = aK;

        Shape batchA(a.begin(), a.end() - 2);
        Shape batchB(b.begin(), b.end() - 2);
        Shape output = infer_broadcast(batchA, batchB);
        output.emplace_back(m);
        output.emplace_back(n);
        // =================================== 作业 ===================================
        // TODO：返回经过 matmul 操作后的 shape
        // REF: https://github.com/onnx/onnx/blob/main/docs/Operators.md#gemm
        // =================================== 作业 ===================================
        return {{output}};
    }

} // namespace infini
