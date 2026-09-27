#include "matmul.hpp"

#include <algorithm>
#include <random>

Matrix multiplyNaive(const Matrix& A, const Matrix& B) {
    if (A.cols != B.rows) {
        throw std::invalid_argument("Matrix dimensions do not match for multiplication");
    }

    Matrix C(A.rows, B.cols);

    // A is i rows by k columns,
    // B is k rows by j columns
    // C is i rows by j columns

    for (size_t i = 0; i < A.rows; i++) {
        for (size_t j = 0; j < B.cols; j++) {
            double sum = 0;
            for (size_t k = 0; k < A.cols; k++) {
                sum += A.at(i, k) * B.at(k, j);
            }
            C.at(i, j) = sum;
        }
    }

    return C;
}

Matrix multiplyBlocked(const Matrix& A, const Matrix& B, std::size_t blockSize) {
    if (A.cols != B.rows) {
        throw std::invalid_argument("Matrix dimensions do not match for multiplication");
    }

    if (blockSize == 0) {
        throw std::invalid_argument("Block size must be greater than zero");
    }

    Matrix C(A.rows, B.cols);

    size_t numBlocksHorizontal = C.cols / blockSize;
    if (C.cols % blockSize != 0) {
        numBlocksHorizontal += 1;
    }

    size_t numBlocksVertical = C.rows / blockSize;
    if (C.rows % blockSize != 0) {
        numBlocksVertical += 1;
    }

    printf("numBlocks: %zu\n", numBlocksHorizontal);

    for (size_t i = 0; i < numBlocksVertical; i++) {
        for (size_t j = 0; j < numBlocksHorizontal; j++) {
            size_t rowStart = i * blockSize;
            size_t colStart = j * blockSize;
            size_t rowEnd   = std::min(rowStart + blockSize, C.rows);
            size_t colEnd   = std::min(colStart + blockSize, C.cols);

            printf("multiplyBlock: rowStart: %zu, rowEnd: %zu, colStart: %zu, colEnd: %zu\n", rowStart, rowEnd, colStart, colEnd);

            multiplyBlock(A, B, C, rowStart, rowEnd, colStart, colEnd, blockSize);
        }
    }

    return C;
}

// rowStart, rowEnd, colStart, colEnd are inclusive
void multiplyBlock(const Matrix& A, const Matrix& B, Matrix& C,
                   std::size_t rowStart, std::size_t rowEnd,
                   std::size_t colStart, std::size_t colEnd,
                   std::size_t blockSize) {

    size_t numBlocksInner = A.cols / blockSize;
    if (A.cols % blockSize != 0) {
        numBlocksInner += 1;
    }
    
    for (size_t i = rowStart; i < rowEnd; i++) {
        for (size_t j = colStart; j < colEnd; j++) {
            double sum = 0;
            for (size_t b = 0; b < numBlocksInner; b++) {
                for (size_t k = 0; k < blockSize; k++) {
                    size_t AColBRow = b * blockSize + k;
                    if (AColBRow >= A.cols) {
                        // TODO this is bad but slightly less bad to assume 
                        // if statements are rarely taken for branch predictor?
                        break;
                    }
                    sum += A.at(i, AColBRow) * B.at(AColBRow, j);
                }
            }
            C.at(i, j) = sum;
        }
    }
}

Matrix multiplyBlockedParallel(const Matrix& A, const Matrix& B, std::size_t blockSize, Threadpool& pool) {
    // TODO: partition C into disjoint tiles, enqueue one multiplyBlock call per tile, then
    // block here until every tile has finished before returning C.
    Matrix C(A.rows, B.cols);
    return C;
}



Matrix randomMatrix(std::size_t rows, std::size_t cols, unsigned int seed) {
    std::mt19937 gen(seed);
    std::uniform_real_distribution<> dis(-1000.0, 1000.0);

    Matrix m(rows, cols);

    for (size_t i = 0; i < rows * cols; i++) {
        m.data[i] = dis(gen);
    }

    return m;
}

bool matricesEqual(const Matrix& a, const Matrix& b, double tolerance) {
    if (a.rows != b.rows || a.cols != b.cols) {
        return false;
    }

    for (size_t i = 0; i < a.data.size(); i++) {
        if (std::fabs(a.data[i] - b.data[i]) > tolerance) {
            return false;
        }
    }

    return true;
}
